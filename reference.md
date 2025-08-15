# MTUM Replica Portfolio - Technical Reference Guide

## Overview

This document provides comprehensive technical background for the MTUM (iShares MSCI USA Momentum Factor ETF) replication project. The system implements a sophisticated quantitative pipeline combining machine learning with modern portfolio theory to create a sparse portfolio that tracks MTUM performance using significantly fewer holdings.

### Project Objective
**Replicate MTUM performance using a sparse portfolio from 11 sector ETFs: XLE, XLF, XLU, XLI, XLK, XLV, XLY, XLP, XLB, SMH, AIQ**

---

## System Architecture

### Complete Analytical Pipeline
```
Raw Data → Feature Engineering → ML Prediction → Portfolio Optimization → Performance Analysis
```

### Five-Stage Process
1. **📊 Data Acquisition** - Collect historical ETF and benchmark data
2. **🔧 Feature Engineering** - Calculate momentum, volatility, and correlation metrics  
3. **🏷️ Label Creation** - Identify optimal securities through optimization
4. **🤖 Model Development** - Train XGBoost classifier for security selection
5. **📈 Portfolio Construction** - Implement walk-forward backtesting with monthly rebalancing

---

## Background: MTUM ETF

### Fund Characteristics
- **Objective**: Track MSCI USA Momentum Index performance
- **Holdings**: ~125-130 stocks with high price momentum
- **Methodology**: 6- and 12-month price appreciation with low volatility filter
- **Rebalancing**: Semi-annual (high turnover)
- **Expense Ratio**: 0.15%
- **Launch Date**: April 16, 2013

### Investment Philosophy
**Momentum Investing**: Strategy based on the principle that securities with strong recent performance tend to continue outperforming.

### Key Risks
- **Market Reversals**: Vulnerable during trend breaks
- **High Turnover**: Increased transaction costs
- **Concentration Risk**: Potential sector/stock concentration
- **Choppy Markets**: May underperform in sideways markets

---

## Technical Implementation

### Data Universe

#### Primary ETFs for Sparse Portfolio
| Ticker | Fund Name | Sector/Focus | Expense Ratio |
|--------|-----------|--------------|---------------|
| **XLE** | Energy Select Sector SPDR | Energy | 0.13% |
| **XLF** | Financial Select Sector SPDR | Financials | 0.13% |
| **XLU** | Utilities Select Sector SPDR | Utilities | 0.13% |
| **XLI** | Industrial Select Sector SPDR | Industrials | 0.13% |
| **XLK** | Technology Select Sector SPDR | Technology | 0.13% |
| **XLV** | Health Care Select Sector SPDR | Healthcare | 0.13% |
| **XLY** | Consumer Discretionary SPDR | Consumer Discretionary | 0.13% |
| **XLP** | Consumer Staples SPDR | Consumer Staples | 0.13% |
| **XLB** | Materials Select Sector SPDR | Materials | 0.13% |
| **SMH** | VanEck Semiconductor ETF | Semiconductors | 0.35% |
| **AIQ** | Global X AI & Technology ETF | Artificial Intelligence | 0.68% |

#### Benchmark
- **MTUM**: iShares MSCI USA Momentum Factor ETF

---

## Feature Engineering Framework

### 1. Momentum Features

**Academic Standard: Skip Most Recent Month**
```
Momentum_k = ln(P_{t-1} / P_{t-k-1})
```

**Calculations**:
- **1-Month Momentum**: `ln(P_1M / P_2M)`
- **3-Month Momentum**: `ln(P_1M / P_4M)` 
- **6-Month Momentum**: `ln(P_1M / P_7M)`
- **12-Month Momentum**: `ln(P_1M / P_13M)` (12-2 momentum)

Where `P_kM` = price k months ago

### 2. Volatility Features

**Daily Log Return**:
```
R_t = ln(P_t / P_{t-1})
```

**Rolling Volatility (Annualized)**:
```
σ_N = std(R_{t-N:t}) × √252
```

**Calculated Metrics**:
- **20-Day Volatility**: `σ_20 × √252`
- **60-Day Volatility**: `σ_60 × √252`

### 3. Correlation Features

**60-Day Realized Correlation with MTUM**:
```
ρ = Cov(R_security, R_MTUM) / (σ_security × σ_MTUM)
```

**Rolling Implementation**:
- Calculate daily returns for both security and MTUM
- Compute 60-day rolling correlation
- Update daily for time-varying relationship

