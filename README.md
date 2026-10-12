# MarketSignalLab 0.7.0 — Phase 2C.1 Baseline + Data Operations

Native iPad Swift Playgrounds research terminal for market-data ingestion, chart analysis, causal feature research, label calibration and walk-forward model validation.

## Current QQQ research state

The QQQ label policy is locked and remains frozen unless explicitly changed:

- LONG target: 8.0× ATR
- LONG stop: 4.0× ATR
- SHORT target: 11.0× ATR
- SHORT stop: 4.5× ATR
- horizon: 90 minutes

The accepted calibration rates were approximately:

- LONG target: 9.4%
- SHORT target: 12.9%

Both are inside the 8–20% target-event acceptance band.

## Phase 2C.1 baseline

Research now includes the first local out-of-sample model baseline.

For each of the three chronological walk-forward folds and for LONG and SHORT separately, the app now:

1. builds the locked-policy research rows;
2. fits feature standardization on the training block only;
3. trains a logistic classifier on the training block only;
4. computes the no-skill probability from training prevalence;
5. selects the classification threshold on validation only;
6. scores the untouched test block;
7. reports Brier score, Brier skill vs no-skill, precision, recall, F1 and accuracy.

The first gate is deliberately conservative: mean Brier skill must be positive for both LONG and SHORT before the pipeline advances.

Probability calibration and richer models come after this baseline.

## Historical data operations

Historical Data now supports both selected-symbol and bulk downloads.

Bulk settings include:

- Tradeable / Context / All universe scope;
- shared start and end timestamps;
- 1-minute historical bars;
- skip symbols whose local coverage already spans the requested range;
- maximum request count;
- approximate provider runtime;
- per-asset and per-chunk progress;
- received-bar and skipped-symbol counts.

Bulk downloads are serialized through the shared Twelve Data rate limiter. Keep Swift Playgrounds open while a long bulk import is running.

Downloading new history invalidates research/calibration/model caches for that symbol, but a locked label policy remains frozen.

## Add Ticker

The Add Ticker sheet now uses explicit iPad keyboard focus instead of Form text-field behavior.

It supports:

- direct ticker/provider-symbol input;
- optional display name;
- Equity / ETF / Crypto / Index / Commodity proxy;
- provider validation when an API key is available;
- persistent local watchlist storage.

## Debugging

Runtime events now go to three places:

- the existing diagnostics JSON;
- the Swift Playgrounds console via tagged `print` output;
- an in-app **System → Debug Console** view.

Console lines use the form:

`[MarketSignalLab][INFO] ...`
`[MarketSignalLab][WARNING] ...`
`[MarketSignalLab][ERROR] ...`

The in-app console can be filtered and cleared.

## Chart

The chart remains the dynamic candle-index implementation:

- 1m → 1D
- 5m → 1D
- 15m → 5D
- 30m → 5D
- 1h → 1M
- horizontal pan;
- pinch zoom;
- +/- zoom;
- Fit and Latest controls;
- visible-range price scaling;
- synchronized volume;
- explicit crosshair mode.

Chart aggregation runs off the UI actor and only the visible viewport plus required indicator lookback is rendered.

## Leakage discipline

The rules remain strict:

- label calibration does not use walk-forward test blocks;
- label policy is locked before model training;
- feature scaling is fitted on train only;
- logistic model is trained on train only;
- decision threshold is selected on validation only;
- test blocks are used only for final fold scoring.

No live signal is allowed into the scanner until the baseline demonstrates out-of-sample skill.

## Verification

The repository contains a macOS GitHub Actions workflow that type-checks every Swift file under `Sources/AppModule` against the iOS Simulator SDK.

Current release:

- Version: 0.7.0
- Build: 32
- Release: Phase 2C.1 — Baseline + Data Operations

The project remains signal/research only. No broker execution is implemented.


## Phase 2C.3 — Regime-aware baseline

The probability-calibrated baseline exposed a strong directional regime drift: SHORT target prevalence fell materially across later development folds while the model continued to overpredict short-event probability.

To address this without increasing model complexity, the logistic baseline now adds six causal multi-session regime features:

- current-session return from the first eligible research row;
- return from the previous session close;
- previous-session return;
- previous 3-session return;
- previous 5-session return;
- prior 3-session realized-volatility average.

The model now uses 22 causal features in total.

These features use only information available at or before each row timestamp. No future labels are used.

## Sealed final holdout

Because model architecture is being refined after inspecting development walk-forward test results, the remaining sessions after the third development fold are now explicitly surfaced as a sealed final holdout.

