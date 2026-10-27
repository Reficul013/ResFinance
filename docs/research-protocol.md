# Research Protocol

Status: Milestone 7 forward-completion protocol predeclared on 2026-10-15; local, non-commercial research only

## Scope

Research dataset V1 contains exactly BTC, ETH, and SOL with daily UTC observations from 2020-04-10 through 2025-01-01 inclusive. It combines market, sentiment, and asset-specific on-chain or documented proxy channels. A fourth asset is rejected at ingestion, feature, model, evaluation, portfolio, API, and fixture boundaries.

## Point-in-time data

Every observation records event time, provider availability time, retrieval time, provider revision, request URL or canonical query, response checksum, license/terms reference, and missingness. Joins use the time at which data was available, not a later revised timestamp. Provider failure appends a failed-attempt record and never overwrites a valid observation.

Planned sources:

- Coin Metrics Community: daily market series; daily `AdrActCnt` and `TxCnt` are the pinned V1 BTC/ETH on-chain metric contract.
- CoinGecko: current quote fallback; historical use requires confirmed plan/terms and coverage.
- DefiLlama: documented SOL TVL and stablecoin-supply proxies.
- GDELT: GKG historical tone/coverage and DOC metadata; full copyrighted articles are not persisted.
- `facebook/bart-large-mnli` at the locked revision: supplemental headline classification.

Provider availability differs by asset and date. Missing inputs are explicit masks; values are never silently backfilled from the future. Coin Metrics `PriceUSD` covers all three assets and `AdrActCnt` plus `TxCnt` cover BTC/ETH on every day of the fixed period. DefiLlama Solana TVL begins on 2021-03-17, leaving 341 masked days. Solana USD stablecoin supply begins on 2021-09-10 and contains 243 later gaps, leaving 761 total masked days. Those masks are model inputs; missing observations are not zero values.

## Reproducibility

Every run records:

- Run ID, purpose, owner, UTC start/end, and status.
- Git commit and dirty-state hash.
- Lock-file, code, configuration, environment, dependency-lock, container, dataset, feature, model, prediction, and artifact hashes.
- Exact provider observation IDs and immutable dataset manifest.
- Fixed random seeds for Python, NumPy, framework, data loader, and optimizer.
- CPU/GPU type, operating system, runtime/library versions, deterministic-mode settings, and known nondeterministic operations.
- Chronological train/validation/test windows and every walk-forward fold.
- Metrics, forecast intervals, baseline/ablation results, failures, and promotion decision.

Generated datasets, features, checkpoints, predictions, plots, and manifests are persisted in ResilientDB. Git contains code, deterministic synthetic generators, and small machine-readable acceptance attestations only. Temporary computation files are deleted after verified persistence.

## Evaluation

- Fit transforms on training windows only.
- Calibrate conformal intervals on validation windows only.
- Evaluate naive/zero-return, linear, and sequence baselines.
- Compare market-only, fixed equal fusion, adaptive gating, and each one-source-removed ablation.
- Report point errors, direction metrics, interval coverage/width, portfolio-relevant outcomes, missingness, and uncertainty.
- Do not claim statistical significance without a predeclared test, correction, and adequate sample.
- Label MSPCIFormer work as a three-asset adaptation; do not copy author source until a compatible license or explicit permission is recorded.

## Artifact protocol

Artifacts are compressed, encrypted with AES-256-GCM, split into 256 KiB logical content-addressed chunks, and segmented into transport-safe records under deterministic `blob:{sha256}:...` keys. A manifest records total size, compression, encryption metadata, ordered logical-chunk and transport-segment hashes, aggregate SHA-256, media type, and producing run. Restoration verifies every segment, logical chunk, authenticated envelope, and aggregate digest before use. Schema-v1 unsegmented blobs remain readable.

The local 100 MiB reconstruction smoke test does not satisfy persistence acceptance; the identical round trip must also pass through real ResilientDB and survive restart.

## Milestone 5 reproducible ML implementation note

The checked-in implementation uses pinned NumPy and PyTorch dependencies, CPU-only deterministic algorithms, one framework thread, no random data shuffling, five expanding walk-forward folds, a 15-day embargo, fold-local masked standardization, and validation-only split-conformal calibration. The clean-room MSPCIFormer adaptation uses separate market, sentiment, and on-chain encoders, masked adaptive gating, multi-scale temporal patches, shared channel-independent Transformer processing, learned scale aggregation, asset embeddings, and five-horizon return, direction, and quantile heads.

Synthetic smoke results validate deterministic mechanics, model contracts, comparisons, and persistence. They do not establish real-data performance, statistical significance, financial advice, or promotion eligibility. A full research run must use the fixed point-in-time provider dataset, retain the same manifest contract, and pass the declared promotion criteria before its model can become an approved forecast source.

## Milestone 7 untouched-forward completion protocol

This protocol is frozen before retrieving or scoring the forward holdout. It is a new evaluation, not a reinterpretation of the already-observed 2020-04-10 through 2025-01-01 five-fold results.