### 4. Optional Enhancement Features

**Market Capitalization**:
```
Weighted Avg Market Cap = Σ(w_i × Market_Cap_i)
```

**Price-to-Earnings Ratio**:
```
Weighted Avg P/E = Σ(w_i × P/E_i)
```

**Earnings Surprise**:
```
Surprise % = (Actual_EPS - Estimated_EPS) / Estimated_EPS × 100%
```

---

## Mathematical Framework

### 1. Label Creation via Optimization

**Objective Function**:
```
minimize: ||Rw - r_M||₂² + λ||w||₁
```

**Constraints**:
```
Σw_i = 1           (weights sum to 1)
w_i ≥ 0            (long-only constraint)
w_i ≤ w_max        (position size limits)
```

**Where**:
- `R` = returns matrix for ETF universe
- `r_M` = MTUM benchmark returns
- `w` = portfolio weights vector
- `λ` = L1 penalty parameter (controls sparsity)

**Label Assignment**:
- Securities with `w_i > threshold` → Label = 1 (Include)
- Securities with `w_i ≤ threshold` → Label = 0 (Exclude)

### 2. Lagrangian Formulation

```
L(w,ν) = ||Rw - r_M||₂² + λ||w||₁ + ν(Σw_i - 1)
```

**Optimality Conditions**:
```
∇_w L = 2R^T(Rw - r_M) + λ∂||w||₁ + ν1 = 0
∂L/∂ν = Σw_i - 1 = 0
```

### 3. Risk Decomposition

**Tracking Error**:
```
TE = √(w^T Σ w)
```

**Marginal Contribution to TE**:
```
MCTR_i = (Σw)_i / TE
```

**Risk Contribution**:
```
RC_i = w_i × MCTR_i
```

---

## Machine Learning Implementation

### XGBoost Classifier Configuration

**Objective**: Predict portfolio inclusion based on features

**Hyperparameter Grid**:
```python
param_grid = {
    'n_estimators': [100, 200, 300],
    'max_depth': [4, 6, 8], 
    'learning_rate': [0.05, 0.1, 0.15],
    'subsample': [0.8, 0.9],
    'colsample_bytree': [0.8, 0.9],
    'reg_alpha': [0, 0.1],
    'reg_lambda': [1, 1.5]
}
```

**Cross-Validation**: TimeSeriesSplit (3 folds) to prevent look-ahead bias

**Performance Metrics**:
- **AUC-ROC**: Area under ROC curve
- **Precision/Recall**: Classification accuracy metrics
- **Feature Importance**: Identifies key predictive factors

### Model Interpretation Guidelines

**AUC Score Interpretation**:
- **0.5-0.7**: Poor to acceptable discrimination
- **0.7-0.8**: Acceptable discrimination  
- **0.8-0.9**: Excellent discrimination
- **>0.9**: Outstanding discrimination

---

## Portfolio Construction & Backtesting

### Walk-Forward Methodology

**Monthly Rebalancing Process**:

1. **Data Window**: Use 13 months of historical data
2. **Feature Calculation**: Compute momentum, volatility, correlation features
3. **ML Prediction**: XGBoost predicts securities to include
4. **Portfolio Optimization**: CVXPY solves for optimal weights
5. **Performance Simulation**: Calculate out-of-sample returns
6. **Results Storage**: Record weights, metrics, and performance data

**Critical Implementation Details**:
- **No Look-Ahead Bias**: Only use data available at rebalancing date
- **Temporal Consistency**: Maintain proper time-series order
- **Feature Lag**: Use lagged features to ensure realistic implementation

### Optimization Framework

**CVXPY Implementation**:
```python
# Objective: minimize tracking error + sparsity penalty
minimize(risk_aversion/2 * quad_form(w, Σ) - μ^T @ w + l1_penalty * norm(w, 1))

# Constraints
subject_to([
    sum(w) == 1,          # budget constraint
    w >= 0,               # long-only
    w <= max_weight       # position limits
])
```

**Parameter Selection**:
- **Risk Aversion**: 1.0 (balanced risk-return)
- **L1 Penalty**: 0.01 (moderate sparsity)  
- **Max Weight**: 30% (concentration limit)
- **Min Weight**: 0.5% (eliminates tiny positions)

---

## Performance Evaluation Framework

### Key Performance Metrics

**Tracking Performance**:
- **Tracking Error**: `σ(R_portfolio - R_benchmark) × √252`
- **Information Ratio**: `E[R_portfolio - R_benchmark] / TE`

