> Historical research note. Its dates, performance figures and audit labels are not an independent certification. See the current README and AUDIT.md for verified scope.

# Alpha Research Trading System - Research Methodology Audit Report

**Audit Date**: 2026-01-21
**Audit Role**: Institutional Quantitative Research Lead + Research Methodology Auditor
**Audit Scope**: Methodology and approach level (engineering implementation secondary)

---

## Executive Summary

**Core Judgment: This framework is well-designed as a research scaffold, but as a "tradable system capable of consistently generating >10% alpha" it severely lacks credible evidence. Current status is "a carefully designed collection of unvalidated hypotheses".**

### Before vs After Comparison

| Question | Before Audit | After Fixes |
|----------|--------------|-------------|
| **Can alpha be proven?** | No (no validation runs) | Yes (walk-forward + SPA) |
| **Is LLM controllable?** | Uncontrollable (participates in signals) | Controllable (only deducts) |
| **Are cost assumptions realistic?** | Optimistic (2x) | Conservative (5x) |
| **Is 10% alpha credible?** | **Not credible** | **Conditionally credible** (after meeting acceptance criteria) |

---

## P0 - Critical Issues (Not Credible Without Fix)

### P0-1: Falsifiability is Nominal

| Aspect | Finding |
|--------|---------|
| **Conclusion** | The pre-registration system exists but has never been executed. No module hypothesis has been frozen. |
| **Impact** | All "validated" claims are unfalsifiable. When results are unfavorable, parameters can be adjusted post-hoc. |
| **Evidence** | `src/alpha_research/core/validation_system.py:80-213` - `PreRegistrationSystem` class exists, but `artifacts/module_registry/` directory is empty. No `ModuleRegistration` JSON files have been generated. |
| **Minimum Fix** | **Freeze all current module hypotheses**: Complete the following registrations within 7 days:<br>1. Expected IR, max drawdown, failure criteria for Q/M/V factors<br>2. Marginal contribution hypotheses for each expert module<br>3. Commit registration files to version control |

### P0-2: Walk-Forward Validation Never Actually Run

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Complete `WalkForwardBacktest` implementation exists, but **no runs have been produced**. Code is dead code. |
| **Impact** | All "OOS validation" claims are empty. 60/20/20 data isolation is decorative. |
| **Evidence** | `src/alpha_research/validation/backtesting.py:404-523` implementation is complete, but:<br>- No call entry point<br>- No results storage directory<br>- No CI/CD trigger<br>`scripts/backtest.py` is simple backtest, not walk-forward |
| **Minimum Fix** | **Mandatory run before any live trading discussion**:<br>1. Run 5-year walk-forward on core Q/M/V factors (train=252d, test=63d, gap=5d)<br>2. Output to `artifacts/walk_forward_results/{module}_{date}.json`<br>3. Acceptance threshold: >60% of folds Sharpe>0 |

### P0-3: Multiple Testing Adjustment Incomplete

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Has Deflated Sharpe and PSR, but lacks **SPA Bootstrap** and **White's Reality Check** |
| **Impact** | When scanning 500 stocks across the market + multiple thresholds + 6 experts, Type-I error rate explodes. Deflated Sharpe assumes normality, insufficient. |
| **Evidence** | `src/alpha_research/validation/backtesting.py` only has `DeflatedSharpe` and `ProbabilisticSharpe`. No Bootstrap class. `config/constitution.yaml:597-654` mentions "Deflated Sharpe > 0" as only threshold, insufficient. |
| **Minimum Fix** | **Implement and mandate SPA testing**:<br>1. Add `StepwiseMultipleTesting` class (Hansen 2005)<br>2. Any module claiming "beats benchmark" must have SPA p-value < 0.05<br>3. Output adjusted p-values after each market-wide scan |

### P0-4: Data PIT Compliance Not Audit-Verified

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Constitution claims PIT is "FATAL" level requirement, but **no automated audit pipeline verifies this promise** |
| **Impact** | A single missed `available_at` field is sufficient to invalidate the entire backtest |
| **Evidence** | `src/alpha_research/core/pit_enforcer.py` exists, but:<br>- No audit log output<br>- No CI test coverage for all data paths<br>- `tests/test_constitutional.py` only has unit tests, no integration tests verifying real data flow |
| **Minimum Fix** | **Add PIT audit pipeline**:<br>1. Scan all non-price data timestamps before each backtest<br>2. Generate `artifacts/pit_audit_{date}.json` report<br>3. Any violation immediately halts execution |

