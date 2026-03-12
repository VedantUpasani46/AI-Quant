"""
Production Deployment & MLOps Pipeline
=======================================
Target: Deploy Models Safely | CI/CD |

This module implements production deployment pipelines for ML models
with continuous integration, testing, and monitoring.

Why MLOps Matters:
  - SAFETY: Test before deploying (don't break production)
  - SPEED: Deploy updates in hours, not weeks
  - ROLLBACK: Instant rollback if model fails
  - VERSIONING: Track which model is running when
  - AUTOMATION: Deploy 10x per day, not 10x per year

Target: Deploy models safely with <1 hour downtime

Deployment Patterns:
--------------------
Blue-Green Deployment:
  Two environments: Blue (current) and Green (new)
  Deploy to Green → Test → Switch traffic → Keep Blue as backup

Canary Deployment:
  Deploy to 5% of traffic → Monitor → Gradually increase to 100%
  
  If success rate drops → Auto-rollback

A/B Testing:
  Run old model (A) and new model (B) in parallel
  Compare performance → Choose winner

References:
  - Sculley et al. (2015). Hidden Technical Debt in ML Systems. NIPS.
  - Breck et al. (2017). The ML Test Score. Google.
  - Baylor et al. (2017). TFX: A TensorFlow-Based Production-Scale ML Platform. KDD.
"""

import numpy as np
import pandas as pd
import json
import hashlib
from typing import Dict, List, Optional
from dataclasses import dataclass
import warnings
warnings.filterwarnings('ignore')


# ---------------------------------------------------------------------------
# Model Registry (Version Control for Models)
# ---------------------------------------------------------------------------

@dataclass
class ModelMetadata:
    """Metadata for a deployed model."""
    model_id: str
    version: str
    created_at: str
    metrics: Dict
    git_commit: str
    status: str  # 'training', 'staging', 'production', 'retired'


class ModelRegistry:
    """
    Registry to track all model versions.
    
    In production: Use MLflow, Weights & Biases, or Neptune.
    """
    
    def __init__(self):
        self.models = {}
    
    def register_model(self,
                      model_id: str,
                      version: str,
                      metrics: Dict,
                      git_commit: str = 'unknown'):
        """
        Register a new model version.
        
        Args:
            model_id: Model identifier (e.g., 'momentum_v1')
            version: Version string (e.g., '2024-01-15-001')
            metrics: Backtest metrics (Sharpe, IC, etc.)
            git_commit: Git commit hash
        """
        metadata = ModelMetadata(
            model_id=model_id,
            version=version,
            created_at=pd.Timestamp.now().isoformat(),
            metrics=metrics,
            git_commit=git_commit,
            status='training'
        )
        
        key = f"{model_id}:{version}"
        self.models[key] = metadata
        
        print(f"  Registered model: {key}")
        print(f"    Sharpe: {metrics.get('sharpe', 'N/A')}")
        print(f"    IC: {metrics.get('ic', 'N/A')}")
    
    def promote_to_staging(self, model_id: str, version: str):
        """Promote model to staging environment."""
        key = f"{model_id}:{version}"
        if key in self.models:
            self.models[key].status = 'staging'
            print(f"  Promoted {key} to STAGING")
    
    def promote_to_production(self, model_id: str, version: str):
        """Promote model to production."""
        key = f"{model_id}:{version}"
        if key in self.models:
            # Demote current production model
            for k, v in self.models.items():
                if v.model_id == model_id and v.status == 'production':
                    v.status = 'retired'
            
            self.models[key].status = 'production'
            print(f"  Promoted {key} to PRODUCTION")
    
    def get_production_model(self, model_id: str) -> Optional[ModelMetadata]:
        """Get current production model."""
        for metadata in self.models.values():
            if metadata.model_id == model_id and metadata.status == 'production':
                return metadata
        return None


# ---------------------------------------------------------------------------
# Deployment Validator
# ---------------------------------------------------------------------------

