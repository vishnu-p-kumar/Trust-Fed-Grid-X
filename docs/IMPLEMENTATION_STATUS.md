# Implementation status

This is an initial functional research slice, not completion of every Step 2 requirement.

## Implemented

- Deterministic IID/moderate/severe label-skew client partitioning.
- Local logistic model training and model-delta exchange in a single process.
- Centralized, local-only, FedAvg, trimmed-mean, trust-only, and provisional combined HATTA metrics.
- Label flip and scale/sign/slow update attack hooks.
- Finite update checks, norm clipping, normalized trust/sample-size aggregation weights, temporal trust history.
- Train/validation/test group-disjoint splits when meter IDs are provided; scaling is fit on training groups only.
- Validation log-loss harm trust signal, robust thresholding, cross-attack-family calibration on separate seeds, auditable update downweighting, recovery tracking, and evidence ablations.
- Reproducible controlled attack sweeps for malicious fractions/strengths, non-IID severities, temporary attacks, client-level metrics, confidence intervals, clipping and recovery conditions.
- Local SGCC wide-CSV loader with ID/label/date validation, SHA-256 provenance, missing-value accounting, and no synthetic fallback.
- JSON result/round logs and parameter checkpoint artifacts.
- Admin-only bounded experiment API and dashboard run/results panel.
- Session checks on operational data/artifact endpoints, strict CORS origins, bounded API limits, and WebSocket session validation.
- Trust decision audit records per round, including evidence values and normalized aggregation weights.
- Removal of synthetic seeded probability from theft probability and gating of demo alert overrides.
- Input range checks, strict prediction request fields, CORS origin allowlist, environment-configured admin password/session secret, and removal of checked-in user records.

## Not implemented or not verified

- Formal DP mechanism/accountant and secure aggregation (explicitly disabled).
- FedProx/SCAFFOLD, asynchronous clients, delayed updates, robust Krum, targeted backdoor, full collusion protocol, and quantitative targeted attack success.
- Confidence intervals for non-synthetic/public datasets, a validated heterogeneity estimator, checkpoint resume, time-held-out evaluation, generated figures, and an executed SGCC benchmark.
- SGCC redistribution/use authorization remains to be verified by the user for their acquired copy; the source repository requests citation but exposes no clear dataset license. No data was downloaded or bundled.
- Production access-control, rate-limiting, CSRF, and deployment security review.
- Dashboard table styling/visual QA and runtime browser verification.

## Verification

The original four-client, three-round severe non-IID sign-attack failure was reproduced before the trust changes: no malicious client was flagged (recall 0). The old PR-AUC-delta signal gave a sign-reversed update positive utility; its norm remained below the clipping bound and its repeated behavior looked temporally consistent. The revised detector uses validation log-loss harm, separate calibration and evaluation seeds, leave-one-attack-family-out threshold selection, and auditable update downweighting.

`python scripts/run_trust_validation.py` completed and generated `reports/research_runs/trust_validation_20261028.json`. The 17-scenario study uses five calibration seeds and five disjoint evaluation seeds. Under the primary utility-only evidence, held-out recall was 1.00 for 25% sign flips, 0.90 for 50% sign flips, 0.20–0.40 for 25% scaling (0.20 for 50% scaling), and 0.90–1.00 for label flips. Honest-client accusation rates were 0–0.10 in benign IID/moderate/severe cases and 0.05–0.10 under benign shifts. The label-flip 25% condition reached FAR 0.133. Utility-plus-integrity did not materially change outcomes; temporal evidence produced high false accusations; heterogeneity adjustment lowered both false accusations and some attack recall. HATTA does not consistently beat trimmed mean.

A separate one-seed online-threshold smoke run also flagged one of four honest clients in both the benign and benign-shift conditions (FAR 0.25). This is a concrete failure and shows the calibrated-study FAR does not characterize the uncalibrated online threshold. Detection and HATTA remain exploratory; results do not establish real-world efficacy.

Verification completed:

- `python -m pytest -q`: **76 passed**, exit 0; 4,131 deprecation warnings (Starlette/httpx compatibility and NumPy/joblib serialization).
- `python scripts/run_trust_validation.py`: completed; regenerated the report JSON.
- Three direct 400-row, four-client smoke runs (benign, sign attack, benign shift): completed. The sign run flagged its simulated attacker (precision 1.0, recall 1.0); benign and shifted runs each falsely accused one of four clients (FAR 0.25).
- `python scripts/run_sgcc_experiment.py --help`, `python scripts/run_trust_validation.py --help`, `python scripts/prepare_ceew_dataset.py --help`, and `python scripts/run_ceew_forecast.py --help`: command interfaces verified. SGCC loader fixture tests pass; no SGCC theft-label experiment ran because no authorized SGCC file was supplied.
- CEEW integration: all eight supplied CSVs were fully scanned in 200,000-row chunks. Both daily aggregates were normalized and used in a five-seed, four-client, three-round real-consumption forecast study (34,011 examples; 20,373 train, 6,801 validation, 6,837 test per seed). Mean FedAvg test MAE was 2.133 kWh versus 1.979 kWh for persistence; the trained methods did not beat that baseline. The intervals measure client-assignment sensitivity only. This is unlabeled consumption evidence, not a theft-detection result; see [DATASET_CARD.md](DATASET_CARD.md).
- `git diff --check`: rerun after final documentation edits; result recorded in the final report.

The complete scenario table and methodological caveats are in [TRUST_VALIDATION.md](TRUST_VALIDATION.md). The bounded generator/trainer workflow was not rerun in this trust-focused task; its existing tests remain included in the full passing suite.