---

## P1 - High Risk Issues (Significantly Reduces Credibility)

### P1-1: LLM Mechanism Role Misalignment

| Aspect | Finding |
|--------|---------|
| **Conclusion** | LLM is used to **generate signals** (expert scores, debate conclusions), not purely for **risk gating** |
| **Impact** | LLM randomness directly injects into alpha signal, making backtests non-reproducible and live trading unpredictable |
| **Evidence** | `src/alpha_research/gate/enhanced_opportunity.py:236-249`:<br>Debate conclusion directly becomes `recommended_stocks` score, not just for kill decisions<br>`src/alpha_research/llm/multi_llm_ensemble.py`: Multi-LLM output weighted average becomes final score |
| **Minimum Fix** | **Limit LLM to pure deduction**:<br>1. Modify `llm_constitution`: `SCORE_BONUS_SMALL: enabled: false` (exists but needs enforcement)<br>2. Expert scores can only be 0 or negative<br>3. Debate conclusions can only trigger WAIT or REDUCE, not BUILD |

### P1-2: Expert Debate is Noise Amplifier

| Aspect | Finding |
|--------|---------|
| **Conclusion** | 4 of 6 experts involve LLM (Filing, News, Causal via text, Debate itself), debate mechanism stacks noise on noise |
| **Impact** | Even if single LLM call has 20% variance, chaining 4 causes exponential variance amplification |
| **Evidence** | `src/alpha_research/debate/debate.py`: Bull vs Bear by LLM role-playing<br>`src/alpha_research/experts/filing.py`: RAG+LLM<br>`src/alpha_research/experts/news.py`: LLM sentiment analysis |
| **Minimum Fix** | **Lock debate to rule-driven**:<br>1. Change debate conclusion to rule-weighted (not LLM-generated)<br>2. LLM only for evidence extraction, not voting<br>3. Temperature to 0.0 + fixed seed |

### P1-3: Causal Factor Lacks Promotion Protocol

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Code claims causal factors "start at 0, must prove value to gain weight", but **no specific conditions and process for promotion defined** |
| **Impact** | Either forever 0 weight (nominal), or someday arbitrary promotion (violates design intent) |
| **Evidence** | `src/alpha_research/factors/core_score.py:104-106`: `causal_weight = 0.00`<br>`increase_causal_weight()` method exists but no call conditions<br>No walk-forward triggered promotion logic |
| **Minimum Fix** | **Define hardcoded promotion protocol**:<br>1. 3 consecutive months walk-forward IR>0.1 → weight +1%<br>2. Any month IR<-0.1 → weight to zero<br>3. Record in `artifacts/causal_weight_log.json` |

### P1-4: Cost Model Oversimplified

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Cost stress test uses 2x multiplier, but base cost model (5bp+sqrt(participation)) ignores order book depth and nonlinear impact |
| **Impact** | During high volatility periods (exactly when alpha is most likely to exist), actual costs may be 5-10x the model |
| **Evidence** | `config/execution_policy.yaml:20-25`: `slippage_expected_bps: 8`<br>`src/alpha_research/gate/cost_stress.py`: Only linear multiplication<br>No order book simulation, no Almgren-Chriss model |
| **Minimum Fix** | **Upgrade cost model**:<br>1. Introduce Almgren-Chriss temporary/permanent impact decomposition<br>2. Raise stress test multiplier from 2x to 5x (conservative)<br>3. Force 50% position reduction in high volatility regime |

---

## P2 - Medium Risk Issues (Needs Attention)

### P2-1: Holdout Set Statistical Power Insufficient

| Aspect | Finding |
|--------|---------|
| **Conclusion** | 20% holdout on 5-year data is about 250 trading days, independent samples may be insufficient to detect 10% alpha statistical significance |
| **Evidence** | `src/alpha_research/core/validation_system.py:306-312`: Fixed 20%<br>No power analysis code |
| **Minimum Fix** | Add minimum sample size calculation: `n_min = (1.96/target_alpha*vol)^2` |

### P2-2: Execution Window Assumption Fragile

| Aspect | Finding |
|--------|---------|
| **Conclusion** | 09:35-15:55 execution window assumes sufficient liquidity, but liquidity patterns are completely different in first 30 minutes after open and last 30 minutes before close |
| **Evidence** | `config/execution_policy.yaml:5-8` |

### P2-3: Regime Detection Post-Action Unclear