The sealed holdout is not used for:

- label calibration;
- feature design;
- probability calibration;
- threshold selection;
- development model comparison.

It should remain unopened until the architecture and signal gate are frozen.


## Phase 2C.4 — Model comparison

The development OOS results showed that the self-regime 22-feature candidate degraded materially, especially on SHORT. The app no longer replaces the original model blindly.

Baseline training now compares three feature variants on the same development walk-forward folds:

- Core 16: the original intraday causal features;
- Self Regime 22: Core 16 plus the six self-regime features;
- Market Context 28: Core 16 plus causal SPY, IWM and VIXY context returns.

The market-context candidate uses, for each context symbol, current-session return and 5/15/60-minute returns. Rows are included only when all required context bars are available at the same timestamp. The candidate is run only when context coverage is at least 70%.

The recommended candidate is selected using the weakest-side development Brier skill, with average skill as a tie-breaker. The sealed holdout remains untouched.

If Market Context is unavailable, download matching SPY / IWM / VIXY 1-minute history via Historical Data → Bulk History and rerun the baseline experiment.


## One-tap market context preparation

Research now exposes **Prepare Context + Retrain** for the selected symbol.

The action:

- derives the required time range from the selected research dataset;
- adds one calendar day of warmup before the first research row;
- downloads only SPY, IWM and VIXY rather than the entire context universe;
- skips symbols whose local coverage already spans the required interval;
- uses the shared Twelve Data rate limiter;
- reports per-asset download progress in Research;
- automatically reruns the Core 16 / Self Regime 22 / Market Context 28 comparison after the context download finishes.

This avoids the previous ambiguity where the generic Context bulk scope did not include SPY because SPY is a tradeable asset.


## Phase 2C.5 — Nested ridge regularization

The Core 16 candidate remained best while Self Regime 22 and Market Context 28 degraded development OOS performance. Before adding more model complexity, the logistic baseline now tunes L2 regularization causally inside each training block.

For every outer walk-forward fold and direction:

- the outer training sessions are split chronologically into inner train and inner validation sessions;
- L2 is selected from a fixed grid using inner-validation Brier score only;
- the final logistic model is refit on the full outer training block with the selected L2;
- outer validation remains reserved for Platt calibration and decision-threshold selection;
- outer test remains development OOS only;
- the sealed holdout remains untouched.

The selected L2 is shown per fold in Research.

This change targets the likely overfitting/multicollinearity exposed by the larger feature sets without adding a neural model prematurely.


## Phase 2D — Asymmetric directional gate

Nested ridge regularization materially reduced the SHORT degradation, but no SHORT candidate achieved positive mean development Brier skill. At the same time, the Core 16 LONG candidate remained positive.

The architecture therefore stops forcing one model to serve both directions.

The new development gate selects the best candidate independently for LONG and SHORT and enables a direction only when:

- mean development Brier skill is positive;
- at least two of three development OOS folds have positive skill;
- at least three folds are available.

If a direction fails the gate, its output is explicitly NO_TRADE.

This development gate does not open the sealed holdout and does not yet create live signals. It is the architecture-freeze step before final development fitting and one-time sealed holdout evaluation.


## Phase 2E — One-time sealed holdout

The development architecture now supports an explicit one-time final holdout check.

The Research screen keeps the final sessions sealed until the user confirms **Open Sealed Holdout Once**. At that moment the app:

- freezes the current directional architecture;
- evaluates only directions enabled by the Phase 2D gate;
- chronologically splits pre-holdout development sessions into final model-training and probability-calibration blocks;
- selects ridge regularization only inside the final training block;
- fits the logistic model on final training data;
- fits Platt probability calibration and the classification threshold on the final calibration block;
- evaluates the reserved holdout exactly once;
- persists the holdout result locally so the same holdout cannot be reopened for another architecture.

The holdout report includes Brier skill vs the calibration-prior no-skill baseline, Brier score, event prevalence, predicted probability, precision, recall, F1, threshold and selected L2.

A consumed holdout must not be used for another round of model tuning. Any architecture change after seeing the holdout requires new future data and a new sealed holdout.

The current QQQ holdout contains only a small number of independent sessions, so a positive result is an initial OOS confirmation rather than production-grade proof.


## Runtime safety and stuck-task protection

Version 0.7.9 adds explicit protection against operations that appear to run indefinitely in Swift Playgrounds.

### Baseline training

