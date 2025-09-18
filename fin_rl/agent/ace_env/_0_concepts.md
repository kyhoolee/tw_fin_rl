# 0) Motivation & First Ideas

## 0.1 Intuition – Why ACE?

* **Limitations of traditional environments & metrics**

  * Fixed entry/exit assumption → only measures start–end trades, ignoring in-between dynamics.
  * Metric bias → Sharpe/AnnRet overlook fee drag and short-term win/loss behavior.
  * Fragmented comparability → each strategy is evaluated on different horizons (daily vs trade-level vs yearly).
  * Under-utilization of dense data → high-frequency data (minute, tick) often collapsed into daily bars.
  * Poor gap handling → missing segments are bridged incorrectly, creating artificial returns.

* **Why ACE?**

  * Anytime capital in/out → assume capital can enter/exit at the smallest bar (minute, hour, tick).
  * Uniform resampling → per-bar returns aggregated into Daily/Weekly/Monthly slices for fair comparison.
  * Robust gap handling → skip returns across long gaps, carry forward equity safely.
  * Explicit cost modeling → turnover, fees, and slippage are tracked per bar.
  * Universal applicability → works for hold, rebalance, momentum, ML-based, and RL-based strategies.
  * Better use of dense data → leverage fine granularity while still reporting intuitive higher-level metrics.

---

## 0.2 Robotics Analogy

* **Robots also aim for long-term goals** (e.g., reaching point B).
* **But** they must decompose this into short-term actions (steps, turns, obstacle avoidance).
* **Evaluation cannot only ask** “did it reach B?”

  * It must measure efficiency, robustness, and the quality of the path.
  * Was it walking or crawling?
  * Did it remain robust under noise, disturbances, or unexpected events?
  * How effective was the entire *sequence of actions*?
* **Parallel in trading**:

  * Strategies aim at long-term wealth growth.
  * But they must be judged on per-step robustness, efficiency, and adaptability.
  * Not just the final PnL at the end of the backtest.

---

## 0.3 First Ideas (Design Decisions)

1. **Action-based metrics, not yearly summaries**

   * Compute metrics at the bar/candle level.
   * Aggregate upward (D/W/M/Y) when needed.
   * Yearly metrics become *derived views*, not primary objectives.

   **Flow:**

   ```
   Raw Equity Path (per bar)
       → Per-bar metrics (PnL, turnover, fees, drawdown deltas)
       → Aggregate (Daily / Weekly / Monthly)
       → Optional Yearly view
   ```

2. **Robustness on fragmented data**

   * Skip evaluation across broken segments: if gap > 2× bar interval → no return is logged, equity simply carries forward.
   * Within valid segments (full features + labels available) → evaluate normally.
   * Bars with missing features or labels → excluded from evaluation.
   * Enables building **mixed environments** with multiple regimes (bull, bear, sideways) without requiring one continuous series that contains them all.

   **Flow:**

   ```
   Dataset (possibly fragmented)
       → Identify valid segments
           - Skip long gaps
           - Skip bars with missing features/labels
       → Evaluate per-bar inside valid segments
       → Join segment-level results into full ledger
   ```

3. **Unified comparability across strategies & time levels**

   * A single evaluation kernel for high-frequency, mid-term, and long-term strategies.
   * Rule-based, ML, and RL agents all operate under the same State–Action–Reward loop.
   * Reporting unified through:

     * Per-bar ledger
     * Time-slice metrics (Daily/Weekly/Monthly)
     * Optional trade-level statistics

   **Flow:**

   ```
   State (features, positions)
       → Agent Action (weights/signals)
       → Environment executes (PnL, fees, gaps)
       → Per-bar Reward (ACE)
       → Resample & Report (bar → slice → summary)
   ```

---

👉 In short, ACE transforms trading evaluation into something closer to robotics evaluation: **assessing the entire trajectory of actions, not just the final outcome**, while remaining robust to fragmented data and comparable across all strategy types and time horizons.


===================================================================================================

## Detail ACE motivation from simple HOLD strategy questionary 

# Example – Hold Strategy under ACE

