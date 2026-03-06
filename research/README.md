# Wheel Strategy Simulator - AI Research & Optimization

This directory serves as the command center for AI-driven discovery of optimal market environments and trading strategy parameters for the Wheel Strategy Simulator.

## Purpose

The goal is to move beyond manual trial-and-error by deploying programmatic parameter sweeps, stress tests, and algorithmic optimization directly against the core TypeScript simulation engine (`src/components/monte-carlo.ts` and `src/components/strategy/simulate.ts`). 

This document tracks our methodologies, active experiments, and final findings.

---

## AI Optimization Approaches

We employ three main strategies to find the best presets:

### 1. Iterative Grid Search (Parameter Sweep)
**Best for:** Finding the optimal balance between a few key variables (e.g., target delta vs. cycle length).
- **Process:** We define a tight range of values for 2-4 parameters. A CLI script runs the simulation across all permutations.
- **Outcome:** A ranked list of parameter combinations highlighting the trade-offs (e.g., higher returns vs. higher max drawdown).
- **Interaction:** The user reviews the top 5, selects a favorite, and we narrow the grid search around that selection for fine-tuning.

### 2. Market Stress Test (Robustness Optimization)
**Best for:** Ensuring a strategy doesn't blow up when market conditions change.
- **Process:** We define three distinct market presets:
  - **Bull Run** (High drift, low/med vol)
  - **Bear Market** (Negative drift, high vol)
  - **High-Vol Sideways** (Zero drift, extreme vol)
- **Outcome:** We run strategy combinations across *all three* environments simultaneously and score them based on their worst-case performance (identifying the most robust "all-weather" strategy).

### 3. Algorithmic Optimization (Random Search / Simulated Annealing)
**Best for:** Exploring the massive, 20+ dimension parameter space (e.g., `adaptiveCalls`, `ivRvSpread`, `rollPutWhenBelow`, etc.) where grid search is computationally impossible.
- **Process:** A script randomly samples thousands of parameter combinations or uses a simple genetic algorithm to "evolve" the best strategy over generations based on a fitness function (e.g., Sharpe Ratio).
- **Outcome:** Discovers non-intuitive parameter synergies that a human might never try.

---

## Active Workflow

1. **Define the Goal:** State what a "good" strategy looks like (Max Return? Lowest Drawdown? Highest Win rate? Best Sharpe?).
2. **Set the Baseline Market:** Choose the market profile to optimize against.
3. **Execute:** AI writes and runs the search script.
4. **Analyze:** AI presents the top results; user provides feedback and direction.
5. **Save:** Winning combinations are baked into `src/components/presets.ts` as new built-in presets (e.g., "Aggressive Wheel", "Conservative Income").

### Performance Note

Sweep scripts should use **multi-threaded execution** (e.g., Node.js `worker_threads`) to parallelize Monte Carlo paths across available CPU cores. Single-threaded sweeps with 200+ combos × 1,000 paths take unnecessarily long when the machine has many cores idle. This is especially critical for multi-year simulations (5yr = 1,825 daily steps per path) where per-path compute is 5× a 1yr sweep — Exps 12–13 were bottlenecked by single-core execution despite having many cores available.

---

## Log of Findings & Presets

*(This section will be updated as we complete our runs)*

### Experiment 1: High-Vol Sideways Grid Search
- **Goal:** Maximize Sharpe Ratio (Risk-Adjusted Return)
- **Market Baseline:** High-Vol Sideways (0% drift, 150% vol, Heston)
- **Approach:** Iterative Grid Search sweeping `targetDelta` (0.10–0.40), `cycleLengthDays` (3–30), and `skipThreshold` (0–10%) across 1,000 Monte Carlo paths over 365 days. 48 total combinations. Rolling disabled.
- **Results:**
  - **Best Risk-Adjusted:** `delta: 0.1, cycle: 30, skip: 0` — 0.013 Sharpe, 0.54% APR, 35.5% Max DD, 56.8% win rate. Sortino of 7.544 reveals right-skewed returns (upside vol >> downside vol).
  - **Best Nominal Return:** `delta: 0.3, cycle: 30, skip: 0` — 8.92% APR but -0.245 Sharpe and 50.7% Max DD. Uncompensated risk.
  - **Worst Strategy:** `delta: 0.4, cycle: 3, skip: 0.1` — -0.440 Sharpe, 61.5% Max DD, 35.2% win rate. Account destroyer.
- **Key Findings:**
  1. **No parameter combination produces a positive risk-adjusted return.** Best Sharpe is 0.013 (effectively zero). In 150% vol with no drift, the wheel is not a viable standalone strategy.
  2. **30 DTE dominates short DTE.** Short-dated options carry lethal gamma exposure in high-vol chop. 30 DTE gives theta room to work and absorbs gaps. The "sell weeklies" approach is the worst performer.
  3. **Delta is a risk factor, not a return lever.** 0.1→0.4 delta increases APR but Sharpe deteriorates monotonically. You're not paid for the extra drawdown.
  4. **Always be in the market.** Skip threshold (premium filter) hurt performance across every delta/cycle combo. Continuous premium collection offsets drawdowns better than selective entry.
  5. **Sharpe understates the strategy.** The 7.5 Sortino vs 0.01 Sharpe divergence shows the return distribution is right-skewed — Sharpe penalizes upside vol, making the strategy look worse than it is for downside-focused investors.
- **Conclusion:** **The wheel strategy is not suitable for high-volatility sideways markets.** With 150% annualized vol and zero drift, no parameterization produces a meaningful risk-adjusted return. The strategy has no edge in this regime — premium collected is fully consumed by assignment losses and gamma-driven drawdowns. Attempting to optimize within this environment is futile; the correct move is to not deploy the wheel here at all.
- **Action Taken:** Results documented in `research/SWEEP1_ANALYSIS.md`. No presets saved — no combination merits a built-in preset for this regime.

### Experiment 2: Normal-Vol Regime Grid Search
- **Goal:** Find vol regimes where the wheel generates positive risk-adjusted returns (alpha over buy-and-hold).
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, tested at 25% vol (typical equity) and 50% vol (moderate crypto).
- **Approach:** Iterative Grid Search sweeping `targetDelta` (0.10–0.40), `cycleLengthDays` (3–30), and `skipThreshold` (0–10%) across 1,000 Monte Carlo paths over 365 days. 180 total combinations. Rolling disabled.
- **Results:**
  - **Best Risk-Adjusted (50% vol):** `delta: 0.1, cycle: 30, skip: 0` — 0.417 Sharpe, 6.68% APR, 20.69% Max DD, 71.7% win rate, +2.82% alpha.
  - **Best Risk-Adjusted (25% vol):** `delta: 0.20, cycle: 3, skip: 0` — 0.352 Sharpe, 13.17% APR, 21.06% Max DD, 62.1% win rate, +8.67% alpha.
  - **Best Nominal Return:** `vol: 50%, delta: 0.4, cycle: 3, skip: 0` — 21.70% APR but 0.051 Sharpe and 40.18% Max DD. Return trap.
