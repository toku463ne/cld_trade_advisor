# Evaluation Guide — concepts and mathematics

A from-first-principles explanation of how we evaluate signs and
strategies in this codebase.  Read this before `docs/evaluation_criteria.md`
(which is the decision rubric — "ship if DR ≥ X") — this guide explains
*what those numbers mean and why we trust them*.

---

## 0. The problem we're solving

We have detectors that fire on stocks ("sign **fires**" — events).  We
want to know:

1. **Does the sign predict price direction?** (per-fire question)
2. **If it does, does using it actually make trading money?** (strategy question)

These are not the same question.  A sign can be a great predictor and a
terrible strategy contributor (because it duplicates other signals, or
fires at bad times, or the strategy doesn't pick it).  The pipeline
below answers both, in order.

---

## 1. Anatomy of a fire and its outcome

When a detector "fires" on bar T for stock S, we record:

  - `fired_at` = datetime of bar T
  - `stock_code` = S
  - `score` ∈ [0, 1] = the detector's confidence (sign-specific formula)

To measure outcome we look **ahead** in the bar series.  Specifically,
we find the next confirmed zigzag peak within ~30 bars and ask:
**did the next major swing go UP or DOWN from the fire?**

  - `trend_dir = +1` if next peak is HIGH (price went up) — long wins
  - `trend_dir = -1` if next peak is LOW (price went down)  — short wins
  - `magnitude` = abs(peak_price − entry_price) / entry_price
  - `signed_return = trend_dir × magnitude` (this is the "what would a
    long trade have returned" number)

**Why zigzag and not "price 10 bars later"?**  Fixed-horizon returns
mix noise with signal.  Zigzag confirms a real swing, so the outcome
measures whether the sign predicted a **structural move**, not noise.

The convention throughout this codebase: **DR is the rate at which
trend_dir = +1** (i.e., "after the fire, did the next swing go UP?").
A sign with DR = 60% means: 60% of its fires were followed by an UP
swing before a DOWN swing.

A "short-direction" sign just inverts: short DR = 1 − long DR.  So a
sign with long DR = 40% works as a short signal (60% of its fires were
followed by a DOWN move first).

---

## 2. Per-fire metrics (does the sign predict at all?)

### 2.1 Direction Rate (DR)

The simplest metric: **what fraction of fires were followed by a UP
swing?**

```
DR = wins / total_fires
   = sum(1 for fire if fire.trend_dir > 0) / n
```

| DR value | Meaning |
|---|---|
| 50% | coin flip — sign predicts nothing |
| 53% | barely useful — needs lots of samples to be sure it's real |
| 55-57% | mildly informative |
| 60%+ | strongly informative (rare in practice) |

**Why it's not enough alone:** DR ignores magnitude.  A sign with DR
55% but tiny moves is worse than DR 52% with big moves.  Also, DR 53%
on 50 fires might be coincidence; DR 53% on 5000 fires is real.

### 2.2 Mean signed return (mean_r)

```
mean_r = sum(fire.signed_return for fire) / n
       = sum(fire.trend_dir × fire.magnitude for fire) / n
```

This is the **average per-fire long-side return**.  If you went long
on every fire and held to the next zigzag, this is your average
return.  Combines direction (DR) and magnitude.

| mean_r | Interpretation |
|---|---|
| 0% | break-even (loses to costs and slippage) |
| +0.5% | weak edge |
| +1-2% | useful edge |
| +3%+ | strong edge |

### 2.3 Binomial test (p)

Question: "Is DR meaningfully different from 50%, given the sample size?"

Math: under H₀ (DR = 50%), the number of wins follows a binomial
distribution Binom(n, 0.5).  The p-value is the probability of getting
DR as extreme as observed (or more) under H₀.

```
p = P(X ≥ wins | n trials, prob=0.5)   # two-sided in practice
```

| p | Interpretation |
|---|---|
| p < 0.001 | very unlikely to be coincidence |
| p < 0.05 | "significant" by convention |
| p > 0.10 | could easily be random noise |

**Limitation:** assumes fires are independent.  In reality fires
cluster (multiple stocks fire on the same N225 event), so a small p
overstates significance.  We address this with the permutation test
below.

### 2.4 Permutation test (perm_p)

Question: "Is the sign's DR better than what we'd get by firing on
random dates?"

Math: shuffle the fire dates 1,000 times.  For each shuffle, compute
DR with the shuffled-date outcomes.  Then:

```
perm_p = (count of shuffles with shuffled_DR ≥ real_DR) / 1000
```

| perm_p | Interpretation |
|---|---|
| < 0.05 | sign's DR is real — better than random fire dates |
| > 0.10 | DR could be explained by "stocks tend to drift up" or similar |

**Why this is stronger than the binomial test:** the binomial test
assumes flat 50/50.  But Japanese stocks have a bullish drift in some
years, so random fires might naturally have DR > 50%.  Permutation
preserves the drift and asks "is your *timing* informative?"

### 2.5 Regime split (bear_DR vs bull_DR)

Some signs work only in one market regime.  We compute DR separately
for fires when N225 was in a bear regime (per the regime indicator) vs
bull.

```
bear_DR = (wins among fires when N225 was bear) / (fires when bear)
bull_DR = (wins among fires when N225 was bull) / (fires when bull)
```

If a sign has overall DR 54% but bear_DR 65% and bull_DR 47%, it's a
**bear-regime sign** — useful only when N225 is falling.  We'd then
gate it to fire only in bear regimes.

This is why benchmark.md tables show per-FY DR alongside bear/bull DR
columns.

### 2.6 EV decomposition (added 2026-05-18)

`mean_r` (§2.2) combines win frequency and trade-size info into one
number.  Decomposing it reveals which of those is doing the work:

```
EV = P(win) · E[win] + P(loss) · E[loss]      (E[loss] is negative)
   = win_rate · avg_win − (1 − win_rate) · |avg_loss|
```

This is algebraically the same as `mean_r`, but separating the
components tells us:

  - **High win rate, small wins** vs **low win rate, big wins**
  - **Whether losses are well-controlled** (small |E[loss]|) or
    occasionally catastrophic
  - **Kelly fraction** for sizing: `f* = EV / E[win²]` — needs the
    decomposition

Example reading: a sign with DR 55%, avg_win +2%, avg_loss −5% has
EV = 0.55 × 2 − 0.45 × 5 = +1.1 − 2.25 = −1.15%.  The high win rate is
illusory — the rare losses overwhelm the frequent small wins.

The A/B output tables now include columns for `P(win)`, `avg_win`,
`avg_loss`, and an `EV check` that should ≈ `mean_r` (sanity check on
the decomposition).

### 2.7 Multiple comparisons — Benjamini-Hochberg FDR (added 2026-05-18)

When we test many signs (currently ~22) across many FYs (7) and
regime cells (~9), we run hundreds of significance tests.  At p<0.05,
about 5% of tests will "pass" by chance alone — that's 70+ false
positives across our test grid.

**False Discovery Rate (FDR)** is the expected fraction of "passes"
that are flukes.  Controlling FDR at 5% means: of the tests we call
significant, ≤ 5% are false discoveries.

The **Benjamini-Hochberg (BH)** procedure adjusts p-values to control
FDR.  Given `m` sorted p-values `p₁ ≤ p₂ ≤ … ≤ pₘ`:

```
q(p_k) = min over j ≥ k of  (p_j × m / j)      (capped at 1.0)
```

A test with `q < 0.05` is "FDR-significant" — meaningful even after
correcting for the multiple tests.  We apply BH **within each sign
family** (`brk_*`, `str_*`, etc.) since within-family signs share
data paths and aren't statistically independent of all signs.

The benchmark.md Score Calibration section now includes both `p(ρ)`
(raw) and `q(ρ)` (FDR-adjusted).  A sign that's `p<0.05` but `q>0.10`
is "weak — could be one of the family's false positives."

Lightweight reading: if you tested 10 brk_* signs and 1 passed
p<0.05, that's chance.  BH would assign that test q ≈ 0.50, telling
you not to trust it without replication.

---

## 3. Score calibration (does the score rank fires?)

Beyond "does the sign predict on average?", we ask "does the
**score** within the sign predict which fires are better?"

If yes, we can use score to **rank** candidates when multiple signs fire
the same day, or to size positions.

### 3.1 Spearman rank correlation (ρ)

Math: rank all fires by score (1 = lowest, n = highest).  Rank all
fires by signed_return.  Compute Pearson correlation between the two
rank vectors.

```
ρ = cov(rank_score, rank_return) / (std(rank_score) × std(rank_return))
```

| ρ | Interpretation |
|---|---|
| 0.00 | no relationship — score is noise |
| 0.05 | weak |
| 0.10 | mildly informative |
| 0.20+ | strong (very rare in single-fire data) |

**Why rank correlation, not Pearson directly?**  Returns have fat
tails — a few huge wins/losses dominate Pearson.  Ranks are robust to
that.

For brk_wall: ρ = 0.020 (p = 0.122) — effectively zero.  The
`(close − wall) / wall` score doesn't predict outcome.  Drop the score
from any ranking.

### 3.2 Quartile EV table

Easier to read than ρ.  Sort fires by score, split into 4 equal
buckets (Q1 = lowest 25%, Q4 = highest 25%), and show DR + mean_r per
bucket.

If the score is informative, **Q4 mean_r should beat Q1 mean_r by a
material margin** (we use ≥ 2pp as the threshold).

```
For each quartile q ∈ {1, 2, 3, 4}:
  fires_q = fires whose score is in quartile q
  DR_q    = wins(fires_q) / |fires_q|
  mean_r_q = sum(signed_return) / |fires_q|

Q4 − Q1 spread = mean_r_4 − mean_r_1
```

| Q4−Q1 spread | Verdict |
|---|---|
| > +2pp | INFORMATIVE — score adds value |
| +0.5 to +2pp | WEAK — borderline |
| < +0.5pp | NOISE — drop the score |

---

## 4. Strategy-level evaluation

Per-fire metrics tell us "the sign predicts."  But a **strategy** is
the full pipeline:

  - load multiple signs
  - rank or combine them per day
  - pick entries
  - hold until exit rule fires
  - track P&L

A sign with great per-fire DR might never get picked (because other
signs rank higher), or might fire only when the strategy is already
in a position, or might cluster with other signs (false
diversification).  So per-fire pass ≠ strategy uplift.

This is the **brk_wall lesson** — perfect DR ≥ 53% canonical pass,
but trade-for-trade identical in regime_sign strategy and dilutes
confluence.

### 4.1 Sharpe ratio (per-trade)

```
Sharpe = mean(trade_returns) / std(trade_returns)
```

This is per-trade Sharpe (we don't have continuous P&L because trades
are sporadic).  It's the "reward per unit of risk" — high mean and
low variance are both rewarded.

| Sharpe | Interpretation |
|---|---|
| < 0 | losing strategy |
| 0 - 1 | break-even-ish |
| 1 - 2 | useful |
| 2 - 3 | strong |
| 3+ | excellent (often too good — check for overfitting) |

**Important caveat:** with small n (e.g., 25 trades/year), Sharpe has
HUGE variance.  A Sharpe of +3 on n=25 has a typical 95% CI of roughly
±2.  Don't read a 0.2 Sharpe difference as meaningful at small n.

### 4.1.1 Sortino ratio (added 2026-05-18)

Sharpe penalizes **all** volatility — including upside.  But traders
care more about losses than equal-sized wins.  Sortino fixes this:

```
downside_returns = [r if r < 0 else 0 for r in trade_returns]
Sortino = mean(trade_returns) / std(downside_returns)
```

Only downside volatility is in the denominator.  Strategies with
asymmetric returns (small frequent gains + rare big losses, or vice
versa) get a more honest assessment.

| Sharpe vs Sortino | What it tells you |
|---|---|
| Sortino ≈ Sharpe | symmetric return distribution |
| Sortino > Sharpe | upside-skewed (good — big wins inflate Sharpe's std) |
| Sortino << Sharpe | downside-skewed (bad — Sharpe is masking tail risk) |

Example from this codebase (2026-05-18 brk_wall A/B at N≥3):
  - A baseline:  Sharpe +3.72  Sortino +8.70
  - B +brk_wall: Sharpe +2.32  Sortino +4.44

Sortino drops by 4.26 (49%) vs Sharpe's 1.40 (38%) — the brk_wall
addition hurts the downside-risk picture more than aggregate Sharpe
shows.  Sortino reveals the worse story.

The A/B output tables include both Sharpe and Sortino columns now.

### 4.2 Win rate

```
win_rate = (trades with positive return) / total_trades
```

Complement to Sharpe.  A high-win-rate-low-Sharpe strategy has many
small wins and few big losses (or vice versa).

### 4.3 Walk-forward (FY) structure

To avoid overfitting, we evaluate FY-by-FY:

  - FY2018, FY2019, …, FY2024 = **training/historical**
  - FY2025 = **out-of-sample (OOS)**

The Apr-to-Mar fiscal year matches Japan's reporting calendar.

For each FY, we use the **prior** FY to build:
  - the universe (which stocks to include — `classified{prev_year}`)
  - the regime rankings (which (sign, kumo) cells perform best)

Then evaluate the strategy on the FY's actual bars.  No future data
leaks into the ranking.

**FY2025 is the cleanest signal** because no fitting decisions used
its data.  When FY2025 OOS is strong, it's a positive sign.  When OOS
is weak but training FYs are strong, the strategy may be overfit.

### 4.4 Per-FY consistency

A strategy with avg Sharpe +3 across 7 FYs is great.  But if 4 of the
7 FYs are negative and 3 are very positive, it's fragile — one
unlucky year and the strategy blows up.

We require **≥ 6/7 FYs non-negative** for ship decisions.  This
penalizes high-variance strategies that look great on aggregate but
have hidden risk.

---

## 5. A/B testing (the binding gate)

After per-fire benchmarking passes, we run an A/B at strategy level:

  - **Arm A (baseline)** — current production strategy
  - **Arm B (variant)** — same strategy with the proposed change

Both arms use the SAME stocks, SAME exit rules, SAME portfolio cap —
ONLY the proposed change differs.  Sharpe / win% / per-FY consistency
are compared.

### Why per-fire ≠ strategy A/B

Three concrete reasons from this codebase:

1. **Rank crowding** (brk_wall): brk_wall's (sign, kumo) cells never
   win the regime ranking against other signs' cells.  The strategy
   picks the top cell per day; brk_wall's cells are always #4 or
   lower.  Per-fire DR doesn't matter if the strategy doesn't pick
   the sign.

2. **Confluence dilution** (brk_wall, K=15 brk_kumo/brk_tenkan):
   adding more bullish signs to a "fire if ≥3 valid signs" gate may
   sound additive but can hurt — extra signs let the gate fire on
   weaker stacks.

3. **Counter-intuitive lift** (brk_sma low/K=3): per-fire showed
   FY2024 regression (DR 54.7% → 47.1%) but strategy A/B showed
   FY2024 IMPROVED (Sharpe −0.90 → +4.16).  The confluence gate
   filtered out the weak new fires.

### How A/B is computed for confluence

We have a helper that:

  - loads fires for each sign in the bullish set (from DB)
  - for each trading day, counts how many signs are "valid" (within
    `valid_bars` after their fire)
  - fires the strategy if count ≥ N
  - runs ZsTpSl exit, two-bar fill, portfolio cap
  - computes per-FY trade metrics

Run twice with different sign sets → compare Sharpe.

### Pre-registered decision rule

Before running, we **commit to the gate** in the code:

```
SHIP variant if:
  (a) avg Sharpe at production N gate ≥ baseline Sharpe
  (b) ≥ 6/7 FYs non-negative
```

If we change the rule after seeing results, we're cheating
(motivated reasoning).  Pre-registration forces honesty.

### 5.4 Marginal contribution analysis (added 2026-05-18)

Aggregate Sharpe/mean_r tells you whether the variant is better, but
hides WHY.  When testing "add sign X to confluence", we now also
report **per-trade marginal metrics** comparing A (baseline) vs B (A
+ X):

| Metric | Math | Tells us |
|---|---|---|
| **Δ trade count** | `n(B) − n(A)` | turnover impact (more trades = more costs) |
| **Δ max drawdown** | `dd(B) − dd(A)` where `dd = max(cum_peak − cum_now)` | did adding X make the worst-case loss worse? |
| **Daily correlation** | Pearson corr of per-day return series A vs B | high (>0.7) = duplication, low (<0.3) = real diversification |
| **Tail-hedge lift** | `mean(B on A's worst quintile days) − mean(A on those days)` | does X cushion when baseline loses? |
| **New-trade win rate** | `wins / total` among trades B has that A doesn't | quality of the marginal trades introduced |

Why these matter: a sign can pass the aggregate Sharpe gate but:
  - DUPLICATE existing trades (high daily correlation → no real
    diversification benefit)
  - MAKE DRAWDOWN WORSE while leaving Sharpe flat (because the bad
    days cluster)
  - FAIL TO HEDGE on baseline's tail days (so it's not the kind of
    addition that makes the strategy robust)

Example from this codebase (2026-05-18 brk_wall A/B at N≥3):
  - Daily correlation: +0.491 — moderate, not full duplication
  - Tail-hedge lift: +4.93% — brk_wall actually HELPS on baseline's
    worst days (positive lift)
  - Δ drawdown: +17.93pp — but overall drawdown gets WORSE
  - New-trade win rate: 57.8% — actually decent quality

The aggregate Sharpe regression (−1.40) hides this nuance.  The
marginal table reveals that brk_wall isn't useless — it provides some
tail-hedge value but worsens drawdown.  The ship-NO decision stands,
but for richer reasons than "Sharpe got worse".

Implementation: `src/analysis/_marginal.py`.  `compute_marginal(a_results,
b_results)` returns a `MarginalReport`; `marginal_table()` renders it as
markdown.  Currently integrated into
`src/analysis/confluence_brk_wall_inclusion_ab.py` as the proof of
concept; other A/B scripts will adopt the pattern next time they're
touched (template upgrade tracked in `docs/followups.md` §4d).

---

## 6. The full pipeline (visual)

```
       PROBE (cheap, in-memory)
       ↓ "is this even worth implementing?"
       PASS: candidate feature has fire-rate + directional bias
       │
       ↓
       CANONICAL BENCHMARK (scripts/rebenchmark_sign.sh)
       ↓ runs in DB; produces benchmark.md tables
       │  - per-FY DR + p + perm_p
       │  - bear/bull regime split
       │  - score calibration (Spearman ρ + quartile EV)
       PASS: DR > 53% pooled, ≥ 2/7 FYs perm_pass, score may or may not be informative
       │
       ↓
       STRATEGY A/B (confluence or regime_sign)
       ↓ same data, with/without the change
       PASS: Sharpe ≥ baseline, ≥ 6/7 FYs non-negative
       │
       ↓
       SHIP — update production defaults or constants
       │
       ↓
       REBENCH — update DB to match production
       UPDATE docs/analysis/<feature>.md with final numbers
```

Each gate filters.  Skipping a gate risks shipping noise.

**A probe that says "this is amazing" but no canonical/A/B follow-up
is not a ship signal.**  See `docs/analysis/probe_vs_canonical_lesson.md`
for two cases (brk_wall, brk_floor) where probes overstated by 20pp
or even INVERTED the canonical pipeline's direction.

---

## 7. Common pitfalls (lessons logged in this codebase)

### 7.1 Per-fire pass ≠ strategy uplift

brk_wall passes canonical (DR 53% pool, FY2025 OOS 59.6%) but is
trade-for-trade identical to "without brk_wall" in regime_sign and
DILUTES confluence by 1.40 Sharpe.

**Always run strategy A/B before shipping a load-bearing sign.**

### 7.2 Probes can overstate or invert

Probes use `detect_peaks(highs, lows)` on the FULL bar series →
peaks settled by post-fact data → cleaner outcomes than what live
trading sees.

The canonical pipeline (sign_benchmark.py) uses `_first_zigzag_peak`
on a 35-bar window from the fire → matches what's knowable at
decision time.

For brk_wall the probe said DR 72%, canonical said 53% (-20pp).  For
brk_floor the probe said breakdowns continue (DR 33%), canonical
said they mean-revert (DR 52%) — direction INVERTED.

### 7.3 Small sample Sharpe is noisy

A single FY with 25 trades has ±2 Sharpe noise.  Pooled across 7
FYs, ±0.5.  Don't read 0.2 Sharpe gaps as meaningful at single-FY
level.

When a 4-FY-positive 3-FY-negative strategy shows pooled Sharpe of
+3, ask: "Are the positive FYs in regimes that will recur?  Or are
they specific to a market that may not return?"

### 7.4 Score calibration takes large n

Spearman ρ needs n ≥ 200-500 fires per sign to be measurable.
Quartile EV needs at least 40 fires (10 per quartile).  Below that
sample size, "score is noise" might just mean "we don't have enough
data to tell."

### 7.5 Strict gates flip negative on cohort changes

A change that PASSES on pooled FY2019–FY2024 may FAIL when
re-segmented by sub-cohort (e.g., per-FY, per-corr_mode).  This is
why we require both pooled CI AND per-FY consistency.

Reference: `project_rev_lo_and_high_per_cohort_reject.md` in memory
— pooled passed, FY2024 had n=3 noise, FY2025 DR 51.5%.

---

## 8. Decision rules (the rubric)

The actual ship/reject thresholds are in `docs/evaluation_criteria.md`:

  - Materiality: DR ≥ +1pp at n ≥ 1,000 or ≥ +2pp at smaller n
  - Sample size: drop of ≥ 50% in n must be justified
  - EV direction: sign-flip is material
  - Per-FY: ≥ 6/7 non-negative for strategy A/B ship

This guide explains the math; that guide explains the gates.

---

## 9. Where the metrics live

| Output | Script / Helper | Section in benchmark.md (or doc) |
|---|---|---|
| Per-FY DR / mean_r / perm_p | `sign_benchmark_multiyear.py --phase benchmark validate report` | "Multi-Year Benchmark" |
| Bear/bull regime split | `sign_regime_analysis.py` | "Regime-Split Analysis" |
| Spearman ρ + quartiles + **q(ρ) FDR** | `sign_score_calibration.py --by-regime` | "Score Calibration" |
| FY2025 OOS canonical | `sign_benchmark_multiyear.py --phase backtest` | "FY2025 OOS" |
| Strategy A/B (Sharpe + **Sortino + EV decomp**) | `confluence_*_ab.py` or `regime_sign_*_ab.py` | top of A/B's own section + `_ev_decomp_table` helper |
| **Marginal contribution** | `src/analysis/_marginal.py` (`compute_marginal`, `marginal_table`) | A/B's "Marginal contribution" sub-section |

Shared helpers (added 2026-05-18):
  - `Metrics.sortino`, `Metrics.avg_win`, `Metrics.avg_loss` in
    `exit_benchmark.py` — used by every A/B's per-trade stats.
  - `_arm_row_from_metrics()` in `confluence_strategy_backtest.py` —
    consolidates `_ArmRow` creation across A/B scripts.
  - `_ev_decomp_table()` in `confluence_strategy_backtest.py` —
    produces the Sortino + EV decomposition sub-table.
  - `_compute_family_qvals()` in `sign_score_calibration.py` —
    BH-FDR adjustment grouped by sign family prefix.

To rebench one sign end-to-end: `scripts/rebenchmark_sign.sh <sign_type>`.

To run a probe: write a script in `src/analysis/<sign>_<test>_probe.py`
that reuses `_first_zigzag_peak` and `BrkXxxDetector`; report to
`docs/analysis/<name>.md`.

---

## 10. Glossary

| Term | Meaning |
|---|---|
| **Fire** | An event when a detector's condition is satisfied on a bar |
| **DR** | Direction Rate — fraction of fires followed by an UP swing |
| **mean_r** | Mean signed return per fire (long-side perspective) |
| **n** | Sample size (number of fires) |
| **perm_p** | Permutation-test p-value (DR vs random-date DR) |
| **p (binomial)** | DR vs 50% under independent-flip assumption |
| **bear_DR / bull_DR** | DR conditional on N225 regime at fire time |
| **Spearman ρ** | Rank correlation of score with signed return |
| **Q4 − Q1 spread** | Top-quartile mean_r minus bottom-quartile mean_r |
| **Sharpe** | mean / std of per-trade returns |
| **win_rate** | Fraction of trades with positive return |
| **Sortino** | mean / std_of_DOWNSIDE_returns — penalizes only losses, not upside variance |
| **EV decomposition** | Splitting mean_r into P(win)·E[win] + P(loss)·E[loss] — same number, more info |
| **avg_win / avg_loss** | Mean return among trades with r>0 / r<0 respectively |
| **BH-FDR** | Benjamini-Hochberg False Discovery Rate adjustment — controls expected fraction of false positives across multiple tests |
| **q-value (q)** | BH-adjusted p-value — q<0.05 means "FDR-significant" even after multiple-test correction |
| **Sign family** | Group of signs sharing a prefix (brk_*, str_*, etc.) — used as the BH-FDR grouping unit |
| **Marginal contribution** | Per-trade comparison of A vs B (turnover, drawdown, daily corr, tail-hedge) beyond aggregate Sharpe |
| **Tail-hedge lift** | How much arm B helps on arm A's worst-quintile days (positive = real diversification on the tail) |
| **Daily correlation** | Pearson corr of per-day returns A vs B — high = trades duplicate, low = real diversification |
| **FY** | Fiscal year (Apr to Mar; e.g., FY2024 = 2024-04-01 to 2025-03-31) |
| **OOS** | Out-of-sample — data not used in any fitting decision |
| **Walk-forward** | Train on FYs ≤ T-1, test on FY T |
| **A/B test** | Run strategy twice differing only in the proposed change |
| **Pre-registered gate** | Decision rule committed in code BEFORE seeing results |
| **valid_bars** | Number of bars a fire is "active" after firing (for confluence count) |
| **Confluence** | Strategy that fires when ≥ N bullish signs are valid same day |
| **regime_sign** | The older "rank (sign, kumo) cells, pick top" strategy |
| **Canonical** | The official pipeline (`sign_benchmark.py`) — windowed per-fire zigzag |
| **Probe** | A one-off exploration script — usually cheaper, often less rigorous |

---

## 11. Worked example — brk_sma (low, K=3) ship decision

Operator asked: should brk_sma switch from `close > sma AND prior 5
closes ≤ sma` to `low > sma AND prior 3 lows ≤ sma`?

### Step 1: per-fire 4-way matrix

`src/analysis/brk_sma_variant_probe.py`:

| Arm | n | DR | mean_r |
|---|---:|---:|---:|
| close, K=5 (production) | 1443 | 52.9% | +0.95% |
| low, K=3 (operator) | 1994 | 52.8% | +1.23% |
| low, K=5 (control) | 1570 | 53.2% | +1.17% |
| close, K=3 (control) | 1858 | 53.2% | +1.20% |

Operator's variant: DR essentially tied, mean_r +0.28pp.  Marginal.

**Warning sign**: FY2024 DR 54.7% → 47.1% under operator's variant
(per-fire regression).  Per-fire data alone would suggest REJECT.

### Step 2: strategy A/B (3-arm)

`src/analysis/confluence_brk_sma_variant_ab.py`:

| N gate | A current | B operator | C control (close, K=3) |
|---|---:|---:|---:|
| N≥3 | +2.64 | **+3.26** | +2.76 |

B wins by +0.62 Sharpe at N=3.  C (no low swap) barely moves →
**the lift comes from close→low, not the K change**.

Per-FY at N=3: same 5/7 non-negative for both A and B.  FY2024
(per-fire warning year) actually IMPROVES at strategy level
(−0.90 → +4.16) — confluence gate filtered out the weak new fires.

### Step 3: ship decision

Both gates pass:
  - Sharpe ≥ baseline (PASS, +0.62 better)
  - Per-FY consistency unchanged (5/7 for both arms)

SHIP variant B.  Update `BrkSmaDetector` defaults:
`min_below_bars: 5 → 3`, `gate_use_low: False → True`.

### Step 4: rebench

DB events now match production.  FY2025 OOS DR 55.8% (p = 0.029).

### Step 5: document

`docs/analysis/brk_sma_variant.md` records the full arc — anyone
reading it cold understands what changed and why.

This is the pattern.  Per-fire is necessary but not sufficient.
Strategy A/B is the binding gate.  Documentation makes the decision
auditable in 6 months.

---

## 12. Deferred upgrades (not yet implemented)

Operator brainstormed (2026-05-18) a longer list of evaluation
extensions.  Three were implemented (Sortino + EV decomp, BH-FDR,
marginal contribution).  The rest are tracked in
`docs/followups.md` §4 with **why** and **trigger to revisit**:

| Item | Status | Trigger to revisit |
|---|---|---|
| **MAE / MFE / time-to-peak path stats** | deferred | When we revisit exit-rule tuning |
| **Calmar / Omega ratio / pooled CVaR** | deferred | When we have a continuous equity curve OR pool n ≥ 100 |
| **New regime axes** (cross-sectional dispersion, N225 realized vol, VXJ) | deferred | When a sign shows bimodal per-FY behavior we want to explain |
| **Bootstrap CI in every A/B template** | deferred | Next time we write a new A/B — back-port via sweep |
| **Hierarchical Bayesian consistency** | SKIP | Only at n ≥ 100/FY and ≥ 10 FYs — overkill at our scale |

When implementing any of these, link the implementation back to the
followups entry and move it to the "Done" section.

### What's the intuition behind each deferred item?

- **MAE/MFE**: instead of "next zigzag peak" as a single point, track
  the WORST and BEST price during the holding period.  A trade that
  was up 8% before exit, or down 5% before TP fired, has hidden
  information that point estimates miss.  Useful for exit-rule
  tuning (e.g., tighter SL for high-MAE cohorts).
- **Calmar / Omega / CVaR**: alternatives to Sharpe and Sortino that
  capture different aspects of tail risk.  Calmar uses max drawdown
  (needs equity curve); CVaR averages the worst α% of trades; Omega
  is a ratio of upside expectation to downside around a threshold.
- **Dispersion / vol / VXJ regimes**: we currently split only on
  N225 bear/bull.  Cross-sectional dispersion (std of stock returns)
  tells whether stocks are moving together or independently — affects
  whether single-stock signs work.  Realized vol regime likely flips
  mean-reversion vs continuation behavior.
- **Bootstrap CI**: resampling trades to get a 95% CI around Sharpe.
  Tells you whether a "0.5 Sharpe improvement" is real or could
  easily be noise.  Already used ad-hoc in some probes; should be
  template-default.
- **Hierarchical Bayesian**: model FY-level Sharpe as draws from a
  distribution with shrinkage.  Statistically principled but requires
  more data than we have to be data-driven rather than prior-driven.
