# workspace-bench — agent runbook

`wsbench` is a growing set of evals of whether an activation-reading lens (prose "O-lens" samples or
top-k "J-lens" tokens) surfaces what a model computes but never writes. Every family plugs
into the shared package in `src/wsbench/` (client, judge config, cache, readout contract,
results schema, registry, runner, CLI, `readplan` = the producer-facing read plan, `capable/` =
the porting gate, `produce/` = the optional HF-transformers producer behind the `gpu` extra).
`plans/` is the 2026-09-15..17 design history of the nine-family restructure, not a current
pointer (`plans/README.md`). Public docs: `README.md`, `NOTICE.md`, `CITATION.cff`.

## Readout contract (input to every family)
Stated once, in README §Quickstart (the contract block) and `docs/producing_readouts.md`; do not
restate it here. Code facts only: `load_readouts` counts malformed lines (never fatal), keeps the
first duplicate `(id, layer, pos)`, counts empty readouts (a result, not a missing cell).
`wsbench convert-gen-dir gen_dir=GEN out=F.jsonl kind=prose|tokens` converts the in-house
`<gen_dir>/<label>/L###.jsonl` layout (id = directory name, layer = filename).

## Judge layer (`llm.py`, `judge_config.py`)
- Default judge `google/gemini-3.8-flash` via OpenRouter, reasoning `{"effort": "minimal"}`.
  Pins: agentic_misalignment + jailbreak_recognition -> `claude-sonnet-5` (reasons: README
  §Judges and the family READMEs). jlens runs all three stages on the default judge.
- Override precedence and what `pinned_instrument` means: README §Judges (the bullets under
  the table); not restated here.
- Routes by model id: `claude-*` -> Anthropic SDK (`ANTHROPIC_API_KEY`, structured output,
  refusal -> `None`); else OpenRouter via the OpenAI SDK (`OPENROUTER_API_KEY`, `sk-or-…`).
  Shared: JSON-schema output, 11 jittered retries (`_ATTEMPTS = 12`) on 408/409/429/5xx/
  timeouts, process-wide thread-safe RPM pacer (`rpm=`, default 240), `preflight` fail-fast,
  `Spend` tally. A failed
  call returns `None` and never scores. `stream_json_async` is the primitive, `stream_json`
  wraps it (`temperature` dropped on the Anthropic route); `stream_text[_async]` is agentic's
  free-text Anthropic-only primitive.

## Family conventions
- `wsbench/family.py` holds the helpers the newer families share: `require_cells` (missing
  cells exit 2 unless `allow_missing=True`; a dry run only reports), `cell_text` (a token bag is
  judged scored but verified against bare tokens), `last_pos_rows`, `quote_in` (verbatim after
  `mc.fold`), `tri_state` (pass / fail / undecided), `rate` / `mean`, `pass_rate_result` (the
  pass-rate `FamilyResult` epilogue: decided-only value, bootstrap CI, completeness, counts).
  A pass-rate family's `run()` is: load bank -> `item_scope` -> `load_readouts` -> select cells ->
  `cell_text` -> `Call`s -> `run_calls` -> per-cell verdicts -> per-item rows -> `pass_rate_result`
  -> `with_readout_count`. `chain_intermediates/judge.py` is the shortest complete example.
- `mcjudge.py`: `Call` + `run_calls` (one schema per batch, fingerprint `(prompt_version, model,
  reasoning, temperature, system, user)`, cache `{result, meta}` in `<out>/cells.jsonl`,
  `validate` re-queues an invalid answer); `Preflighter` (one preflight per model per process);
  `item_scope` = bank ∩ `items=` then `limit=`; `base_config` / `base_counts`. `mc.py`: seeds,
  shuffles, `fold`, `letter_index` (a lone letter or a letter with its own option text).
  `summarizer.py`: token bag -> prose (prompt in `docs/summarizer.md`).
- Shared judges: `basic/` (the bank judge, `bank_family(name, title)`) and `multitoken/`
  (`mt_family(name, title, calls_per_arm=)`): its scorer of record is the deterministic regex
  contract `multitoken/regex.py` (a port of the source repo's `bank/matching.py` +
  `contract.py` + `conjunctive.py`; no call, `spend_usd` 0, `EvalSpec.scorer="regex"`, pinned by
  goldens `tests/golden/mt_regex_*.json` made by the source code); the forced-choice judge is
  `opts=judge=mc` (never pinned). Token bags are summarized first (`summarizer.summarize`, same
  bundle text / cache key / fingerprint as the MC path, so its cached interpretations are reused),
  then matched: a unit hits in the summary OR in a single token (`SUMMARIZED_SCORER_VERSION`; for
  token arms `judge_model` = the summarizer model, pinned/spend/undecided follow it). Their
  families are three-line packages under `evals/`. Option
  lists are pinned by goldens in `tests/golden/`. A spec with `scorer` set is not preflighted by
  `run` unless `opts=judge=mc`, and `wsbench list` shows the scorer in the judge column.
- Baselines (`baselines/`): `lucky_guessing` (option lists from the judges' own builders, blind /
  described / uniform) and `prompt_only`; `wsbench freeze` stamps entries with the family's
  `prompt_version`, and `report` shows a floor only while the stamp matches.
- Per-family read regimes, pass rules and floors are documented in each `evals/<family>/README.md`
  (the source of truth); do not restate them here. Ten families keep their own `judge.py` +
  `score.py`: Camila's nine originals (agentic, jailbreak, hallucination, jlens_concept_pr,
  moral, relational, role-bound, conjunctive, user_modeling) and directed_modulation.