The nested-ridge baseline was previously too expensive on iPad because every feature variant, fold and direction trained many full 120-epoch logistic models across an eight-value regularization grid.

The bounded implementation now:

- uses four L2 candidates instead of eight;
- uses 25 epochs for inner regularization selection;
- caps inner tuning to 2,000 evenly sampled examples;
- uses 60 epochs for the final outer fit;
- checks Task cancellation inside the optimizer;
- exposes a live elapsed timer;
- provides Cancel Training;
- automatically cancels a baseline run after 5 minutes;
- discards partial results after cancellation.

### Historical downloads

Historical data operations now expose:

- elapsed runtime;
- current-request runtime;
- time since last progress;
- watchdog time remaining;
- current symbol/chunk;
- Cancel;
- per-request start/end logs.

Twelve Data HTTP calls now use an explicit 30-second request timeout. Bulk runs have a computed watchdog based on request count, with a safety floor and cap, so an overnight spinner is no longer treated as normal operation.

Console output includes tagged HTTP timing lines without exposing the API key.


## Phase 2D.2 — Independent tail events

The first Big Short Watch run exposed two issues: too few severe-downside observations and row-level event counting that could overstate the number of independent tail events.

The detector now evaluates tail risk at the session level:

- a development session counts as one severe event if any eligible row reaches the severe-downside label;
- recall measures the share of severe-event sessions with at least one alert;
- precision measures the share of alerted sessions that were actually severe-event sessions;
- alert rate measures the share of sessions that generated at least one alert;
- validation thresholds are chosen on these session-level metrics;
- validation folds with no severe events use a conservative high-probability threshold instead of collapsing to an ultra-low alert threshold.

The development readiness gate now requires severe events in at least two test folds and at least four independent severe-event sessions in total.

Research also includes **Extend Tail History · 1Y** for insufficient-event cases. The workflow downloads QQQ (or the selected tradeable) plus SPY, IWM and VIXY in sequential provider-safe windows, uses seven-day market-data chunks, rebuilds the locked-policy research dataset, and reruns Big Short Watch automatically. The final sealed holdout remains untouched.


## Phase 2D.3 — Multi-tier tail risk

One year of expanded QQQ/context development data still produced only two independent max(1.5%, 8×ATR14) severe-downside sessions across the development test folds. That is insufficient to validate a direct crash detector.

The tail-risk architecture therefore becomes hierarchical instead of forcing one ultra-rare label:

- Tail Watch: max(0.75%, 4×ATR14)
- Big Short: max(1.25%, 6×ATR14)
- Crash Watch: max(1.50%, 8×ATR14)

All three tiers are evaluated on the same chronological development folds. The experiment selects the most severe tier that passes the recall/precision/alert-rate development gate. A less-severe tier is an early-warning detector, not an automatic short entry.

The final holdout remains locked. Because the expanded development workflow consumed the previously remainder-based data partition during model development, those sessions are not treated as pristine final OOS data. Phase 2E is now presented as a prospective holdout: after the architecture is frozen, fresh future sessions must be collected before one-time final evaluation.


## Phase 2D.4 — Robust validation and stress features

The expanded historical run showed that a simple same-session tail-event score was not strict enough for the user's objective of catching major selloffs without flooding the terminal with false short alerts.

Phase 2D.4 therefore makes four architecture changes before any final holdout is opened:

- walk-forward validation automatically expands from three to five chronological folds when at least 40 independent sessions are available;
- the directional LONG/SHORT gate now requires a majority of development folds to have positive Brier skill, rather than always using a fixed 2-of-3 rule;
- tail-risk recall is now counted only when an alert occurs on a causal row whose forward horizon actually contains the later downside event, so an unrelated alert elsewhere in the same session no longer counts as a hit;
- Big Short Watch adds ten causal stress features on top of the original Core16 + SPY/IWM/VIXY context: short-horizon downside acceleration, medium-horizon acceleration, range expansion, positive volume shock, normalized below-VWAP pressure, session-low pressure, relative weakness versus SPY and IWM, VIXY 5-minute return, and VIXY acceleration.

A separate deterministic **Market Stress Monitor** is evaluated beside the learned detector. It uses only contemporaneous information such as downside momentum, range expansion, volume shock, below-VWAP pressure, broad-market weakness and VIXY acceleration. It can qualify only as a WATCH layer; it is not an automatic short-entry rule.

The final prospective holdout remains locked. Phase 2D.4 must first establish a stable directional gate and either a learned tail-risk WATCH model or a validated deterministic stress-monitor fallback.
