# Deriv Step Index AI Research Platform

Institutional-grade probabilistic research platform for Step Index 100/200/300/400/500.
Built incrementally, one module at a time, per the project's development rules.

## Status: Beyond the 8-level hierarchy — Backtest Engine (Monte Carlo + Walk-Forward) ✅, plus a real bug found and fixed

```
Market Data Layer          ✅ done
    ↓
Feature Engineering Pipeline   ✅ done
    ↓
Market State Encoder       ✅ done
    ↓
Level 1 — Regime Detection     ✅ done
    ↓
Level 2 — Probability Estimation   ✅ done
    ↓
Level 3 — Expected Value Estimation    ✅ done
    ↓
Level 4 — Risk Assessment      ✅ done (+ a real self-locking bug found and fixed this stage)
    ↓
Level 5 — Trade Opportunity Scoring    ✅ done
    ↓
Level 6 — Execution Decision   ✅ done
    ↓
Level 7 — Trade Management (RL)    ✅ done
    ↓
Level 8 — Post-Trade Analysis  ✅ done
    ↓
Backtest Engine (Monte Carlo Stress Testing + Walk-Forward Analysis)   ✅ done  <-- YOU ARE HERE
    ↓
Model Registry / Drift Detection / Champion-Challenger / Continuous Learning Pipeline   <-- next
```

## What's in this delivery

### Modules

| Module | File | Responsibility |
|---|---|---|
| Backtest types | `backtesting/types.py` | `MonteCarloStressResult`, `WalkForwardWindowResult`, `WalkForwardReport` |
| Monte Carlo stress tester | `backtesting/monte_carlo.py` | Circular block bootstrap resampling of a realized trade sequence |
| Walk-forward backtester | `backtesting/walk_forward.py` | Rolling train/test evaluation using **real** realized outcomes, not simulated coin-flips |
| Backtest config | `configs/backtest_schema.py` | Block size, path count, window sizes — all typed and validated |
| Risk engine fix | `risk/engine.py`, `configs/risk_schema.py` | A real bug found via this stage's own end-to-end testing, fixed: see below |

### Monte Carlo Stress Testing — circular block bootstrap

A single realized backtest path is one sample from a distribution — Monte Carlo stress testing asks "how much of what happened was luck?" by resampling the trade sequence thousands of times. Uses the **circular block bootstrap** (Politis & Romano, 1992) rather than an ordinary i.i.d. bootstrap, since a real trade sequence has short-range dependence (regime persistence, RL-agent streaks, the adaptive opportunity threshold) that resampling trade-by-trade would destroy:

```
Given series length n, block size L:
  n_blocks = ceil(n/L)
  for each block: draw random start s in [0,n), take L elements circularly (index (s+i) mod n)
  concatenate blocks, truncate to length n
```

`block_size=1` degenerates to an ordinary i.i.d. bootstrap — deliberately, since that's the independence assumption Stage 7's analytical `risk_of_ruin()` formula relies on. Running the Monte Carlo tester at `block_size=1` against a large synthetic i.i.d. trade pool and comparing its **empirical** probability of ruin to the **analytical** Cramér-Lundberg result is a genuine cross-validation of that earlier formula, not two disconnected numbers — verified directly in `test_empirical_ruin_probability_cross_validates_analytical_formula`.

### Walk-Forward Analysis — with a methodological correction from earlier stages

Every end-to-end demo in Stages 5-11 settled simulated trades via `rng.uniform(0,1) < probability_used` — appropriate for illustrating a pipeline's mechanics, but **not a real backtest**, since it manufactures outcomes from the model's own belief rather than checking that belief against what actually happened. `WalkForwardBacktester` fixes this: it uses the **real** realized direction (whether the next candle actually closed higher or lower) to settle every trade. The probability model refits fresh on each rolling training window and is evaluated strictly out-of-sample on the window immediately after; the Risk Engine's equity curve and the Opportunity Scorer's adaptive threshold carry continuously across all windows, since they're modeling one continuous account.

### A real bug, found by this stage's own end-to-end testing, and fixed

Running the walk-forward backtester against the familiar 20,000-tick simulation surfaced something serious: **trading stopped completely after window 2 and never resumed.** Rather than assume this was expected model decay, it was traced concretely:

1. First hypothesis (wrong, checked and ruled out): the model lost its edge in later windows. Directly inspecting freshly-refit models' predicted probabilities in later windows showed most still cleared the payout's breakeven threshold — the model wasn't the problem.
2. Real cause, confirmed by instrumenting the actual `RiskEngine` state at the point trading stopped: the **consecutive-loss circuit breaker** had tripped and could never recover. Its only reset path was `consecutive_losses = 0` on a win inside `record_trade_result()` — but a win can never happen while the breaker itself is blocking every trade. This is a genuine self-locking failure mode, not a hypothetical: an account that hits `max_consecutive_losses` would have been **permanently frozen** in any real deployment.

The fix: `RiskConfig.consecutive_loss_cooldown_evaluations` — a time-based cooldown (ticked once per `assess()` call, i.e. once per candle evaluated, whether or not a trade occurs) that clears the streak counter after a configurable number of evaluations, letting trading resume and be freshly re-evaluated. This is deliberately **not** applied to the drawdown breaker, which stays a hard stop requiring an explicit `reset()` — matching how institutional risk desks typically treat a drawdown breach (pending manual review) versus a losing streak (a scheduled pause), a distinction now stated explicitly in the code rather than left implicit. Both behaviors are pinned by tests: `test_consecutive_loss_breaker_recovers_after_cooldown_elapses` and `test_drawdown_breaker_does_not_auto_recover_without_manual_reset`.

### Verified end-to-end, twice — before and after the fix

