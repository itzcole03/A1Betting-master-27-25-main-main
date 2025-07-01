#!/usr/bin/env python3
"""
ML Performance Benchmarking Script for A1Betting Platform

This script benchmarks ML model performance across various metrics
including speed, memory usage, accuracy, and scalability.
"""

import os
import sys
import json
import time
import psutil
import logging
import numpy as np
import pandas as pd
from datetime import datetime
from pathlib import Path
import argparse
import gc
import threading
from typing import Dict, List, Any, Tuple, Optional
import warnings
warnings.filterwarnings('ignore')

# Setup logging
logging.basicConfig(
    level=logging.INFO,
    format='%(asctime)s - %(levelname)s - %(message)s'
)
logger = logging.getLogger(__name__)

class MLPerformanceBenchmarker:
    """Comprehensive ML model performance benchmarking system."""
    
    def __init__(self, reports_dir: str = "automation/reports"):
        self.reports_dir = Path(reports_dir)
        self.reports_dir.mkdir(parents=True, exist_ok=True)
        self.benchmark_results = {}
        self.process = psutil.Process()
        
    def load_model_safely(self, model_path: str) -> Any:
        """Safely load a model with error handling."""
        try:
            import joblib
            
            if model_path.endswith('.joblib'):
                return joblib.load(model_path)
            elif model_path.endswith(('.pkl', '.pickle')):
                logger.error(
                    f"Refusing to load model '{model_path}' from a pickle file due to security risks. "
                    f"Please re-save this model using a secure format like joblib."
                )
                return None
            else:
                logger.error(f"Unsupported model format: {model_path}")
                return None
        except Exception as e:
            logger.error(f"Error loading model {model_path}: {e}")
            return None
    
    def generate_synthetic_data(self, n_samples: int = 1000, n_features: int = 10) -> Tuple[np.ndarray, np.ndarray]:
        """Generate synthetic data for benchmarking."""
        np.random.seed(42)
        X = np.random.randn(n_samples, n_features)
        y = np.random.choice([0, 1], n_samples)
        return X, y
    
    def monitor_memory_usage(self, func, *args, **kwargs) -> Tuple[Any, Dict[str, float]]:
        """Monitor memory usage during function execution."""
        initial_memory = self.process.memory_info().rss / 1024 / 1024  # MB
        gc.collect()  # Force garbage collection
        
        start_time = time.time()
        result = func(*args, **kwargs)
        end_time = time.time()
        
        final_memory = self.process.memory_info().rss / 1024 / 1024  # MB
        peak_memory = max(initial_memory, final_memory)
        
        memory_stats = {
            "initial_memory_mb": initial_memory,
            "final_memory_mb": final_memory,
            "peak_memory_mb": peak_memory,
            "memory_increase_mb": final_memory - initial_memory,
            "execution_time_s": end_time - start_time
        }
        
        return result, memory_stats
    
    def benchmark_inference_speed(self, model: Any, X_test: np.ndarray, 
                                 iterations: int = 100) -> Dict[str, Any]:
        """Benchmark model inference speed."""
        try:
            logger.info(f"Benchmarking inference speed with {iterations} iterations...")
            
            # Warm-up runs
            for _ in range(5):
                _ = model.predict(X_test[:10])
            
            # Benchmark single prediction
            single_sample = X_test[:1]
            single_times = []
            
            for _ in range(iterations):
                start = time.perf_counter()
                _ = model.predict(single_sample)
                end = time.perf_counter()
                single_times.append(end - start)
            
            # Benchmark batch predictions
            batch_sizes = [1, 10, 100, min(1000, len(X_test))]
            batch_results = {}
            
            for batch_size in batch_sizes:
                if batch_size <= len(X_test):
                    batch_data = X_test[:batch_size]
                    batch_times = []
                    
                    for _ in range(min(50, iterations)):
                        start = time.perf_counter()
                        _ = model.predict(batch_data)
                        end = time.perf_counter()
                        batch_times.append(end - start)
                    
                    batch_results[f"batch_{batch_size}"] = {
                        "avg_time_s": np.mean(batch_times),
                        "std_time_s": np.std(batch_times),
                        "min_time_s": np.min(batch_times),
                        "max_time_s": np.max(batch_times),
                        "throughput_samples_per_sec": batch_size / np.mean(batch_times)
                    }
            
            speed_results = {
                "status": "success",
                "single_prediction": {
                    "avg_time_s": np.mean(single_times),
                    "std_time_s": np.std(single_times),
                    "min_time_s": np.min(single_times),
                    "max_time_s": np.max(single_times),
                    "predictions_per_sec": 1 / np.mean(single_times)
                },
                "batch_predictions": batch_results,
                "total_iterations": iterations
            }
            
            return speed_results
            
        except Exception as e:
            logger.error(f"Error benchmarking inference speed: {e}")
            return {"status": "error", "message": str(e)}
    
    def benchmark_memory_usage(self, model: Any, X_test: np.ndarray) -> Dict[str, Any]:
        """Benchmark model memory usage."""
        try:
            logger.info("Benchmarking memory usage...")
            
            memory_results = {
                "status": "success",
                "baseline_memory": {},
                "prediction_memory": {},
                "scaling_memory": {}
            }
            
            # Baseline memory
            gc.collect()
            baseline_memory = self.process.memory_info().rss / 1024 / 1024
            memory_results["baseline_memory"]["initial_mb"] = baseline_memory
            
            # Memory during prediction
            def make_prediction():
                return model.predict(X_test)
            
            predictions, memory_stats = self.monitor_memory_usage(make_prediction)
            memory_results["prediction_memory"] = memory_stats
            
            # Memory scaling with data size
            scaling_tests = [100, 500, 1000] if len(X_test) >= 1000 else [10, 50, 100]
            
            for size in scaling_tests:
                if size <= len(X_test):
                    test_data = X_test[:size]
                    
                    def predict_subset():
                        return model.predict(test_data)
                    
                    _, mem_stats = self.monitor_memory_usage(predict_subset)
                    memory_results["scaling_memory"][f"size_{size}"] = mem_stats
            
            return memory_results
            
        except Exception as e:
            logger.error(f"Error benchmarking memory usage: {e}")
            return {"status": "error", "message": str(e)}
    
    def benchmark_model_accuracy(self, model: Any, X_test: np.ndarray, 
                                y_test: np.ndarray) -> Dict[str, Any]:
        """Benchmark model accuracy with various metrics."""
        try:
            logger.info("Benchmarking model accuracy...")
            
            # Make predictions
            y_pred = model.predict(X_test)
            
            # Get probabilities if available
            y_proba = None
            if hasattr(model, 'predict_proba'):
                try:
                    y_proba = model.predict_proba(X_test)
                except:
                    pass
            
            # Determine if classification or regression
            unique_targets = len(np.unique(y_test))
            is_classification = unique_targets <= 20 and all(isinstance(val, (int, np.integer)) or val in [0, 1] for val in np.unique(y_test))
            
            accuracy_results = {
                "status": "success",
                "model_type": "classification" if is_classification else "regression",
                "test_samples": len(y_test),
                "metrics": {}
            }
            
            if is_classification:
                # Classification metrics
                accuracy = np.mean(y_test == y_pred)
                accuracy_results["metrics"]["accuracy"] = float(accuracy)
                
                # Try to compute advanced metrics if scikit-learn is available
                try:
                    from sklearn.metrics import precision_score, recall_score, f1_score, confusion_matrix
                    
                    accuracy_results["metrics"]["precision"] = float(precision_score(y_test, y_pred, average='weighted', zero_division=0))
                    accuracy_results["metrics"]["recall"] = float(recall_score(y_test, y_pred, average='weighted', zero_division=0))
                    accuracy_results["metrics"]["f1_score"] = float(f1_score(y_test, y_pred, average='weighted', zero_division=0))
                    
                    cm = confusion_matrix(y_test, y_pred)
                    accuracy_results["metrics"]["confusion_matrix"] = cm.tolist()
                    
                    if y_proba is not None:
                        from sklearn.metrics import roc_auc_score, log_loss
                        try:
                            if unique_targets == 2:
                                accuracy_results["metrics"]["roc_auc"] = float(roc_auc_score(y_test, y_proba[:, 1]))
                            else:
                                accuracy_results["metrics"]["roc_auc"] = float(roc_auc_score(y_test, y_proba, multi_class='ovr'))
                            accuracy_results["metrics"]["log_loss"] = float(log_loss(y_test, y_proba))
                        except Exception as e:
                            logger.warning(f"Could not compute advanced metrics: {e}")
                
                except ImportError:
                    logger.warning("scikit-learn not available for advanced metrics")
            
            else:
                # Regression metrics
                mse = np.mean((y_test - y_pred) ** 2)
                mae = np.mean(np.abs(y_test - y_pred))
                
                accuracy_results["metrics"]["mse"] = float(mse)
                accuracy_results["metrics"]["rmse"] = float(np.sqrt(mse))
                accuracy_results["metrics"]["mae"] = float(mae)
                
                # R² score
                ss_res = np.sum((y_test - y_pred) ** 2)
                ss_tot = np.sum((y_test - np.mean(y_test)) ** 2)
                r2 = 1 - (ss_res / ss_tot) if ss_tot != 0 else 0
                accuracy_results["metrics"]["r2_score"] = float(r2)
                
                # MAPE
                mape = np.mean(np.abs((y_test - y_pred) / (y_test + 1e-8))) * 100
                accuracy_results["metrics"]["mape"] = float(mape)
            
            return accuracy_results
            
        except Exception as e:
            logger.error(f"Error benchmarking model accuracy: {e}")
            return {"status": "error", "message": str(e)}
    
    def benchmark_scalability(self, model: Any, base_data: np.ndarray) -> Dict[str, Any]:
        """Benchmark model scalability with increasing data sizes."""
        try:
            logger.info("Benchmarking model scalability...")
            
            scalability_results = {
                "status": "success",
                "data_size_tests": {},
                "complexity_analysis": {}
            }
            
            # Test different data sizes
            base_size = len(base_data)
            test_sizes = [
                min(100, base_size),
                min(500, base_size),
                min(1000, base_size),
                min(5000, base_size),
                base_size
            ]
            
            times = []
            sizes = []
            
            for size in test_sizes:
                if size <= base_size:
                    test_data = base_data[:size]
                    
                    # Time multiple predictions
                    prediction_times = []
                    for _ in range(10):
                        start = time.perf_counter()
                        _ = model.predict(test_data)
                        end = time.perf_counter()
                        prediction_times.append(end - start)
                    
                    avg_time = np.mean(prediction_times)
                    times.append(avg_time)
                    sizes.append(size)
                    
                    scalability_results["data_size_tests"][f"size_{size}"] = {
                        "avg_time_s": avg_time,
                        "std_time_s": np.std(prediction_times),
                        "throughput_samples_per_sec": size / avg_time,
                        "time_per_sample_ms": (avg_time / size) * 1000
                    }
            
            # Analyze complexity (linear, quadratic, etc.)
            if len(times) >= 3:
                # Linear regression to estimate complexity
                log_sizes = np.log(sizes)
                log_times = np.log(times)
                
                # Simple linear regression
                n = len(log_sizes)
                sum_x = np.sum(log_sizes)
                sum_y = np.sum(log_times)
                sum_xy = np.sum(log_sizes * log_times)
                sum_x2 = np.sum(log_sizes ** 2)
                
                slope = (n * sum_xy - sum_x * sum_y) / (n * sum_x2 - sum_x ** 2)
                
                complexity_analysis = {
                    "estimated_complexity_exponent": float(slope),
                    "interpretation": self._interpret_complexity(slope),
                    "scaling_efficiency": "good" if slope < 1.2 else "moderate" if slope < 2.0 else "poor"
                }
                
                scalability_results["complexity_analysis"] = complexity_analysis
            
            return scalability_results
            
        except Exception as e:
            logger.error(f"Error benchmarking scalability: {e}")
            return {"status": "error", "message": str(e)}
    
    def _interpret_complexity(self, slope: float) -> str:
        """Interpret complexity exponent."""
        if slope < 0.5:
            return "Sub-linear (very efficient)"
        elif slope < 1.2:
            return "Linear (efficient)"
        elif slope < 1.8:
            return "Slightly super-linear"
        elif slope < 2.5:
            return "Quadratic (inefficient for large data)"
        else:
            return "Polynomial/Exponential (very inefficient)"
    
    def benchmark_robustness(self, model: Any, X_test: np.ndarray) -> Dict[str, Any]:
        """Benchmark model robustness to noise and perturbations."""
        try:
            logger.info("Benchmarking model robustness...")
            
            robustness_results = {
                "status": "success",
                "noise_sensitivity": {},
                "perturbation_analysis": {},
                "stability_metrics": {}
            }
            
            # Original predictions
            original_pred = model.predict(X_test[:100])  # Use subset for speed
            
            # Test with different noise levels
            noise_levels = [0.01, 0.05, 0.1, 0.2]
            
            for noise_level in noise_levels:
                noisy_data = X_test[:100] + np.random.normal(0, noise_level, X_test[:100].shape)
                noisy_pred = model.predict(noisy_data)
                
                # Calculate difference metrics
                pred_diff = np.abs(original_pred - noisy_pred)
                
                robustness_results["noise_sensitivity"][f"noise_{noise_level}"] = {
                    "avg_prediction_change": float(np.mean(pred_diff)),
                    "max_prediction_change": float(np.max(pred_diff)),
                    "std_prediction_change": float(np.std(pred_diff)),
                    "stability_score": float(1 - (np.mean(pred_diff) / (np.mean(np.abs(original_pred)) + 1e-8)))
                }
            
            # Feature perturbation analysis
            n_features = X_test.shape[1]
            feature_sensitivity = {}
            
            for i in range(min(5, n_features)):  # Test first 5 features
                perturbed_data = X_test[:50].copy()
                perturbed_data[:, i] += np.random.normal(0, 0.1, perturbed_data[:, i].shape)
                
                perturbed_pred = model.predict(perturbed_data)
                original_subset = model.predict(X_test[:50])
                
                feature_impact = np.mean(np.abs(perturbed_pred - original_subset))
                feature_sensitivity[f"feature_{i}"] = float(feature_impact)
            
            robustness_results["perturbation_analysis"]["feature_sensitivity"] = feature_sensitivity
            
            # Overall stability metrics
            all_stability_scores = [
                metrics["stability_score"] 
                for metrics in robustness_results["noise_sensitivity"].values()
            ]
            
            robustness_results["stability_metrics"] = {
                "average_stability": float(np.mean(all_stability_scores)),
                "min_stability": float(np.min(all_stability_scores)),
                "robustness_rating": "high" if np.mean(all_stability_scores) > 0.8 else "medium" if np.mean(all_stability_scores) > 0.6 else "low"
            }
            
            return robustness_results
            
        except Exception as e:
            logger.error(f"Error benchmarking robustness: {e}")
            return {"status": "error", "message": str(e)}
    
    def run_comprehensive_benchmark(self, models_dir: str = "models", 
                                  test_data_path: str = None) -> Dict[str, Any]:
        """Run comprehensive ML performance benchmarking."""
        logger.info("Starting comprehensive ML performance benchmarking...")
        
        benchmark_summary = {
            "timestamp": datetime.now().isoformat(),
            "status": "success",
            "models_benchmarked": 0,
            "benchmark_results": {},
            "performance_summary": {},
            "recommendations": []
        }
        
        try:
            # Find model files
            model_files = []
            if os.path.exists(models_dir):
                for root, dirs, files in os.walk(models_dir):
                    for file in files:
                        if file.endswith(('.pkl', '.pickle', '.joblib')):
                            model_files.append(os.path.join(root, file))
            
            # Generate test data if needed
            if test_data_path and os.path.exists(test_data_path):
                # Load test data
                try:
                    if test_data_path.endswith('.csv'):
                        df = pd.read_csv(test_data_path)
                        X_test = df.iloc[:, :-1].values
                        y_test = df.iloc[:, -1].values
                    else:
                        X_test, y_test = self.generate_synthetic_data(1000, 10)
                except:
                    X_test, y_test = self.generate_synthetic_data(1000, 10)
            else:
                X_test, y_test = self.generate_synthetic_data(1000, 10)
            
            # If no models found, create mock benchmark
            if not model_files:
                logger.warning("No models found. Creating mock benchmark results...")
                benchmark_summary["benchmark_results"]["mock_model"] = self._create_mock_benchmark()
                benchmark_summary["models_benchmarked"] = 1
            else:
                # Benchmark each model
                for model_file in model_files:
                    logger.info(f"Benchmarking model: {model_file}")
                    
                    model = self.load_model_safely(model_file)
                    if model is None:
                        continue
                    
                    try:
                        model_benchmarks = {}
                        
                        # Speed benchmark
                        model_benchmarks["speed"] = self.benchmark_inference_speed(model, X_test)
                        
                        # Memory benchmark
                        model_benchmarks["memory"] = self.benchmark_memory_usage(model, X_test)
                        
                        # Accuracy benchmark
                        model_benchmarks["accuracy"] = self.benchmark_model_accuracy(model, X_test, y_test)
                        
                        # Scalability benchmark
                        model_benchmarks["scalability"] = self.benchmark_scalability(model, X_test)
                        
                        # Robustness benchmark
                        model_benchmarks["robustness"] = self.benchmark_robustness(model, X_test)
                        
                        # Calculate overall score
                        model_benchmarks["overall_score"] = self._calculate_benchmark_score(model_benchmarks)
                        
                        benchmark_summary["benchmark_results"][os.path.basename(model_file)] = model_benchmarks
                        benchmark_summary["models_benchmarked"] += 1
                        
                    except Exception as e:
                        logger.error(f"Error benchmarking model {model_file}: {e}")
                        benchmark_summary["benchmark_results"][os.path.basename(model_file)] = {
                            "status": "error",
                            "error": str(e)
                        }
            
            # Calculate performance summary
            benchmark_summary["performance_summary"] = self._calculate_performance_summary(benchmark_summary)
            
            # Generate recommendations
            benchmark_summary["recommendations"] = self._generate_benchmark_recommendations(benchmark_summary)
            
            # Save detailed report
            report_file = self.reports_dir / f"ml_performance_benchmark_{datetime.now().strftime('%Y%m%d_%H%M%S')}.json"
            with open(report_file, 'w') as f:
                json.dump(benchmark_summary, f, indent=2, default=str)
            
            logger.info(f"ML performance benchmarking completed. Report saved to: {report_file}")
            return benchmark_summary
            
        except Exception as e:
            logger.error(f"Error during ML performance benchmarking: {e}")
            benchmark_summary["status"] = "error"
            benchmark_summary["error"] = str(e)
            return benchmark_summary
    
    def _create_mock_benchmark(self) -> Dict[str, Any]:
        """Create mock benchmark results."""
        return {
            "speed": {
                "status": "success",
                "single_prediction": {"avg_time_s": 0.001, "predictions_per_sec": 1000},
                "batch_predictions": {"batch_100": {"throughput_samples_per_sec": 5000}}
            },
            "memory": {
                "status": "success",
                "prediction_memory": {"memory_increase_mb": 10}
            },
            "accuracy": {
                "status": "success",
                "metrics": {"accuracy": 0.85}
            },
            "scalability": {
                "status": "success",
                "complexity_analysis": {"scaling_efficiency": "good"}
            },
            "robustness": {
                "status": "success",
                "stability_metrics": {"robustness_rating": "high"}
            },
            "overall_score": 85
        }
    
    def _calculate_benchmark_score(self, benchmarks: Dict[str, Any]) -> float:
        """Calculate overall benchmark score."""
        score = 0
        components = 0
        
        # Speed score (inverse of time, normalized)
        if benchmarks.get("speed", {}).get("status") == "success":
            speed_data = benchmarks["speed"]["single_prediction"]
            predictions_per_sec = speed_data.get("predictions_per_sec", 1)
            speed_score = min(100, (predictions_per_sec / 1000) * 100)  # 1000 predictions/sec = 100 points
            score += speed_score
            components += 1
        
        # Memory efficiency score
        if benchmarks.get("memory", {}).get("status") == "success":
            memory_increase = benchmarks["memory"]["prediction_memory"].get("memory_increase_mb", 100)
            memory_score = max(0, 100 - memory_increase)  # Lower memory = higher score
            score += memory_score
            components += 1
        
        # Accuracy score
        if benchmarks.get("accuracy", {}).get("status") == "success":
            accuracy = benchmarks["accuracy"]["metrics"].get("accuracy", 0)
            accuracy_score = accuracy * 100
            score += accuracy_score
            components += 1
        
        # Robustness score
        if benchmarks.get("robustness", {}).get("status") == "success":
            stability = benchmarks["robustness"]["stability_metrics"].get("average_stability", 0)
            robustness_score = stability * 100
            score += robustness_score
            components += 1
        
        return score / components if components > 0 else 0
    
    def _calculate_performance_summary(self, benchmark_summary: Dict[str, Any]) -> Dict[str, Any]:
        """Calculate overall performance summary."""
        summary = {
            "total_models": benchmark_summary["models_benchmarked"],
            "average_score": 0,
            "best_model": None,
            "performance_distribution": {}
        }
        
        if benchmark_summary["models_benchmarked"] == 0:
            return summary
        
        scores = []
        best_score = 0
        best_model = None
        
        for model_name, results in benchmark_summary["benchmark_results"].items():
            if isinstance(results, dict) and "overall_score" in results:
                score = results["overall_score"]
                scores.append(score)
                
                if score > best_score:
                    best_score = score
                    best_model = model_name
        
        if scores:
            summary["average_score"] = sum(scores) / len(scores)
            summary["best_model"] = best_model
            summary["best_score"] = best_score
            
            # Performance distribution
            excellent = sum(1 for s in scores if s >= 80)
            good = sum(1 for s in scores if 60 <= s < 80)
            moderate = sum(1 for s in scores if 40 <= s < 60)
            poor = sum(1 for s in scores if s < 40)
            
            summary["performance_distribution"] = {
                "excellent": excellent,
                "good": good,
                "moderate": moderate,
                "poor": poor
            }
        
        return summary
    
    def _generate_benchmark_recommendations(self, benchmark_summary: Dict[str, Any]) -> List[str]:
        """Generate recommendations based on benchmark results."""
        recommendations = []
        
        perf_summary = benchmark_summary["performance_summary"]
        
        if perf_summary["average_score"] < 50:
            recommendations.append("Overall model performance is below expectations. Consider model optimization.")
        
        if perf_summary["performance_distribution"]["poor"] > 0:
            recommendations.append(f"{perf_summary['performance_distribution']['poor']} models have poor performance. Review and retrain.")
        
        # Analyze specific issues
        speed_issues = 0
        memory_issues = 0
        accuracy_issues = 0
        
        for model_name, results in benchmark_summary["benchmark_results"].items():
            if isinstance(results, dict):
                # Check speed issues
                speed_data = results.get("speed", {})
                if speed_data.get("status") == "success":
                    pps = speed_data.get("single_prediction", {}).get("predictions_per_sec", 1000)
                    if pps < 100:
                        speed_issues += 1
                
                # Check memory issues
                memory_data = results.get("memory", {})
                if memory_data.get("status") == "success":
                    mem_increase = memory_data.get("prediction_memory", {}).get("memory_increase_mb", 0)
                    if mem_increase > 50:
                        memory_issues += 1
                
                # Check accuracy issues
                accuracy_data = results.get("accuracy", {})
                if accuracy_data.get("status") == "success":
                    acc = accuracy_data.get("metrics", {}).get("accuracy", 1)
                    if acc < 0.7:
                        accuracy_issues += 1
        
        if speed_issues > 0:
            recommendations.append(f"{speed_issues} models have slow inference speed. Consider model optimization.")
        
        if memory_issues > 0:
            recommendations.append(f"{memory_issues} models have high memory usage. Consider model compression.")
        
        if accuracy_issues > 0:
            recommendations.append(f"{accuracy_issues} models have low accuracy. Consider retraining with more data.")
        
        if not recommendations:
            recommendations.append("All models show good performance across benchmarks.")
        
        return recommendations