- **Key Findings:**
  1. **The wheel generates genuine alpha in normal-vol regimes.** 43.3% of combos had positive Sharpe. 100% had positive mean APR.
  2. **Stochastic IV reveals divergent optimal strategies by vol level.** 50% vol favors long DTE (30-day); 25% vol favors short DTE (3-day) to capture IV variability.
  3. **50% vol is the sweet spot for conservative strategies.** `delta: 0.1, cycle: 30` tops 50% vol rankings — unchanged from Experiment 1.
  4. **Skip threshold always hurts.** Every top strategy uses `skip: 0`.
  5. **High delta is a return trap.** 21%+ APR at delta 0.4 but Sharpe near zero.
  6. **Stochastic IV deflated static-IV alpha by 25%.** 50% vol best alpha went from +3.77% (static IV) to +2.82% (stochastic IV), confirming the remaining edge is genuine VRP harvesting.
- **Conclusion:** **The wheel is viable at 25–50% vol with mild positive drift, but the optimal strategy is regime-specific.** At 50% vol, conservative parameterization (low delta 0.10, long cycle 30-day) delivers 0.42 Sharpe with +2.8% alpha. At 25% vol, the opposite works: moderate delta (0.15–0.25) with short 3-day cycles delivers 0.35 Sharpe with +6–10% alpha but higher tail risk. High delta is a return trap at 50% vol but viable at 25% vol — the delta-risk relationship is non-linear and vol-dependent.
- **Action Taken:** Full analysis in `research/sweep2/SWEEP2_ANALYSIS.md`. Preset candidates identified ("Conservative Income" at 50% vol, "Active Premium" at 25% vol).

### Experiment 3: Vol Boundary Search
- **Goal:** Find the exact vol level (between 50% and 150%) where Sharpe crosses zero — defining the "wheel deployment zone."
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, vol range 40%–155%.
- **Approach:** Two-phase search. Phase 1: coarse sweep across 24 vol levels (5% increments) × 3 strategies (Conservative δ0.10/30d, Moderate δ0.20/14d, Active δ0.20/3d) × 1,000 paths. Phase 2: fine-grained 1% increment search around detected crossover points. 80,000 total simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d):** Sharpe positive across entire range (40%–155%). Peak Sharpe **0.448 at 60% vol** (8.19% APR, +4.61% alpha, 23.7% MaxDD). No vol ceiling found.
  - **Moderate (δ0.20/14d):** Sharpe crosses zero at **~82% vol**. Peak Sharpe 0.153 at 40% vol (11.64% APR, +7.51% alpha, 28.5% MaxDD).
  - **Active (δ0.20/3d):** Sharpe crosses zero at **~77% vol**. Peak Sharpe 0.157 at 40% vol (14.63% APR, +10.51% alpha, 32.2% MaxDD).
- **Key Findings:**
  1. **The conservative strategy has no practical vol ceiling.** δ0.10/30d maintains positive Sharpe even at 155% vol (0.039). Low delta minimizes gamma exposure; 30-day cycles provide time diversification.
  2. **Higher delta = lower vol ceiling.** The relationship is monotonic: δ0.10 → no ceiling, δ0.20/14d → 82%, δ0.20/3d → 77%. Higher delta amplifies gamma-driven assignment losses that overwhelm premium at high vol.
  3. **The sweet spot is 55%–65% vol.** Conservative strategy peaks at 60% — vol is high enough for meaningful premium but low enough that assignment losses don't consume it.
  4. **Sharpe and APR move in opposite directions.** At 155% vol, conservative earns 20.65% APR (4× the 40% vol return) but Sharpe is only 0.039. Classic return trap.
  5. **Alpha is universal but misleading.** The wheel beats buy-and-hold at every vol level tested in raw return terms. But positive alpha with negative Sharpe means you're not compensated for the risk.
- **Conclusion:** **The vol boundary is strategy-dependent, not universal.** Conservative parameterization (δ0.10/30d) is viable at any vol below ~155%. Moderate/active strategies have firm ceilings at 82%/77% vol respectively. The optimal deployment zone is 55%–65% vol for all strategies. Above 80% vol, only conservative parameterization should be used. For live deployment: monitor 30-day realized vol; exit moderate/active when RV > 75%, exit conservative when RV > 150%.
- **Action Taken:** Full analysis in `research/sweep3/SWEEP3_ANALYSIS.md`. Deployment zone boundaries established for all three strategy profiles.

### Experiment 4: Regime Filter
- **Goal:** Test whether skipping premium selling when IV/RV is below a threshold (no positive variance risk premium) improves risk-adjusted returns.
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, tested at 8 vol levels (40%–150%).
- **Approach:** Sweep `skipBelowRatio` (0, 0.8, 0.9, 1.0, 1.05, 1.1, 1.2, 1.3) × 3 strategies × 8 vol levels × 1,000 paths. 192 total combinations. IV/RV spread scaling enabled (lookback=20, minMult=0.8, maxMult=1.3).
- **Results:**
  - **Conservative (δ0.10/30d):** Best Sharpe 0.494 at 50% vol with skip<1.0 (+0.083 vs baseline). Sweet spot 0.90–1.00.
  - **Moderate (δ0.20/14d):** Best Sharpe 0.341 at 40% vol with skip<1.3 (+0.174). Vol ceiling shifts ~84%→~88%.
  - **Active (δ0.20/3d):** Best Sharpe 0.346 at 40% vol with skip<1.3 (+0.167). Vol ceiling shifts ~76%→~84%.
- **Key Findings:**
  1. **Universally beneficial.** 24/24 strategy-vol combos improved. First parameter with no losers.
  2. **Optimal threshold is strategy-dependent.** Conservative: skip=0.90–1.00. Moderate/Active: skip=1.10–1.20. Higher gamma → higher threshold.
  3. **Raises vol ceilings 5–10pp.** Active 76%→84%, Moderate 84%→88%.
  4. **Aggregate sweet spot: skip=1.10** (+0.056 mean ΔSharpe across all combos).
  5. **Over-filtering (skip=1.30) degrades at high vol** — skips 40%+ of cycles, APR drops 5–15pp for marginal Sharpe gain.
- **Conclusion:** **The regime filter is the most universally effective parameter discovered.** Recommended: `skipBelowRatio=1.0` for conservative, `1.10–1.20` for moderate/active.
- **Action Taken:** Full analysis in `research/sweep4/SWEEP4_ANALYSIS.md`. Engine: `skipBelowRatio` on `IVRVSpreadConfig`, integrated into `computeIVRVMultiplier`.

### Experiment 5: Put-Only Regime Filter
- **Goal:** Determine whether applying `skipBelowRatio` to puts only (always sell calls when holding ETH) improves risk-adjusted returns vs. the current "skip both" behavior from Experiment 4.
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, tested at 8 vol levels (40%–150%).
- **Approach:** Sweep `skipSide` ("both", "put") × `skipBelowRatio` (0, 0.9, 1.0, 1.1, 1.2) × 3 strategies × 8 vol levels × 1,000 paths. 216 unique combinations.
- **Results:**
  - **Conservative (δ0.10/30d):** put-only wins 22/32 combos, mean ΔSharpe +0.008. Best: vol=60%, skip=1.1, side=put → Sharpe **0.503**, APR 10.92%.
  - **Moderate (δ0.20/14d):** put-only wins 28/32 combos, mean ΔSharpe +0.024. Best: vol=40%, skip=1.2, side=put → Sharpe **0.372**, APR 16.44%.
  - **Active (δ0.20/3d):** put-only wins **30/32** combos, mean ΔSharpe **+0.065**. Best: vol=40%, skip=1.2, side=put → Sharpe **0.473**, APR 21.31%. Largest single Sharpe improvement in the research program.