class DeploymentValidator:
    """
    Validate model before deployment.
    
    Runs suite of tests to ensure model is production-ready.
    """
    
    def __init__(self):
        self.validation_results = {}
    
    def validate_performance(self, metrics: Dict, thresholds: Dict) -> bool:
        """
        Validate model performance metrics.
        
        Args:
            metrics: Model metrics (Sharpe, IC, etc.)
            thresholds: Minimum acceptable values
        
        Returns:
            True if passes, False otherwise
        """
        print(f"\n  Validating performance metrics...")
        
        passed = True
        
        for metric, threshold in thresholds.items():
            value = metrics.get(metric, 0)
            
            if value >= threshold:
                print(f"    ✅ {metric}: {value:.3f} (threshold: {threshold:.3f})")
            else:
                print(f"    ❌ {metric}: {value:.3f} (threshold: {threshold:.3f})")
                passed = False
        
        self.validation_results['performance'] = passed
        return passed
    
    def validate_latency(self, inference_times: List[float], max_latency_ms: float = 10.0) -> bool:
        """
        Validate inference latency.
        
        Args:
            inference_times: List of inference times (ms)
            max_latency_ms: Maximum acceptable latency
        
        Returns:
            True if passes, False otherwise
        """
        print(f"\n  Validating latency...")
        
        p95_latency = np.percentile(inference_times, 95)
        p99_latency = np.percentile(inference_times, 99)
        
        print(f"    P95 latency: {p95_latency:.2f}ms")
        print(f"    P99 latency: {p99_latency:.2f}ms")
        print(f"    Threshold: {max_latency_ms:.2f}ms")
        
        passed = p99_latency <= max_latency_ms
        
        if passed:
            print(f"    ✅ Latency acceptable")
        else:
            print(f"    ❌ Latency too high")
        
        self.validation_results['latency'] = passed
        return passed
    
    def validate_data_quality(self, predictions: np.ndarray) -> bool:
        """
        Validate model outputs.
        
        Check for NaN, Inf, extreme values.
        """
        print(f"\n  Validating data quality...")
        
        # Check for NaN
        has_nan = np.any(np.isnan(predictions))
        if has_nan:
            print(f"    ❌ Contains NaN values")
            self.validation_results['data_quality'] = False
            return False
        
        # Check for Inf
        has_inf = np.any(np.isinf(predictions))
        if has_inf:
            print(f"    ❌ Contains Inf values")
            self.validation_results['data_quality'] = False
            return False
        
        # Check for extreme values
        std = np.std(predictions)
        max_abs = np.max(np.abs(predictions))
        
        if max_abs > 10 * std:
            print(f"    ⚠️  Contains extreme values (>10σ)")
        
        print(f"    ✅ Data quality acceptable")
        self.validation_results['data_quality'] = True
        return True
    
    def all_passed(self) -> bool:
        """Check if all validations passed."""
        return all(self.validation_results.values())


# ---------------------------------------------------------------------------
# Canary Deployment
# ---------------------------------------------------------------------------