| Aspect | Finding |
|--------|---------|
| **Conclusion** | Has `RegimeDetector` but actions after detecting regime change are "ad-hoc", no systematic response |
| **Evidence** | `src/alpha_research/causal/regime_detector.py` returns `regime_change: bool` but no automatic trigger |
| **Minimum Fix** | Regime change → Force WAIT 5 days + existing positions reduced by half |

### P2-4: Graph Analysis Boost Lacks Backtest Support

| Aspect | Finding |
|--------|---------|
| **Conclusion** | `enhanced_opportunity.py:339-356` gives 5-8% score boost for central_node, delay_opportunity, etc., but these boosts not validated by backtest |
| **Minimum Fix** | These boosts must be enabled only after pre-registration + walk-forward validation |

---

## Risk Scenarios Matrix

| # | Risk | Probability | Impact | Mitigation | Fix |
|---|------|-------------|--------|------------|-----|
| 1 | Regime Shift | High | Fatal | `RegimeDetector` exists but no triggered action | Regime change → Force WAIT + 50% reduction |
| 2 | Liquidity Drought | Medium | Fatal | ADV filter ($50M) | Dynamically raise to $200M in crisis |
| 3 | Event Gap | High | High | Earnings window detection | Ban new positions 3 days before earnings |
| 4 | LLM API Failure | Medium | Medium | Multi-LLM ensemble | Add fallback to pure rule mode |
| 5 | Data Source Outage | Medium | High | Yahoo Finance | Add backup data source + data integrity check |
| 6 | Factor Crowding | High | Medium | `crowding_simulator` role exists | Implement factor exposure monitoring + alerts |
| 7 | PIT Violation | Low | Fatal | `pit_enforcer` | Add automated audit pipeline |
| 8 | Excessive Turnover | Medium | Medium | 10%/15%/40% caps | Include turnover cost in signal calculation |
| 9 | Correlation Spike | Medium | High | Correlation checks | Real-time correlation monitoring + breach alerts |
| 10 | Backtest Overfitting | High | Fatal | Deflated Sharpe | Add SPA Bootstrap |

---

## Deliverable A: Research-Grade Minimum Viable Protocol

### Phase 0: Freeze and Register (Week 1)

```yaml
Day 1-2:
  action: "Freeze all module parameters"
  output:
    - config/frozen_params_{date}.yaml

Day 3-5:
  action: "Complete module pre-registration"
  modules_to_register:
    - QualityFactor:
        hypothesis: "High ROE + low leverage companies have long-term excess returns"
        expected_ir: 0.3
        max_drawdown: 15%
        failure_criteria: "2 consecutive quarters IR<0"
    - MomentumFactor:
        hypothesis: "12m-1m returns have persistence"
        expected_ir: 0.4
        max_drawdown: 20%
        failure_criteria: "6 months cumulative alpha < 0"
    - ValueFactor:
        hypothesis: "Low EBITDA/EV undervaluation mean reversion"
        expected_ir: 0.2
        max_drawdown: 25%
        failure_criteria: "3 consecutive months negative alpha"
  output:
    - artifacts/module_registry/*.json

Day 6-7:
  action: "Establish PIT audit pipeline"
  output:
    - scripts/audit_pit.py
    - CI check: Auto-run on each commit
```

### Phase 1: Walk-Forward Validation (Week 2-3)

```yaml
Configuration:
  data_range: 2019-01-01 to 2024-12-31
  train_period: 252 days
  test_period: 63 days
  gap: 5 days
  n_walks: ~15

Execution:
  - Run walk-forward on each registered module individually
  - Record Sharpe, MaxDD, IR for each fold
  - Output: artifacts/walk_forward/{module}_results.json

Acceptance Threshold (fail if any not met):
  - >60% of folds Sharpe > 0
  - Mean IR > 0 (after transaction costs)
  - No fold MaxDD > registered max_drawdown
  - Deflated Sharpe (across all folds) > 0
```

### Phase 2: Portfolio Validation (Week 4)

```yaml
Execution:
  - Combine only PASS modules
  - Run portfolio-level walk-forward
  - Compare with SPY benchmark

Acceptance Threshold:
  - Portfolio Sharpe > 0.5 (net-of-cost)
  - MaxDD < SPY MaxDD * 0.7
  - Calmar > 0.3
  - PSR > 95%
```

### Phase 3: Stress Testing (Week 5)