- **Key Findings:**
  1. **Put-only filtering is strictly superior for moderate/active strategies.** Skipping calls leaves naked ETH exposure with zero premium income — call premium cushions drawdowns during low-VRP periods.
  2. **Effect scales with gamma exposure.** Conservative: +0.008 mean ΔSharpe. Moderate: +0.024. Active: +0.065. Higher delta + shorter cycles = more value from keeping calls enabled.
  3. **Vol ceilings extend dramatically.** Active: 76%→92% (+16pp). Moderate: 84%→93% (+9pp). Put-only filtering makes moderate/active strategies viable in significantly more volatile markets.
  4. **APR slightly lower, Sharpe much higher.** Put-only sacrifices 0.3–1.0% APR for 2–5pp lower MaxDD and 2–6pp higher win rates — classic risk-adjustment win.
  5. **Active strategy rehabilitated.** At skip=1.2/put-only/40% vol, Active achieves 0.473 Sharpe — higher than Conservative's baseline 0.41. Previously uncompetitive on risk-adjusted basis.
  6. **Always sell calls when holding ETH.** The VRP regime signal is irrelevant for covered calls — you already own the ETH, so selling calls always reduces risk regardless of IV/RV ratio.
- **Conclusion:** **`skipSide: "put"` should be the default for moderate and active strategies.** There is no scenario where "both" is clearly better for these profiles. For conservative, the effect is small but still net positive. Recommended: `skipBelowRatio=1.2, skipSide="put"` for moderate/active; `skipBelowRatio=1.0–1.2, skipSide="put"` for conservative.
- **Action Taken:** Full analysis in `research/sweep5/SWEEP5_ANALYSIS.md`. Engine: `skipSide` on `IVRVSpreadConfig`, `side` parameter on `computeIVRVMultiplier`.

### Experiment 6: Combined Feature Stack
- **Goal:** Test the full combination of best settings from Experiments 2–5 — regime filter, adaptive calls, call rolling, put rolling, stop-loss — all enabled simultaneously. Answer: Do features stack additively or interfere?
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, tested at 4 vol levels (40%, 60%, 80%, 100%).
- **Approach:** Full factorial over 5 binary feature toggles × 3 strategies × 4 vol levels. Conservative/Moderate: 2^5 = 32 combos; Active: 2^4 = 16 (no put rolling). 320 total configurations × 1,000 paths = 320,000 simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d):** Best config **RF+AC+PR** (Regime Filter + Adaptive Calls + Put Rolling). Sharpe 0.569 at 40% vol, 0.515 at 60%. Robust across all vol levels.
  - **Moderate (δ0.20/14d):** Best config **RF** or **RF+PR** (Regime Filter ± Put Rolling). Sharpe 0.422 at 40% vol, 0.323 at 60%. Adaptive calls harmful (-0.011 to -0.071 ΔSharpe).
  - **Active (δ0.20/3d):** Best config **RF only** (Regime Filter alone). Sharpe **1.044** at 40% vol — highest risk-adjusted return in entire research program. 33.94% APR, 15.1% MaxDD, 86.2% win rate.
- **Key Findings:**
  1. **Features do NOT stack additively.** The dominant feature (regime filter, +0.186 mean ΔSharpe) provides the vast majority of improvement. Adding more features yields diminishing or negative returns.
  2. **Adaptive Calls are strategy-dependent.** Beneficial for Conservative (low δ0.10, +0.083–0.118 marginal), but harmful for Moderate/Active (higher δ0.20, -0.011 to -0.383 marginal). Conflicts with regime filter at higher delta: -0.231 interaction for Active.
  3. **Stop-Loss has zero impact.** Zero triggers across all 320 configurations. The wheel strategy's cycling structure inherently limits drawdowns below the 25% threshold. Stop-loss is not redundant because of filtering — it's structurally unnecessary.
  4. **Call Rolling has zero impact.** At δ0.10–0.20, calls are sold far enough OTM that the 5% ITM threshold for rolling is never triggered.
  5. **Put Rolling helps Conservative only.** +0.020 mean ΔSharpe. Extends OTM put duration, reducing whipsaw. Weakly positive for Moderate at higher vol, disabled for Active (3d cycle too short).
  6. **Full stack actively degrades Active.** At 60% vol: full stack 0.302 Sharpe vs RF-only 0.797 — a -0.495 loss. More features ≠ better.
  7. **Less is more.** Optimal feature count: Conservative=3 (RF+AC+PR), Moderate=1–2 (RF or RF+PR), Active=1 (RF only).
- **Conclusion:** **The regime filter is the single most important feature, and it's sufficient alone for Moderate/Active strategies.** Conservative benefits from layering adaptive calls and put rolling on top, but only because its low delta avoids the filter-adaptive conflict. Stop-loss and call rolling should default to OFF — they contribute nothing at the tested parameter ranges. The Active strategy with regime filter alone (1.044 Sharpe at 40% vol) is the strongest risk-adjusted configuration discovered in the research program.
- **Action Taken:** Full analysis in `research/sweep6/SWEEP6_ANALYSIS.md`. Presets updated: Conservative (δ0.10/30d, RF+AC+PR), Moderate (δ0.20/14d, RF+PR), Aggressive (δ0.20/3d, RF only).

### Experiment 7: Drift Sensitivity
- **Goal:** Test whether the Exp 6 optimal configs remain viable across different drift regimes. All prior experiments assumed 5% annual drift. Crypto drift ranges from -80% (bear) to +200% (bull).
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), tested at 6 drift levels (-30%, -10%, 0%, +5%, +20%, +50%) and 4 vol levels (40%, 60%, 80%, 100%).
- **Approach:** Each strategy tested with optimal config (RF ON) and baseline (RF OFF) across all drift × vol combos. 144 total combinations × 1,000 paths = 144,000 simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d, RF+AC+PR):** Sharpe positive at 20/24 combos (83%). Fails only at -30% drift (all vol levels). Best: +50% drift / 40% vol → Sharpe 1.477. Crossover at ~-17% to -25% drift depending on vol.
  - **Moderate (δ0.20/14d, RF+PR):** Sharpe positive at 20/24 combos (83%). Fails only at -30% drift. Best: +50% drift / 40% vol → Sharpe 1.245. Crossover at ~-11% to -18% drift depending on vol.
  - **Active (δ0.20/3d, RF only):** **Sharpe positive at ALL 24/24 combos (100%).** Even at -30% drift / 100% vol: Sharpe 0.296, APR 34.86%, 66.5% win rate. Best: +50% drift / 40% vol → Sharpe 1.765.
- **Key Findings:**
  1. **Active is drift-immune.** Positive Sharpe across the entire tested parameter space (-30% to +50% drift, 40-100% vol). The regime filter naturally adapts by skipping more put cycles in adverse conditions; the ~6% of cycles it accepts remain profitable. No drift guard needed.
  2. **Conservative/Moderate fail only at -30% drift.** At -10% drift, both strategies are viable across all vol levels. Deployment floor is approximately -15% (Conservative) to -10% (Moderate) annual drift.
  3. **Regime filter wins 72/72 combinations (100%).** Not a single case where removing RF improves Sharpe. RF's value *increases* in bear markets: Active ΔSharpe from RF is +0.308 at -30% drift vs +0.177 at +50% drift.
  4. **Skip rates are insensitive to drift.** Conservative: 98-99% skip at any drift. Active: ~94%. The filter is not over-skipping in bear markets — skip rates vary <2% across drift levels.
  5. **Alpha inverts with drift.** The wheel generates massive alpha in bear markets (+54% avg for Active at -30% drift) and trails buy-and-hold in strong bulls (-34% for Conservative at +50% drift). The wheel is a bear market outperformer that trades upside participation for downside protection.
  6. **Drift sensitivity is monotonic and smooth.** No regime cliffs or non-linear breakpoints. Sharpe degrades linearly with decreasing drift, enabling simple linear deployment rules.
  7. **Exp 6 configs are drift-stable.** RF ON is optimal at every drift × vol × strategy combination. No need for drift-specific preset configurations.