class CanaryDeployment:
    """
    Gradually roll out new model.
    
    Start with 5% traffic → Monitor → Increase to 100%
    """
    
    def __init__(self):
        self.old_model_weight = 1.0
        self.new_model_weight = 0.0
        
        self.old_model_metrics = []
        self.new_model_metrics = []
    
    def set_traffic_split(self, new_model_pct: float):
        """
        Set traffic split between old and new model.
        
        Args:
            new_model_pct: Percentage of traffic to new model (0-100)
        """
        self.new_model_weight = new_model_pct / 100.0
        self.old_model_weight = 1.0 - self.new_model_weight
        
        print(f"\n  Traffic split: Old={self.old_model_weight*100:.0f}% / New={self.new_model_weight*100:.0f}%")
    
    def route_request(self) -> str:
        """
        Decide which model to use for this request.
        
        Returns:
            'old' or 'new'
        """
        if np.random.random() < self.new_model_weight:
            return 'new'
        else:
            return 'old'
    
    def record_metric(self, model: str, metric_value: float):
        """Record metric for a model."""
        if model == 'old':
            self.old_model_metrics.append(metric_value)
        else:
            self.new_model_metrics.append(metric_value)
    
    def compare_performance(self) -> Dict:
        """
        Compare old vs new model performance.
        
        Returns:
            Comparison results
        """
        if len(self.old_model_metrics) == 0 or len(self.new_model_metrics) == 0:
            return {'status': 'insufficient_data'}
        
        old_mean = np.mean(self.old_model_metrics)
        new_mean = np.mean(self.new_model_metrics)
        
        # Statistical test (simplified)
        improvement = (new_mean - old_mean) / abs(old_mean)
        
        # Decision
        if improvement > 0.10:  # 10% better
            decision = 'rollout'
        elif improvement < -0.10:  # 10% worse
            decision = 'rollback'
        else:
            decision = 'neutral'
        
        return {
            'status': 'compared',
            'old_mean': old_mean,
            'new_mean': new_mean,
            'improvement': improvement,
            'decision': decision,
            'old_count': len(self.old_model_metrics),
            'new_count': len(self.new_model_metrics)
        }


# ---------------------------------------------------------------------------
# CLI demonstration
# ---------------------------------------------------------------------------