- `opts=key=value,k2=v2` fills `JudgeArgs.extra`; `aux_models` comes from the family `JudgeConfig`.
  `EvalSpec.calls_per_arm` / `.sources` feed `wsbench list`; every non-empty `sources` must
  appear verbatim in README §Credits and NOTICE.md (`tests/test_readme.py`).

## Driver (`runner.py`, `cli.py`)
- `run all=True|families=a,b readouts_root=DIR out=DIR [family_workers=3] [json=True]` reads
  `DIR/<family>.jsonl` (missing -> `skipped`). Order: parse `opts=` once (bad pair = one exit
  2), resolve every judge once, preflight each distinct judge model once (not aux; skipped
  under `dry_run=True`; failure = exit 3 before any thread), then judge in a `ThreadPoolExecutor`
  (`min(n, family_workers)`, 1 under `dry_run=True`) under the shared pacer. Fail-soft per
  family: `JudgeConfigError` -> failed/3, `SystemExit` -> failed/2 (text `e.code` or `exit N`),
  listed under "## skipped / failed" in `summary.md`; other exceptions propagate. Exit 130 on
  `KeyboardInterrupt` (unstarted families cancelled, in-flight ones finish their batch), else
  3 > 2 > 0. Writes `summary.md` + `run.json` = `{started, finished, families: {name: {status,
  error?, results_path, value, complete, pinned_instrument, spend_usd, n_calls?}},
  judge_overrides: {flag, env}, readouts_root}`.
- `report dir=DIR [json=True]`: table with `(lower is better)`, `n (k no readouts)`, macro row (in-row
  `excluded:` + "Not in macro:" footnotes); rewrites `summary.md`. Exit 2 = not a directory /
  unreadable results.

## Results contract (`results.py`)
README §Results contract is the single statement (schema, `complete`, the macro row); `results.py`
implements it. Not restated here.

## Invariants
- Every judge prompt lives in the family's `prompts.py` (`PROMPTS`; `{name}` placeholders
  rendered by `str.replace`, never `str.format` — hallucination's `JUDGE_USER` and
  `VERIFY_USER` are the exceptions) AND verbatim in a fenced block of the family README under "Judge prompts";
  `tests/test_prompts_in_readme.py` asserts equality. Bump `prompt_version` on any edit.
- Failures never score; they are counted. Frozen banks are never edited in place. `spec.run`
  returns a `FamilyResult` and writes nothing. `counts` has a fixed key set (other tallies go
  in `extras`); no `Spend` crosses the family boundary. Cache rows are append-only.
- README: each family entry is `**<spec.title>** — [link]` followed by exactly three lines
  `- *What it is:*` / `- *Example:*` / `- *Judged by:*`, grouped Basic (single token) · Basic
  (multi-token) · Computational · Safety · Association · Bag of words · Precision · Logical processing. Credits live in README §Credits and NOTICE.md, one
  bullet per external source; in-house families get no credit line.
- Style, enforced by review rather than a linter: module docstrings are 1–3 lines (rationale
  goes in the README beside the code, not the file header); no `from __future__ import
  annotations` (Python ≥ 3.11, write the modern syntax directly).

## Adding a family
`src/wsbench/evals/<family>/{__init__,prompts,judge}.py` following the skeleton above (register an
`EvalSpec` in `__init__` with `calls_per_arm` and `sources`), `evals/<family>/{items.json,README.md}`
with every prompt verbatim, a toy `examples/readouts/<family>.jsonl` (a few rows), an offline
`tests/test_<family>.py` (monkeypatch the module's `run_calls`), the README entry and Judges row,
and a credit if the items are external. Smoke `limit=3` live before any full run.

## Workflow
- CLI (pydra, `wsbench <command> key=value ...`): `wsbench list` | `wsbench judge family=F
  readouts=F.jsonl out=DIR` | `wsbench run all=True readouts_root=DIR out=DIR` |
  `wsbench report dir=DIR` | `wsbench baseline` / `wsbench freeze` |
  `wsbench plan [families=a,b] [out=DIR]` (the producer interface: render, positions rule and
  layers per item, `docs/producing_readouts.md`; `readplan.resolve` turns a rule into indices) |
  `wsbench produce family=F method=M out=F.jsonl` or `text=... method=M positions=-1
  layers=20,36,60` (methods logit_lens | jlens | rlens | olens | nla; needs the `gpu` extra) |
  `wsbench capable model=M` (re-run a bank's own gate on another model; porting notes and
  the pre-run sanity checks live in `AGENTS.md`) | `wsbench convert-gen-dir
  gen_dir=GEN out=F.jsonl kind=prose|tokens` | `wsbench convert-read-json read=R out=F.jsonl`
  (legacy). Shared judge keys: README §Quickstart (the output-layout paragraph). Each command is
  a `pydra.Config` in `cli.py`: declare a field in `__init__`, normalise it in `finalize()`;
  `runner.py` reads the same attribute names.
- `uv sync --extra dev` (add `--extra gpu` for `produce`); `uv run pytest -q`; `uv run ruff
  check .`; `uv run ruff format .`. Keys
in the environment, never committed; tests make no network calls. Work
in a git worktree (prefix commands with `PYTHONPATH=src` when it shares the main checkout's
`.venv`); PRs are gated by `.github/workflows/ci.yml` (ruff + pytest).