```
[1. Traditional Evaluation = Biased]
Dataset split:  [ Train+Valid ] --- [ Test ] --- [ Unseen ]
Hold strategy outcome:
    - Depends ONLY on (LastPrice - FirstPrice) of each split
    - If Test happens to end higher → "win"
    - If Unseen ends lower → "loss"
Problem:
    - Entire strategy judged by just 2 candles (start & end)
    - Sharpe / Annualized return meaningless across different split lengths

------------------------------------------------------------

[2. ACE Evaluation = Step-Action Returns]
Each candle t → t+1:
    Action: Hold position
    Reward: Return(t) = Price[t]/Price[t-1] - 1
    State : Current equity + features
Trajectory becomes:
    [+ , - , + , + , - , ...]   (sequence of wins/losses)
Metrics:
    - Step-level win rate
    - Profit factor
    - Expectancy
    - Aggregation: per-day / per-week / per-month

------------------------------------------------------------

[3. Robustness with Fragmented Data]
Dataset:   [ Segment A ]   GAP   [ Segment B ]
ACE handles:
    - Skip returns across GAP (no artificial bridge)
    - Evaluate normally within each segment
    - Carry equity forward across missing data
Result:
    - Easy to construct ENV with mixed regimes
    - No need for one continuous time series containing all regimes

------------------------------------------------------------

[4. Generality & Robotics Analogy]
Robotics goal:
    Reach point B (long-term)
But evaluation requires:
    - Step-level actions (walk, turn, avoid obstacle)
    - Measure robustness under noise/disturbance
    - Path efficiency, not just final arrival

Trading under ACE:
    Long-term goal = Wealth growth
    But evaluation = step-action returns
    - Robust across regimes
    - Comparable across strategies
    - Aggregates naturally to higher horizons
```

---




===================================================================================================


# ACE-Compatible Generic Environment & Agent Template

## 1) Core Definitions

**Goal.** Provide a single environment (Env) interface that:

* runs at the **smallest bar** (the ACE “anytime” unit),
* is **gap-aware** (handles missing/irregular data),
* exposes a **clear State → Action → Reward** loop,
* supports **rules / classical ML / RL** with the same API,
* evaluates agents with **ACE resampling & metrics**.

### 1.1 Entities

* **State `S_t`**: what the agent can observe at bar `t`.
* **Action `A_t`**: the decision issued at bar `t` (e.g., target weights, orders, discrete signals).
* **Reward `R_t`**: per-bar payoff including fees/slippage, aligned with ACE mark-to-market.
* **Info `I_t`**: diagnostics (turnover, fees, constraints, drawdown, etc.).

### 1.2 Minimal Interfaces (Python-style)

```python
from dataclasses import dataclass
from typing import Dict, Any, Optional, Tuple, Protocol
import numpy as np

@dataclass
class State:
    t: int                         # bar index
    features: np.ndarray           # [N, F] or flat vector; gap-masked if needed
    positions: np.ndarray          # current target or held weights [N]
    cash: float                    # remaining cash (if explicit)
    mask: Optional[np.ndarray]     # [N] availability mask for assets at t
    meta: Dict[str, Any] = None    # e.g., regime id, calendar info

@dataclass
class Action:
    target_weights: np.ndarray     # [N], sum to 1 if fully invested (cash implied if <1)
    meta: Dict[str, Any] = None

@dataclass
class StepOutput:
    state: State
    reward: float                  # per-bar reward (ACE)
    done: bool
    info: Dict[str, Any]

class Env(Protocol):
    def reset(self, seed: Optional[int] = None) -> State: ...
    def step(self, action: Action) -> StepOutput: ...
    def set_eval_mode(self, enable: bool): ...   # freeze randomness if any
```

Agents share a tiny interface:

```python
class Agent(Protocol):
    def reset(self, observation_space: Any, action_space: Any): ...
    def act(self, state: State) -> Action: ...
    def learn(self, transition: Tuple[State, Action, float, State, Dict]): ...
```

---

## 2) Step Mechanics (per ACE time-step)

At each bar `t → t+1`:

1. **State construction**

   * `features[t]`: prices/returns/indicators; include **gap mask** per asset.
   * `positions[t]`: last target or held weights (post-execution).
   * `meta`: calendar/regime tags.