- Candidate: the same clean-room adaptive-gating architecture with a validation-locked reliability shrinkage coefficient selected from the fixed grid `0.00, 0.25, 0.50, 0.75, 1.00`. The coefficient scales predicted returns and direction confidence toward the naive zero-return/50-percent baseline. A coefficient of zero is an explicit, recorded abstention; it may tie but cannot outperform naive MAE by construction. The smallest coefficient wins an exact validation tie.
- Training decisions: all labeled samples through 2024-12-17. No record after that cutoff may fit weights or feature transforms.
- Embargo: 15 calendar days after the training cutoff.
- Validation/calibration decisions: 2025-01-02 through 2025-03-17. This window selects the fixed shrinkage coefficient and calibrates split-conformal intervals only.
- Forward embargo: 15 calendar days after the validation cutoff.
- Untouched holdout decisions: 2025-04-02 through the latest decision date whose 15-day target is fully observed. Holdout labels may be read exactly once by the immutable evaluation run and may not change the candidate, coefficient, transforms, epochs, loss, or promotion criteria.
- Current inference cutoff: the latest complete provider decision time whose inputs satisfy `available_at <= decision cutoff`. Labels are not required for this final inference row.
- Promotion remains `forecast-promotion-v1`: adaptive MAE must be less than or equal to naive MAE and adaptive interval coverage must be at least 70 percent. No tolerance, override, synthetic substitution, or post-holdout tuning is permitted.
- After a pass, a deployment checkpoint may be refit on all labels mature at the current cutoff using the frozen configuration. Its hash, standardizer, calibration, evaluated checkpoint, dataset, run, and promotion event must be recorded before a forecast snapshot is eligible.

The completion run must report per-model forward metrics, the chosen coefficient and validation scores for every grid value, exact window boundaries, input record IDs, point-in-time cutoff checks, conformal adjustment, evaluated and deployment artifact hashes, and whether holdout labels were consumed. A failed forward run remains useful immutable evidence but cannot publish a live recommendation.

## Forecast policy `no-change-centre-native-heads-v1`

This policy replaces the Milestone 7 reliability-shrinkage candidate for new forward runs.
It does not reinterpret the recorded `0.0` coefficient result, which remains evidence under
the schema-v1 calibration.

- **Point-in-time alignment.** Non-market features use the newest observation whose
  `available_at` is at or before the decision time and whose observed day is at or before
  the row date. Each row records `feature_age_days`. A source older than the maximum source
  age (three days) is masked. Market prices remain strictly same-day.
- **Centre.** The expected return is fixed at zero. No evaluated point forecast beat the
  zero-return baseline.
- **Ranges and P(up).** p10/p50/p90 and P(up) come from the adaptive model's native quantile
  and direction heads. Ranges receive a symmetric split-conformal adjustment from the frozen
  validation window.
- **Stale-source switch.** When an asset's sentiment or on-chain source is missing or stale
  at the decision row, that asset uses the market-only fusion model, persisted as
  `deployment-checkpoint-market-only.json` and named by `fallback_model_artifact`.
- **Promotion.** `forecast-promotion-v1` is unchanged. The candidate's point error equals
  naive MAE by construction, so promotion rests on interval coverage.
- **Before relying on the gain.** Predeclare a forward-protocol update covering seed
  averaging, the calibration window, and horizons, and score it on new data.

## Forward protocol `untouched-forward-holdout-v2`

Predeclared 2026-10-27, before any v2 run on provider data. It brings the forward protocol in
line with the exploratory 15–30 day study, whose final configuration scored 4.7% better than
no-change on pinball loss. It uses forecast policy `no-change-centre-native-heads-v1` and the
stale-source switch above.

- **Horizons.** 15, 20 and 30 days. The forecast snapshot and portfolio optimizer still use
  the 15-day horizon. The 20- and 30-day forecasts are trained, evaluated and recorded with
  each run.
- **Seeds.** 11, 23 and 37. Every neural model, including each ablation and the market-only
  fallback, is trained once per seed. Predictions are averaged over the three seeds: the
  expected return, P(up) after the sigmoid, and each quantile.
- **Training.** Lookback 16 days. Full-batch Adam for 100 epochs at learning rate 0.001,
  which is the Transformer configuration selected in the study's final run. The loss is
  unchanged.
- **Windows (decision dates).**

  | Window | Dates |
  |---|---|
  | Training | first eligible date through 2024-01-30 |
  | Embargo | 30 days |
  | Validation / calibration | 2024-03-01 through 2025-02-28 (one full year) |
  | Embargo | 30 days |
  | Holdout | 2025-04-01 through the latest decision date with a mature 30-day target |

  Every training target matures before validation begins. Every validation target matures
  before the holdout begins.
- **Calibration.** Symmetric split-conformal adjustment per horizon at alpha 0.2, fit on
  the validation window from the switched seed-averaged outputs.
- **Deployment.** The evaluated seed ensembles are deployed unchanged, with no refit. They
  are stored as one deterministic bundle per model, so each model has a single artifact hash.
- **Promotion.** `forecast-promotion-v1` is unchanged.
- **Holdout status.** The 2025-04-01 onward period was scored once by the exploratory study
  on 2026-10-26. A v2 holdout result therefore confirms the implementation; it is not new
  untouched evidence. New evidence must come from prospective snapshots published after this
  predeclaration. Holdout labels may be read only by the immutable evaluation, and no
  post-holdout tuning is permitted.