**Before the fix**: window 2 executed exactly 1 trade, then zero trades for the remaining 6 windows (2,500+ evaluated candles), permanently. **After the fix**: window 2 correctly resumed trading (23 trades, adapting to the model's degrading edge with a falling win rate), and the *subsequent* permanent stop in windows 3-8 was confirmed — by direct inspection of the veto reasons — to be the drawdown breaker correctly halting a strategy that had breached its 20% limit, exactly as designed, not a bug. A coherent, realistic outcome: profitable windows, a degrading edge, a real drawdown breach, and a risk engine that correctly refuses to keep trading a strategy that's stopped working.

The Monte Carlo stress test run against this real 146-trade sequence (post-fix) is genuinely informative in exactly the way it's supposed to be: the single realized path ended at $1,222 from a $1,000 start, but the resampled distribution shows a 5th-percentile outcome of $724 and a 95th-percentile max drawdown of 45.8% — the realized path was on the better side of what the same underlying edge could plausibly have produced, not a guaranteed result.

## Stage 11 recap: Level 8 — Post-Trade Analysis

### Modules

| Module | File | Responsibility |
|---|---|---|
| Post-trade types | `post_trade/types.py` | `CompletedTrade`, `CalibrationBin`, `PerformanceMetrics` |
| Post-trade analyzer | `post_trade/analyzer.py` | Every metric: win rate, profit factor, Sharpe/Sortino/Calmar, drawdown, recovery factor, Brier score, Expected Calibration Error |

### Every metric the spec's Backtest Engine section names, all hand-verified

Win rate, profit factor, expectancy, average trade, Sharpe ratio, Sortino ratio, Calmar ratio, maximum drawdown, maximum consecutive losses, recovery factor, and probability calibration error (both Brier score and Expected Calibration Error via a reliability-diagram binning) — every single one checked in tests against a hand-computed value on a small controlled trade list, not just "the code runs."

### No annualization, stated up front

Deriv synthetic-index tick contracts don't sit on a trading calendar the way daily-bar equities do. Every ratio metric here (Sharpe, Sortino, Calmar) is reported **per-trade**, not pretend-annualized against an arbitrary assumed trading frequency — manufacturing that kind of false precision would be worse than not having the number at all.

### A real, non-obvious finding from building this honestly

Running the full seven-level chain's real simulated outcomes through the analyzer surfaced something worth stating plainly rather than smoothing over: for a binary option, a **losing trade's return is always exactly -100% of that trade's own stake** — that's just what losing one of these contracts means. Compounding a normalized equity curve at "this trade's return_pct is the fraction of the curve currently at risk" therefore zeroes the curve the instant *any* single loss occurs, capping `max_drawdown_pct` at exactly 100% and making `calmar_ratio` a large negative number for basically any real trade history — regardless of how profitable the strategy actually was. This isn't a bug; the compounding formula is doing exactly what compounding means. But it does mean those two metrics answer a narrower, more theoretical question than the *operationally* meaningful portfolio drawdown — which is what `RiskEngine.current_drawdown_pct` (Stage 7) already tracks against real account equity, and remains the number to actually monitor risk against. `Sharpe`, `Sortino`, `profit_factor`, and `expectancy` don't share this degeneracy and stay informative regardless. This behavior is now pinned by an explicit test (`test_max_drawdown_pct_caps_at_100_percent_after_any_full_loss`) rather than left as a surprise someone finds in production.

### Verified end-to-end (Stage 11)

Ran all seven upstream levels against the familiar 20,000-tick simulation, recording every approved-and-settled trade into the analyzer: 389 trades, 62.2% win rate, profit factor 1.55, Sharpe 0.20, Sortino 0.30, and a calibration report showing the model's own 56.1% average predicted probability landing close to (though not exactly at) the realized 62.2% win rate — Expected Calibration Error of 0.060, a modest but real miscalibration a genuine Champion-Challenger framework would want to correct in a later model version. That gap being visible and quantified, rather than assumed away, is the entire point of this stage existing.

## Stage 10 recap: Level 7 — Trade Management (RL)

### Modules

| Module | File | Responsibility |
|---|---|---|
| Trade management types | `trade_management/types.py` | `TradeManagementAction` (HOLD/SELL), `OpenContractState`, `TradeManagementDecision` |
| Discretizer | `trade_management/discretizer.py` | Continuous state → discrete bins for the tabular agent |
| Q-learning agent | `trade_management/q_learning_agent.py` | The RL core: epsilon-greedy action selection, TD updates |
| Episode simulator | `trade_management/simulator.py` | Synthetic contract-lifetime generator for training/testing (explicitly NOT a Deriv pricing model) |
| Episode runner | `trade_management/trainer.py` | Wires simulator + agent together, handling terminal-vs-bootstrap correctly in one shared place |

### Scope, stated honestly before writing any code

The spec's action space (Trade/Wait/Hold/Exit/Reduce/Increase/Scale In/Scale Out) assumes a continuously-adjustable position — standard framing in RL trading literature, but not what a single Deriv Rise/Fall contract actually is. Once bought, there's nothing to scale; the only two real actions before expiry are **HOLD** (ride it to settlement) and **SELL** (exit early via Deriv's sell-back, locking in the current bid price). "Increase/Reduce Exposure" would mean buying *additional* contracts, which is an Execution-layer decision (Level 6) about opening a new trade, not a Trade-Management decision about an existing one — so it's out of scope here rather than faked.

### Why tabular Q-learning instead of PPO/SAC/DQN

The spec names algorithms built for large or continuous state/action spaces via neural function approximation. This problem has 2 discrete actions, a horizon of a handful of ticks, and a state that compresses naturally into a few informative dimensions (time remaining, unrealized return, price trend since entry). Tabular Q-learning is the textbook-correct tool for exactly this regime: it provably converges under standard conditions, needs no training infrastructure beyond a dictionary, and every learned value is directly inspectable — literally a table you can print — which serves the platform's explainability requirement better than a neural net's opacity would here. The interface doesn't preclude swapping in function approximation later if the state space grows.

### Math implemented in Stage 10 (RL trade management)

**One-step Q-learning (Watkins, 1989):**
```
Q(s,a) <- Q(s,a) + alpha * [ r + gamma * max_a' Q(s',a') - Q(s,a) ]
```
Terminal transitions (sold, or expired) use `target = r` with no bootstrap term — getting this branch right is the single most common tabular Q-learning bug (bootstrapping past an episode's end silently corrupts everything learned after), so it's an explicit `done` flag, not inferred from a sentinel state. Verified directly against hand-computed TD targets for both the terminal and bootstrapping cases.

**Reward structure** (defined by the episode runner, not the agent — the agent itself is reward-agnostic):
```
SELL:                reward = current_bid_price - stake                (terminal)
HOLD, not last tick: reward = 0                                        (bootstrap to next state)
HOLD, last tick:      reward = final_payout - stake                     (terminal, forced settlement)
```

**Episode simulator's pricing proxy** — explicitly labeled as a training-only simplification, not Deriv's real pricing engine:
```
z = favorable_move_pct / (tick_volatility * sqrt(ticks_remaining))
P(finish ITM) ≈ sigmoid(k * z)
bid_price ≈ P(finish ITM) * payout
```

### Verified end-to-end: does it actually learn?

Structural correctness (bounds, terminal handling, epsilon decay) isn't the interesting question for an RL component — whether it actually learns something useful is. Two tests target that directly:

1. **Outperforms a naive baseline.** Trained for 6,000 episodes under adverse drift (price tends to move against the contract's direction — a genuinely bad setup for blindly holding to expiry), the trained agent's average realized return on 500 held-out evaluation episodes exceeds an always-HOLD policy on the *same* episode distribution (same seed).
2. **The learned policy makes sense on inspection.** Querying the trained Q-table directly: at 6 ticks remaining, a deep-out-of-the-money state prefers HOLD (there's still time to recover, and locking in a near-total loss early is worse than holding), while a comfortably in-the-money state prefers SELL (lock in the gain rather than risk time-decay reversing it) — exactly the qualitative behavior a sensible trade-management policy should exhibit, arrived at through TD learning, not hardcoded.

One honest caveat visible in that same inspection: states near expiry (1-3 ticks remaining) that weren't actually reached during training under the simulator's natural price dynamics still show all-zero Q-values — a real, expected artifact of tabular Q-learning's sparse state coverage, not a bug. More training episodes or a coarser discretization would close those gaps; worth knowing about before this gets pointed at anything real.

## Stage 9 recap: Level 6 — Execution Decision

### Modules

| Module | File | Responsibility |
|---|---|---|
| Execution types | `execution/types.py` | `ExecutionMode`, `ExecutionDecision`, the `BrokerClient` protocol |
| Execution engine | `execution/engine.py` | Paper/live dispatch, staleness/slippage checks, the actual buy call |
| Deriv client extensions | `data/deriv_client.py` | `fetch_proposal()` / `buy()` methods, same request/response pattern as Stage 1's historical backfill |

### This is the stage that can touch real money — so it gets three independent safety rails, not one

1. **Config default is paper.** `ExecutionConfig.mode` defaults to `"paper"` — nothing executes for real unless someone deliberately opts in.
2. **Two flags must agree, checked at construction.** Live mode requires *both* `ExecutionConfig.mode == "live"` *and* the top-level `PlatformConfig.environment == "live"`. `ExecutionEngine.__init__` raises `ExecutionConfigurationError` immediately if they disagree — verified directly against the real `configs/default.yaml` (whose `environment` is `development`): constructing a live-mode engine against it fails loudly before any trade is ever attempted, not silently on the first one.
3. **Live proposals are re-validated against the decision basis before buying.** The EV/Risk/Opportunity chain scored a trade against a *hypothetical* payout. By execution time, Deriv's real live pricing may have moved. The engine recomputes `reward_to_risk` from the live proposal and aborts — does not buy — if it's drifted more than `max_payout_drift_pct` from what the decision was actually based on, or if the ask price exceeds slippage tolerance.

### Contract type scoping, stated honestly

Only `RISE_FALL` is wired for execution right now — direction=+1 maps to Deriv's `"CALL"` code, direction=-1 to `"PUT"`. The other `ContractType` values (`HIGHER_LOWER`, `TOUCH_NO_TOUCH`, `IN_OUT`) need barrier parameters `ContractSpec` doesn't carry yet; attempting to execute one returns an explicit `action="error"` decision rather than silently mis-mapping it to the wrong Deriv contract code.

### Failure handling: reported, not raised

Broker call failures (proposal request fails, buy fails) are caught and returned as `ExecutionDecision(action="error", reason=...)` rather than propagating a raw exception — every attempted trade, successful or not, produces one auditable record with a human-readable reason, consistent with the explainability discipline every gate in this pipeline has followed since Stage 6.

### Verified end-to-end (Stage 9)

Ran the full six-level chain (Regime → Probability → EV → Risk → Opportunity Scoring → Execution) in paper mode against 100 real states from the simulated tick stream: 33 buys, 67 skips, ending at $993 equity from a $1,000 start with realistic stake/payout numbers scaling correctly with Kelly-sized position sizing. Separately confirmed the live-mode safety rail actually fires against the real shipped `configs/default.yaml` — not just a synthetic test fixture — since its `environment` field defaults to `development`.

## Stage 8 recap: Level 5 — Trade Opportunity Scoring

### Modules

| Module | File | Responsibility |
|---|---|---|
| Opportunity types | `opportunity/types.py` | `TradeOpportunity`, `QualityScoreComponents`, `FrequencyStats` |
| Opportunity scorer | `opportunity/scorer.py` | Confidence Engine (quality score) + adaptive Trade Opportunity Management (frequency-driven threshold) |

### Two jobs, cleanly separated

The spec names these as two distinct components, and the code keeps them structurally distinct too:

1. **Confidence Engine** — `_compute_components()` + `_weighted_score()`: combines expected value, risk-adjusted return, regime confidence, probability confidence, and prediction certainty into one normalized [0,1] quality score. Pure function of its four inputs, no state.
2. **Trade Opportunity Management** — `_record_and_maybe_adjust()`: the adaptive threshold logic, entirely separate from score computation. This is the only stateful part of the module, and its only lever is *where the bar sits* — it can never approve a trade the quality score itself didn't clear, and it can never touch the EV/Risk gates.

### The three guarantees the spec explicitly demands, made structural rather than aspirational

- **"Never forces trades simply to meet a quota"** — the adaptive mechanism only ever moves `threshold_applied`. There's no code path where a rejected trade becomes approved by fiat; starvation only makes the *next* trade's bar easier to clear, never retroactively approves the current one.
- **"Never lowers standards below the minimum positive expected value and risk requirements"** — `evaluate()` checks `ev.is_positive_ev` and `risk.approved` unconditionally, before the adaptive threshold is even consulted. `threshold_min` bounds how low the *quality-score* bar can go, but that bar is layered on top of, never a replacement for, the hard EV/Risk gates from Stages 6-7 — verified directly by tests that set the threshold floor to near-zero and confirm a negative-EV trade is still rejected.
- **"Adapts differently for each detected market regime"** — `per_regime_adjustment` maintains an entirely independent threshold and rolling history per `RegimeLabel`. Verified end-to-end below: different regimes' thresholds diverged in opposite directions from the same starting point, based purely on their own opportunity quality.

### Math implemented in Stage 8 (opportunity scoring)

**Quality score** — each unbounded input normalized to [0,1] before a weighted sum (weights validated to sum to exactly 1.0):
```
ev_component            = clip(ev_pct / ev_pct_scale, 0, 1)
risk_adjusted_component = clip(risk_adjusted_score / risk_adjusted_scale, 0, 1)
regime_confidence_component      = regime.confidence                    (already [0,1])
probability_confidence_component = 2*(probability.confidence - 0.5)     (maps [0.5,1] -> [0,1])
certainty_component     = 1 - probability.uncertainty

quality_score = w_ev*ev_component + w_ra*risk_adjusted_component + w_rc*regime_confidence_component
              + w_pc*probability_confidence_component + w_c*certainty_component
```

**Adaptive threshold** — bounded, hysteresis-protected drift, evaluated only every `adjustment_cooldown` opportunities and only once `min_samples_for_adjustment` rolling-window samples exist:
```
observed_frequency = approved_count / window_size
if observed_frequency < target * frequency_band_low:   threshold -= step   (floored at threshold_min)
elif observed_frequency > target * frequency_band_high: threshold += step   (capped at threshold_max)
```

### Verified end-to-end (Stage 8)

Ran all 1,899 states from the by-now-familiar simulated tick stream through the complete five-level chain (Regime → Probability → EV → Risk → Opportunity Scoring), with real simulated trade outcomes feeding back into the Risk Engine's equity curve. 173 of 1,899 opportunities (9.1%) were ultimately approved, ending at $1,227 equity from a $1,000 start. The per-regime frequency stats confirm the adaptive mechanism working exactly as designed: `strong_trend`, `weak_trend`, and `compression` — the regimes that accumulated enough rolling history while being under-approved relative to target — had their thresholds ease down from the 0.55 base toward the 0.40 floor, while regimes that never accumulated the minimum sample count (`range`, `expansion`, `high_volatility`, `low_volatility`) correctly stayed anchored at the unadjusted base threshold rather than drifting on insufficient evidence.

## Stage 7 recap: Level 4 — Risk Assessment

### Modules

| Module | File | Responsibility |
|---|---|---|
| Risk types | `risk/types.py` | `TradeOutcome`, `RiskAssessment` — the output contract, with a *list* of veto reasons (not just one) |
| Kelly sizing | `risk/kelly.py` | Optimal position-size fraction for a binary bet |
| Risk of ruin | `risk/ruin.py` | Cramér-Lundberg adjustment-coefficient ruin probability, solved numerically |
| Risk engine | `risk/engine.py` | Stateful: equity curve, circuit breakers, position sizing, the actual veto authority |

### The engine with veto power

Every prior stage produced evidence. This is the first stage that can say no to all of it. `RiskEngine.assess()` runs six independent checks — the upstream EV gate, daily loss, drawdown, consecutive losses, risk of ruin, and expected shortfall — and `approved` is `False` if *any* of them fail, with every failing check's reason collected in `veto_reasons` (not just the first one hit), so a trade that's simultaneously in a drawdown breach and outside its risk-of-ruin budget shows both, not one arbitrarily chosen.

Unlike the ML models in Stages 4-5, this engine needs no offline fit — it's wired to be genuinely stateful and usable live from the start, tracking a real equity curve via `record_trade_result()`.

### Math implemented in Stage 7 (risk assessment)

**Kelly criterion** — optimal fraction of capital for a binary bet with win probability p and reward-to-risk b:
```
f* = (b*p - q) / b,   q = 1 - p,   clipped to [0, 1]
```
Applied as *fractional* Kelly (`kelly_fraction_multiplier`, default 0.25 = quarter-Kelly) — full Kelly is growth-optimal in theory but has ruinous real-world variance, especially when the "edge" itself is a statistical estimate with its own uncertainty rather than a known constant.

**Risk of ruin** — via the Cramér-Lundberg adjustment coefficient (classical ruin theory from actuarial science, applied here to a sequence of trades instead of an insurer's claims process). Model equity as a random walk in stake-units: +w (=reward_to_risk) with probability p, -1 with probability q. The nontrivial root r* of the martingale equation
```
p * r^w + q * r^(-1) = 1
```
gives ruin probability `P(ruin | capital C) = (r*)^C` via the optional stopping theorem. Solved numerically (convexity of the reparametrized equation in θ = -ln(r) guarantees a unique nontrivial root, bracketed and found via Brent's method). A satisfying consistency check: the positive-drift condition this requires (`p*w > q`) is *exactly* the EV>0 condition from Stage 6, restated in these units — verified directly in the tests.

**Expected shortfall (CVaR)** — empirical, from the actual recorded trade history once enough exists:
```
ES_alpha = -mean(worst (1-alpha) fraction of historical trade P&L, as % of equity at the time)
```

### Verified end-to-end (Stage 7)

Ran the Stage 5 Bayesian model's predictions through EV → Risk assessment → simulated real outcomes (win/loss sampled from the model's own claimed probability) across 40 candidate trades on realistic Deriv economics and a $1,000 starting account. The gate chain worked as designed at every layer: negative-EV candidates rejected before reaching risk assessment at all, one thin-edge candidate rejected by the minimum-stake floor, Kelly sizing scaling visibly with the model's confidence (stakes ranged ~$2.50 to ~$20 as EV varied from $0.09 to $1.32), and a live equity curve that actually tracked realized wins and losses, ending at $984 with a real 4.09% drawdown from its peak — exactly the kind of number the drawdown circuit breaker exists to eventually catch.

## Stage 6 recap: Level 3 — Expected Value Estimation

### Modules

| Module | File | Responsibility |
|---|---|---|
| EV types | `expected_value/types.py` | `ContractSpec` (Deriv payout economics), `EVEstimate` — the output contract |
| EV engine | `expected_value/engine.py` | Deterministic EV/reward-risk/risk-adjusted-score computation, with the hard positive-EV gate |

### The simplest stage so far, on purpose

Every prior stage needed fitting (Welford stats, EM, IRLS, gradient boosting) because they were all estimating something uncertain from data. Expected value isn't uncertain once you have a probability and a payout — it's arithmetic. `ExpectedValueEngine.evaluate()` is a pure function: no `fit()`, no training data, no state carried between calls. That's not a shortcut; it's what the math actually calls for here.

### Math implemented in Stage 6 (expected value)

```
EV               = p * payout - stake                    (p = probability of the contract's own direction winning)
EV_pct           = EV / stake
reward_to_risk   = profit_if_win / stake                  (profit_if_win = payout - stake)
win_component    = p * profit_if_win
loss_component   = (1-p) * loss_if_lose                   (loss_if_lose = -stake; negative)
outcome_std      = sqrt( p(1-p) * (profit_if_win - loss_if_lose)^2 )     (Bernoulli two-point-distribution variance)
risk_adjusted_score = EV / outcome_std                    (Sharpe-style ratio for a single bet — a signal-to-noise
                                                             measure, distinct from Level 4's portfolio-level risk)
```

`win_component + loss_component == EV` is checked directly as an identity in the tests — not just "the formula looks right," but "the two ways of computing it agree."

### The hard gate, made concrete

The spec's rule "never execute negative EV trades" is `min_ev_threshold` (default `0.0`) in `ExpectedValueConfig` — `EVEstimate.is_positive_ev` is `False` whenever expected value falls below it, and every rejection carries a `rejection_reason` string, satisfying the spec's explainability requirement that rejected trades explain themselves. Two additional optional gates layer on top: `min_reward_to_risk` (reject positive-EV trades whose payout multiple is too thin to be worth the tail risk) and `min_probability_confidence` (reject trades where the model's edge barely clears 50/50). All three are independently configurable and default to permissive (0.0 / 0.0 / 0.5) so the EV threshold alone drives the gate unless deliberately tightened.

### Verified end-to-end (Stage 6)

Ran the `BayesianLogisticRegression` model (trained in Stage 5's own end-to-end run) through the EV engine against realistic Deriv Rise/Fall economics (stake=10, payout=19 — a ~95% payout ratio, meaning breakeven probability ≈ 52.6%). Of 15 candidate trades, the gate correctly rejected the 2 where the model's edge didn't clear that breakeven line and approved the other 13, with expected value and the risk-adjusted score scaling sensibly as the model's confidence increased.

## Stage 5 recap: Level 2 — Probability Estimation

### Modules

| Module | File | Responsibility |
|---|---|---|
| Probability types | `probability/types.py` | `ProbabilityEstimate`, the shared `ProbabilityEstimator` protocol |
| Bayesian Logistic Regression | `probability/bayesian_logistic.py` | Laplace-approximation Bayesian logistic regression, from scratch in numpy — genuine predictive uncertainty, not just p(1-p) |
| Bagged GBM ensemble | `probability/gbm.py` | Bootstrap ensemble of gradient-boosted trees; uncertainty from cross-member disagreement |
| Platt calibrator | `probability/calibration.py` | Post-hoc probability calibration for any upstream raw score |

### Two probability models, two different sources of uncertainty

- **`BayesianLogisticRegression`** — MAP-fit via Newton-Raphson (IRLS) with a Gaussian prior, then a Laplace approximation to the posterior over weights. Uncertainty comes from `x*^T Sigma x*`: genuine epistemic uncertainty that's larger for points far from the training data in feature space, even when the point estimate is confident. Converges in single-digit iterations in practice (3 on the end-to-end run below).
- **`BaggedGBMEstimator`** — an ensemble of `HistGradientBoostingClassifier` models (scikit-learn's histogram-based gradient boosting — same algorithm family as XGBoost/LightGBM/CatBoost from the spec, lighter dependency footprint, swappable behind the same interface), each trained on an independent bootstrap resample. Uncertainty is the standard deviation of predicted probabilities *across* ensemble members — a different, complementary notion of uncertainty (model disagreement) from the Bayesian model's (posterior spread).
- **`PlattCalibrator`** — a general-purpose post-hoc calibration wrapper (1D logistic regression on raw score → outcome, fit via Newton's method) usable on either model's raw output, or any future model's.

Consistent with the champion/challenger discipline from Stage 4: neither model is wired into `main.py`'s live path in this delivery, since both require labeled historical training data (`fit(X, y)`) that only exists once enough of the pipeline has actually run. Calling `.predict()` before `.fit()` raises loudly on both, exactly like the HMM detector.

### Math implemented in Stage 5 (probability estimation)

**Bayesian Logistic Regression — Newton-Raphson MAP + Laplace posterior:**
```
Gradient:  g(w) = X^T(y - p) - alpha*w
Hessian:   H(w) = -X^T S X - alpha*I,   S = diag(p_i(1-p_i))
Newton:    w_new = w + (X^T S X + alpha*I)^-1 g
Posterior: Sigma = (X^T S X + alpha*I)^-1   at w_map (Laplace approximation)
```

**Predictive probability — MacKay's probit approximation** (handles the fact that integrating a sigmoid against a Gaussian has no closed form):
```
mu_a = w_map^T x*,   sigma_a^2 = x*^T Sigma x*
p(y=1|x*) ≈ sigmoid( mu_a / sqrt(1 + pi*sigma_a^2/8) )
```

**Platt scaling — 1D logistic regression on raw scores, fit via Newton's method:**
```
p_calibrated(s) = sigmoid(A*s + B)
```

### A numerical trap worth knowing about (same family as Stage 4's fix)

Both the Bayesian model's IRLS and Platt's Newton fit clip predicted probabilities away from exactly 0/1 before forming `S = p(1-p)` — without this, a point the current iterate is extremely confident about drives `S` to exactly 0, which can silently zero out that row's contribution to the Hessian and destabilize the Newton step. Small thing, but exactly the kind of edge case that only shows up on real, separable-ish market data rather than toy examples — worth stating explicitly rather than leaving implicit in the code.

### Verified end-to-end (Stage 5)

Both models were fit on 1,899 `MarketState` observations generated by streaming 20,000 simulated ticks through the full Stage 1→3 pipeline, labeled by simple next-candle direction. Bayesian Logistic converged in 3 iterations; the GBM ensemble trained all 10 members; both produced sensible, broadly-agreeing probability estimates with plausible uncertainty on held-out states.

## Stage 4 recap: Level 1 — Market Regime Detection

### Modules

| Module | File | Responsibility |
|---|---|---|
| Regime types | `regime/types.py` | `RegimeLabel` (12 labels), `RegimeClassification`, the shared `RegimeDetector` protocol |
| Rule-based detector | `regime/rule_based.py` | Threshold-based classifier on `MarketState` — the active default, needs zero training data |
| Gaussian HMM core | `regime/hmm.py` | Baum-Welch EM training, scaled forward-backward, incremental live filtering, Viterbi — from scratch in numpy |
| HMM regime detector | `regime/hmm_detector.py` | Wraps the HMM: offline `fit()`, automatic hidden-state → `RegimeLabel` mapping, causal streaming `classify()` |

### Two detectors, one interface, an honest champion/challenger relationship

- **`RuleBasedRegimeDetector`** is what's actually wired into `main.py` right now. Deterministic thresholds on `trend`, `volatility`, `persistence`, `compression_expansion` — available from the very first valid `MarketState`, no training data needed. This is the champion.
- **`GaussianHMMRegimeDetector`** is a challenger: it needs `fit()` called on accumulated historical `MarketState` vectors before `classify()` will even run (calling it unfit raises `HMMNotFittedError` rather than silently returning garbage). Once fit, validated, and proven statistically superior via a proper Champion-Challenger comparison — a later stage, not this one — it can be swapped in.
- Both implement the same `RegimeDetector` protocol (`classify(state) -> RegimeClassification`), so swapping, or later fusing both as independent evidence in the Ensemble Fusion Engine, requires no interface changes.

### Regime labels

`strong_trend, weak_trend, mean_reversion, range, compression, expansion, breakout, false_breakout, transition, random_walk, high_volatility, low_volatility` — matching the spec's list. `false_breakout` and `transition` are intentionally unreachable by the rule-based detector (they need temporal context a single-snapshot rule engine can't see) — reserved for detectors with memory.

### Math implemented in Stage 4 (regime detection)

**Gaussian HMM — diagonal-covariance emission model:**
```
b_i(x) = prod_d N(x_d; mu[i,d], sigma[i,d]^2)     (dims conditionally independent given state)
```

**Baum-Welch (EM), with Rabiner scaling for numerical stability:**
```
Forward:   alpha_hat_t(i) = c_t * b_i(x_t) * sum_j alpha_hat_{t-1}(j) * A(j,i)
Backward:  beta_hat_t(i)  = c_{t+1} * sum_j A(i,j) * b_j(x_{t+1}) * beta_hat_{t+1}(j)
E-step:    gamma_t(i) ∝ alpha_hat_t(i) * beta_hat_t(i)
           xi_t(i,j)  ∝ alpha_hat_t(i) * A(i,j) * b_j(x_{t+1}) * beta_hat_{t+1}(j)
M-step:    pi_i = gamma_1(i);  A(i,j) = sum_t xi_t(i,j) / sum_t gamma_t(i)
           mu_k = sum_t gamma_t(k) x_t / sum_t gamma_t(k)
           sigma_k^2 = sum_t gamma_t(k) (x_t - mu_k)^2 / sum_t gamma_t(k)
log-likelihood = -sum_t log(c_t)
```

A subtlety worth flagging: the emission model rescales each timestep's `b_i(x)` by its max (to prevent `exp()` underflow on bounded [-1,1] features with small variances), which would silently bias the reported log-likelihood by a timestep-and-iteration-dependent constant if left uncorrected — enough to break EM's monotonic-improvement guarantee between iterations. The scale offset is tracked and added back explicitly (`_emission_probs_and_log_scale` / `_forward_backward` in `regime/hmm.py`) so the reported log-likelihood is the true one. Verified directly by `test_log_likelihood_monotonically_nondecreasing_during_em`.

**Live filtering is the same recursion, one step at a time:**
```
forward_step(alpha_hat_{t-1}, x_t) -> alpha_hat_t
```
No lookahead, no stored history beyond the previous step — this is what makes it usable in a real-time loop, and it's proven identical to the batch forward pass via `test_forward_step_matches_batch_forward_filter`.

### Why streaming and batch can't drift apart here either

Same discipline as Stages 2 and 3: `GaussianHMMRegimeDetector.classify()` uses the identical `forward_step` recursion that `GaussianHMM.forward_filter()` uses internally in a loop — verified by `test_streaming_classify_matches_batch_forward_filter`, which replays a sequence live one state at a time and checks it against a full batch replay of the same data.

## Stage 3 recap: Market State Encoder

### Modules

| Module | File | Responsibility |
|---|---|---|
| Online normalizer | `state_encoder/normalizer.py` | Welford's algorithm — streaming mean/std per feature key, O(1) memory, no lookahead |
| State types | `state_encoder/types.py` | `MarketState` — the fixed 11-dimension, bounded [-1,1] "universal state" contract |
| State encoder | `state_encoder/encoder.py` | Combines feature-vector keys into each conceptual dimension via z-score+tanh or direct affine mapping |
| State encoder config | `configs/state_encoder_schema.py` | Which feature keys feed which dimension, and with what weights — fully configurable, not hardcoded |

### The 11 state dimensions

`trend, momentum, acceleration, volatility, noise, persistence, compression_expansion, complexity, uncertainty, liquidity, market_phase` — matching the spec's list (compression and expansion are represented as one signed dimension rather than two, since they're literally opposite signs of the same log-vol-ratio quantity).

### Math implemented in Stage 3 (state encoding)

**Online (Welford) normalization** — streaming mean/variance with no stored history, numerically stable, and causally correct (no lookahead — this is what lets live and backtest runs produce identical z-score sequences given the same chronological data):
```
n += 1; delta = x - mean; mean += delta/n; delta2 = x - mean; M2 += delta*delta2
variance = M2/(n-1),  std = sqrt(variance),  z = (x - mean) / std
```

**Generic dimension combination** (trend, momentum, acceleration, volatility, noise, uncertainty): weighted average of z-scored feature keys, squashed through `tanh` to bound the result in (-1, 1) without hard-clipping outliers.

**Naturally-bounded features mapped directly** (not z-scored, since they're already meaningful on an absolute scale):
- `persistence = clip((hurst_exponent - 0.5) / 0.5, -1, 1)` — H≈0.5 (random walk) → 0; H>0.5 (trending) → positive; H<0.5 (mean-reverting) → negative.
- `complexity = clip((fractal_dimension - 1.5) / 0.5, -1, 1)` — Higuchi FD naturally ranges ~[1,2].

**Compression/expansion** — log-ratio of short-window to long-window volatility:
```
compression_expansion = tanh( ln(std_short / std_long) )
```
Positive = short-term vol exceeds long-term (expansion/breakout-like); negative = short-term vol subdued relative to history (compression).

**Market phase** — explicitly a rough continuous proxy, not the categorical regime classification Level 1 will produce:
```
market_phase = tanh(w_trend * trend + w_compression * compression_expansion)
```

**Liquidity** — deliberately hardcoded to `0.0` with a loud comment explaining why: Deriv's synthetic indices have no real order book, bid/ask spread, or market depth, so there is no genuine liquidity signal to encode. Fabricating a plausible-looking number here would be actively misleading to downstream models; an honest placeholder is kept instead, purely for interface compatibility with the spec's dimension list.

### Why this stays consistent between live and backtest

`OnlineNormalizer` never looks ahead — every z-score is computed from only the observations seen so far, in the order they were fed. Fed the same feature vectors in the same order, two independent encoder instances produce bit-identical `MarketState` output (verified directly in `tests/test_state_encoder.py::test_encode_is_deterministic_given_same_normalizer_state`). The normalizer's running stats are also serializable (`to_dict`/`from_dict`) so they can be persisted (e.g. to Supabase) and restored across restarts rather than re-warming from scratch after every Railway redeploy.

## Stage 2 recap: Feature Engineering Pipeline

### Modules

| Module | File | Responsibility |
|---|---|---|
| Candle aggregator | `data/candle_aggregator.py` | Buckets the tick stream into OHLC candles (bridges Stage 1's tick output to Stage 2's candle input); also tracks `tick_count` per candle, used by Stage 3's liquidity/activity dimension |
| Feature math core | `features/math_utils.py` | Pure numpy functions — one implementation per formula, shared by streaming and offline/batch code |
| Feature vector | `features/types.py` | `FeatureVector` — the output contract for this stage |
| Feature config | `configs/feature_schema.py` | Every window size / parameter, typed and validated |
| Feature pipeline | `features/pipeline.py` | Stateful per-symbol rolling buffer + `compute_feature_vector()` orchestration |

### Features implemented (grouped by family, per the spec's categories)

- **Trend / momentum**: SMA, EMA, WMA (multiple windows), momentum, ROC, velocity, acceleration, MACD (line/signal/histogram), RSI (Wilder's)
- **Volatility**: ATR, rolling variance, rolling std (multiple windows), z-score
- **Statistical / distributional**: Shannon entropy, skewness, excess kurtosis, autocorrelation (multiple lags)
- **Fractal / complexity**: Hurst exponent (R/S analysis), Higuchi fractal dimension

Microstructure/regime-flavored features (compression ratio, support/resistance probability, price clustering, etc.) are deferred to the Market State Encoder / Regime Detection stage, since they're more naturally computed there against regime context rather than as standalone features here.

### Math implemented in Stage 2 (feature formulas)
```
RS = average_gain / average_loss  (over trailing window)
RSI = 100 - 100 / (1 + RS)
```

**MACD**:
```
MACD line   = EMA_fast(price) - EMA_slow(price)
Signal line = EMA_signal(MACD line)
Histogram   = MACD line - Signal line
```

**Hurst exponent** (rescaled range / R-S analysis on log returns):
```
For chunk sizes n:  R/S(n) = avg over chunks of [ (max(cumsum(r-mean)) - min(cumsum(r-mean))) / std(r) ]
log(R/S) = H * log(n) + c     <- H fit via least squares (linear regression slope)
```
H ≈ 0.5 = random walk, H > 0.5 = trending/persistent, H < 0.5 = mean-reverting.

**Higuchi fractal dimension**:
```
For k = 1..k_max: build k subsequences (offset m, step k), compute normalized curve length L(k)
log(L_avg(k)) = -D * log(k) + c    <- D = fractal dimension, bounded in [1,2]
```

**Shannon entropy** (on the return distribution):
```
H = -sum(p_i * log2(p_i))   over histogram bins of the trailing return window
```

### Why streaming and batch can never drift apart

`compute_feature_vector()` in `features/pipeline.py` is a pure function of
(closes, highs, lows, config) → FeatureVector. The streaming
`FeatureEngineeringPipeline` class calls it after buffering; offline
training/backtesting code will call it directly on historical arrays.
There is exactly one code path per formula — verified by
`test_streaming_matches_direct_batch_computation` in
`tests/test_feature_pipeline.py`, which asserts the streaming and direct
batch results are bit-for-bit equal (or both NaN) on the same data.

### Connection layer: REST OTP bootstrap (updated)

Deriv retired the legacy `wss://ws.derivws.com/websockets/v3?app_id=...`
connection pattern. The current flow, implemented in `DerivOTPBootstrap`
(`data/deriv_client.py`):

- **Public / unauthenticated** (all that's needed for Step Index market
  data): connect straight to `wss://api.derivws.com/trading/v1/options/ws/public`.
- **Authenticated** (needed once later stages place trades):
  1. `POST https://api.derivws.com/trading/v1/options/accounts/{account_id}/otp`
     with headers `Deriv-App-ID` and `Authorization: Bearer <api_token>`
  2. Response: `{"data": {"url": "wss://.../ws/demo?otp=..."}}`
  3. Connect to that URL directly.

OTP tokens are short-lived, so a fresh one is requested on **every**
reconnect, not just the first connect — `_resolve_connect_url()` is
called at the top of every connection attempt. The bootstrap logic is
its own class (`DerivOTPBootstrap`), independently unit-tested by
mocking the HTTP call — no live socket needed.

### Math implemented so far

**Price-jump detection** (`data/integrity.py`) — rolling z-score on log returns:

```
r_t = ln(P_t / P_{t-1})
z_t = (r_t - mean(r)) / std(r)     over trailing N returns
```

A tick is flagged `PRICE_JUMP_SUSPECT` if `|z_t| > max_price_jump_sigma`.
This is detection, not rejection — the flag travels with the tick so
downstream layers (e.g. feature engineering) decide how to treat it,
consistent with "no individual model makes trading decisions."

**Reconnect backoff** (`data/deriv_client.py`):

```
backoff_n = min(initial_backoff * multiplier^n, max_backoff)
```

## Running it

Local development (SQLite storage, YAML-only config):

```bash
pip install -r requirements.txt
cp configs/default.yaml configs/local.yaml   # fill in your real Deriv app_id (and account_id/api_token if you need authenticated access)
python main.py --config configs/local.yaml
```

Railway / production (Supabase storage, secrets via env vars — see the
Railway deployment section below for the full variable list and the
Supabase table DDL):

```bash
# In Railway's dashboard, set: DERIV_APP_ID, DERIV_API_TOKEN,
# DERIV_ACCOUNT_ID, STORAGE_BACKEND=supabase, SUPABASE_URL, SUPABASE_KEY
git push   # Procfile/railway.json run `python main.py --config configs/default.yaml`
```

## Testing

```bash
python -m pytest tests/ -v
```

357/357 tests passing. This stage's additions beyond the backtest engine
(see below): `SupabaseTickStore` (upsert batching, HTTP error handling,
symbol/epoch range filtering on read — all against a mocked `aiohttp`
session, no real network calls in the test suite), the config loader's
environment-variable override behavior, `DerivWebSocketClient.fetch_bootstrap_history`
(tested against a faked `websockets.connect` that actually round-trips
through `_listen()`'s real message-handling path, not a shortcut around
it), `PaperTradingOrchestrator` (bootstrap fitting, settlement PnL math
for both wins and losses, per-symbol independence, and a full synthetic
multi-candle run whose trade count and equity change are checked against
the same kind of signal `WalkForwardBacktester` is validated with), and a
`main.py` wiring smoke test that drives real `Tick` objects through the
actual `on_tick -> aggregator -> on_candle -> orchestrator` chain with
`DerivWebSocketClient`'s network calls mocked — this is exactly the kind
of construction-order/closure mistake (wrong attribute names, a callback
wired to the wrong variable) that compiling `main.py` cleanly cannot
catch, since Python only discovers those at call time.

Backtest engine (Stage 12) testing recap: the circular block
bootstrap's structural properties (correct output shape, `block_size=1`
degenerating to values drawn from the original series, within-block
order preserved for `block_size>1`), the Monte Carlo tester's edge cases
(all-positive pnls never ruin, all-negative pnls always ruin), the
empirical-vs-analytical risk-of-ruin cross-validation described above,
the walk-forward backtester's window-indexing arithmetic verified
exactly, and — the two that matter most — the consecutive-loss cooldown
actually recovering after the configured number of evaluations (with
the exact off-by-one timing of tick-and-check-in-the-same-call verified,
not assumed) and the drawdown breaker confirmed to stay hard-stopped
across 50 consecutive evaluations with no trades, only clearing on an
explicit `reset()`.

Stage 11 (Post-Trade Analysis) testing recap: every performance metric
verified against a hand-computed value on a small controlled trade list
(win rate, profit factor including the infinite-with-no-losses edge
case, expectancy, average return, max consecutive losses including the
all-wins zero case, max drawdown, recovery factor, Sharpe, Sortino,
Brier score), calibration verified at both extremes (a perfectly
calibrated synthetic distribution gives exactly zero ECE; a deliberately
miscalibrated one gives ECE > 0.3), the rolling-window behavior
(default window vs an explicit override), and the documented
compounded-drawdown degeneracy for binary options pinned as an explicit
test.

## Design decisions worth knowing about

- **Detection vs. rejection**: the integrity layer flags, it doesn't drop
  (except literal duplicates, per policy). A "suspect" tick is still real
  information for later stages to weigh.
- **Storage is behind a `Protocol`**: swapping SQLite for Postgres/Supabase
  later means writing one new class, not touching any caller.
- **OTP bootstrap is its own class**, separate from the WebSocket client,
  so the REST leg is testable without a live socket and reusable by later
  stages (execution) that also need an authenticated connection.
- **Ordering/duplicates keyed on exchange epoch, not wall clock**: network
  jitter can reorder delivery even when the exchange's own sequence is
  fine — validating on `epoch` avoids false positives from that jitter.
- **No trading logic anywhere in this stage.** Intentional — this is the
  data layer only.
- **Circuit breakers are not all the same shape.** A losing-streak pause
  and a drawdown breach are different kinds of events with different
  correct responses — one should self-heal on a schedule, the other
  should require a human to look at what happened. Treating them
  identically (or, as the pre-fix version of `RiskEngine` did, giving
  neither an explicit reset path) is how a risk system quietly becomes
  either a permanent lockout or a rubber stamp.

## Railway deployment

- **Live decision pipeline** — ✅ done. `main.py` now wires Regime →
  Probability → EV → Risk → Opportunity Scoring → Execution (paper mode)
  → settlement → Post-Trade on every completed candle, via
  `paper_trading/orchestrator.py`'s `PaperTradingOrchestrator`. Before
  live streaming starts, each symbol's probability model is bootstrap-fit
  from historical candles (`DerivWebSocketClient.fetch_bootstrap_history`)
  replayed through the same feature-pipeline/state-encoder instances that
  continue into live streaming, so rolling-window warm-up carries over
  rather than resetting. Set `paper_trading.enabled: false` to fall back
  to the original data-collection + regime-logging-only mode.

  **Deliberate v1 scope, stated up front rather than faked** (see
  `configs/paper_trading_schema.py`'s module docstring for the full
  reasoning): settlement is next-candle-close direction, not a real
  `duration_ticks` expiry (matches the exact label definition the
  probability model is trained on and `WalkForwardBacktester` already
  uses); payout is `stake * assumed_payout_ratio`, not a live Deriv
  proposal (a real `fetch_proposal` call is a natural v1.1 improvement);
  and Level 7 (RL Trade Management) is explicitly NOT wired in — every
  trade holds to its one-candle settlement. This was an explicit,
  agreed-upon scoping decision, not an oversight: RL needs real
  paper-trading data to train against, which doesn't exist until this
  runs for a while first.

- **Ephemeral filesystem** — ✅ done. `SupabaseTickStore` (`data/storage.py`)
  implements the same `TickStore` Protocol as `SQLiteTickStore`; select it
  via `STORAGE_BACKEND=supabase` (env var) or `market_data.storage.backend:
  supabase` in YAML. Requires a `ticks` table in Supabase with a unique
  constraint on `(symbol, epoch)` for the upsert's `on_conflict` to work:
  ```sql
  create table ticks (
      symbol text not null,
      epoch bigint not null,
      quote double precision not null,
      received_at timestamptz not null,
      quality text not null,
      primary key (symbol, epoch)
  );
  create index idx_ticks_symbol_epoch on ticks (symbol, epoch);
  ```
- **Worker process, not web service** — ✅ done. `Procfile` and
  `railway.json` both run `python main.py --config configs/default.yaml`
  as a worker (no HTTP port to bind).
- **Secrets via env vars** — ✅ done. `configs/loader.py` applies a fixed,
  documented set of environment variable overrides on top of the YAML
  (`DERIV_APP_ID`, `DERIV_API_TOKEN`, `DERIV_ACCOUNT_ID`,
  `DERIV_ACCOUNT_TYPE`, `STORAGE_BACKEND`, `SQLITE_PATH`, `SUPABASE_URL`,
  `SUPABASE_KEY`) — deliberately not a generic "any field from env"
  mechanism, to keep the override surface small and auditable. Set these
  in Railway's dashboard; never commit real secrets to `default.yaml`.
- **OTP short lifetime + Railway network blips** — ✅ already was in
  place: the fresh-OTP-per-reconnect design and exponential backoff in
  `data/deriv_client.py` matter more here than in local dev, and were
  built with this in mind from the start.

## What's left

The original spec extends further into infrastructure this delivery
hasn't touched: the Continuous Learning Pipeline (the daily
collect/validate/retrain/paper-trade workflow — this stage's
`WalkForwardBacktester` provides the evaluation harness that pipeline
would call, but not the scheduling/orchestration around it), a Model
Registry with versioning and rollback, Drift Detection (feature,
concept, and performance drift), the actual Champion-Challenger
promotion logic (Stage 4's rule-based-vs-HMM and Stage 5's
Bayesian-vs-GBM framing have been architectural preparation for this —
two interchangeable models behind one interface — but nothing yet
automates "compare and promote"), sequence models (LSTM/GRU/Transformer),
anomaly detection, meta-learning for dynamic ensemble weighting, and a
monitoring dashboard. Built the same way as everything so far when it's
next: one module at a time, math and scope stated up front, unit tested.

The live decision pipeline itself (Regime → Probability → EV → Risk →
Opportunity Scoring → Execution → Post-Trade, paper-trading mode) IS now
wired into `main.py` — see the Railway deployment section above for its
scope and the deliberate v1 simplifications.