**Risk-Adjusted Returns**:
- **Sharpe Ratio**: `(E[R] - R_f) / σ(R)`
- **Sortino Ratio**: `(E[R] - R_f) / σ_downside`
- **Calmar Ratio**: `E[R] / |Max_Drawdown|`

**Portfolio Characteristics**:
- **Average Holdings**: Mean number of positions
- **Turnover**: `Σ|w_i,t - w_i,t-1| / 2`
- **Concentration**: Top N holdings percentage

**CAPM Analysis**:
- **Beta**: Systematic risk vs benchmark
- **Alpha**: Risk-adjusted excess return
- **R-squared**: Explained variance

### Target Performance

**Acceptable Ranges**:
- **Tracking Error**: 2-4% annualized
- **Information Ratio**: >0.5 for good active management
- **Portfolio Size**: 15-25 holdings (vs 200+ in MTUM)
- **Annual Turnover**: <200% for reasonable costs

---

## Implementation Considerations

### Data Quality Management

**Survivorship Bias**: Include delisted securities in historical analysis
**Corporate Actions**: Use dividend-adjusted prices
**Missing Data**: Handle gaps with forward-fill or interpolation
**Outlier Detection**: Identify and treat extreme return observations

### Computational Efficiency

**Bulk Mode Processing**:
```python
BULK_MODE_CONFIG = {
    'SAVE_MONTHLY_CHARTS': False,
    'SAVE_EXPECTED_RETURNS_PLOTS': False, 
    'CHECKPOINT_EVERY_N_MONTHS': 24,
    'MINIMAL_LOGGING': True
}
```

**Memory Management**:
- Process data in chunks for large datasets
- Use efficient data types (category for tickers)
- Clear variables after processing

### Risk Management

**Model Validation**:
- Out-of-sample testing on unseen periods
- Cross-validation with proper time-series splits
- Feature stability analysis over time

**Operational Risk**:
- Data quality monitoring
- Model performance tracking
- Fallback procedures for optimization failures

---

## System Architecture: Three Core Modules

### 1. xgb_portfolio_model.py
**🧠 Machine Learning Engine**

**Purpose**: Security selection using ML prediction
- Trains XGBoost on historical features
- Predicts monthly portfolio inclusion
- Provides feature importance analysis

### 2. portfolio_optimization.py  
**📊 Mathematical Optimizer**

**Purpose**: Portfolio weight determination
- CVXPY-based convex optimization
- L1 regularization for sparsity
- Comprehensive risk management

### 3. backtest_storage.py
**📁 Results Management System**

**Purpose**: Performance tracking and analysis
- Stores monthly optimization results
- Calculates performance metrics
- Generates analysis-ready datasets

### Integration Flow
```
Historical Data → ML Predictions → Portfolio Weights → Performance Storage
```

---

## Advanced Topics

### Expected Returns Models

**Multi-Factor Approach**:
```
E[R_i] = α + β_momentum × MOM_i + β_reversion × REV_i + β_vol × VOL_i
```

**Available Methods**:
- **Historical**: Simple historical means
- **Shrinkage**: James-Stein estimator
- **Momentum**: Trend-based forecasts
- **Mean Reversion**: Short-term reversal signals
- **Multi-Factor**: Combined approach (recommended)

### Alternative Optimization Objectives

**Risk Parity**: Equal risk contribution across assets
**Maximum Diversification**: Optimize diversification ratio
**Minimum Variance**: Pure risk minimization
**Black-Litterman**: Bayesian approach with views

### Regime Detection

**Market State Classification**:
- Bull/Bear market identification
- Volatility regime changes  
- Correlation structure shifts
- Factor performance cycles

---

## Conclusion

This reference guide provides the mathematical and technical foundation for implementing a sophisticated MTUM replication system. The combination of machine learning for security selection and convex optimization for portfolio construction creates a robust framework for systematic portfolio management.

**Key Success Factors**:
1. **Proper Implementation**: Avoid look-ahead bias in backtesting
2. **Feature Engineering**: Quality momentum and risk features
3. **Parameter Tuning**: Balance between sparsity and tracking performance
4. **Risk Management**: Comprehensive monitoring and validation
5. **Performance Attribution**: Understanding sources of returns and risks

The system successfully demonstrates how modern quantitative techniques can create efficient portfolio solutions that maintain the essential characteristics of complex benchmarks while providing operational advantages through reduced complexity and improved cost efficiency.