# CLAUDE.md

This file provides guidance to Claude Code (claude.ai/code) when working with code in this repository.

## Project boundary

NBA data-ingestion, feature-engineering, modeling, betting simulation, dashboard, and autoresearch workflows. Run Python commands from this repository root so `src` imports and relative data paths resolve consistently.

## Commands

```
pip install -r requirements.txt
python experiment.py                                   # run one experiment/backtest
streamlit run dashboard.py                              # launch dashboard
python autorun.py --dry-run                             # autoresearch loop, no LLM calls
python autorun.py --groq --max-iters 20                 # autoresearch loop, LLM-driven config edits
```
`autorun.py` resolves `experiment.py`, `program.md`, `results.tsv`, and `experiments/` relative to its own location, so it can be invoked from any working directory. Data locations are overridable via `NBA_DATA_DIR` / `NBA_OUTPUTS_DIR` env vars (default `./data`, `./outputs`).

There is no test suite (the only `test_*.py` file is a standalone script under `src/ingest/old/Scripts/`, not part of an automated suite) — verify changes by running the narrowest relevant import, compile, or dry-run check, not by looking for tests to pass.

Do not commit raw or processed datasets, generated outputs, model artifacts, runtime logs, or credentials — small reproducible fixtures belong under `data/sample/`.

## Architecture: the autoresearch loop

This repo's central mechanism is `autorun.py` driving an LLM (Groq or OpenAI, per `requirements.txt`) to iteratively edit `experiment.py`:

- `experiment.py` is split by two markers autorun.py parses directly: `# AGENT-EDITABLE CONFIG` (an agent/LLM may freely rewrite this block — training size, test size, and other tunables) and `# FROZEN` (everything from this line down — data loading, walk-forward split logic, leakage filters, target construction, Kelly ROI calc, results logging — is a correctness boundary, never a tuning knob). `autorun.py` refuses to proceed if it can't locate `CONFIG_MARKER` in the file, rather than silently guessing a boundary.
- Each iteration: autorun.py sends the current AGENT-EDITABLE CONFIG (plus `program.md`'s rules and recent score history) to the LLM, expects back *only* a replacement CONFIG block, splices it into `experiment.py`, runs the experiment, and scores it as `roi / (1 + ensemble_rmse)` — higher is better. `program.md` is auto-updated by autorun.py with a `<!-- autorun:state:start/end -->` block recording best score and recently-tried changes (to avoid the LLM repeating them) — this block is machine-managed, don't hand-edit it.
- `results.tsv` is the append-only log of every experiment run (`experiment.py`'s FROZEN logging function writes to it).
- When working on the modeling code directly (not via the autorun loop): keep walk-forward splits chronological, fit any preprocessing/feature-selection/transforms on the training fold only, and report RMSE, calibration, odds-match quality, ROI, drawdown, and Kelly behavior separately rather than treating one run as proof a change helped.

## Data pipeline

- `src/ingest/dataPrep/config.py` owns shared DataPrep defaults and per-step overrides; `src/ingest/dataPrep/pipeline.py` owns orchestration; individual steps live under `src/ingest/dataPrep/steps/`.
- `src/ingest/models/` holds trained model artifacts by name (e.g. `Edge_LightGBM/`); `src/ingest/old/` is prior-generation ingestion code kept for reference, not part of the active pipeline.
- For lineup ingestion, official boxscore-listed players count as appearances (including DNPs) — don't add a separate player-stat download path for this.
- Prefer read-through caches and full artifact reconstruction over partial-cache assumptions; check cache completeness, file dates, and column names before re-fetching. Preserve existing cache paths/schemas unless a migration is explicit.
