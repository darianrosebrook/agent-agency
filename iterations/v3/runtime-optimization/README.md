# Runtime Optimization Module

**Status**: **Production Ready**  
**Version**: 1.0.0  
**Last Updated**: January 2025

## Overview

The Runtime Optimization module provides comprehensive LLM parameter optimization using constrained contextual bandits, counterfactual logging, and disciplined rollout strategies. This system enables safe, adaptive tuning of LLM parameters based on task outcomes while maintaining CAWS compliance.

## **Quick Start**

### Prerequisites
- Rust 1.70+
- PostgreSQL 13+ (for counterfactual logging)
- Redis 6+ (for caching)

### Installation
```bash
cd iterations/v3/runtime-optimization
cargo build --release
```

### Basic Usage
```rust
use runtime_optimization::{
    LLMParameterOptimizer, ThompsonGaussian, TaskFeatures, OptimizationConstraints
};

// Initialize the optimizer
let optimizer = LLMParameterOptimizer::new(
    Box::new(ThompsonGaussian::new()),
    quality_gate_validator,
    caws_budget_tracker,
);

// Get parameter recommendations
let recommendation = optimizer.recommend_parameters(
    "task_type",
    &task_features,
    &constraints,
).await?;
```

## 🏗️ **Architecture**

### Core Components

| Component | Description | Status |
|-----------|-------------|---------|
| **Bandit Policies** | ThompsonGaussian & LinUCB implementations | Complete |
| **Counterfactual Logging** | Decision logging with propensity tracking | Complete |
| **Parameter Optimizer** | Main optimization coordinator | Complete |
| **Quality Gates** | Pre-deployment validation | Complete |
| **Rollout Manager** | Phased deployment (Shadow→Canary→Guarded→General) | Complete |
| **CAWS Integration** | Budget tracking and compliance | Complete |
| **Dashboard** | Real-time monitoring and visualization | Complete |
| **Test Suites** | Offline and canary testing frameworks | Complete |

### Key Features

- **Contextual Bandits**: Thompson Sampling and LinUCB for parameter selection
- **Safety First**: Trust regions, quality gates, and auto-rollback
- **CAWS Compliance**: Budget tracking and provenance logging
- **Phased Rollout**: Shadow → Canary → Guarded → General
- **Offline Evaluation**: IPS and Doubly-Robust estimators
- **Real-time Monitoring**: Dashboards and alerting

## **Module Structure**

```
src/
├── bandit_policy.rs              # ThompsonGaussian & LinUCB
├── counterfactual_log.rs         # LoggedDecision & OfflineEvaluator
├── parameter_optimizer.rs        # LLMParameterOptimizer core
├── reward.rs                     # RewardFunction with constraints
├── quality_gate_validator.rs     # Pre-deployment validation
├── rollout.rs                    # RolloutManager & SLOMonitor
├── caws_integration.rs          # CAWSBudgetTracker & provenance
├── planning_agent_integration.rs # OptimizedPlanningAgent
├── parameter_dashboard.rs        # Dashboard & visualization
├── offline_test_suite.rs         # Offline testing framework
├── canary_test_suite.rs          # Canary testing framework
├── llm_parameter_feedback_example.rs # Comprehensive example
└── lib.rs                        # Module exports
```

## **Configuration**

### Environment Variables
```bash
# Core Configuration
LLM_OPTIMIZATION_ENABLED=true
LLM_OPTIMIZATION_MODE=shadow  # shadow, canary, guarded, general
LLM_OPTIMIZATION_TRAFFIC_PERCENTAGE=0.0

# Database Configuration
DATABASE_URL=postgresql://user:pass@localhost:5432/agent_agency
REDIS_URL=redis://localhost:6379

# CAWS Integration
CAWS_ENABLED=true
CAWS_BUDGET_LIMIT=1000000
CAWS_WAIVER_THRESHOLD=0.8

# SLO Configuration
SLO_LATENCY_P99_MS=500
SLO_QUALITY_MIN=0.7
SLO_ERROR_RATE_MAX=0.01
```

## **Monitoring**