- **Conclusion:** **Active (δ0.20/3d, RF only) is the all-weather strategy.** It maintains positive risk-adjusted returns across the entire tested drift × vol space, generating +54% alpha over buy-and-hold in deep bear markets while still delivering 1.765 Sharpe in strong bulls. Conservative/Moderate need a drift guard (exit when trailing annualized return < -15%/-10%) but are otherwise robust. The regime filter is universally beneficial and becomes *more* valuable in adverse drift conditions. No changes to preset configurations are needed — Exp 6 optimal configs are drift-regime invariant.
- **Action Taken:** Full analysis in `research/sweep7/SWEEP7_ANALYSIS.md`. Deployment zone updated with drift boundaries. No preset changes — Exp 6 configs confirmed stable across drift regimes.

### Experiment 8: VRP Sensitivity
- **Goal:** Test whether the regime filter and strategy viability depend on the assumed Variance Risk Premium (VRP). All prior experiments assumed VRP=15%. The regime filter explicitly exploits VRP — if real VRP is lower, the filtering signal degrades and the entire framework may be overfitted.
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5), VRP varied from 0% to 25%, tested at drift levels 0% and -30%, vol levels 40%–100%.
- **Approach:** Sweep VRP (0%, 5%, 10%, 15%, 25%) × drift (0%, -30%) × vol (40%, 60%, 80%, 100%) × 3 strategies × 2 configs (Optimal RF ON, Baseline RF OFF) × 1,000 paths. 240 total combinations = 240,000 simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d, RF+AC+PR):** At drift=0%, viable (Sharpe>0) at VRP≥5%. At drift=-30%, not viable at any tested VRP except VRP=25% at vol≥60%. Avg Sharpe ranges from -0.150 (VRP=0%) to 0.300 (VRP=25%).
  - **Moderate (δ0.20/14d, RF+PR):** At drift=0%, viable at VRP≥10%. At drift=-30%, not viable at 40-60% vol even at VRP=25%. Avg Sharpe ranges from -0.187 (VRP=0%) to 0.172 (VRP=25%).
  - **Active (δ0.20/3d, RF only):** At drift=0%, viable at VRP≥5% (all vol≤80% at VRP=0%). At drift=-30%, viable at VRP≥10%. Avg Sharpe ranges from 0.060 (VRP=0%) to 0.889 (VRP=25%). Drift-immune at VRP≥10%.
- **Key Findings:**
  1. **Regime filter wins 120/120 combinations — universally beneficial at every VRP level.** Even at VRP=0%, RF improves Sharpe for every strategy × drift × vol combo. RF value *inversely* correlates with VRP: Active ΔSharpe is +0.517 at VRP=0% vs +0.164 at VRP=25%. RF exploits IV/RV *variance*, not just mean VRP.
  2. **Active's drift immunity breaks below VRP=10%.** At VRP=15%: 8/8 positive (confirming Exp 7). At VRP=10%: still 8/8. At VRP=5%: 7/8 (fails at -30% drift / 100% vol). At VRP=0%: 4/8 failures. The drift immunity threshold is VRP≥10%.
  3. **VRP=10% is the practical deployment floor.** Below 10%: Active loses drift immunity, Moderate has negative avg Sharpe, Conservative near-zero even at drift=0%. Above 10%, framework is robust.
  4. **Sharpe scales linearly with VRP — no cliff edges.** ~+0.16 Sharpe per 5pp of VRP for Active (constant slope). Framework degrades gracefully, not catastrophically. Interpolation between tested levels is reliable.
  5. **Skip rates are VRP-insensitive.** Active: 97.0% skip at VRP=0% vs 91.0% at VRP=25% — the filter finds transient IV>RV windows even with zero mean VRP. Confirms RF exploits stochastic IV variance, not just the VRP offset.
  6. **The framework is NOT overfitted to VRP=15%.** Active achieves positive Sharpe at VRP=0% / drift=0% (avg 0.195). RF is universally beneficial. Feature stack ranking unchanged. The 15% assumption provides comfortable margin, not structural dependence.
  7. **`skipBelowRatio` thresholds do not need recalibration.** RF helps at every VRP level with no sign of the current thresholds (1.0 Conservative, 1.2 Moderate/Active) being suboptimal at low VRP.
- **Conclusion:** **VRP=10% is the deployment floor for the framework.** Below this, Active loses drift immunity and Conservative/Moderate produce negative Sharpe. The regime filter is VRP-independent — it helps at every level tested, with value increasing as VRP decreases. The framework is not overfitted to VRP=15%; Active remains viable down to VRP≈0% in non-bear markets. For live deployment: estimate trailing IV-RV spread; if below 10%, restrict to Active only; if below 5%, reduce sizing or pause.
- **Action Taken:** Full analysis in `research/sweep8/SWEEP8_ANALYSIS.md`. Deployment zone updated with VRP floor. No preset changes — Exp 6 configs confirmed stable across VRP regimes.

### Experiment 9: Model Robustness
- **Goal:** Test whether the Exp 6 optimal configs remain viable across all 4 price models (GBM, Heston, Jump, Heston-Jump). All prior experiments used GBM only.
- **Market Baseline:** 4 models × 3 vol levels (40%, 60%, 80%) × 3 drifts (+5%, 0%, −30%). GBM/Jump: stochastic OU IV (κ=5, ξ=0.5, VRP=15%). Heston/Heston-Jump: IV from variance process √v. Heston: κ=2, σ=0.5, ρ=−0.7, θ=vol². Jump: λ=10, μJ=0, σJ=0.05.
- **Approach:** Each of 3 strategies tested with Optimal (RF ON) and Baseline (RF OFF) across all model × drift × vol combos. 216 total combinations × 1,000 paths = 216,000 simulation paths.
- **Results:**
  - **GBM:** Avg Sharpe 0.345, 21/27 positive. Active 9/9 positive, drift-immune. Baseline control.
  - **Jump:** Avg Sharpe 0.272, 21/27 positive. Active 9/9 positive, drift-immune. −21% Sharpe vs GBM.
  - **Heston:** Avg Sharpe **−0.216**, 5/27 positive. Active 0/9 positive. Moderate 0/9 positive. Conservative 5/9 positive (marginal, 0.042–0.146 Sharpe at drift ≥ 0%).
  - **Heston-Jump:** Avg Sharpe **−0.289**, 2/27 positive. Every strategy fails at nearly every combo.
