# Project Name

One paragraph: what question this project answers, and what the core method is.

## Setup

```bash
uv sync --extra dev --extra llm
pre-commit install
```

The `llm` extra carries the Anthropic, OpenAI and LiteLLM SDKs. Without it the scripts in
`scripts/` fail on import, so install it up front unless the project calls no APIs at all.

Add inference-stack dependencies (vLLM, transformers, torch, etc.) to the `inference` extra in
`pyproject.toml` as needed, then:

```bash
uv sync --extra dev --extra llm --extra inference
```

Copy `.env.example` to `.env` and fill in your keys. `.env` is gitignored; `.env.example` is the
only file in the repo that may show a key, and only as a placeholder.

## Repo structure

```
configs/        experiment configs and model lists, one YAML per experiment
data/raw/       untouched source data, read-only
data/processed/ cleaned/filtered data, produced by scripts in src/data/
data/splits/    fixed question IDs, seeds, eval splits saved as files
src/data/       dataset loading and preprocessing
src/generation/ model inference, prompting, sampling, LLM cache wrapper
src/finetuning/ training loops
src/interp/     probes, features, hook points
src/metrics/    metric computation and downstream analysis (regressions, stats)
src/utils/      seeding, logging, git hash, shared helpers
scripts/        entry points that call into src/, one per pipeline stage
results/raw/    generation outputs, append-only, one subfolder per run
results/tables/ final tables for the paper
results/figures/ final figures for the paper
tests/          tests mirroring the src/ modules they cover
docs/           experimental design and pre-registered decisions
research_log.md running log of what was run and what was found
```

## Running an experiment

Every run passes `--output_dir`, `--seed`, and `--model_id`. Use `--num_tasks 10` to confirm a
script runs before committing to a full run.

```bash
uv run -m scripts.run_generation \
  --dataset_path data/processed/prompts.jsonl \
  --output_dir results/raw/250612_example_v1 \
  --model_id claude-sonnet-4-6 \
  --num_tasks 10 \
  --seed 42

uv run -m scripts.run_metrics \
  --dataset_path results/raw/250612_example_v1/outputs.jsonl \
  --output_dir results/raw/250612_example_v1 \
  --model_id claude-sonnet-4-6 \
  --seed 42
```

Never invoke scripts with bare `python`. Everything runs through `uv run -m`.

### Configs

The `Config` dataclass in `src/utils/config.py` is authoritative — it defines the fields, types,
and defaults. A YAML in `configs/` seeds those defaults for one experiment:

```bash
uv run -m scripts.run_generation --config_path configs/example_experiment.yaml --num_tasks 10
```

Precedence is **explicit CLI flag > `--config_path` YAML > dataclass default**. `dataset_path` has
no default and must always be given, by flag or by config.

## Conventions

- `results/raw/` is append-only. A rerun writes a new `YYMMDD_description_v1/` subfolder rather
  than overwriting prior results.
- Every run directory gets a `config.json` (git hash, model, seed) and a `run.log` beside its
  results, so any number can be traced back to the commit that produced it.
- Structured results are committed. Bulk artifacts too large for git go in
  `results/raw/<run>/generations/`, which is gitignored — everything else in the run directory
  stays in version control.
- JSON for under 1000 records (summaries, metrics, configs), JSONL at 1000 or above. One JSON
  object per line, `id` first. Floats rounded to 4 decimal places.
- Per-run figures go in `<output_dir>/figures/`. Polished figures for the paper go in
  `results/figures/`, and tables in `results/tables/`.
- Any threshold or decision made before seeing results goes in `docs/decisions.md`, dated.
- `data/raw/` is never edited directly.
- Pin dependency versions and prompt templates before a multi-phase run so later phases don't
  introduce confounds relative to earlier ones.
- Log every run in `research_log.md` immediately after it finishes.

## Documenting a script

Every script gets an entry here with four things: one sentence on what it tests, the exact command
including all required args, what it expects as input (file format and fields), and what it
produces as output (file format and fields). No vague descriptions like "loads data" — you will be
reading this during a rebuttal three months from now.

```
## Experiment: steering vector non-identifiability baseline

Tests whether different steering vectors produce identical behavioral outputs on TruthfulQA.

**Input:** `data/processed/truthfulqa_prompts.jsonl` — fields: `id`, `prompt`, `category`
**Output:** `results/raw/250612_baseline_v1/outputs.jsonl` — fields: `id`, `prompt`, `response`

**Run:**
uv run -m scripts.run_generation \
  --dataset_path data/processed/truthfulqa_prompts.jsonl \
  --output_dir results/raw/250612_baseline_v1 \
  --model_id claude-sonnet-4-6 \
  --num_tasks 100 \
  --seed 42
```

## Contributing

Work on a branch, never directly on `main`. With a collaborator or CI, merge through a pull
request — see `coding_guide.md` for that workflow. Solo with no CI, merge the branch locally; a PR
you approve yourself is not a review. Run `pre-commit run --all-files` before every commit, and see
`CLAUDE.md` for code conventions.

## Experimental design

See `docs/experimental_design.md`, `docs/decisions.md`, and `docs/project_design_decisions.md`.