def main():
    """Main execution function."""
    parser = argparse.ArgumentParser(description="ML Performance Benchmarking for A1Betting")
    parser.add_argument("--models-dir", default="models", help="Directory containing model files")
    parser.add_argument("--test-data", help="Path to test data file")
    parser.add_argument("--reports-dir", default="automation/reports", help="Directory for reports")
    parser.add_argument("--verbose", action="store_true", help="Enable verbose logging")
    
    args = parser.parse_args()
    
    if args.verbose:
        logging.getLogger().setLevel(logging.DEBUG)
    
    # Create benchmarker
    benchmarker = MLPerformanceBenchmarker(reports_dir=args.reports_dir)
    
    # Run benchmarking
    results = benchmarker.run_comprehensive_benchmark(
        models_dir=args.models_dir, 
        test_data_path=args.test_data
    )
    
    # Print summary
    print("\n" + "="*50)
    print("ML PERFORMANCE BENCHMARK SUMMARY")
    print("="*50)
    print(f"Status: {results['status']}")
    print(f"Models Benchmarked: {results['models_benchmarked']}")
    
    if results.get('performance_summary'):
        perf = results['performance_summary']
        print(f"Average Score: {perf.get('average_score', 0):.1f}/100")
        if perf.get('best_model'):
            print(f"Best Model: {perf['best_model']} (Score: {perf.get('best_score', 0):.1f})")
    
    if results.get('recommendations'):
        print("\nRecommendations:")
        for i, rec in enumerate(results['recommendations'], 1):
            print(f"  {i}. {rec}")
    
    # Exit with appropriate code
    if results['status'] == 'error':
        sys.exit(1)
    elif results.get('performance_summary', {}).get('average_score', 100) < 60:
        print("\nWarning: Average performance below recommended threshold")
        sys.exit(1)
    else:
        print("\nML performance benchmarking completed successfully!")
        sys.exit(0)

if __name__ == "__main__":
    main()