- **Key Findings:**
  1. **The IV path source is the critical differentiator.** GBM/Jump (OU-based IV) work; Heston/Heston-Jump (variance-based IV) fail. The split is clean and absolute. Jump processes are benign (−21% Sharpe); stochastic variance is the Achilles' heel (−143% to −360% Sharpe).
  2. **The regime filter was implicitly calibrated on OU-generated IV/RV signals.** OU produces smooth, normally-distributed IV paths with predictable mean-reversion. Heston's variance process produces clustered vol with abrupt transitions. Under Heston, the filter skips ~3% more cycles but accepted-trade win rates collapse from 78% to 47%.
  3. **RF is still beneficial under Heston for Moderate/Active (9/9 wins each)** but can't rescue them. Exception: RF *hurts* Conservative under Heston (1/9 wins, −0.018 ΔSharpe) — at δ0.10 with 99%+ skip rates, the filter's few accepted trades are net-negative.
  4. **Active's drift immunity breaks completely under Heston.** 0/9 positive — fails at every drift × vol combo including +5%/40% (Sharpe −0.200). This is not a bear market problem; the strategy is fundamentally non-viable under stochastic variance dynamics.
  5. **The "all-weather" claim requires model qualification.** Active: 18/36 combos positive (all 18 failures under Heston-family). Corrected: "all-weather under diffusion models (GBM, Jump); non-viable under stochastic variance models (Heston, Heston-Jump)."
  6. **Jump processes are benign.** Merton jumps reduce Sharpe by ~21% but preserve all qualitative properties: drift immunity, RF universality (27/27), positive Sharpe at all combos. No assignment cascades observed.
  7. **MaxDD increases are moderate under Heston** (+2–6pp vs GBM). The problem is insufficient return, not excess drawdown. The strategy loses money slowly, not through blowups.
- **Conclusion:** **The framework is model-dependent, not model-robust.** It works under GBM and Jump (OU-based IV), fails under Heston and Heston-Jump (variance-based IV). The regime filter's IV/RV signal degrades under Heston dynamics due to vol clustering and abrupt regime transitions. No preset changes are needed — the issue is structural, not parametric. For live deployment: the framework's edge depends on IV/RV dynamics that follow OU-like mean-reversion. Monitor IV/RV autocorrelation; if clustering is detected (ACF > 0.5 at lag 1), reduce sizing or pause. Experiment 11 (Lookback × Cycle Interaction) should now be tested under both GBM and Heston to determine if lookback tuning can recover Heston performance.
- **Action Taken:** Full analysis in `research/sweep9/SWEEP9_ANALYSIS.md`. "All-weather" claim qualified. Deployment zone updated with model condition. No preset changes — structural mismatch, not parameter issue.

### Experiment 10: Lookback × Cycle Interaction
- **Goal:** Determine whether tuning `lookbackDays` (hardcoded at 20 in all prior experiments) can (a) improve GBM performance and (b) recover positive Sharpe under Heston — the critical path question from Exp 9.
- **Market Baseline:** GBM and Heston, stochastic IV (OU for GBM: κ=5.0, ξ=0.5, VRP=15%; variance-derived for Heston), tested at 2 drift levels (0%, −30%) and 2 vol levels (40%, 60%).
- **Approach:** Sweep `lookbackDays` (5, 10, 15, 20, 30, 45, 60) × 2 models × 2 drifts × 2 vols × 3 strategies × 2 configs (RF ON/OFF) × 1,000 paths. 336 total combinations = 336,000 simulation paths.
- **Results:**
  - **GBM Conservative (δ0.10/30d):** Best lookback **45d**, Sharpe 0.126 (+0.025 vs 20d). The only above-threshold improvement.
  - **GBM Moderate (δ0.20/14d):** Best lookback 30d, Sharpe 0.052 (+0.018 vs 20d). Sub-threshold.
  - **GBM Active (δ0.20/3d):** Best lookback 30d, Sharpe 0.658 (+0.018 vs 20d). Sub-threshold. 4/4 positive at every lookback.
  - **Heston Conservative:** Best lookback 60d, Sharpe **−0.278** (1/4 positive). No recovery.
  - **Heston Moderate:** Best lookback 30d, Sharpe **−0.307** (0/4 positive). No recovery.
  - **Heston Active:** Best lookback 30d, Sharpe **−0.371** (0/4 positive). No recovery.
- **Key Findings:**
  1. **Lookback tuning CANNOT recover Heston performance.** No lookback value achieves positive Sharpe for Moderate or Active under Heston. The best improvements are marginal (ΔSharpe +0.01–0.04), and zero conditions flip from negative to positive. The GBM-Heston win rate gap (−7 to −33pp) is persistent and unclosable at any lookback.
  2. **Optimal GBM lookback is 30–45d, not 20d.** Longer lookback windows smooth the realized vol estimate, producing more stable IV/RV ratios. Conservative benefits most (45d, +0.025 ΔSharpe). All three strategies peak at 30d+, but Moderate/Active improvements are below the 0.02 significance threshold.
  3. **No lookback/cycle ratio rule exists.** The hypothesis that lookback ≈ 2× cycle length does not hold. Active converges to 30d despite its 3-day cycle (ratio 10×). There's a **floor around 30d** driven by the minimum sample size for meaningful RV estimation, irrespective of trade frequency.
  4. **Short lookback (5d) hurts every strategy.** 5d lookback produces the worst Sharpe at 5/6 model × strategy combinations. The noisy RV estimate at 5d degrades the regime filter's signal quality. Minimum viable lookback is 15d.
  5. **RF is universally beneficial at lookback ≥ 15d under GBM.** Below 15d, Conservative's RF signal degrades (2–3/4 wins instead of 4/4). For Moderate/Active, RF helps at every lookback under both models.
  6. **RF hurts Conservative under Heston at short lookbacks.** At 5–15d, RF produces negative ΔSharpe for Conservative under Heston — the only model × strategy × lookback combination where RF is harmful. At δ0.10 with 99%+ skip rates, the few admitted trades are net-negative under Heston dynamics.
  7. **Skip rate increases monotonically with lookback.** Longer lookback → more stable RV → more conservative filtering → fewer trades. GBM Active: 88.9% (5d) → 94.8% (30d). The 30d lookback hits the optimal accuracy/frequency tradeoff.
- **Conclusion:** **The Heston failure is structural, not parametric — lookback tuning cannot solve it.** The regime filter's IV/RV signal fundamentally degrades under Heston's variance clustering, regardless of how much price history is used for RV estimation. For GBM, the default lookback of 20d is near-optimal; Conservative benefits from extending to 45d (+0.025 ΔSharpe), while Moderate/Active see sub-threshold improvements at 30d. The absolute minimum viable lookback is 15d. Proceed to Exp 11 (Heston skip threshold recalibration) as the next recovery attempt; if that also fails, close the Heston investigation.
- **Action Taken:** Full analysis in `research/sweep10/SWEEP10_ANALYSIS.md`. Conservative preset lookback updated: 20d → 45d. Heston recovery remains open → Exp 11.

### Experiment 11: Heston Skip Threshold Recalibration
- **Goal:** Last Heston recovery attempt. Test whether recalibrating `skipBelowRatio` under Heston-specific IV/RV distributions restores positive Sharpe. If this also fails, close the Heston investigation permanently.
- **Market Baseline:** Heston (κ=2, σ=0.5, ρ=−0.7, θ=vol²), tested at 2 drift levels (+0%, +5%) and 2 vol levels (40%, 60%). Lookbacks from Exp 10: Conservative=60d, Moderate/Active=30d.
- **Approach:** Sweep `skipBelowRatio` (0.8, 0.9, 1.0, 1.1, 1.2, 1.3, 1.4, 1.5, 1.6, 1.8, 2.0) × 2 drifts × 2 vols × 3 strategies × RF ON + RF OFF baselines. 144 Heston combinations × 1,000 paths = 144,000 simulations. GBM cross-validation: 32 additional combos.
- **Results:**
  - **Conservative (δ0.10/30d):** Best threshold **0.9**, avg Sharpe **0.089**, 3/4 positive. But RF OFF baseline is better (avg Sharpe 0.103). RF hurts Conservative under Heston — confirmed.
  - **Moderate (δ0.20/14d):** Best threshold **1.2** (same as GBM), avg Sharpe **−0.054**, **0/4 positive**. No recovery. RF improves vs baseline (−0.182) but can't reach positive.
  - **Active (δ0.20/3d):** Best threshold **1.1**, avg Sharpe **−0.199**, **0/4 positive**. No recovery. RF improves vs baseline (−0.255) but can't reach positive.