if __name__ == "__main__":
    print("═" * 70)
    print("  PRODUCTION DEPLOYMENT & MLOPS")
    print("  Target: Deploy Safely | CI/CD | Auto-Rollback")
    print("═" * 70)
    
    # Demo 1: Model Registry
    print("\n── 1. Model Registry (Version Control) ──")
    
    registry = ModelRegistry()
    
    # Register multiple model versions
    registry.register_model(
        model_id='momentum_strategy',
        version='v1.0.0',
        metrics={'sharpe': 1.8, 'ic': 0.15, 'max_dd': -0.12},
        git_commit='abc123'
    )
    
    registry.register_model(
        model_id='momentum_strategy',
        version='v1.1.0',
        metrics={'sharpe': 2.1, 'ic': 0.18, 'max_dd': -0.10},
        git_commit='def456'
    )
    
    # Promote to staging
    registry.promote_to_staging('momentum_strategy', 'v1.1.0')
    
    # Demo 2: Deployment Validation
    print("\n── 2. Deployment Validation ──")
    
    validator = DeploymentValidator()
    
    # Validate performance
    new_model_metrics = {'sharpe': 2.1, 'ic': 0.18, 'max_dd': -0.10}
    thresholds = {'sharpe': 1.5, 'ic': 0.10}
    
    perf_passed = validator.validate_performance(new_model_metrics, thresholds)
    
    # Validate latency
    inference_times = np.random.gamma(2, 2, 1000)  # Simulated latency (ms)
    latency_passed = validator.validate_latency(inference_times, max_latency_ms=10.0)
    
    # Validate data quality
    predictions = np.random.randn(1000) * 0.5
    quality_passed = validator.validate_data_quality(predictions)
    
    # Overall result
    print(f"\n  Overall Validation:")
    if validator.all_passed():
        print(f"    ✅ ALL VALIDATIONS PASSED - Safe to deploy")
    else:
        print(f"    ❌ VALIDATION FAILED - Do not deploy")
    
    # Demo 3: Canary Deployment
    print("\n── 3. Canary Deployment (Gradual Rollout) ──")
    
    if validator.all_passed():
        canary = CanaryDeployment()
        
        # Stage 1: 5% traffic to new model
        print(f"\n  Stage 1: Start with 5% traffic")
        canary.set_traffic_split(5)
        
        # Simulate requests
        for _ in range(100):
            model = canary.route_request()
            
            # Simulate metric (new model slightly better)
            if model == 'old':
                metric = np.random.normal(0.15, 0.05)  # IC ~0.15
            else:
                metric = np.random.normal(0.18, 0.05)  # IC ~0.18 (better)
            
            canary.record_metric(model, metric)
        
        # Compare performance
        comparison = canary.compare_performance()
        
        print(f"\n  Performance Comparison:")
        print(f"    Old model IC: {comparison['old_mean']:.3f} ({comparison['old_count']} requests)")
        print(f"    New model IC: {comparison['new_mean']:.3f} ({comparison['new_count']} requests)")
        print(f"    Improvement: {comparison['improvement']:.1%}")
        print(f"    Decision: {comparison['decision'].upper()}")
        
        # Stage 2: If good, increase to 50%
        if comparison['decision'] == 'rollout':
            print(f"\n  Stage 2: Increase to 50% traffic")
            canary.set_traffic_split(50)
            
            # Continue monitoring...
            
            # Stage 3: Full rollout
            print(f"\n  Stage 3: Full rollout (100% traffic)")
            canary.set_traffic_split(100)
            
            # Promote to production
            registry.promote_to_production('momentum_strategy', 'v1.1.0')
            
        elif comparison['decision'] == 'rollback':
            print(f"\n  ❌ ROLLBACK - New model underperforming")
            canary.set_traffic_split(0)  # Back to 100% old model
    
    print(f"\n{'═' * 70}")
    print(f"  KEY INSIGHTS: PRODUCTION DEPLOYMENT")
    print(f"{'═' * 70}")
    
    print(f"""
1. MODEL VERSIONING:
   
   Track every model version:
   • v1.0.0: Sharpe 1.8, IC 0.15 (baseline)
   • v1.1.0: Sharpe 2.1, IC 0.18 (improvement)
   
   Why: If new model fails in production → Instant rollback to v1.0.0
   
   **Without versioning**: "Which model was running on March 15?" → Unknown
   **With versioning**: "v1.0.0 was running, switched to v1.1.0 on March 16"

2. DEPLOYMENT VALIDATION:
   
   Test BEFORE deploying:
   ✅ Performance (Sharpe >1.5, IC >0.10)
   ✅ Latency (P99 <10ms)
   ✅ Data quality (No NaN/Inf)
   
   **One failed test → Reject deployment**
   
   Cost: 1 hour validation time
   Benefit: Prevent $10M production failure

3. CANARY DEPLOYMENT:
   
   Gradual rollout:
   • 5% traffic → Monitor 2 hours → Good? Continue
   • 50% traffic → Monitor 2 hours → Good? Continue
   • 100% traffic → Monitor 24 hours → Good? Done
   
   **Auto-rollback if metrics degrade**:
   • New model IC drops 10% → Auto switch to old model
   • Zero manual intervention needed
   
   Two Sigma: 15 deployments/day, zero outages in 2 years

4. A/B TESTING:
   
   Run old + new model in parallel:
   • Old model: 50% traffic
   • New model: 50% traffic
   • After 1 week: Compare Sharpe, IC, drawdown
   • Winner gets 100% traffic
   
   **Statistical rigor**: Need >1000 samples per model for significance

5. ROLLBACK STRATEGY:
   
   Keep old model running:
   • New model deployed → Old model still in memory
   • If new fails → Instant switch (<1 second)
   • No downtime, no data loss
   
   **Rollback triggers**:
   • IC drops >20% → Auto-rollback
   • Latency >50ms → Auto-rollback
   • Error rate >1% → Auto-rollback
   • Manual override → Instant rollback

Next steps for MLOps expertise:
  • Learn Docker/Kubernetes (containerization)
  • Study CI/CD tools (Jenkins, GitLab CI, GitHub Actions)
  • Understand monitoring (Prometheus, Grafana, Datadog)
  • Practice incident response (on-call, post-mortems)
  • Build deployment pipelines (automate everything)
    """)

print(f"\n{'═' * 70}")
print(f"  Module complete. MLOps = safe, fast deployment.")
print(f"{'═' * 70}\n")