2. **Agent action**

   * `A_t = target_weights[t]` (or other action type, see §5).
   * Optional constraints enforced by Env: long-only, leverage cap, per-asset caps, turnover cap, etc.

3. **Execution & costs**

   * Compute **turnover**: `τ_t = ||w_t^target − w_{t-1}^effective||₁ / 2`.
   * Apply **fees/slippage**: `fee_t = f(τ_t, notional, bps_config)`.
   * Apply **gap logic** (see §4): unavailable assets cannot be traded; weights are renormalized to available set or parked in cash.

4. **Mark-to-market**

   * Per-asset net return `r_t` from bar prices (mid/open/close as defined).
   * Portfolio return before fees `p_t = w_{t-1}^effective · r_t`.
   * **Per-bar reward (ACE)**:

     $$
     R_t = p_t - \text{fee}_t - \text{slippage}_t
     $$
   * Update equity: `E_t = E_{t-1} * (1 + R_t)`.

5. **Emit next state** and **info**: turnover, fee drag, instantaneous dd, masks.

---

## 3) Reward Design (short-term) & Long-horizon Objectives

* **Default short-term reward (ACE)**: per-bar net portfolio return (after costs).

* **Optional shaping** (toggleable):

  * Risk-adjusted: `R_t = (p_t - fee_t)/σ̂_local` (stabilize variance).
  * Drawdown-aware: penalize increasing DD (e.g., `−λ * ΔDD⁺`).
  * Turnover penalty beyond cap: `−γ * max(0, τ_t − τ_max)`.

* **Long-horizon summaries**: computed by the evaluator (not baked into `R_t`):

  * Cumulative return, MaxDD/Time-in-DD, Ulcer index.
  * ACE **time-slice metrics** (Daily/Weekly/Monthly resamples).
  * ACE **trade-level** stats if the policy uses discrete entries/exits (see §6).

---

## 4) Gap-Aware, Irregular, and Broken Data Handling

To preserve ACE fairness:

* **Bar availability mask** `mask[t] ∈ {0,1}^N`.

  * If `mask[t,i]==0`: asset `i` is not tradable this bar (halted, missing print, listing change).
* **No bridge returns across long gaps**:

  * If a time gap `> 2×bar_interval`, **do not** fabricate compounded returns.
  * Carry equity forward (flat) across the gap; next bar resumes normal calc.
* **Weight renormalization**:

  * Remove unavailable assets; optionally keep unallocated weight as **cash**.
* **Calendar**: trading sessions & holidays baked into time index; env only steps on **valid bars**.

---

## 5) Action Spaces (choose per use case)

1. **Target Weights** (continuous)

   * `A_t = w_t ∈ Δ^N` (simplex or with leverage).
   * Env computes orders from weight delta.

2. **Discrete Signals** (rule & ML-friendly)

   * Per asset in {−1, 0, +1} or {0, 1} (flat/long) → mapped to target weights by an **allocation policy** (e.g., equal weight among active longs).

3. **Order-Like Actions**

   * Limit/market orders with size; env simulates fills with slippage model.

**Recommendation:** default to **Target Weights** for ACE clarity, add wrappers to auto-derive from discrete signals or order intents.

---

## 6) Trade Tracking (Optional but Useful)

Even with per-bar reward, keep a parallel **round-trip ledger**:

* Identify entries/exits (FIFO) from changes in **effective exposure**.
* Track **holding time**, **gross/net PnL**, **max adverse excursion**, etc.
* Enables ACE **trade-level** metrics without changing the per-bar reward.

---

## 7) Evaluation (ACE-native)

### 7.1 Per-bar to Time-slice

* Compute per-bar net returns `{R_t}`.
* **Resample** to Daily/Weekly/Monthly (calendar-aware).
* Metrics per slice:

  * Win rate, Profit factor, Expectancy.
  * Drawdowns (MaxDD, TiDD, Ulcer).
  * **Turnover & Fee drag** (avg turnover, fees as % equity & % returns).

### 7.2 Trade-level (if enabled)