- **Key Findings:**
  1. **Threshold recalibration FAILS to recover Heston.** Only 3/12 total combos achieve positive Sharpe — all Conservative. Moderate: 0/4. Active: 0/4. No threshold in the 0.8–2.0 range restores positive risk-adjusted returns for Moderate or Active under Heston.
  2. **Conservative RF OFF is confirmed superior under Heston.** RF OFF wins 3/4 conditions. At 40% vol, RF actively degrades Conservative Sharpe by 0.02–0.03. At 60% vol, RF has zero effect. The δ0.10/30d cycle already over-filters at 98%+ skip rates.
  3. **Higher thresholds monotonically degrade Sharpe.** Unlike GBM where 1.0–1.2 is optimal, under Heston Conservative collapses to −2.7 Sharpe at t=2.0. With 99.9% skip and 0.2 cycles/year, the rare accepted trades are random draws from Heston's fat tails.
  4. **Win rates improve with threshold but can't reach GBM levels.** Active plateaus at ~57% by t=1.5 — far below GBM's ~78%. The filter removes the worst trades but remaining accepted trades still have sub-50% per-cycle win rates under Heston.
  5. **GBM presets confirmed optimal.** Cross-validation shows Heston-optimal thresholds would degrade GBM: Active loses −0.034 Sharpe at t=1.1 vs t=1.2. No changes to existing `skipBelowRatio` values.
  6. **Root cause identified (synthesis of Exps 9–11).** Heston's variance-derived IV exhibits vol clustering with abrupt regime transitions. The IV/RV ratio under Heston signals vol regime shifts, not transient premium opportunities. All parametric solutions (lookback, threshold) fail because they can't distinguish vol regimes from trade opportunities — the filter needs a fundamentally different signal.
- **Conclusion:** **HESTON INVESTIGATION CLOSED.** Three independent recovery attempts (model testing Exp 9, lookback tuning Exp 10, threshold recalibration Exp 11) all fail. The wheel strategy under Heston dynamics is structurally non-viable for Moderate and Active. Conservative is marginally viable with RF OFF (avg Sharpe 0.103) but earns <1% APR with <2 trades/year — not deployable. No preset changes needed. For live deployment: monitor IV/RV autocorrelation; if clustering is detected (ACF > 0.5 at lag 1), the framework's edge does not exist.
- **Action Taken:** Full analysis in `research/sweep11/SWEEP11_ANALYSIS.md`. Heston investigation closed. No preset changes — all GBM thresholds confirmed optimal.

### Experiment 12: Multi-Year Horizon
- **Goal:** Test whether the Exp 6 optimal configs remain viable over 2-year and 5-year horizons. All prior experiments used 365-day simulations. Key questions: does Active's drift immunity survive sustained multi-year decline? Does the regime filter's ~94–97% skip rate compound differently? Are `skipBelowRatio` thresholds stable? How does MaxDD evolve?
- **Market Baseline:** GBM and Jump (Heston closed per Exp 11), 60% vol (Exp 3 sweet spot), stochastic IV (OU process, κ=5.0, ξ=0.5). Tested at 3 drift levels (0%, +5%, −30%) and 2 VRP levels (10%, 15%).
- **Approach:** Sweep horizons (365d, 730d, 1825d) × drift (0%, +5%, −30%) × VRP (10%, 15%) × model (GBM, Jump) × 3 strategies × 2 configs (RF ON/OFF). 216 total combinations × 1,000 paths = 216,000 simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d, RF+AC+PR):** Sharpe collapses: 0.262 (1yr) → −0.077 (2yr) → **−0.287 (5yr)**. 0/12 positive at 5yr. MaxDD: 26.2% → 59.3% (2.27×, linear growth). Only 0.4–1.6 executed cycles over entire period — too few trades to recover from multi-year drawdowns.
  - **Moderate (δ0.20/14d, RF+PR):** Sharpe degrades: 0.076 (1yr) → 0.006 (2yr) → **−0.057 (5yr)**. 7/12 positive at 5yr. MaxDD: 31.4% → 43.8% (1.40×, saturating). APR stable at ~13% across all horizons.
  - **Active (δ0.20/3d, RF only):** Sharpe stable: **0.506 (1yr) → 0.483 (2yr) → 0.397 (5yr)**. **11/12 positive at 5yr.** MaxDD: 23.0% → 28.6% (1.25×, saturating). APR stable at ~29% across all horizons. 38+ executed trades over 5yr provide continuous premium income.
- **Key Findings:**
  1. **Active is the only multi-year viable strategy.** Sharpe declines only 22% over 5yr (vs −209% Conservative, −175% Moderate). High cycle frequency (38+ trades) continuously generates premium to offset drawdowns. At 5yr: 11/12 positive, 28.5% APR, 28.6% MaxDD.
  2. **Active's drift immunity survives 5 years.** At −30% drift: Sharpe 0.280 (1yr) → 0.100 (5yr), APR 12%, MaxDD 27.5%, +28% alpha over buy-and-hold. Single failure: Jump/VRP=10%/−30% at 5yr (Sharpe −0.005 — essentially zero). Compounding drawdown does NOT overwhelm premium income.
  3. **Conservative is a 1-year strategy only.** Every 5yr combination — including +5% drift / VRP=15% — produces negative Sharpe. The 99.2–99.8% skip rate executes only 0.4–1.6 cycles over 5 years, providing no drawdown recovery.
  4. **MaxDD behavior is strategy-dependent.** Active: saturating at ~29% (1.25× over 5yr). Moderate: saturating at ~44% (1.40×). Conservative: linear growth to 59% (2.27×). Active's high trade frequency caps MaxDD; Conservative's near-zero trades allow unbounded drawdown accumulation.
  5. **RF is universally beneficial at ALL horizons.** 108/108 wins — the most comprehensive universality test. For Active, RF ΔSharpe is stable-to-increasing: +0.316 (1yr) → +0.335 (5yr). For Conservative, RF value shrinks: +0.099 → +0.050, but still positive.
  6. **Skip rates are horizon-invariant.** Active: 95.2% (1yr) → 95.5% (5yr). Moderate: 97.6% → 97.7%. Conservative: 99.2% → 99.8%. The regime filter's acceptance rate is a property of the IV/RV stochastic process, not simulation length. No `skipBelowRatio` recalibration needed for longer horizons.
  7. **VRP=10% floor weakens at 5yr for Conservative/Moderate** (0/6 and 3/6 positive respectively) but holds for Active (5/6, avg Sharpe 0.329).
  8. **Jump processes are benign over multi-year horizons.** GBM-Jump Sharpe gap for Active: 1yr=+0.106 → 5yr=+0.119 — gap does not widen. No compounding jump damage.
