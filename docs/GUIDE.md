<!--
  AuditKIT — Complete Technical Guide
  Written against the AuditKit 1.0.0 source; counts, red-teaming, scenarios and the CLI re-checked against 1.1.2.
  Renders on GitHub (mermaid + tables) and as a hosted page.
-->

# AuditKIT — Complete Technical Guide

> **Version:** 1.1.2 (written for 1.0.0; counts, red-teaming, scenarios and the CLI re-checked for 1.1.2) · **Python:** ≥ 3.10 · **License:** LSAL v1.2
>
> This guide is written against the code. Limitations are stated inline, in context, wherever they matter.

---

## Table of contents

1. [What AuditKIT is, and why it exists](#1-what-auditkit-is-and-why-it-exists)
2. [Install and optional extras](#2-install-and-optional-extras)
3. [The mental model and architecture](#3-the-mental-model-and-architecture)
4. [Core concepts (the data model)](#4-core-concepts-the-data-model)
5. [The Python API](#5-the-python-api)
6. [Configuration reference: `RunConfig`](#6-configuration-reference-runconfig)
7. [Model backends](#7-model-backends)
8. [Two engines: native vs lm-eval](#8-two-engines-native-vs-lm-eval)
9. [Adapters and routing](#9-adapters-and-routing)
10. [The metric catalog](#10-the-metric-catalog)
11. [LLM-as-judge](#11-llm-as-judge)
12. [Comparison and experiments](#12-comparison-and-experiments)
13. [Red-teaming (a basic probe suite)](#13-red-teaming-a-basic-probe-suite)
14. [Performance metrics](#14-performance-metrics)
15. [CLI and YAML reference](#15-cli-and-yaml-reference)
16. [Scenarios and data loading](#16-scenarios-and-data-loading)
17. [Extending AuditKIT](#17-extending-auditkit)
18. [Known limitations (consolidated)](#18-known-limitations-consolidated)
19. [Appendix: glossary and file map](#19-appendix-glossary-and-file-map)

---

## 1. What AuditKIT is, and why it exists

**AuditKIT (`auditkit`, imported as `ak`) is a single Python library for evaluating any AI model, on any dataset, across any technique — through one call, `ak.evaluate()`.**

Model evaluation today is fragmented: academic benchmarks (MMLU, GSM8K) live in one tool, LLM-as-judge in another, RAG and performance profiling in yet others. Each has its own data model, so results can't be compared across techniques. AuditKIT unifies them behind **one evaluation spine** and **one result object** (`RunResult`) with a **stable fingerprint**, so a benchmark run, a judge run, and a RAG run are all the same shape — cacheable, diffable, and reproducible by construction.

**What it does:**

| Technique | What you get | Example scorers |
|---|---|---|
| Academic benchmarks | MCQ / generative accuracy via the real lm-eval-harness | `arc_easy`, `gsm8k`, `mmlu` (lm-eval tasks) |
| Deterministic checks | Exact/fuzzy string, JSON, regex, edit distance | `exact_match`, `contains`, `is_json`, `f1_score` |
| Generation quality | Overlap metrics | `bleu`, `rouge_l`, `chrf`, `word_error_rate` |
| LLM-as-judge | Model-graded classifier / numeric / rubric | `LLMJudge`, `GEval`, `Factuality`, `Relevance` |
| RAG | Groundedness / context quality | `lexical_groundedness`, `context_coverage`, `context_overlap` |
| Embedding similarity | Semantic closeness | `cosine_similarity`, `token_overlap`, `bm25_similarity` |
| Safety / toxicity | Toxicity, demographic representation, hate-speech, LLM-judge bias | `toxicity_score`, `representation_skew`, `hate_speech_score`, `bias_judge` |
| Security | Keyword detection + guard-model safety scoring | `keyword_detector`, `guard_judge` |
| Model comparison | Base-vs-pruned, N-model bake-offs, significance | `compare_models()`, `RunComparison` |
| Performance | Latency / throughput / model-size / tokens / cost | measured automatically on every run |

**Design commitments (enforced, not aspirational):**

- **Zero required third-party dependencies.** The core runs on the Python standard library. Every backend and heavy metric is an *optional extra* that is imported lazily and raises a clear `ExtraNotInstalled` with a `pip install` hint if missing — never an import-time crash. (`pyproject.toml` declares `dependencies = []`.)
- **Provenance by default.** Every run produces a `RunResult` carrying a `fingerprint` (a sha256 over model + config + tasks + scorers). Identical inputs → identical fingerprint → a disk-cache hit. Change any knob and the fingerprint changes.
- **The spine never changes to add a feature.** A new modality, technique, or backend is a new plugin file + one registry line — never an edit to `runner.py`/`score.py`/`sample.py`.

> **What it evaluates.** Text generation, multiple choice, RAG, LLM-as-judge, code and string checks, safety and security, performance, red-teaming probes, and agents and tool use (`ToolCallAdapter`, `ak.agent_eval`). Vision models take images through `Sample.images` on `hf:` and `api:`.

---

## 2. Install and optional extras

```bash
pip install auditkit                 # core, zero third-party deps
pip install "auditkit[openai]"       # + OpenAI backend
pip install "auditkit[all]"          # everything
```

The complete extras table (from `pyproject.toml`):

| Extra | Pulls in | Unlocks |
|---|---|---|
| `openai` | `openai` | `openai:` backend |
| `anthropic` | `anthropic` | `anthropic:` backend |
| `transformers` | `torch`, `transformers`, `peft` | `hf:` backend (including PEFT adapter folders), `perplexity`, `factual_consistency`, `toxicity_score`(model), `hate_speech_score`(model) |
| `lmeval` | `lm-eval`, `accelerate` | the **lm-eval engine** (`ak.run_lmeval`, `engine="lmeval"`) |
| `vision` | `pillow`, `torchvision`, `torchmetrics` | images for vision models (`Sample.images`): PIL images and local paths; `torchvision` for transformers' image processors |
| `interop` | `datasets`, `mlcroissant`, `GitPython` | native built-in scenarios (`load_hf`, `load_croissant`) |
| `mlflow` | `mlflow` | `Experiment.log_mlflow()`, `lexsi:` MLflow logging |
| `requests` | `requests` | `api:`, `groq:`, `openrouter:`, `lexsi:` backends |
| `sglang` | `sglang` | SGLang in its own environment (it can't share one with `vllm`/`transformers`); evaluate a running SGLang server with `api:` |
| `vllm` | `vllm` | `vllm:` backend |
| `litellm` | `litellm` | `litellm:` backend (Ollama, 100+ providers) |
| `bert-score` | `bert-score`, `torch` | `bert_score` metric |
| `relay` | `flask`, `werkzeug`, `requests` | `LexsiCompletionsRelay` |
| `lexsi-sdk` | `lexsi-sdk` | `lexsi_login()`, `run_benchmark(lexsi_org=...)` |
| `dev` | `pytest`, `pytest-asyncio`, `pytest-mock` | test suite |
| `all` | all of the above except `sglang` and `dev` | — |

> **Install hints.** Two lazy imports print a hint that doesn't match the real extra name: `bert_score` says `pip install bert-score` (works, but the extra is spelled `bert-score`), and `LexsiModel`'s missing-`requests` hint is a bare `pip install requests` rather than `auditkit[requests]`. Harmless, but you'll see it. There is **no standalone `groq` extra** — the Groq backend rides the `requests` extra.

---

## 3. The mental model and architecture

Everything flows through one directional pipeline, **the spine**, driven by `runner.py`:

```mermaid
flowchart LR
    A["Dataset<br/><i>Samples · Scenario · callable · CSV</i>"] --> B["Adapter<br/><i>generation · mcq · chat · rag · …</i>"]
    B --> C["Model<br/><i>echo · openai · hf · groq · …</i>"]
    C --> D["Annotator<br/><i>optional: regex / LLM / strip-thinking</i>"]
    D --> E{"Metrics"}
    E -->|per sample| F["Score + Prediction"]
    F --> G["Aggregate<br/><i>Stat per metric</i>"]
    G --> H["RunResult<br/><i>headline · fingerprint · perf · cache</i>"]
```

Each stage is a swappable plugin resolved from a **registry**. `ak.evaluate()` composes them into a `RunSpec`, the `Runner` executes it, and you get a `RunResult` back.

### Two engines behind one API

AuditKIT has **two independent execution engines**, both returning the *same* `RunResult`:

```mermaid
flowchart TD
    E["ak.evaluate(...)"] -->|engine='native' default| N["Native spine<br/><i>owns prompting + scoring</i>"]
    E -->|engine='lmeval'| L["lm-eval engine"]
    B["ak.run_lmeval(tasks, model)"] --> L
    N --> R["RunResult"]
    L -->|"lm_eval.simple_evaluate()"| R
    R --> CMP["compare / diff / answer-browser<br/><i>work identically on both</i>"]
```

- **Native engine** (`engine="native"`, the default): AuditKIT owns the whole pipeline above — it builds prompts via adapters, calls the model backend, and scores with its own metrics.
- **lm-eval engine** (`engine="lmeval"` or the dedicated `ak.run_lmeval()`): delegates to the real [lm-evaluation-harness](https://github.com/EleutherAI/lm-evaluation-harness) — its task templates, filters, and metrics — then maps lm-eval's aggregates + per-doc samples back into a `RunResult`. Requires `auditkit[lmeval]`. See [§8](#8-two-engines-native-vs-lm-eval).

> The native `scenarios/` package (mmlu, gsm8k, …) is a **separate reimplementation** that does *not* use lm-eval, and does less: no few-shot prompting and no code execution (see [§16](#16-scenarios-and-data-loading)). For academic benchmarks, `ak.run_lmeval()` (the lm-eval engine) is the more complete path.

### Provenance & caching

```mermaid
flowchart LR
    S["RunSpec<br/>model+adapter+metrics+config"] -->|fingerprint&#40;&#41;| FP["sha256[:16]"]
    FP --> C{"DiskCache<br/>~/.cache/auditkit/runs/"}
    C -->|hit| RR["cached RunResult (instant)"]
    C -->|miss| RUN["run the spine"] --> RR
    RUN -.->|cache.set| C
```

`RunSpec.fingerprint()` hashes the running `auditkit.__version__` (so a library upgrade that changes a metric never replays an old cached score), the model identity, scenario name, adapter identity (incl. its prompt template/system prompt), each metric's identity (a judge folds in its model + prompt + choices, but not transport/secret args like `api_key` or `timeout`), the annotators, and the **entire** `RunConfig`. Any change to any of these changes the fingerprint and forces a fresh run. This is what makes `compare()` and the disk cache correct.

The inline-dataset (`ListScenario`) name folds in each sample's content — including a **caller-supplied** `Sample.id`, so two datasets that differ only in their ids hash apart. An auto-assigned id (the `str(index)` the runner writes into an unset id) does not enter the hash, so re-running the same id-less samples still hits the cache.

---

## 4. Core concepts (the data model)

### `Sample` — one evaluation example

```python
ak.Sample(
    input,                       # str (required) — the prompt/question
    target=None,                 # str | int — gold answer (None = no gold)
    id=None,                     # str — stable id (auto-assigned if None)
    task="",                     # str — free-form task label (groups per-task deltas)
    kind=TaskKind.GENERATIVE,    # TaskKind enum
    choices=None,                # list[str] — MCQ options (presence → MCQ routing)
    retrieval_context=None,      # list[str] — RAG context (presence → RAG routing)
    metadata={},                 # dict — anything; judge prompts can reference keys
    tags=[],                     # list[str]
    actual_output=None,          # str — pre-generated output (precomputed/generate flow)
    tools=None,                  # list[dict] — tool schemas offered to the model (ToolCallAdapter)
    expected_tool_calls=None,    # list | dict | str — expected tool calls (agent metrics)
    reference_contexts=None,     # list[str] | dict[id, grade] — gold contexts for ranked retrieval metrics
    actual_trace=None,           # dict — a recorded agent/RAG run to score offline (messages, tool_calls, retrieved_contexts)
    images=None,                 # list — images for vision models (PIL images, paths or URLs; hf: and api:)
)
```
- `sample.is_golden` → `target is not None`. When `scorers=None`, this decides whether `ExactMatch` is auto-selected.
- **Two fields drive automatic adapter routing**: `choices` → MCQ, `retrieval_context` → RAG (see [§9](#9-adapters-and-routing)).

### `Model` & `Capability`

A `Model` implements `generate(requests) -> list[Result_]` (required) and optionally `loglikelihood(requests)`. Each declares its `Capability` set:

`Capability` = `GENERATE`, `LOGLIKELIHOOD`, `CHAT`, `EMBED`. Only `HFGenModel` declares `LOGLIKELIHOOD` (needed for MCQ-by-loglikelihood scoring); everything else is `GENERATE`-only. See [§7](#7-model-backends).

### `Metric` & `Direction`

A `Metric` turns `(sample, output, context) -> Score | list[Score]`. Contract:
- `required_fields` — a `frozenset` of `Sample` fields that must be present; if any is missing the metric is **skipped** for that sample (not errored).
- **`direction` is compulsory.** Every concrete `Metric` subclass *must* declare `direction = Direction.MAXIMIZE` or `Direction.MINIMIZE` as a class attribute — `Metric.__init_subclass__` raises `TypeError` at class-definition time otherwise. This exists so comparison/grading knows which way is "better": a lower-is-better metric graded as MAXIMIZE would report a regression as an improvement.
- `identity()` — the config that defines this metric's scoring, folded into the run fingerprint. Judges override it to include their model + prompt.

```python
Direction.MAXIMIZE  # higher value = better (accuracy, F1, faithfulness, …)
Direction.MINIMIZE  # lower value = better (perplexity)
```
> Built-ins that are genuinely `MINIMIZE`: `perplexity`, `representation_skew` (0 = balanced), and `bias_judge` (0 = no biased opinions). Deceptively-named ones (`word_error_rate`, `toxicity_score`) are pre-inverted in code to a higher-is-better 0–1 scale, so they're correctly `MAXIMIZE`. Direction describes the returned *value's* convention, not the phenomenon's name.

### `Score` & `Stat`

`Score` fields: `name`, `value` (float), `kind` (`ScoreKind`), `data_type` (`DataType`), `direction`, `label`, `reason`, `threshold`, `weight` (1.0), `source`, `metadata`. `passed` is a **computed property**: `None` if no `threshold`; for `MINIMIZE`, `value <= threshold`; else `value >= threshold`.

`Stat` aggregates many values per metric: `mean`, `std` (**population** std — divides by *n*, `0.0` when *n*<2), `stderr`, `min`, `max`, `percentile(p)` (**linear-interpolated**). Thread-safe (`add()` under a lock).

`ScoreKind` = `BENCHMARK, JUDGE, CODE, SECURITY, PERF, HUMAN, RAG`.
`TaskKind` = `MCQ, GENERATIVE, RAG, SECURITY, PERFORMANCE, LANGUAGE_MODELING`.
`DataType` = `NUMERIC, CATEGORICAL, BOOLEAN`. `Source` = `SDK, UI, ONLINE`.

### `Prediction` & `RunResult`

Every run returns a **`RunResult`**:

| Field | Contents |
|---|---|
| `run_id` | run name or fingerprint |
| `fingerprint` | sha256[:16] — the provenance/cache key |
| `headline` | `{metric_name: mean}` — the top-line numbers |
| `stats` | `{metric_name: Stat}` — full distribution |
| `predictions` | `list[Prediction]` — the per-sample answer browser |
| `config` | the `RunConfig` used |
| `model_spec` | the model (see serialization caveat below) |
| `errors` / `failed_count` | per-sample/metric errors (never abort the run) |
| `unscored` | per metric, results left out of the aggregate because they aren't measurements (`unknown` / `not_tested` counts) |
| `experiment_name` / `tags` | optional tracking metadata |
| `perf` | `{latency_ms: {...}, throughput: {...}}` — measured (see [§14](#14-performance-metrics)) |
| `model_size` | introspected params/sparsity/MB for local models; identity-only for hosted |
| `token_usage` | provider-reported `{prompt_tokens, completion_tokens, total_tokens}` |
| `metadata` | run-level facts: input lineage (`inputs`) and backend notes such as `api_server` |

Each **`Prediction`**: `run_id`, `task`, `sample_id`, `prompt`, `raw_output`, `parsed_answer`, `expected`, `correct` (`bool|None`), `score`, `choice_likelihoods`, `context`, `metadata` (holds the per-score dicts under `metadata["scores"]` — the source for per-task deltas and direction).

Useful `RunResult` methods:
- `summary()` → a printable multi-line digest (metrics ± stderr, perf line, model-size line, token line).
- `cost(pricing)` → dollar cost; `pricing = {"input_per_1m": ..., "output_per_1m": ...}`. Returns `None` if no token usage; **raises `KeyError`** if a pricing key is missing (only reachable when there *is* usage). No bundled price table by design.
- `save(path, fmt="json"|"csv")` / `RunResult.load(path)` / `to_dict()` / `from_dict()`.

> **`model_spec` doesn't serialize cleanly.** `to_dict()` stores the live `Model` object, so `save()`/cache writes render it as an unusable repr string like `"<auditkit.model.groq_gen.GroqModel object at 0x…>"`. Everything else (`config`, `headline`, `predictions`, `perf`, `token_usage`) round-trips fine. This also affects cached runs.

`ak.Result` is a public alias of `RunResult`.

---

## 5. The Python API

Five public functions do almost everything. All live in `api.py`.

### `ak.evaluate(...)` — the native front door

```python
result = ak.evaluate(
    dataset,                     # list[Sample] | scenario name | callable | Scenario
    model="hf:gpt2",              # str spec | callable | Model instance -- required, no default
    scorers=None,                # None | str | @scorer fn | Metric | list of these
    *,
    engine="native",            # "native" | "lmeval"
    adapter=None,                # None | "auto" | adapter name | Adapter
    annotators=None,             # None | str | Annotator | list
    extract_with=None,           # str — annotator name whose output feeds scoring
    config=None,                 # RunConfig
    verbose=False,
    experiment_name=None,        # str — persist this run to the ExperimentDB
    tags=None,                   # list[str]
    dataset_config=None,         # str — named config of a Hub dataset / local folder (e.g. "sft_alpaca")
    dataset_split=None,          # str — split of a Hub dataset (e.g. "test")
    **opts,                      # forwarded to the model constructor (api_key, device, …)
)
```

**How loose inputs are coerced (native path):**

| You pass | Becomes |
|---|---|
| `dataset` = `list[Sample]` | `ListScenario(list)` |
| `dataset` = `str` | looked up in the `SCENARIOS` registry (`AuditKitError` if unknown) |
| `dataset` = callable | `CallableScenario(fn)` (re-invoked each read) |
| `model` = `str` | `AutoModel.resolve(spec, **opts)` (prefix dispatch — [§7](#7-model-backends)) |
| `model` = callable | `CallableModel(fn)` |
| `scorers` = `None` | `[ExactMatch()]` if any sample has a `target`, else `[]` |
| `scorers` = `"exact_match"` etc. | built-in map, else `METRICS` registry lookup (`ValueError` if unknown) |
| `scorers` = `@scorer` fn / bare callable | wrapped as `FunctionScorer` → `ScorerMetric` |
| `scorers` = `Metric` | used as-is |
| `adapter` = `None` | `GenerationAdapter()` |
| `adapter` = `"auto"` | `route_adapter(samples)` — shape-based ([§9](#9-adapters-and-routing)) |

> **String scorers only work for zero-config metrics.** Passing `scorers="contains"` (or `regex`, `keyword_detector`, `g_eval`, …) fails, because the registry does `METRICS.get(name)()` with no args and those classes need constructor arguments. Pass an **instance** for parameterized metrics: `scorers=[ak.Contains("cat")]`. Bare strings are fine for `exact_match`, `quasi_exact_match`, `acc`, `bleu`, `rouge_l`, `f1_score`, `token_overlap`, `lexical_groundedness`, etc.

```python
import auditkit as ak

samples = [ak.Sample(input="2+2?", target="4"), ak.Sample(input="3+3?", target="6")]

# simplest possible run
r = ak.evaluate(samples, model=lambda prompts: ["4", "6"])
print(r.summary())

# your own model + custom scorer + explicit config
r = ak.evaluate(
    samples,
    model=lambda prompts: ["4", "6"],
    scorers=["exact_match", ak.Contains("6")],
    config=ak.RunConfig(seed=7, temperature=0.0, limit=100),
)
```

### `ak.run_lmeval(...)` — the lm-eval front door

```python
result = ak.run_lmeval(
    tasks,                # str | list[str] — lm-eval task name(s), comma-sep ok
    model,                # str spec (hf:/vllm:/openai:/anthropic:/groq:/api:)
    *,
    num_fewshot=None,
    limit=None,           # cap samples/task (smoke runs)
    config=None,          # RunConfig (overrides num_fewshot/limit if given)
    experiment_name=None,
    tags=None,
    **opts,               # device=, base_url=, hf_token=, api_key=, gen_kwargs=, …
)
```
```python
r = ak.run_lmeval("gsm8k", model="hf:gpt2", limit=5, device="cpu")
r = ak.run_lmeval("arc_easy,hellaswag", model="hf:sshleifer/tiny-gpt2", limit=20, device="cpu")
```
See [§8](#8-two-engines-native-vs-lm-eval) for backends, the chat-only guard, and the Groq wiring.

### `ak.generate(...)` — stage 1 of generate-then-score

Runs the model over the dataset with **no scoring**, returning `list[Sample]` with `actual_output` filled in. Score them later (repeatedly, with different scorers) without re-generating:

```python
generated = ak.generate(samples, model="groq:llama-3.3-70b-versatile")
r1 = ak.evaluate(generated, model="precomputed", scorers=["exact_match"])
r2 = ak.evaluate(generated, model="precomputed", scorers=[my_judge])   # no new API calls
```
The `precomputed` model reads `Sample.actual_output` and makes zero model calls.

### `ak.compare(...)` — polymorphic

```python
ak.compare([r1, r2, r3], metric="exact_match")   # → leaderboard: list[dict] sorted desc
ak.compare(baseline_run, candidate_run)          # → RunComparison (per-task deltas, grades)
ak.compare(base, cand, pass_threshold=0.02, warn_threshold=0.05)   # thresholds forwarded
```
Two results → a rich `RunComparison` ([§12](#12-comparison-and-experiments)). A list → a simple leaderboard of `{run_id, fingerprint, **headline}` rows.

### `ak.compare_models(...)` — run several models, then compare

```python
res = ak.compare_models(
    ["hf:gpt2", my_fn, "groq:llama-3.3-70b-versatile"],
    dataset=samples,
    scorers=["exact_match"],
    model_names=["base", "pruned", "prod"],
    config=ak.RunConfig(limit=50),
    configs={"pruned": ak.RunConfig(limit=50, temperature=0.2)},   # per-model RunConfig overrides
    adapter="auto",                          # shared across all models, like evaluate()'s own default
    annotators=[my_regex_annotator],         # shared across all models
    model_opts={
        "prod": {"api_key": "...", "adapter": ak.ChatAdapter(), "extract_with": "my_regex"},
    },
)
print(res.summary())
cmp = res.pairwise("base", "pruned")   # zoom into two → RunComparison
```

`adapter=`/`annotators=`/`extract_with=` on `compare_models()` itself work exactly
like on `evaluate()`, applied to every model. `model_opts[name]` can override any
of those for one model only — the rest of that dict (`api_key`, `dtype`, `device`,
...) still flows through unchanged to model construction, same as before.
`scorers` is deliberately **not** overridable per-model — comparison assumes one
shared metric set across models, so it stays a single top-level argument. This is
the only place per-model adapter/annotators are configurable — there's no
separate `adapters=`/`annotators_by_model=` param.
Runs each model on the shared dataset, isolates per-model failures into `res.errors`, and gives a leaderboard + per-task tables + pairwise significance ([§12](#12-comparison-and-experiments)).

---

## 6. Configuration reference: `RunConfig`

Every knob, with its real default:

| Field | Type | Default | Notes |
|---|---|---|---|
| `num_fewshot` | `int \| None` | `None` | few-shot count; overrides an adapter's own `num_shots` |
| `limit` | `int \| None` | `None` | cap samples (applied after scenario load) |
| `seed` | `int \| None` | `None` | fingerprint + split shuffling |
| `trials` | `int` | `1` | repeated trials |
| `batch_size` | `str \| int` | `"auto"` | forwarded to lm-eval / batched backends |
| `concurrency` | `int` | `1` | parallel chunks; only used when the model is `threadsafe` |
| `split` | `SplitConfig \| None` | `None` | train/val/test partition (few-shot pool) |
| `temperature` | `float` | `0.0` | |
| `top_p` | `float \| None` | `None` | |
| `top_k` | `int \| None` | `None` | |
| `max_tokens` | `int \| None` | `None` | |
| `stop_sequences` | `list[str] \| None` | `None` | |
| `presence_penalty` | `float \| None` | `None` | |
| `frequency_penalty` | `float \| None` | `None` | |
| `num_completions` | `int \| None` | `None` | reaches the API but **only `completions[0]` is scored** |
| `best_of` | `int \| None` | `None` | reaches the API; not reflected in the score |
| `timeout` | `float \| None` | `None` | per-call timeout (seconds) |
| `max_retries` | `int` | `3` | exponential backoff between attempts |
| `retry_delay` | `float` | `1.0` | base backoff (seconds); `retry_delay * 2**attempt` |
| `judge_model` | `str \| None` | `None` | |
| `judge_prompt_version` | `str \| None` | `None` | |
| `track_performance` | `bool` | `True` | record latency, throughput, token usage and model size in `RunResult.perf` |
| `chat_template_kwargs` | `dict \| None` | `None` | passed to the chat template on `hf:`/`vllm:` and sent to `api:` servers (e.g. `{"enable_thinking": False}`); a request's own values win |
| `extra` | `dict` | `{}` | hashed into the fingerprint; no built-in component reads it |

`SplitConfig`: `strategy` (`"sequential"` default, or `"random"`/`"stratified"`), `train_ratio` (0.0), `val_ratio` (0.0), `test_ratio` (1.0), `fold` (0), `seed` (fixed at 0 so baseline/candidate don't reshuffle differently).

> **Concurrency.** With `concurrency > 1`, the Runner splits requests into at most `concurrency` chunks (never more chunks than requests) and runs them in parallel, but only when the model declares `threadsafe=True`; otherwise it runs sequentially.
>
> **Generation params depend on the backend.** Each backend forwards only the params in its own key-map; the rest are silently dropped. E.g. `HFGenModel` ignores `num_completions` (`stop_sequences`/`seed` are now forwarded — `seed` via `transformers.set_seed()`, a global RNG reset, since `generate()` has no per-call seed kwarg); `LexsiModel` forwards only `temperature`/`max_tokens`. See the forwarding table in [§7](#7-model-backends).

---

## 7. Model backends

`AutoModel.resolve(spec, **opts)` dispatches by prefix. Each backend is one lazily-imported file mapped to an optional extra.

| Spec / prefix | Class | Extra | Capabilities | API-key env | `is_local` | `model_info()` | token usage | latency |
|---|---|---|---|---|---|---|---|---|
| callable | `CallableModel` | core | GENERATE | — | — | identity | — | — |
| `"precomputed"` | `PrecomputedModel` | core | GENERATE¹ | — | — | identity | — | — |
| `openai:` | `OpenAIModel` | `openai` | GENERATE | `OPENAI_API_KEY`² | ✗ | identity | ✓ | — |
| `anthropic:` | `AnthropicModel` | `anthropic` | GENERATE | `ANTHROPIC_API_KEY`² | ✗ | identity | ✓ | — |
| `hf:` | `HFGenModel` | `transformers` | GENERATE **+ LOGLIKELIHOOD** | (kwarg `hf_token`) | ✓ | **real** params/sparsity/MB | — | — |
| `vllm:` | `VLLMModel` | `vllm` | GENERATE | — | ✓ | identity-only³ | — | — |
| `litellm:` | `LiteLLMModel` | `litellm` | GENERATE | (LiteLLM's own) | ✗ | identity | ✓ | — |
| `api:` | `APIModel` | `requests` | GENERATE | `API_KEY`→`OPENAI_API_KEY` | ✗ | identity | ✓ | ✓ |
| `groq:` | `GroqModel` | `requests` | GENERATE | `GROQ_API_KEY` | ✗ | identity | ✓ | ✓ |
| `openrouter:` | `OpenRouterModel` | `requests` | GENERATE | `OPENROUTER_API_KEY` | ✗ | identity | ✓ | ✓ |
| `lexsi:` | `LexsiModel` | `requests` | GENERATE | `LEXSI_API_KEY` | ✗ | identity | ✗ | ✓ |

¹ `PrecomputedModel.reads_actual_output = True` — the Runner special-cases it and never calls `generate()`.
² OpenAI/Anthropic don't read the env var in AuditKIT code — they pass `api_key=None` and let the vendor SDK read it.
³ `VLLMModel` is marked `is_local=True` but intentionally does **not** override `model_info()`, so it reports identity-only (no size). A known gap.

**`threadsafe=True`** (safe to call concurrently): `CallableModel`, `PrecomputedModel`, `LiteLLMModel`. Explicitly `False`: `VLLMModel`, `APIModel`, `GroqModel`, `OpenRouterModel`. Default `False`: everything else. Only `threadsafe` models actually parallelize at `concurrency>1`.

**Constructor signatures (defaults shown):**

```python
OpenAIModel(model="gpt-4o-mini", api_key=None, api_base=None, name="openai", **kwargs)
AnthropicModel(model="claude-sonnet-4-20250514", api_key=None, name="anthropic", **kwargs)
HFGenModel(model="gpt2", device="auto", name="hf", hf_token=None, token=None, **kwargs)
VLLMModel(model="gpt2", name="vllm", **kwargs)
LiteLLMModel(model="gpt-4o-mini", name="litellm", **kwargs)
APIModel(model="gpt-4o-mini", api_base="https://api.openai.com/v1", api_key=None, chat_template=True, name="api", **kwargs)
GroqModel(model="llama-3.3-70b-versatile", api_key=None, api_base="https://api.groq.com/openai/v1", name="groq", **kwargs)
OpenRouterModel(model="openai/gpt-4o-mini", api_key=None, api_base="https://openrouter.ai/api/v1",
                 site_url=None, app_name=None, name="openrouter", **kwargs)
LexsiModel(model="lexsi-3.5", api_key=None, api_base="https://api.lexsi.ai/v1",
           mlflow_tracking_uri=None, mlflow_experiment=None, name="lexsi", **kwargs)
CallableModel(fn, name=None)   # any list[str] -> list[str]
```
`HFGenModel.device`: `"auto"`/`None` → CUDA > MPS > CPU; pass `device="cpu"` on a CPU box.

```python
# resolve directly, or just pass the spec to evaluate()
from auditkit.model import AutoModel
m = AutoModel.resolve("groq:llama-3.3-70b-versatile", api_key="gsk_...")
m = AutoModel.resolve("openrouter:openai/gpt-4o-mini", api_key="sk-or-...")

ak.evaluate(samples, model="hf:gpt2", device="cpu")          # opts forwarded to constructor
ak.evaluate(samples, model="api:my-model",
            api_base="https://my-host/v1", api_key="...")
ak.evaluate(samples, model=lambda ps: [p.upper() for p in ps])   # any callable
```

**Generation-param forwarding** (internal name → API name; everything else dropped):

| Backend | Forwards | Drops |
|---|---|---|
| OpenAI | temperature, top_p, max_tokens, stop_sequences→`stop`, presence/frequency_penalty, num_completions→`n`, seed | top_k, best_of |
| Anthropic | temperature, top_p, top_k, max_tokens, stop_sequences | penalties, seed, num_completions |
| HF | temperature, top_p, top_k, max_tokens→`max_new_tokens`, stop_sequences→`stop_strings`, seed (via `transformers.set_seed()`) | num_completions |
| vLLM | temperature, top_p, top_k, max_tokens, stop_sequences→`stop`, penalties, seed | num_completions |
| LiteLLM / API / Groq / OpenRouter | temperature, top_p, max_tokens, stop_sequences→`stop`, penalties, num_completions→`n`, seed | top_k |
| Lexsi | **temperature, max_tokens only** | everything else |

> **Note.** There is **no** `ollama:` backend; use `litellm:ollama/llama3`. `AutoModel.resolve` also keeps a dead code path (`_T1_PREFIXES` is empty).

---

## 8. Two engines: native vs lm-eval

| | Native (`engine="native"`) | lm-eval (`ak.run_lmeval` / `engine="lmeval"`) |
|---|---|---|
| Owns prompting | AuditKIT adapters | lm-eval task templates |
| Owns scoring | AuditKIT metrics | lm-eval metrics + filters |
| Use for | your own datasets, judges, RAG, custom scorers | standard academic benchmarks (MMLU, GSM8K, ARC, HellaSwag, …) |
| Model specs | all backends in [§7](#7-model-backends) | `hf:`, `vllm:`, `openai:`, `anthropic:`, `groq:`, `openrouter:`, `api:` (+`base_url`) |
| Extra | core (+ backend extra) | `auditkit[lmeval]` |

Both return the identical `RunResult`, so `compare`, diff, and the answer-browser work the same either way.

**lm-eval backend mapping** (`map_model_spec`): `hf:`→`hf`, `vllm:`→`vllm`, `openai:`/`groq:`/`openrouter:`→`openai-chat-completions`, `anthropic:`→`anthropic-chat`, `api:`/`lexsi:`→`local-completions` (needs `base_url`).

**The chat-only / MCQ guard.** MCQ tasks (arc, hellaswag, mmlu) are scored by *loglikelihood*, which needs a logprob-capable backend (`hf:`, `vllm:`, or `api:` with `base_url`). A chat-only backend (`openai:`, `anthropic:`, `groq:`, `openrouter:`) on an MCQ task raises `CapabilityError` up front. Chat-only backends work on **generative** tasks (gsm8k). 

```python
ak.run_lmeval("gsm8k", model="hf:gpt2", limit=10, device="cpu")     # generative — any backend
ak.run_lmeval("arc_easy", model="hf:gpt2", limit=20, device="cpu")  # MCQ — needs hf/vllm/api
ak.run_lmeval("arc_easy", model="groq:llama-3.3-70b-versatile")     # raises CapabilityError
```

**Groq / OpenRouter on lm-eval.** Both map to lm-eval's `openai-chat-completions` backend with their base URL filled in automatically. Both are chat-only (no logprobs), so **generative tasks only**. Auth: the backend reads `OPENAI_API_KEY`, so AuditKIT mirrors `GROQ_API_KEY`/`OPENROUTER_API_KEY` (or a passed `api_key`) into it for the run's duration only. Missing key → a clear `AuditKitError`.

> **Required, not optional: `apply_chat_template=True`.** Live-confirmed against real OpenRouter models — omitting it doesn't degrade gracefully, it crashes outright with `AssertionError: chat-completions require the --apply_chat_template flag.` lm-eval's `openai-chat-completions` model class always builds a `messages` list internally when this flag is set, and always passes the task's raw string prompt straight through otherwise, which its own chat-completions payload builder then rejects. This applies to **any** model on this backend, `groq:` included, not just "instruct variants" as the flag's own name suggests.

```python
# needs GROQ_API_KEY (or api_key=...)
ak.run_lmeval("gsm8k", model="groq:llama-3.3-70b-versatile", limit=5, apply_chat_template=True)
# needs OPENROUTER_API_KEY (or api_key=...)
ak.run_lmeval("gsm8k", model="openrouter:openai/gpt-4o-mini", limit=5, apply_chat_template=True)
```

**Passing lm-eval knobs** (native adapters don't have these — they're lm-eval-only): `apply_chat_template=True` (**required** for `groq:`/`openrouter:`/`openai:`/`anthropic:` — see above), `system_instruction=...`, `gen_kwargs="temperature=0,max_gen_toks=256"`, `fewshot_as_multiturn=True`, or anything else via `lmeval_kwargs={...}`. Gated models: pass `hf_token=` (also mirrored to `HF_TOKEN` for gated datasets).

**The Lexsi gateway (`lexsi:`).** Rides the same `local-completions` backend as `api:` (needs `base_url=`), plus three things `api:` doesn't have:
- **Auto-`tokenizer=`.** `map_model_spec()` infers it from the model name when not given explicitly: strips a trailing `_v<digits>` version suffix, then splits org/repo at the first remaining hyphen (`"Qwen-Qwen3-0.6B_v1"` → `"Qwen/Qwen3-0.6B"`). An explicit `tokenizer=` always wins.
- **`project_name=`/`provider=`/`client_id=`.** The gateway rejects requests missing these. `run_benchmark()` folds them into `gen_kwargs` automatically, for any backend pointed at a Lexsi gateway via `base_url=`. Caller-supplied `gen_kwargs` values win on key conflicts.
- **`relay=True`.** The chat/generation endpoint (`/gateway/v1/chat/completions`) accepts the three fields directly, no relay needed. The completions/loglikelihood endpoint (`/gateway/v1/completions`) reroutes a direct request carrying those fields server-side and 404s instead, confirmed against the real gateway. `relay=True` starts a short-lived local `LexsiCompletionsRelay` (optional `auditkit[relay]` extra) right before the call, repoints `base_url` at it, and stops it in a `finally`, so teardown happens whether the run succeeds or raises. The disk-cache fingerprint is computed from the real `base_url=` before the relay's ephemeral local port gets substituted in, so caching stays stable across runs.

```python
TOKEN, PROJECT_ID, CLIENT_ID = ak.lexsi_login("MyOrg", "MyWorkspace", "MyProject")  # optional auditkit[lexsi-sdk] extra

ak.run_lmeval("gsm8k", model="openai:my-model",
              base_url="https://.../gateway/v1/chat/completions",
              project_name=PROJECT_ID, provider="Lexsi", client_id=CLIENT_ID, api_key=TOKEN,
              apply_chat_template=True, num_fewshot=0, limit=10)

ak.run_lmeval("arc_easy", model="lexsi:my-model",   # auto-infers tokenizer=
              base_url="https://.../gateway/v1/completions",
              project_name=PROJECT_ID, provider="Lexsi", client_id=CLIENT_ID, api_key=TOKEN,
              relay=True, num_fewshot=0, limit=10)
```

`ak.lexsi_login(org, workspace, project, sdk_access_token=None, api_url=..., app_url=...)` (`lexsi_login.py`, the only place `lexsi_sdk` is imported) does the login and project lookup once, returning `(token, project_id, client_id)`. `client_id` is the logged-in user's own username, resolved automatically on a best-effort basis: it comes back `None` when it can't be determined, and you can pass your own instead. `sdk_access_token` falls back to the `SDK_ACCESS_TOKEN` env var, so calling code never needs a literal token. For a single call without a separate login step, pass `lexsi_org=`/`lexsi_workspace=`/`lexsi_project=` straight to `run_benchmark`/`ak.run_lmeval` instead.

---

## 9. Adapters and routing

An **adapter** turns a `Sample` into one or more `Request`s (the wire format sent to the model). There are **7**, all registered by name:

| Name | Class | Targets | Key constructor params |
|---|---|---|---|
| `generation` | `GenerationAdapter` | free-form generation (default) | — |
| `mcq` | `MCQAdapter` | multiple choice (`choices`) | `method="mcq_joint"` or `"mcq_loglikelihood"` |
| `chat` | `ChatAdapter` | chat with a system prompt | `system_prompt="You are a helpful assistant."` |
| `fewshot` | `FewShotAdapter` | in-context examples | `num_shots=3`, `separator="\n\n"`, `pool=None` |
| `instruction` | `InstructionAdapter` | instruction-prefixed | `instruction="Answer the following question:"` |
| `rag` | `RAGAdapter` | retrieval-augmented (`retrieval_context`) | `context_separator="\nContext:\n"`, `max_context_chars=None` |
| `template` | `TemplateAdapter` | custom template | `template="{input}"` (placeholders `{input}`, `{target}`, `{context}`) |

**Routing** — `route_adapter(samples)` picks purely from task *shape* (the model argument is accepted but ignored):

```mermaid
flowchart TD
    S["first sample"] --> Q1{"has choices?"}
    Q1 -->|yes| MCQ["MCQAdapter"]
    Q1 -->|no| Q2{"has retrieval_context?"}
    Q2 -->|yes| RAG["RAGAdapter"]
    Q2 -->|no| GEN["GenerationAdapter"]
```

> The router **never** auto-selects `chat`, `fewshot`, `instruction`, or `template` — those are opt-in (`adapter="chat"` or an instance). `adapter="auto"` invokes the router; `adapter=None` (the default) always uses `GenerationAdapter`.

**MCQ has two modes.** `mcq_joint` (default) builds one prompt listing choices as `0. …`, `1. …` with `Answer:` and scores the generated index. `mcq_loglikelihood` emits **N** requests (one per choice) with `request_type="loglikelihood"` — this is the classic MCQ-by-logprob technique, and needs a `LOGLIKELIHOOD`-capable model (`hf:`). Choices are labeled **0-based numeric** (not letters) to avoid the >26-choice letter-overflow bug and to line up with `sample.target` indexing.

```python
ak.evaluate(mcq_samples, adapter="auto", scorers=["acc"])                 # → MCQAdapter (joint)
ak.evaluate(mcq_samples, adapter=ak.MCQAdapter(method="mcq_loglikelihood"),
            model="hf:gpt2", scorers=["acc"], device="cpu")
ak.evaluate(qs, adapter=ak.ChatAdapter(system_prompt="You are a terse expert."))
ak.evaluate(qs, adapter=ak.FewShotAdapter(num_shots=5, pool=train_samples))
ak.evaluate(rag_samples, adapter="auto", scorers=["lexical_groundedness","context_coverage"])
```

The system prompt / messages story: `ChatAdapter` puts a structured `messages` list in `request.params["messages"]` **and** a flattened `System:…\n\nUser:…` string in `request.prompt`. Chat backends (OpenAI, Anthropic, Groq, OpenRouter, LiteLLM, `api:` with `chat_template=True`) read `messages` via the `resolve_messages()` helper; `hf:` re-derives chat formatting through the tokenizer's own `chat_template`; `vllm:`/`lexsi:` use the raw prompt text.

> **Note.** `apply_chat_template`, `system_instruction`, and `fewshot_as_multiturn` are **lm-eval engine knobs, not native adapter features** — don't expect them on the native path; use `ChatAdapter`/`FewShotAdapter` there instead.

---

## 10. The metric catalog

Pass a metric as a **string** (zero-config only) or an **instance** (for parameters). Every metric declares a `direction`; only `perplexity` is `MINIMIZE`.

### Built-ins (`metric.py`) — all MAXIMIZE, deterministic

| Name | Measures | Requires | Params |
|---|---|---|---|
| `exact_match` | `output.strip() == target.strip()` | `target` | — |
| `quasi_exact_match` | exact match after normalization (lowercase, strip punctuation + articles, collapse whitespace) | `target` | — |
| `acc` | output resolves to same choice index as target | `target`, `choices` | — |
| `acc_norm` | same as `acc` (identical body) | `target`, `choices` | — |

Target/output accept three encodings: choice text, 0-based index, or a single A–Z letter (≤26 choices).

### Code / deterministic (`metrics/code.py`) — MAXIMIZE, deterministic

| Name | Measures | Requires | Params |
|---|---|---|---|
| `equals` | trimmed equality (optional case-insensitive) | `target` | `ignore_case=False` |
| `contains` | substring present | — | `substring` (required), `ignore_case=False` |
| `starts_with` | prefix match | — | `prefix`, `ignore_case=False` |
| `ends_with` | suffix match | — | `suffix`, `ignore_case=False` |
| `regex` | `re.search(pattern, output)` | — | `pattern` (required) |
| `levenshtein` | `1 - editdist/maxlen` (continuous) | — | — |
| `word_count` | word count within `[min,max]` | — | `min_words=0`, `max_words=None` |
| `is_json` | parses as JSON (+ required keys) | — | `require_keys=None` |
| `f1_score` | token-set F1 (continuous) | `target` | — |

### Structured output (`metrics/structured.py`) - MAXIMIZE, deterministic

| Name | Measures | Requires | Params | Extra |
|---|---|---|---|---|
| `json_schema_valid` | output parses as JSON and validates against a JSON Schema; reason = first failing path | schema via `schema=` or `metadata["schema"]` | `schema=None`, `backend="auto"\|"jsonschema"\|"minimal"`, `strip_fences=False`, `schema_key="schema"` | `jsonschema` (optional; a built-in subset validator is used without it) |
| `field_f1` | micro precision / recall / F1 over the scalar leaves of the output JSON vs `target` JSON; emits `field_f1`, `field_precision`, `field_recall` | `target` | `normalize_numbers=False`, `number_tol=0.0`, `case_sensitive=True`, `strip=True`, `date_formats=None`, `normalizers=None`, `list_keys=None`, `ignore=()`, `strip_fences=False` | - |

`field_f1` aligns lists before comparing: scalar lists as multisets, object lists by `list_keys` (a key field name, or `{path pattern: key field}`) and otherwise greedily by most matching leaves. Path patterns use `*` and write list indices as `[]` (`items[].price`).

### Generation quality (`metrics/generation.py`)

| Name | Measures | Dir | Det | Requires | Params | Extra |
|---|---|---|---|---|---|---|
| `bleu` | BLEU (brevity penalty + n-gram) | MAX | ✓ | `target` | `max_n=4`, `smooth=True` | — |
| `rouge_l` | ROUGE-L F1 (LCS) | MAX | ✓ | `target` | — | — |
| `chrf` | character n-gram F-β | MAX | ✓ | `target` | `n=6`, `beta=1.0` | — |
| `word_error_rate` | `max(0, 1-WER)` — **pre-inverted, so MAX** | MAX | ✓ | `target` | — | — |
| `perplexity` | raw `exp(loss)` — genuinely **MINIMIZE** | MIN | ✗ | `target` | `model_name="gpt2"` | `transformers` |
| `bert_score` | BERTScore F1 | MAX | ✗ | `target` | `model_name="microsoft/deberta-xlarge-mnli"` | `bert-score` |

### Embedding similarity (`metrics/embedding.py`) — MAXIMIZE, requires `target`

| Name | Measures | Det | Params | Extra |
|---|---|---|---|---|
| `cosine_similarity` | cosine of sentence embeddings (plain `transformers`, not the `sentence-transformers` package) | ✗ | `model_name="sentence-transformers/all-MiniLM-L6-v2"` | `transformers` |
| `token_overlap` | Jaccard of token sets | ✓ | — | — |
| `bm25_similarity` | clipped token-frequency overlap | ✓ | — | — |

### RAG (`metrics/rag.py`) — MAXIMIZE, deterministic

All four share one tokenizer (lowercase + strip punctuation). Contexts come from the trace's `retrieved_contexts` when present, else `Sample.retrieval_context`; a sample with no context is skipped (no fake 0), so these are not gated on `retrieval_context` being set.

| Name | Measures | Requires |
|---|---|---|
| `lexical_groundedness` | fraction of output tokens backed by context (word-prefix match) | context (trace or sample) |
| `context_coverage` | fraction of *target* vocab present in context (retrieval quality; ignores output) | `target` + context |
| `context_overlap` | fraction of context chunks sharing a token with output | context (trace or sample) |
| `answer_overlap` | token-set overlap of output vs target | `target` |

### Hallucination / consistency (`metrics/hallucination.py`) — MAXIMIZE, requires `target`

| Name | Measures | Det | Extra | Caveat |
|---|---|---|---|---|
| `factual_consistency` | NLI entailment (entail=1, contradict=0, neutral=0.5) | ✗ | `transformers` | — |

### Toxicity / bias (`metrics/toxicity.py`) — MAXIMIZE (1.0 = clean)

| Name | Measures | Params | Extra |
|---|---|---|---|
| `toxicity_score` | 1.0 clean → 0.0 toxic; model or blacklist | `use_model=True`, `model_name="unitary/toxic-bert"`, `blacklist=None` | `transformers` (model path) |
| `representation_skew` | **MINIMIZE**, 0 = balanced. TV-distance from balanced representation of demographic groups per axis, averaged over axes mentioned | `demographic_terms=None` | — |
| `hate_speech_score` | `0.6*toxicity + 0.4*(1 - representation_skew)` | `use_model=True` | `transformers` (model path) |
| `bias_judge` | **MINIMIZE**, 0 = no bias. LLM-as-judge: fraction of the output's own opinions flagged biased | `judge_model=...` | judge model |

> **Note.** `representation_skew` measures demographic-*representation* balance, not bias — it can't see meaning (a balanced-but-sexist sentence scores 0.0) and is best read in aggregate over a run. For biased *content* use `bias_judge` (reads meaning via a judge, but is non-deterministic and inherits the judge's own biases — pin the model, `temperature=0`); for whether the model *treats groups differently*, run BBQ/CrowS-Pairs via `run_lmeval`. `toxicity_score`/`hate_speech_score` with `use_model=False` are keyword-blacklist heuristics.

### Pairwise / preference (`metrics/pairwise.py`) — MAXIMIZE, requires `target`

| Name | Measures | Params | Caveat |
|---|---|---|---|
| `win_rate` | fraction of `context["candidates"]` the output beats | `comparator="exact"` | 0.0 if no candidates |
| `elo_score` | Elo from `context["pairwise_results"]` | `k=32`, `initial_rating=1000` | **returns 0–2000**, not 0–1; falls back to a token-overlap proxy |
| `preference_accuracy` | accuracy over `context["preference_data"]` pairs | — | **returns 0.5** when no preference data |

> **Note.** All three silently fall back to a crude token-overlap proxy when you don't populate the relevant `context` key — easy to use without realizing you're getting the degraded path. `elo_score` is the only metric not on a 0–1 scale.

### Security (`metrics/security.py`)

| Name | Measures | Dir | Requires | Params |
|---|---|---|---|---|
| `keyword_detector` | 0.0 if any blacklisted keyword present (unless whitelisted), else 1.0 | MAX | — | `blacklist` (required), `whitelist=None` |

### Judges (`metrics/judge.py`) — see [§11](#11-llm-as-judge)

`llm_judge`, `g_eval`, `factuality`, `closed_qa`, `relevance` — all `JudgeMetric` (JUDGE kind, MAXIMIZE default, non-deterministic).

### Not a scorer: `perf.py`

`metrics/perf.py` registers **no** metric. It holds the `LatencyStats`/`Throughput` aggregators the Runner uses to populate `RunResult.perf` ([§14](#14-performance-metrics)) — there is no `"perf"` string to pass as a scorer.

```python
# strings for zero-config; instances for parameters
ak.evaluate(s, scorers=["exact_match", "f1_score", "bleu"])
ak.evaluate(s, scorers=[ak.Contains("cat"), ak.Regex(r"\d+"), ak.WordCount(max_words=50)])
ak.evaluate(s, scorers=[ak.KeywordDetector(blacklist=["ssn","password"])])
```

---

## 11. LLM-as-judge

A judge is a `Metric` that asks *another model* to grade the output. Base class `JudgeMetric` (JUDGE kind, `MAXIMIZE`, non-deterministic). The generic one is `LLMJudge`; four prebuilt judges wrap it with fixed rubrics.

### `LLMJudge` — full constructor (all keyword-only)

```python
ak.LLMJudge(
    judge_model=None,            # str spec | Model — the grader (resolved via AutoModel)
    prompt="Rate the OUTPUT.\nInput: {input}\nExpected: {expected}\nOutput: {output}",
    choices=None,                # {label: score} → classifier mode
    scale=None,                  # (lo, hi) → numeric mode (mutually exclusive with choices)
    system_prompt=None,
    name="llm_judge",
    use_cot=False,               # chain-of-thought: verdict on the final line
    prompt_version=None,
    threshold=None,
    required_fields=frozenset(),
    unknown_score=0.0,           # value when the verdict can't be parsed
    judge_model_args=None,       # connection kwargs: api_key/api_base/device/hf_token/timeout
    temperature=None, max_tokens=None, top_p=None,   # judge generation settings
    direction=Direction.MAXIMIZE,
)
```

- **Classifier vs numeric.** Give `choices={"yes":1.0,"partial":0.5,"no":0.0}` *or* `scale=(1.0,5.0)` — not both (raises `ValueError`). Neither → defaults to `scale=(0.0,1.0)`.
- **Parsing is robust.** The judge is instructed to emit a marker line (`CHOICE: …` or `SCORE: …`); the parser reads the **last** marker (so CoT reasoning above it is ignored), falls back to the final line, and for ties picks the label occurring **last by text position**. Unparseable → an explicit **Unknown** (`value=unknown_score`, `metadata["unknown"]=True`), never a silent midpoint.
- **Prompt placeholders:** `{input}`, `{output}`, `{expected}`/`{target}`, `{context}` (joined `retrieval_context`), plus any `sample.metadata` key.
- **Fingerprint.** `identity()` folds in the judge model, prompt, system prompt, choices/scale, `use_cot`, `prompt_version`, and generation params — so changing the "ruler" changes the run fingerprint and never silently reuses a cached score graded by a different judge. Transport/secret kwargs in `judge_model_args` (`api_key`, `timeout`, `device`, `hf_token`, …) are **excluded**, so rotating a key or bumping a timeout still hits the cache; `api_base` is kept, since for a string spec it's the only record of which server (hence which model) graded.
- **Judge timeout.** When `judge_model` is an `api:` spec, the resolved model gets a longer default timeout (600s, vs the backend's 120s) so a slow reasoning judge doesn't time out. Override with `judge_model_args={"timeout": …}` or the `AUDITKIT_JUDGE_TIMEOUT` env var.

```python
judge = ak.LLMJudge(
    judge_model="groq:llama-3.3-70b-versatile",
    prompt="Q: {input}\nAnswer: {output}\nIs the answer correct and clear?",
    choices={"yes": 1.0, "partial": 0.5, "no": 0.0},
    use_cot=True, name="quality",
)
r = ak.evaluate(qa_samples, model="hf:gpt2", scorers=[judge], device="cpu")
```

### Prebuilt judges

| Name | Class | Convention | Notes |
|---|---|---|---|
| `factuality` | `Factuality` | autoevals A–E → `{A:0.4,B:0.6,C:1.0,D:0.0,E:1.0}` | needs `expected`; CoT |
| `closed_qa` | `ClosedQA` | `{yes:1.0,no:0.0}` | no gold needed; `criteria="factually correct and complete"` |
| `relevance` | `Relevance` | `{relevant:1.0,partially_relevant:0.5,irrelevant:0.0}` | output-vs-input relevance; CoT |
| `g_eval` | `GEval` | numeric `scale=(1.0,5.0)` from a weighted rubric | CoT; needs a `rubric` |

```python
ak.evaluate(s, model=m, scorers=[ak.Factuality(judge_model="groq:llama-3.3-70b-versatile")])

rubric = [ak.RubricItem("Correctness", weight=2.0, description="factually right"),
          ak.RubricItem("Clarity", weight=1.0)]
geval = ak.GEval(rubric, judge_model="groq:llama-3.3-70b-versatile")
```
All prebuilt judges ship a default `system_prompt` that guards against verbosity/sycophancy/position bias and prompt-injection inside the data sections.

---

## 12. Comparison and experiments

Comparison is a **read-side layer over finished `RunResult`s**. It re-reads the stored per-sample scores and never re-runs models. (`compare_models()` is the exception — it runs the models first, then hands you the read-side view.)

### `RunComparison` — baseline vs candidate

```python
cmp = ak.compare(baseline_run, candidate_run)   # or RunComparison(base, cand, pass_threshold=.02, warn_threshold=.05)
```

| Method | Returns |
|---|---|
| `metric_deltas()` | `list[MetricDelta]` — per-metric baseline/candidate/delta/grade + counts + std |
| `per_task_deltas()` | `list[TaskDelta]` — the same, grouped by `sample.task` (engine-agnostic) |
| `grade()` | the **worst** `DeltaGrade` across tasks — the ship/no-ship headline |
| `grades()` | `{metric: DeltaGrade}` |
| `retention(metric=None)` | fraction of baseline quality kept (1.0 = parity); dict if `metric=None` |
| `significance(metric=None)` | paired bootstrap aligned by `sample_id` |
| `tradeoff(metric=None)` | quality vs measured size/latency (`size_ratio`, `quality_per_mb`, `speedup`, or `api_based`) |
| `performance()` | measured latency/throughput/speedup only |
| `cost(base_pricing, cand_pricing)` | dollar cost per side + ratio |
| `regressed()` / `improved()` / `still_wrong()` | per-sample browser (aligned by `sample_id`) |
| `failure_summary()` / `coverage_warnings()` | failed-sample counts; per-metric/task N mismatches |
| `summary()` | printable digest of all of the above |

**Grading is direction-aware.** `grade_delta(delta, direction, pass_threshold=0.02, warn_threshold=0.05)`: `regression = -delta if MAXIMIZE else delta`; `≤ pass` → PASS, `≤ warn` → WARN, else FAIL. So a *drop* in accuracy and a *rise* in latency both grade as regressions.

**`DeltaGrade`** = `PASS`, `WARN`, `FAIL`, `NOT_COMPARABLE`. The last one is for a metric scored on only one side — it's ranked *below* PASS in the worst-case reduction (order: `NOT_COMPARABLE(-1) < PASS(0) < WARN(1) < FAIL(2)`), so an incomparable metric can't masquerade as a real regression, and `MetricDelta`/`TaskDelta` carry `None` (never a fabricated `0.0`) for the missing side.

```python
cmp = ak.compare(base, cand)
print(cmp.grade())                       # PASS / WARN / FAIL
print(cmp.per_task_deltas())
print(cmp.retention("exact_match"))      # e.g. 0.98
print([p.sample_id for p in cmp.regressed()])
print(cmp.tradeoff(metric="exact_match"))
print(cmp.performance())
```

### `RunDiff` — the lower-level two-run diff

`RunComparison` wraps a `RunDiff` for the sample browser. You can use `RunDiff(baseline, contrast)` directly (it's also what `Experiment.pairwise_diff()` returns): `metric_deltas()`, `grade(metric)`, `grades()`, `regressed()/improved()/still_wrong()/still_correct()`, `sample_summary()`. It classifies each `sample_id` into newly_wrong / newly_correct / still_wrong / still_correct / unknown, using the score's own `passed` gate (so threshold-gated/continuous metrics diff correctly, not just 0/1).

### `compare_models()` → `CompareResult` (N models)

```python
res = ak.compare_models([...], dataset, scorers=[...], model_names=[...], config=..., configs={...}, model_opts={...})
```

| `CompareResult` method | Returns |
|---|---|
| `per_metric()` / `winner(metric=None)` | direction-aware per-metric winner |
| `pairwise(base_name, cand_name)` | a `RunComparison` between two of the models |
| `significance(a, b, metric=None)` | paired bootstrap between two models |
| `comparison_table()` | one row/metric: `{name}_score/_n/_std` + `winner` |
| `per_task_table()` / `task_macro_average_table()` | per-(task,metric) and macro-averaged |
| `performance_table()` | per-model latency mean, rps, out-tok/s, calls |
| `size_table()` | per-model params/sparsity/MB (real for `hf:`) |
| `cost_table(pricing)` | `pricing = {model_name: {"input_per_1m","output_per_1m"}}` |
| `coverage_warnings()` / `errors` | failed models + N mismatches |
| `summary()` | everything above, printable |

Per-model failures are isolated into `res.errors[name]` — a crashing model never takes down the comparison; winner selection is direction-aware (uses `min` for MINIMIZE metrics).

### Significance — read this caveat

`significance()` / `CompareResult.significance()` / `Experiment.significance()` all call `paired_bootstrap(score_pairs(...))`, aligned by `sample_id`. The result dict: `{n, mean_baseline, mean_candidate, delta, p_value, significant}` (`significant = p < 0.05`, deterministic with `seed=42`).

> **It's a conservative heuristic, not a rigorous test.** The bootstrap resamples the observed per-sample diffs and compares each resample's mean magnitude to the observed mean — the reference distribution is centered on the observed effect, not a null centered at zero. So a large but *low-variance* difference (every sample flips the same way) can report `significant=False`. Treat it as a rough guard.

### Experiment tracking

```python
r = ak.evaluate(data, model="hf:gpt2", experiment_name="math")   # auto-persists to ExperimentDB
exp = ak.ExperimentDB().load("math")
exp.aggregate(); exp.leaderboard(); exp.significance("exact_match")
exp.pairwise_diff(0, -1)          # RunDiff between first and last run
exp.log_mlflow(tracking_uri=...)  # optional, needs auditkit[mlflow]
```
`ExperimentDB` stores JSON under `${XDG_DATA_HOME|~/.local/share}/auditkit/experiments/`.

---

## 13. Red-teaming (a basic probe suite)

AuditKIT ships a basic red-team suite: four probes (`prompt_injection`, `jailbreak`, `encoding`, `refusal`), four detectors (`keyword`, `refusal`, `injection_success`, `system_prompt_leak`), `RedTeamRunner`, and `auditkit redteam` (`--model`, `--probes`, `--detectors`, `--output`):

```bash
auditkit redteam --model openai:gpt-4o-mini --probes prompt_injection,jailbreak
```

```python
from auditkit.redteam import RedTeamRunner
print(RedTeamRunner(model="openai:gpt-4o-mini").run(probes=["jailbreak"]).summary())
```

It's deliberately small: fixed probe lists and keyword/pattern detectors, not an attack
generator. For broad adversarial testing, Garak, Promptfoo or DeepTeam go much further.

What *does* ship today for safety/security is a set of ordinary **metrics** you
run through the normal `ak.evaluate()` path: `asr` (an attack-success-rate
proxy — token-overlap threshold, see [§10](#10-the-metric-catalog)),
`keyword_detector`, and the toxicity/bias/hate-speech scorers. Those are
`Metric`s, not an attack generator — you supply the adversarial prompts as your
dataset; AuditKIT scores the responses.

---

## 14. Performance metrics

Every run measures performance automatically — no scorer needed. It lands on `RunResult.perf`, `.model_size`, and `.token_usage`, and surfaces in `summary()`, `RunComparison.performance()/tradeoff()`, and `CompareResult.performance_table()/size_table()/cost_table()`.

| Metric | Source | Available for |
|---|---|---|
| **Latency** (dict has count/mean/min/max/p50/p95/p99/std; `summary()` prints the **mean**) | Runner times each model call | all runs with a model call |
| **Throughput** (`rps`, `output_tokens_per_sec`, `total_tokens_per_sec`) | request count + token usage over wall-clock | rps always; tokens/sec only when the backend reports usage |
| **Model size** (`total_params`, `nonzero_params`, `sparsity`, `size_mb`) | `HFGenModel.model_info()` introspects the loaded checkpoint | `hf:` (real); hosted/callable → identity-only |
| **Token usage** (`prompt`/`completion`/`total`) | provider API response | `openai`/`anthropic`/`groq`/`openrouter`/`api`/`litellm` (0 for local — never estimated) |
| **Cost** | `RunResult.cost(pricing)` — real tokens × your `$/1M` | any run with token usage |

```python
r = ak.evaluate(qa, model="groq:llama-3.3-70b-versatile", scorers=[judge])
print(r.perf["latency_ms"])                 # {count, mean, p50, p95, p99, std, ...}
print(r.perf["throughput"])                 # {rps, output_tokens_per_sec, ...}
print(r.token_usage)                        # {prompt_tokens, completion_tokens, total_tokens}
print(r.cost({"input_per_1m": 0.59, "output_per_1m": 0.79}))
```

> **Measurement caveats to know before you quote these numbers.**
> - **Latency is call-level, not per-request.** The Runner times each `generate()` call (a batched backend answers many requests in one call), so at the default `concurrency=1` a whole run makes **one** call → the latency distribution has *n=1* (mean == p50 == p95). The `summary()` therefore prints just the mean; the percentile fields exist in `perf["latency_ms"]` but are only meaningful at `concurrency>1` (n = number of chunks). `groq:`/`api:` also compute a per-request latency, which the Runner doesn't use; it reports the call-level number.
> - **Percentiles and throughput.** `LatencyStats` computes percentiles by index truncation, so at small *n* p95/p99 collapse toward the minimum; read the mean. `Throughput.rps` and tokens-per-second divide by the **summed** per-call service time, which overcounts elapsed time under `concurrency>1` and understates real throughput.


---

## 15. CLI and YAML reference

Installed as `auditkit`. Six subcommands (`eval`, `init`, `list`, `compare`, `redteam`, `agent`); a bare invocation defaults to `eval`.

```bash
auditkit eval    ...   # run an evaluation (default if no subcommand)
auditkit compare ...   # compare multiple models
auditkit list    ...   # list registered metrics/datasets/adapters/annotators/models
auditkit init    [dir] # scaffold an auditkit.yaml
auditkit redteam ...   # run the red-team probes against a model
auditkit agent   ...   # end-to-end agent evaluation: eval / import-agenttune / rescore
```

**`eval`** — key flags: `--config <yaml>`, `--model` (required, unless the config sets `model:`), `--csv --input-col --target-col`, `--dataset <mmlu|gsm8k|arc|hellaswag|truthfulqa|humaneval> --subject`, `--engine <native|lmeval> --tasks`, `--adapter <generation|chat|instruction|fewshot|rag|template> --system-prompt --instruction --template`, generation flags (`--temperature --top-p --max-tokens --stop --seed`), `--limit --trials --num-fewshot --concurrency`, split flags (`--split-strategy --train-ratio --val-ratio --test-ratio`), `--experiment --tag --mlflow-uri`, `--output/-o --format <json|csv|md>`, `--verbose`. `--engine lmeval` (or any `--tasks`) routes to `run_lmeval()`.

**`compare`** — `--models` (**required**, comma-sep), `--csv`/`--dataset`, `--scorers`, `--baseline <model>` (prints a `RunComparison.summary()` of each other model against this one), `--output`.

**`list`** — positional `all|metrics|datasets|adapters|annotators|models`.

```bash
auditkit eval --model hf:gpt2 <<< "What is 2+2?"
echo "hello" | auditkit --model hf:gpt2 --output report.md --format md
auditkit eval --csv data.csv --input-col question --target-col answer -o results.json
auditkit compare --models "hf:gpt2,groq:llama-3.3-70b-versatile" --dataset gsm8k --baseline hf:gpt2
auditkit list metrics
```

**YAML config** (`auditkit eval --config auditkit.yaml`):
```yaml
model: openai:gpt-4o-mini
temperature: 0.0
max_tokens: 256
seed: 42
concurrency: 8              # parallel only for threadsafe models (§6)
prompts:                    # inline dataset (or dataset/subject; a CSV goes through --csv)
  - "What is the capital of France?"
adapter: generation         # chat + system_prompt, or fewshot + num_fewshot, etc.
output: results.json
format: json
experiment: my-eval
tags: [test, v1]
```
CLI flags override YAML values (when the flag is set).

---

## 16. Scenarios and data loading

A **`Scenario`** yields `Sample`s. Three ways in:

- **`ListScenario(samples)`** — the common path (a `list[Sample]` passed to `evaluate()` becomes this). Auto-names itself from a content hash over `(input, target, choices, retrieval_context, actual_output)` of every sample — so the generate-then-score flow doesn't collide two different models' outputs (the hash includes `actual_output`; it excludes `id`, which the Runner mutates).
- **`CallableScenario(fn)`** — wraps a zero-arg callable, re-invoked on each read.
- **Registered scenarios** — looked up by name from the `SCENARIOS` registry when you pass `dataset="mmlu"`.

**Data loaders** (in `__all__`): `load_csv`, `load_hf`, `load_croissant`. `load_hf`/`load_croissant` need `auditkit[interop]` (`datasets` + `mlcroissant`).

> **The built-in native scenarios.** The `scenarios/` package registers 6 (`mmlu`, `gsm8k`, `arc`, `hellaswag`, `truthfulqa`, `humaneval`), all needing `auditkit[interop]`. All six load (2026-10-01): MMLU 14,042, GSM8K 1,319, ARC-Challenge 1,172, HellaSwag 10,042, TruthfulQA 817 and HumanEval 164 samples. They use namespaced Hub ids now (`cais/mmlu`, `openai/gsm8k`, `allenai/ai2_arc`, `Rowan/hellaswag`, `truthfulqa/truthful_qa`, `openai/openai_humaneval`), and HumanEval no longer uses the nonexistent `TaskKind.CODE`. HumanEval loads as a generative task whose target is the reference solution: AuditKIT has no code-execution metric, so it can't score pass@k. **For academic benchmarks, `ak.run_lmeval()` (the lm-eval engine) is still the more complete path** (standard prompts, few-shot, and lm-eval's own scoring, including HumanEval execution).

---

## 17. Extending AuditKIT

The core invariant: **add a plugin file + one registry line; never touch the spine** (`runner.py`/`score.py`/`sample.py`).

**Custom scorer (function).** `direction` is required.
```python
@ak.scorer(direction=ak.Direction.MAXIMIZE)
def mentions_positive(sample, output):
    return 1.0 if "positive" in output.lower() else 0.0

ak.evaluate(samples, model=m, scorers=[mentions_positive])
```

**Custom metric (class).** Must declare `direction` (else `TypeError` at import), set `required_fields`, and — if it takes constructor args — either override `identity()` or make `self.name` parameter-derived (so config enters the fingerprint).
```python
from auditkit.metric import Metric
from auditkit.score import Score
from auditkit.types import Direction, ScoreKind
from auditkit.registry import METRICS

@METRICS.register("length_ok")
class LengthOK(Metric):
    direction = Direction.MAXIMIZE
    required_fields = frozenset()
    def __init__(self, max_len=100):
        self.max_len = max_len
        self.name = f"length_ok({max_len})"   # param-derived → safe fingerprint
    def score(self, sample, output, context=None):
        return Score(name=self.name, value=1.0 if len(output) <= self.max_len else 0.0,
                     kind=ScoreKind.CODE)
```

**Custom model backend.** Subclass `Model`, implement `generate()`, declare `capabilities()`, register (or just pass an instance / callable). Populate `Result_.usage`/`latency_ms` if you can, for the perf surface.

**Custom adapter.** Subclass `Adapter`, set `method`, implement `adapt(sample, config) -> list[Request]`, register with `@ADAPTERS.register("name")`.

The six registries: `SCENARIOS`, `ADAPTERS`, `MODELS`, `METRICS`, `ANNOTATORS`, `EVALUATORS`. Registration happens at import time via the decorators.

---

## 18. Known limitations (consolidated)

A single list of everything flagged inline above. None of these break the *correctness of a score* unless noted. Most are about coverage, ergonomics, or reporting.

**Confirmed bugs / rough edges**
- **`model_spec` doesn't serialize**: `save()`/cache store an unusable object-repr string for the model; everything else round-trips.
- **String scorers only work zero-config**: parameterized metrics (`contains`, `regex`, `keyword_detector`, `g_eval`, …) must be passed as instances.
- **Native built-in scenarios** have no few-shot prompting or code execution (HumanEval can't be scored for pass@k); `ak.run_lmeval()` covers both.
- **Latency is call-level**: at `concurrency=1`, latency percentiles are a single sample (n=1). Per-request latency from `groq:`/`api:` is computed but unused.
- **Percentiles and throughput**: `LatencyStats` percentiles use index truncation (they differ from `Stat.percentile()`), and throughput divides by summed call time, understating it under `concurrency>1`.
- **`VLLMModel` size**: `model_info()` introspects the loaded model where the installed vLLM allows it, else reports identity only.
- **`num_completions`/`best_of`**: reach the API but only `completions[0]` is scored. `RunConfig.extra` is hashed but never read.
- **`LexsiModel`** forwards only `temperature`/`max_tokens`.

**Proxy metrics (names oversell them)**
- `representation_skew` — measures demographic-representation balance, not bias; use `bias_judge` for biased content.
- `win_rate` / `elo_score` / `preference_accuracy` — silently fall back to a token-overlap proxy without their `context` data; `elo_score` returns 0–2000, not 0–1.
- `toxicity_score`/`hate_speech_score` with `use_model=False` — keyword blacklist.

**Statistical rigor**
- `paired_bootstrap` significance is a conservative heuristic (can under-report significance for low-variance differences), not an exact permutation/sign test.
- `CompareResult` runs an independent p-test per model pair with no multiple-comparisons correction; `winner()` ignores significance (picks the raw best mean).

**bert_score** hits an upstream `bert_score`-vs-`transformers>=5` tokenizer incompatibility on its own — `BertScore.score()` works around it with a scoped monkeypatch clamping the affected tokenizer's `model_max_length`; `cosine_similarity` isn't affected.

---

## 19. Appendix: glossary and file map

**Glossary.** *Spine* — the fixed Sample→Adapter→Model→Metric→RunResult pipeline. *Engine* — native (owned) vs lm-eval (delegated). *Adapter* — Sample→Request wire-format builder. *Scorer/Metric* — turns output into a `Score`. *Direction* — whether higher or lower is better. *Fingerprint* — sha256 provenance/cache key over the full `RunSpec`. *RunResult* — the uniform output object. *Prediction* — one per-sample record.

**Repo map:**

| Path | What |
|---|---|
| `src/auditkit/api.py` | `evaluate` / `run_lmeval` / `generate` / `compare` / `evaluate_many` |
| `src/auditkit/runner.py` | the Runner (5 stages, 3 execution paths, retry/timeout/concurrency) |
| `src/auditkit/runspec.py` | `RunConfig`, `RunSpec`, `fingerprint()` |
| `src/auditkit/sample.py`, `score.py`, `report.py`, `types.py` | the data model |
| `src/auditkit/adapter.py`, `router.py` | adapters + shape routing |
| `src/auditkit/model/` | 10 backends + echo/callable/precomputed |
| `src/auditkit/metric.py`, `metrics/` | built-ins + 12 metric families (70 registered metrics) |
| `src/auditkit/lmeval_engine.py` | the lm-eval bridge |
| `src/auditkit/comparison.py`, `diff.py`, `model_compare.py`, `_bootstrap.py`, `experiment.py` | comparison + significance + tracking |
| `src/auditkit/redteam/` | probes + detectors + `RedTeamRunner` |
| `src/auditkit/agent_eval/` | end-to-end agent evaluation (episodes, importers, outcome oracles, rescoring) |
| `src/auditkit/trace.py`, `bfcl.py` | tool-call parsing and matching; the BFCL loader |
| `src/auditkit/compat.py` | `check_compat()` and the SGLang/vLLM launch advice |
| `src/auditkit/scenarios/`, `loaders.py` | built-in datasets + loaders |
| `src/auditkit/cache.py`, `cli.py`, `scorers.py`, `scoring.py`, `annotator.py` | cache, CLI, custom-scorer plumbing, annotators |
| `examples/` | runnable scripts + the model-comparison notebook |

**Runner execution paths** — the three branches inside `Runner.run()`:

```mermaid
flowchart TD
    R["Runner.run(spec)"] --> C{"fingerprint in DiskCache?"}
    C -->|yes| HIT["return cached RunResult"]
    C -->|no| P{"which path?"}
    P -->|model.reads_actual_output| A["score Sample.actual_output<br/>(no model call)"]
    P -->|metrics need loglikelihood| B["model.loglikelihood(requests)<br/>(needs LOGLIKELIHOOD capability)"]
    P -->|otherwise| G["execute() → model.generate()<br/>concurrency · retry · timeout"]
    A --> AGG["aggregate → RunResult → cache.set"]
    B --> AGG
    G --> AGG
```

---

*Written against AuditKit 1.0.0, with counts, red-teaming, scenarios and the CLI re-checked against 1.1.2. If a detail here ever disagrees with the code, the code wins — regenerate this guide.*