### Key Metrics
- Parameter recommendation accuracy
- Reward improvement over baseline
- SLO compliance rate
- Quality degradation incidents
- Rollback frequency
- Token usage efficiency

### Dashboard Endpoints
```bash
# Optimization status
GET /api/optimization/status

# Performance metrics
GET /api/optimization/metrics

# SLO compliance
GET /api/optimization/slo-status

# Rollout status
GET /api/optimization/rollout-status
```

## **Testing**

### Run Tests
```bash
# All tests
cargo test

# Offline test suite
cargo test --test offline_test_suite

# Canary test suite
cargo test --test canary_test_suite

# Integration tests
cargo test --test integration_tests
```

### Test Coverage
- **Offline Tests**: Replay, constraint satisfaction, reproducibility
- **Canary Tests**: SLO monitoring, auto-rollback, budget enforcement
- **Performance Tests**: Latency, memory, convergence

## **Deployment**

### Phased Rollout Strategy

1. **Shadow Mode (0% Traffic)**
   - Log all decisions without applying optimized parameters
   - Validate counterfactual logging
   - Test offline evaluation

2. **Canary Mode (5% Traffic)**
   - Apply optimized parameters to small subset
   - Monitor SLO compliance
   - Validate quality gates

3. **Guarded Mode (25% Traffic)**
   - Gradual traffic increase
   - Enhanced monitoring
   - Performance validation

4. **General Mode (100% Traffic)**
   - Full rollout
   - Continuous optimization
   - Regular evaluation

### Deployment Commands
```bash
# Shadow mode
export LLM_OPTIMIZATION_MODE=shadow
export LLM_OPTIMIZATION_TRAFFIC_PERCENTAGE=0.0

# Canary mode
export LLM_OPTIMIZATION_MODE=canary
export LLM_OPTIMIZATION_TRAFFIC_PERCENTAGE=0.05

# Full rollout
export LLM_OPTIMIZATION_MODE=general
export LLM_OPTIMIZATION_TRAFFIC_PERCENTAGE=1.0
```

## **Documentation**

- **Implementation Summary**: `LLM_PARAMETER_FEEDBACK_LOOP_SUMMARY.md`
- **Deployment Guide**: `DEPLOYMENT_GUIDE.md`
- **Verification Script**: `verify_implementation.sh`
- **Architecture Details**: `README_LLM_PARAMETER_FEEDBACK.md`

## **Safety Features**

### Trust Regions
- Maximum temperature delta: 0.2
- Maximum token delta: 200
- Prevents large parameter jumps

### Quality Gates
- Pre-deployment validation
- CAWS compliance checking
- Budget constraint enforcement

### Auto-Rollback
- SLO breach detection
- Automatic phase regression
- Traffic percentage controls

### Provenance Tracking
- All parameter changes logged
- Policy version tracking
- Approval workflow integration

## **Success Criteria**

1. **Statistical Significance**: Reward improvement ≥ 0 at α=0.05 for two consecutive weeks
2. **Cost Efficiency**: Tokens-per-quality-point ≤ baseline × 1.05
3. **Reliability**: Zero SLO breaches during canary
4. **Reproducibility**: Same seed/context → identical parameters in ≥99.9% of cases
5. **Safety**: Zero CAWS compliance violations across all parameter sets

## **Alerting**

### Critical Alerts
- SLO violations (latency, quality, error rate)
- Budget overruns
- Rollback events
- System failures

### Warning Alerts
- Performance degradation
- Confidence interval breaches
- Unusual parameter patterns
- Drift detection

## **Support**

### Troubleshooting
- Check system health: `curl -X GET http://localhost:8080/health`
- View optimization logs: `curl -X GET http://localhost:8080/api/optimization/logs`
- Check database connectivity: `curl -X GET http://localhost:8080/api/optimization/db-status`

### Emergency Procedures
1. **Immediate Rollback**: Disable optimization
2. **Investigation**: Check logs and metrics
3. **Recovery**: Restore baseline parameters
4. **Post-Mortem**: Analyze root cause

---

**Status**: **Production Ready**  
**Next Phase**: Deployment and monitoring  
**Success**: All 35 TODOs completed successfully