- **Conclusion:** **Multi-year deployment is viable for Active only.** Active (δ0.20/3d, RF only) maintains 0.397 Sharpe and 28.5% APR at 5yr with saturating MaxDD (~29%), powered by 38+ executed trades that continuously generate premium. Active's drift immunity survives even a sustained 5-year bear market (−30% drift → 0.100 Sharpe, 12% APR). Conservative and Moderate are short-horizon strategies (≤1yr) — Conservative's extreme skip rate (99%+) produces too few trades for multi-year drawdown recovery. RF is universally beneficial (108/108 wins) and skip rates are horizon-invariant. No preset changes needed — the finding is about deployment horizon, not parameterization.
- **Action Taken:** Full analysis in `research/sweep12/SWEEP12_ANALYSIS.md`. No preset changes. Deployment guidance updated: Active for multi-year, Conservative/Moderate for ≤1yr only.

### Experiment 13: Execution Cost Sensitivity
- **Goal:** Determine whether Active's edge survives realistic Deribit execution friction. All prior experiments assumed fixed 5% bid-ask spread and $0.50 fee per trade. Real Deribit spreads vary by delta, expiry, and liquidity (1–15% for far OTM options).
- **Market Baseline:** GBM with stochastic IV (OU process, κ=5.0, ξ=0.5, VRP=15%), 5% annual drift, tested at 2 vol levels (40%, 60%).
- **Approach:** Sweep `bidAskSpreadPct` (1%, 3%, 5%, 8%, 12%) × `feePerTrade` ($0.25, $0.50, $1.00, $2.00) × 3 strategies × 2 vol levels × 2 horizons (1yr, 5yr). 240 total combinations × 1,000 paths = 240,000 simulation paths.
- **Results:**
  - **Conservative (δ0.10/30d, RF+AC+PR):** 1yr Sharpe positive at all costs (0.324–0.657). 5yr Sharpe near-zero at 40% vol (0.105 best), negative at 60% vol at all costs. 0/40 combos achieve Sharpe ≥ 0.20 at 5yr.
  - **Moderate (δ0.20/14d, RF+PR):** 1yr Sharpe positive at all costs (0.132–0.522). 5yr Sharpe positive at all but one combo (12%/$2.00/60%vol → −0.003). 19/40 combos achieve Sharpe ≥ 0.20 at 5yr.
  - **Active (δ0.20/3d, RF only):** **Sharpe positive at ALL 80/80 combos.** 1yr: 0.475–1.189. 5yr: 0.389–1.236. **40/40 combos achieve Sharpe ≥ 0.20 at 5yr** — including worst case (12% spread, $2.00 fee, 60% vol → Sharpe 0.389, APR 35.44%).
- **Key Findings:**
  1. **Active's edge is cost-immune.** Sharpe never crosses zero at any tested cost level, vol, or horizon. Even at extreme worst case (12%/$2.00/60%vol/5yr), Active maintains 0.389 Sharpe and 35.44% APR. The "all-weather" designation survives realistic execution friction.
  2. **Active is the least cost-sensitive per trade.** Despite 20× more trades than Conservative, Active loses only −0.0602 Sharpe per executed cycle vs Conservative's −0.6444 (10.7× worse). Higher trade frequency amortizes cost per unit of premium income.
  3. **Active's multi-year advantage is cost-invariant.** 1yr→5yr Sharpe decay is ≤3.8% for Active at any cost level. Conservative collapses 92–119%, Moderate degrades 30–63%. Costs do not amplify Active's time decay.
  4. **Conservative is 1yr-only (now cost-qualified).** At realistic costs (8%/$1.00), 5yr Sharpe is −0.025. Even at lowest cost (1%/$0.25), 5yr Sharpe is 0.048/40%vol and negative at 60%vol.
  5. **No strategy ranking reversal at any cost level.** Active > Moderate > Conservative at every tested (spread, fee, vol, horizon) combination. There is no scenario where Moderate becomes the practical choice over Active due to friction.
  6. **Spread dominates fee as cost driver.** Spread contributes ~3–5× more Sharpe erosion per unit increase than fee per trade. Optimizing execution quality (tighter spreads via limit orders) matters more than fee negotiation.
  7. **At conservative Deribit costs (8%/$1.00), Active delivers 0.784 Sharpe and 33.19% APR at 1yr, 0.768 Sharpe and 39.81% APR at 5yr.** These are deployment-grade returns.
- **Conclusion:** **Execution costs do not threaten the framework's viability.** Active (δ0.20/3d, RF only) maintains Sharpe ≥ 0.39 even at extreme cost assumptions over 5 years. The strategy's high trade frequency, counterintuitively, makes it the most cost-resilient — each trade is a small fraction of total return, so per-trade friction is diluted across ~40 executed cycles over 5yr. The prior "all-weather" claim for Active is strengthened. For live deployment: focus on minimizing bid-ask spread (use limit orders, avoid illiquid strikes) rather than fee negotiation — spread is the dominant cost factor.
- **Action Taken:** Full analysis in `research/sweep13/SWEEP13_ANALYSIS.md`. No preset changes. Execution cost sensitivity confirmed as non-blocking for deployment.

### Experiment 14: Deployment Signal Estimation
- **Goal:** Test whether trailing VRP estimates and IV/RV autocorrelation can reliably drive automated deploy/pause decisions for the Active strategy. Prior experiments established drift floors (Exp 7), VRP floor (Exp 8), OU-dynamics requirement (Exp 9), and cost resilience (Exp 13). Can these conditions be estimated from trailing market data to automate deployment timing?
- **Market Baseline:** GBM and Jump with stochastic IV (OU process, κ=5.0 and κ=1.0, ξ=0.5), VRP 5%/10%/15%, tested at drifts 0%/+5%/−30%, vol 40%/60%, horizons 1yr/5yr.
- **Approach:** Four sub-experiments. A: Signal accuracy — validate VRP estimation bias/RMSE and ACF distinguishability across 72 condition combos. B: VRP deployment — test trailing VRP threshold (0%/5%/8%/10%) × 3 windows × 3 VRP × 3 drift × 2 horizons = 216 combos. C: ACF guard — test ACF ceiling (0.3/0.5/0.7) × 2 windows × 2 κ values × 4 conditions = 56 combos. D: Combined — best VRP + best ACF vs individual signals across 288 combos. All × 1,000 paths. Multi-threaded (8 workers), 1,102s total.
- **Results:**
  - **VRP estimation:** Systematic underestimation (true 5% → est 3.3%, true 15% → 7.1% at 40% vol). RMSE 14–17% — 1.5–3× larger than the VRP being estimated. Noise overwhelms signal. Drift-invariant (correct). Longer windows reduce RMSE marginally (15.4% → 13.9%).
  - **VRP deployment (B):** Best config w=20d, t=5%. Mean ΔSharpe **−0.030**, win rate 5.6%. Only 1/162 combos achieves positive ΔSharpe. Higher thresholds and longer windows strictly degrade performance.
  - **ACF guard (C):** Best config w=30d, t=0.7. Mean ΔSharpe **−0.656**, win rate **0.0%**. Catastrophically destructive — ACF is universally high (0.68–0.87) under OU dynamics, so any threshold blocks most trading.
  - **Combined (D):** Mean ΔSharpe **−0.620**, worse than either individual signal. ACF dominates, blocking 81–88% of the 5yr period.