* Win rate, Profit factor, Expectancy/trade.
* Holding time distribution.
* Max consecutive wins/losses.

### 7.3 Universal report

* Same report for **hold, rebalance, intraday** — identical resampling horizons.
* Export TSV/Parquet: per-bar ledger, per-slice ledger, trade ledger, summary JSON.

---

## 8) Dataset Splits, Regimes & Synthetic Blocks

* **Splits**: `train / valid / test / unseen` with **embargo** windows to reduce leakage.
* **Regime tags**: bull/bear/sideways, high/low vol, event periods. Tags flow into `State.meta`.
* **Curriculum / augmentation**:

  * Bootstrap or block-shuffle contiguous windows.
  * Synthetic shocks (gap injections, volatility spikes) for stress-training.
  * Multiple calendars (24/7 crypto vs market hours).

Agents can train on **mixtures** of regimes and be validated on held-out regimes.

---

## 9) Extensibility: Method Families

* **Rule-based**: from HOLD/EW to signal-driven (momentum, mean-reversion). Implement `act()` from deterministic rules; no `learn()`.
* **Traditional ML**: fit models offline on `train` (e.g., classifiers → signals, regressors → expected returns), then map to weights.
* **Optimization / Genetic**: search parameters for rule families; env provides fast vectorized rollouts.
* **RL**: `learn()` from `(S_t, A_t, R_t, S_{t+1})` transitions; reward is ACE per-bar net return (or shaped).

All share the **same Env** and **same ACE evaluator**.

---

## 10) Reference Config (YAML Sketch)

```yaml
env:
  bar_interval: "1m"
  price_field: "close"            # or mid/open
  slippage_bps: 0.0
  fee_bps: 7.5
  turnover_cap: 0.60              # per bar (optional)
  allow_short: false
  leverage_max: 1.0
  cash_bucket: true
  gap_policy:
    max_bridge_multiples: 2       # no bridge if gap exceeds 2×bar
    renormalize_to_available: true
datasets:
  train:
    path: "bundle/splits/train.parquet"
    embargo: "12h"
    regimes: ["bull","bear","sideways"]
  valid:
    path: "bundle/splits/test.parquet"
  unseen:
    path: "bundle/splits/unseen.parquet"
evaluation:
  resample: ["1D","1W","1M"]
  trade_tracking: true
  outputs:
    bar_ledger: "reports/bar_ledger.parquet"
    slice_ledger: "reports/slice_ledger.parquet"
    trade_ledger: "reports/trade_ledger.parquet"
    summary: "reports/summary.json"
agent:
  type: "rl"                      # "rule" | "ml" | "rl"
  action_space: "weights"         # "weights" | "signals" | "orders"
  constraints:
    long_only: true
    per_asset_cap: 0.35
```

---

## 11) Example Reward & Turnover Formulas (precise)

* **Portfolio pre-fee return**:

  $$
  p_t = \sum_{i=1}^{N} w_{t-1,i}^{\text{eff}} \cdot r_{t,i}
  $$
* **Turnover** (L1/2):

  $$
  \tau_t = \tfrac{1}{2}\sum_{i=1}^{N} \big| w_{t,i}^{\text{target}} - w_{t-1,i}^{\text{eff}} \big|
  $$
* **Fee**: `fee_t = τ_t × fee_bps / 10_000`.
* **Reward**: `R_t = p_t − fee_t − slippage_t`.

---

## 12) Practical Notes

* Keep **execution semantics** explicit: weight-to-order mapping, fill price, and timing (close→close, open→open, or MOO/MOC assumptions).
* Log **everything**: masks, gaps, renormalizations, caps triggered.
* Provide a **vectorized runner** for speed (crucial for genetic/RL sweeps).
* Make the **ACE evaluator** a standalone module callable on any equity path.

---

### TL;DR

> A single, gap-aware Env that issues **per-bar ACE rewards**, plus a universal evaluator that **resamples** to common horizons (D/W/M) and reports both **time-slice** and **trade-level** metrics. Agents—rule, ML, RL—all plug into the same loop and are directly comparable.

If you want, I can add a small **mermaid flowchart** and a **minimal reference implementation stub** (env + evaluator) next.