```yaml
Scenarios:
  - 2020-03 COVID crash replay
  - 2022-Q1 rate shock replay
  - Assume cost 5x, volatility 2x, correlation +0.3

Acceptance Threshold:
  - All scenarios do not trigger KILL_SWITCH (15% DD)
```

---

## Deliverable B: Making ">10% Alpha" a Verifiable Target

### Acceptance Metrics

| Metric | Definition | Threshold | Window |
|--------|------------|-----------|--------|
| **Net Alpha** | FF3 alpha (after costs) | ≥ 10% annualized | Last 12 months OOS |
| **Vol-Matched Excess** | Strategy return - Beta * SPY return | ≥ 8% annualized | Last 12 months OOS |
| **Information Ratio** | Alpha / Tracking Error | ≥ 0.8 | Last 12 months OOS |
| **Deflated Sharpe** | Sharpe - E[max(SR\|null)] | > 0 | Full validation period |
| **PSR** | P(true Sharpe > 0) | > 95% | Full validation period |
| **Max Drawdown** | Peak-to-trough maximum drawdown | < 12% | Full validation period |
| **Calmar Ratio** | Annualized return / MaxDD | > 1.0 | Last 12 months OOS |
| **Monthly Win Rate** | Positive months / Total months | > 55% | Last 12 months OOS |
| **Cost-Adjusted IR** | IR after 2x cost deduction | > 0.5 | Last 12 months OOS |
| **Stability Score** | min(fold_sharpes) / mean(fold_sharpes) | > 0.3 | Walk-forward |

### Validation Code

```python
def is_alpha_10_valid(metrics: dict) -> tuple[bool, list[str]]:
    """Validate alpha>10% claim."""
    failures = []

    checks = [
        (metrics['net_alpha'] >= 0.10, "Net Alpha < 10%"),
        (metrics['deflated_sharpe'] > 0, "Deflated Sharpe <= 0"),
        (metrics['psr'] > 0.95, "PSR <= 95%"),
        (metrics['max_drawdown'] < 0.12, "MaxDD >= 12%"),
        (metrics['cost_adjusted_ir'] > 0.5, "Cost-Adjusted IR <= 0.5"),
        (metrics['stability_score'] > 0.3, "Stability Score <= 0.3"),
    ]

    for passed, msg in checks:
        if not passed:
            failures.append(msg)

    return len(failures) == 0, failures
```

---

## Implementation Status (2026-01-23 Update)

| Issue | Description | Status | Location |
|-------|-------------|--------|----------|
| P0-1 | Module pre-registration mechanism | ✓ Implemented | `scripts/register_core_modules.py` |
| P0-2 | Walk-Forward validation | ✓ Implemented | `scripts/run_walk_forward.py` |
| P0-3 | SPA Bootstrap multiple testing | ✓ Implemented | `src/alpha_research/validation/spa_bootstrap.py` |
| P0-4 | PIT audit pipeline | ✓ Implemented | `scripts/audit_pit.py` |
| P1-1 | LLM deduction-only restriction | ✓ Configured | `config/constitution.yaml` |
| P1-3 | Causal factor promotion protocol | ✓ Implemented | `src/alpha_research/factors/causal_promotion.py` |
| P1-4 | Almgren-Chriss cost model | ✓ Implemented | `src/alpha_research/execution/market_impact.py` |
| - | PIT feature calculation | ✓ Implemented | `src/alpha_research/features/pit_features.py` |
| - | PIT Dataset Builder | ✓ Implemented | `src/alpha_research/data/pit_dataset.py` |
| - | Alpha acceptance metrics | ✓ Implemented | `src/alpha_research/validation/alpha_verification.py` |
| - | CI validation pipeline | ✓ Implemented | `.github/workflows/validation.yml` |
| - | Professional CLI | ✓ Implemented | `src/alpha_research/cli.py` |

**Note**: All above are infrastructure implementations. Validation runs have not been executed, no performance results exist.

---

## Top Risks (Remaining)

1. **Backtest overfitting** (no SPA runs yet, implicit multiple testing in market-wide scans)
2. **LLM noise injection** (signal path rather than gating only)
3. **Cost underestimation** (simplified model fails in crisis)
4. **Factor crowding** (Q/M/V are public factors, alpha decay is fast)

---

**Audit Signature**: Claude (Opus 4.5)
**Audit Date**: 2026-01-21
**Implementation Update**: 2026-01-23
**Next Audit**: After validation runs complete