- **Key Findings:**
  1. **No deployment signal improves performance.** Only 1/210 signal combos (0.5%) achieves positive ΔSharpe. Mean ΔSharpe across all signal types is −0.225. The existing regime filter is strictly superior to any additional deployment layer.
  2. **VRP estimation noise is fundamental.** RMSE of 14–17% against true VRP of 5–15% produces signal-to-noise ratio <1. Any threshold randomly rejects ~50% of deploy-worthy days. Not fixable with longer windows or better estimators.
  3. **ACF guard is structurally incompatible with OU dynamics.** OU processes at realistic κ produce ACF(1) of 0.68–0.87 universally. The guard cannot distinguish "dangerous clustering" from "normal mean-reversion" because OU-driven IV is persistently autocorrelated by construction. The Exp 9/11 "ACF > 0.5" guidance is valid for Heston-vs-OU *detection*, not for within-OU filtering.
  4. **The regime filter already IS the deployment signal.** Active's RF checks IV/RV ratio at each put-sale decision, operating at the correct granularity (per-trade). A daily deploy/pause layer is redundant and reduces profitable exposure.
  5. **Active's smooth degradation makes signals unnecessary.** Sharpe degrades linearly with drift (Exp 7) and VRP (Exp 8) — no regime cliffs. A binary deploy/pause signal provides no value when the underlying edge erodes gradually.
  6. **Estimation lag causes whipsaw, not margin protection.** 26–33 skip days per executed cycle — constant deploy/pause oscillation driven by estimation noise.
- **Conclusion:** **No deployment signal should be added to the framework.** The regime filter (`skipBelowRatio`, `skipSide: "put"`) provides optimal deployment decisions at per-trade granularity. VRP and ACF checks remain valid as human-level monitoring before deploying to a new market, but should NOT be automated as real-time signal gates. The `deploymentSignal` engine integration can be removed or left disabled. No remaining experiments block live deployment — the framework is deployment-ready for Active (δ0.20/3d, RF only) under OU-like IV dynamics.
- **Action Taken:** Full analysis in `research/sweep14/SWEEP14_ANALYSIS.md`. No preset changes. Deployment signal confirmed as non-beneficial — existing regime filter is sufficient. **Engine integration was fully implemented** (`src/components/signals.ts` with `computeTrailingVRP`, `computeTrailingACF`, `shouldDeploy`; `DeploymentSignalConfig` in `strategy/types.ts`; deployment signal check in `simulate.ts`; `deploymentSkips` tracking in `monte-carlo.ts` `RunSummary`) **and then removed** after the experiment conclusively showed no signal improves performance. Production code reverted to pre-experiment state (net zero changes). Signal module and its 30 tests deleted as dead code.

---

<!-- NOTE: Keep this section at the end of the file. New experiments append above this section; new follow-up ideas append to the list below. -->
## Recommended Next Experiments

*No remaining experiments block live deployment. Exp 14 closed the last blocker. All remaining work is edge optimization, robustness validation, or speculative.*

### Medium — Edge optimization & robustness

- **Experiment 15: Multi-Year Vol Sensitivity** — *(Fills a gap from Exp 12.)* Exp 12 confirmed Active's multi-year viability but only at 60% vol. Exp 13 tested 40% and 60% vol at 5yr but only for cost sensitivity (Active Sharpe ≥0.39 at both). Active's 1yr vol ceiling is 77–92% (Exps 3, 5). The critical unanswered question: does the multi-year property hold at 80%+ vol? Key sub-questions: does Active's saturating MaxDD (1.25× at 60% vol, Exp 12) hold at higher vol, or does gamma exposure compound over 5yr? If Active remains viable at 80%+ vol over multi-year horizons, the effective vol ceiling rises significantly for long-horizon deployers — a major practical finding. Test at horizons 1yr, 2yr, 5yr × vol (40%, 60%, 80%, 100%) × drift (0%, +5%, −30%) × VRP (10%, 15%) × model (GBM, Jump) × RF ON/OFF. ~288 combos.
- **Experiment 16: Historical IV/RV Dynamics Validation** — *(NEW. Motivated by Exp 14 and the OU-model dependency from Exps 9–11.)* The entire framework is validated against OU-driven stochastic IV. Heston dynamics kill the strategy (Exps 9–11). The biggest remaining risk is that real crypto IV dynamics don't match OU assumptions. Fetch historical Deribit ETH options data (IV surfaces, underlying prices) and analyze: (a) does realized IV/RV autocorrelation match OU (ACF ≈ 0.7–0.9) or Heston (ACF >> 0.9 with clustering)? (b) what is the empirical VRP — does trailing IV-RV spread sustain ≥10% (Exp 8 floor)? (c) how does the IV/RV ratio distribution compare with simulated OU paths? (d) do the regime filter's skip rates under real data match the simulated 94–97%? This is a data analysis task, not a Monte Carlo experiment — no simulation needed, just statistical comparison of real vs simulated IV/RV dynamics. If OU fits well, the framework is validated for deployment. If Heston-like clustering is detected, the framework needs the IV model reconsidered before live use. No engine changes required.

### Low — Speculative or requires engine changes

- **Experiment 17: Limit Order Simulation** — *(Demoted from Medium. Active is cost-immune at any realistic spread per Exp 13; limit orders provide diminishing marginal benefit for the only viable strategy.)* Exp 13 identified bid-ask spread as the dominant cost driver (3–5× more Sharpe erosion per unit vs. fee per trade). In practice, limit orders can significantly tighten effective spread. Test: simulate effective spread reduction factors (100%, 75%, 50%, 25% of quoted spread) with corresponding fill rate penalties (100%, 95%, 85%, 70%). Key questions: (a) what effective spread reduction is needed to make Moderate viable at 5yr? (b) is Active's cost immunity so strong that limit orders provide diminishing marginal benefit? Test across strategies × vol (40%, 60%) × horizons (1yr, 5yr) × spread levels (5%, 8%, 12%). ~144 combos. No engine changes needed — model as adjusted `bidAskSpreadPct` with a skip penalty for unfilled orders.
- **Experiment 18: Adaptive Calls Rehabilitation** — *(Active dominates without AC; Conservative/Moderate are ≤1yr only per Exp 12; Exp 13 further confirms Active as sole deployment strategy.)* Exp 6 found AC harmful for Moderate/Active (up to −0.383 ΔSharpe) due to −0.231 interaction with regime filter. AC helps Conservative (+0.118) but Conservative is now confirmed as ≤1yr only and cost-fragile (Exp 13: 10.7× more cost-sensitive per cycle). Very low urgency since Active doesn't need it and Moderate is secondary.
- **Experiment 19: Defined-Risk Spreads** — Vertical spreads (5-wide, 10-wide put spreads) to cap max loss per cycle. Exp 12 showed Active's MaxDD saturates at ~29% over 5yr. Exp 13 showed Active maintains 0.389+ Sharpe even at extreme costs, further reducing urgency. Primary remaining value is extending Active's vol ceiling (77–92%) to higher vol regimes. Requires engine changes: spread payoff logic, margin treatment, and dual-leg rolling. High implementation cost, moderate expected impact.
- **Experiment 20: Kelly Sizing** — Fractional Kelly criterion for position sizing. Exp 12 showed Active's MaxDD saturates at ~29% over 5yr with fixed 1-contract sizing, limiting Kelly's value at the sweet spot (60% vol). Main benefit is in marginal vol regimes (80–100%) where exposure reduction during thin-edge periods could lift Sharpe. Test ½-Kelly and ¼-Kelly against fixed sizing. Requires bankroll tracking in the simulation engine.
