# RFC: Unified Model Quality Evaluation Framework

**Authors:**
- Lipika Sreedharan
- Antoni Viros i Martin
- Saurabh Srivastava
- Rishika Kedia
- Ajit Samuel John

**Tracking issue:** https://github.com/torch-spyre/torch-spyre/issues/4477

---

## 1. Summary

This RFC proposes a unified, config-driven model quality evaluation framework for IBM Spyre, using GPU as the reference platform. Evaluation can be done at different layers of the Spyre stack — torch-spyre (low-level hardware backend), spyre-inference (the serving/HTTP layer) and hf-adapters (HuggingFace-compatible model loading for Spyre).

The primary and recommended path for Spyre evaluations is the **vLLM backend** — the eval process connects to a running vLLM server over HTTP, hosted either on IBM Spyre or on a GPU (declared via `platform: "spyre"` or `platform: "gpu"` in the config). The recommended cross-platform comparison is **vLLM on Spyre vs vLLM on GPU**, ensuring any quality delta is attributable to the hardware backend rather than differences in request/response processing. A direct hf-adapters backend is also available for in-process Spyre debugging, and a CPU backend is retained for local development only.

The framework evaluates both decoder (generative/LLM) and encoder (embedding/sentence-embedding) models using a single entry point and a single YAML configuration file. It integrates two complementary evaluation paradigms - free-form generation quality (ROUGE, BLEU, METEOR, BERTScore, Exact Match) and standardized academic benchmarks via lm-evaluation-harness (MMLU, ARC, HellaSwag, GSM8K) and produces machine-readable JSON result files consumed by a downstream dashboard.

---

## 2. Motivation

The primary question this framework answers is: **does IBM Spyre produce inference results of expected quality consistent with a reference platform (GPU) across the range of scenarios the runtime stack must support?**

This is a **platform correctness** concern, not a model ranking concern. We do not care whether a model outperforms another model. We care whether a model running on Spyre behaves the way it is supposed to: producing the same quality of output it would produce on a GPU reference, across varied and realistic inference scenarios.

### Inference scenarios that must be validated

| Scenario | Why it matters for Spyre |
|---|---|
| Short context, short generation | Baseline correctness |
| Short context, long generation | Tests generation loop stability |
| Long context, short generation | Tests context handling, attention, padding |
| Long context, long generation | Tests memory pressure and graph shape limits |
| Tool calling / function calling | Tests structured output and special token handling |
| Special characters and non-Latin scripts | Tests model output quality on multi-byte and uncommon token sequences |
| Multimodal inputs (text + image) | Tests VLM inference path *(gap — see Section 9)* |

### Problems addressed

Before this framework, evaluating inference quality on Spyre required bespoke scripts per model and per dataset, with no standardized output format, no reproducibility guarantees, and no shared tooling. Comparing a Spyre run against a GPU reference meant manually diffing ad-hoc outputs.

| Problem | Impact |
|---|---|
| No unified entry point for multi-dataset, multi-model Spyre eval | Each engineer wrote their own runner script |
| No standard output format for dashboard consumption | Dashboard couldn't auto-discover results |
| No reproducible sampling (same N samples every run) | Results not comparable across runs |
| lm-eval harness not wired to Spyre-inference backend | Benchmark consistency with reference platform not measurable |
| No embedding model evaluation path | Embedding models had no quality gate |
| No per-run metric metadata in JSON | No shared understanding of metric value meaning (scale, direction) across tools |

---

## 3. Proposed Implementation

### 3.1 Architecture Overview

The framework has four layers — Configuration, Decoder Model Path (generative), Encoder Model Path (embedding) and Output — all dispatched from a single entry point.

![Architecture Diagram — four layers: Configuration dispatches to Decoder path (dataset loading → prompt building → model inference [primary: vLLM server over HTTP | hf-adapters: direct in-process Spyre | cpu: HuggingFace Transformers local fallback for machines without Spyre or a vLLM server] → metric computation → result serialization → benchmark runner) and Encoder path (embedding runner via vLLM /v1/embeddings [primary] or local sentence-transformers [fallback] → MTEB tasks); both feed into Output (result files → results manifest → dashboard)](architecture_diagram.png)

The model inference stage supports three backends. The **recommended comparison setup** is **vLLM on Spyre vs vLLM on GPU** - both sides use the same vLLM version and configuration, so any quality delta is attributable to the backend hardware/kernel path rather than differences in prompt templating, tokenization, or output parsing.

- **VLLMAdapter** - connects to a running vLLM server over HTTP (`backend: "vllm"`). The adapter does not depend on the hardware behind the server; the hardware is declared with `platform: "spyre"` or `platform: "gpu"` and recorded in the results. vLLM on Spyre is the primary Spyre evaluation path; vLLM on GPU is the **reference platform** for cross-platform comparisons and is preferred over CPU as the reference baseline.
- **SpyreAdapter** - loads the model via `hf_adapters.AutoSpyreModelForCausalLM` directly in the eval process (`backend: "hf-adapters"`). Available for in-process Spyre debugging, but not the primary comparison path.
- **CpuAdapter** - loads the model via HuggingFace Transformers and runs on CPU (`backend: "cpu"`). **Development/debugging only** - CPU inference is too slow for regular use and vLLM on GPU is the correct reference platform. Retained for local development convenience.

All runs, regardless of model type or backend, write to the same `results/` directory and append one entry to a shared `results_index.json` manifest. The dashboard reads this manifest to discover all available runs without scanning the filesystem. The framework ships a single Python entry point and a single YAML configuration file — these are the only two files an engineer needs to interact with to run an evaluation.

### 3.2 Entry Point and Configuration

All runs go through a single dispatcher:

```bash
python quality_eval_pipeline.py --config eval_config.yaml
```

`eval_config.yaml` is the only file that needs to be edited before a run. It has three sections: required fields, decoder model settings (generative) and encoder model settings (embedding).

**Required fields:**

```yaml
model: "ibm-granite/granite-3.3-8b-instruct"
model_type: "decoder"   # or "encoder"
```

**Decoder model settings:**

```yaml
decoder:
  backend: "vllm"           # "cpu" | "hf-adapters" | "vllm"
  platform: "spyre"         # hardware behind the vLLM server: "spyre" | "gpu" (vllm backend only; recorded in results)
  base_url: "http://localhost:8000"

  datasets:
    - name: "squad"
      metrics: ["exact_match", "rouge", "bleu", "meteor"]
      num_samples: 200
      max_new_tokens: 50
    - name: "triviaqa"
      metrics: ["exact_match", "rouge", "bleu", "meteor"]
      num_samples: 200
      max_new_tokens: 50
    - name: "xsum"
      metrics: ["rouge", "bleu", "meteor"]
      num_samples: 200
      max_new_tokens: 80
    - name: "gsm8k"
      metrics: ["exact_match", "rouge", "bleu"]
      num_samples: 200
      max_new_tokens: 200
    - name: "wmt"
      metrics: ["bleu", "meteor", "rouge"]
      num_samples: 200
      max_new_tokens: 100
      src_lang: "de"   # must be a valid WMT14 pair — supported: de-en, fr-en, cs-en, ru-en, fi-en
      tgt_lang: "en"   # arbitrary language codes will fail at dataset load time

  max_new_tokens: 100   # global default; overridden per-dataset if max_new_tokens is set there
  max_input_tokens: 256     # hf-adapters backend only (debugging)
  seed: 42
  dtype: null
  warmup: true

  lm_tasks: ["mmlu", "arc_easy", "hellaswag"]
  lm_backend: "local-completions"   # "cpu" | "spyre" | "local-completions"
  lm_base_url: "http://localhost:8000/v1"
  lm_num_fewshot: 5
  lm_limit: 200
  lm_output_suffix: "lmeval"
```

**max_input_tokens (`hf-adapters` backend only, debugging):** When `backend: "hf-adapters"`, the SpyreAdapter truncates every prompt to `max_input_tokens` tokens and left-pads the batch so Spyre compiles a single graph shape. This is a limitation of the direct in-process path and is **not used for cross-platform quality comparisons**, because it would change the inputs seen by one side. For the `vllm` backend the framework applies no truncation and both sides receive identical prompts; sequence length is managed by the server (via `--max-model-len`). This field has no effect on the `cpu` or `vllm` backends.

**backend: "vllm" prerequisite:** The vLLM backend requires a running vLLM server before the pipeline is started. When the server runs on Spyre it uses Spyre internally (via torch_spyre), but the eval process itself communicates with it purely over HTTP — no torch or hf_adapters imports in the eval process. The pipeline polls `/v1/models` with retries until the server responds before running any evaluation.

![alt text](image.png)**`lm_backend: "local-completions"`:** Use this when you are already running a vLLM server for the quality eval and want lm-eval benchmarks to route to the same server rather than loading the model a second time. vLLM still handles all inference — `local-completions` is lm-eval's built-in HTTP backend that forwards requests to any OpenAI-compatible `/v1` endpoint (set via `lm_base_url`). Without this, lm-eval would attempt to load the model in-process, either wasting memory or causing a device-conflict error if the vLLM server already holds the Spyre VFIO device.

**Encoder model settings** (set `model_type: "encoder"` in the required fields above, then):

```yaml
encoder:
  backend: "vllm"           # "local" (sentence-transformers, in-process) | "vllm"
  base_url: "http://localhost:8000"
  tasks:
    - "NFCorpus"
    - "SciFact"
    - "STS12"
    - "STSBenchmark"
    - "Banking77Classification"
    - "ArxivClusteringS2S"
  batch_size: 32
  device: null
  normalize_embeddings: false
  output_folder: "mteb_results"
```

CLI overrides are available without editing the file:

```bash
python quality_eval_pipeline.py --config eval_config.yaml \
    --set decoder.backend=vllm \
    --set decoder.max_new_tokens=100
```

### 3.3 Generation Quality Pipeline

The generation pipeline has five sequential stages as seen in the architecture diagram above:

#### Stage 1 — Dataset loading

The dataset loader loads and caches N samples from any registered dataset. Samples are shuffled with `seed=42` and cached locally — the same N samples are selected every run for reproducibility. Each sample is a dict with `"input"` and `"reference"` keys.

**Supported datasets:**

| Name | Source | Task |
|---|---|---|
| `xsum` | HuggingFace `EdinburghNLP/xsum` | One-sentence summarization |
| `squad` | HuggingFace `rajpurkar/squad` | Reading-comprehension QA |
| `triviaqa` | HuggingFace `trivia_qa/rc` | Open-domain QA |
| `gsm8k` | HuggingFace `openai/gsm8k` | Math word problems |
| `wmt` | HuggingFace `wmt14/de-en` | Translation |
| `custom_csv` | Local CSV | Any |
| `custom_jsonl` | Local JSONL | Any |
| `prompts_txt` | Local TXT | Any |

New datasets can be added by implementing a loader function and registering it in the dataset registry — no changes to the pipeline or config schema are required.

#### Stage 2 — Prompt building

The prompt builder formats each raw sample into a `(prompt, reference)` pair. Each task has a dedicated builder (e.g. `SummarizationBuilder`, `QABuilder`, `TranslationBuilder`). Builders are resolved by dataset key and expose a `default_metrics` list.

**Chat templates:** The prompt builder wraps each prompt in the model's chat template. On the `hf-adapters` and `cpu` backends this is done in the builder using the model's tokenizer (`apply_chat_template`). On the vLLM backends the server applies the template via `/v1/chat/completions`. The framework is intended for instruct-tuned models. If a model has no chat template (e.g. a base model), the raw prompt is used, and results should not be compared against instruct-model results.


**Note on prompt sensitivity:** Different models may respond differently to the same prompt format. Chat templates (above) handle the model-specific formatting. The prompt builder layer is also extensible — a model-specific builder can be registered per dataset key without any pipeline changes. Model-specific prompt template support is planned as a follow-up improvement.

#### Stage 3 — Model inference

The model adapter layer defines an abstract `ModelAdapter` interface. Four backends are registered:

- **`VLLMAdapter` (`vllm`)** — connects to a vLLM server running on either IBM Spyre or GPU (declared with `platform`). Generation requests go to `/v1/chat/completions`; log-likelihood scoring uses `/v1/completions` with `echo=True` and `logprobs`. vLLM on Spyre is the **primary Spyre evaluation path**; vLLM on GPU is the **reference platform** for Spyre-vs-GPU comparisons. Using the same vLLM version and config on both sides ensures any quality delta is attributable to the hardware, not to differences in request/response processing.
- **`SpyreAdapter` (`hf-adapters`)** — uses `hf_adapters.AutoSpyreModelForCausalLM` directly in the eval process. See `max_input_tokens` in Section 3.2 for prompt truncation, batch padding, and graph-shape constraints. Available for in-process Spyre debugging.
- **`CpuAdapter` (`cpu`)** — uses `AutoModelForCausalLM` from HuggingFace Transformers. **Development/debugging only** — not suitable for regular quality comparisons due to speed; use vLLM on GPU as the reference instead.

#### Stage 4 — Metric computation

The metric computation module dispatches to the appropriate scoring library:

| Metric key | Library | Scale |
|---|---|---|
| `rouge` | `rouge-score` (Google) | 0–1 |
| `bleu` | `sacrebleu` (ACL standard) | 0–100 |
| `meteor` | `nltk` | 0–1 |
| `bertscore` | `bert-score` (Zhang et al. 2020) | 0–1 |
| `exact_match` | built-in normalizer | 0 or 1 |

All metrics are computed with standard open-source libraries.

#### Stage 5 — Result serialization

The result serializer writes results to JSON. Every output file follows a fixed schema:

```json
{
  "model": "<model-id>",
  "model_type": "decoder",
  "task_category": "qa",
  "metrics": { "rouge1": 0.412, "exact_match": 0.35 },
  "metric_metadata": {
    "rouge1":      { "scale": "0–1", "higher_is_better": true },
    "exact_match": { "scale": "0–1", "higher_is_better": true }
  },
  "metadata": {
    "backend": "vllm",
    "platform": "spyre",
    "dataset": "squad",
    "num_samples": 200,
    "load_time_s": 4.2,
    "total_inference_time_s": 86.0
  }
}
```

The `metric_metadata` block is machine-readable — it tells any downstream consumer whether higher is better and what the scale is, without hardcoding that knowledge in the dashboard. The `scale` field can be used directly by a dashboard to display metric values with context — for example as a label (`0.412 / 1.0`), a progress bar filled to `value / max`, or to normalize metrics onto a common axis for side-by-side comparison charts.

### 3.4 lm-eval Harness Integration

The lm-eval harness module uses `lm-evaluation-harness` (EleutherAI) for standardized academic benchmarks. The framework requires `lm-eval>=0.4` and has been validated against `lm-eval==0.4.8`. Task names follow the lm-eval v0.4 convention: "mmlu"` runs the full 57-subject aggregated benchmark; individual subjects (e.g. "mmlu_philosophy", "mmlu_clinical_knowledge") can also be specified directly to run a targeted subset. Other supported tasks include "arc_easy", "arc_challenge", "hellaswag", "gsm8k", and "truthfulqa_mc1".

It supports three backends:

- **`hf-adapters`** — routes through a `SpyreLM` adapter which wraps `AutoSpyreModelForCausalLM` and exposes the `loglikelihood` and `generate_until` interfaces required by lm-eval.
- **`cpu`** (or `huggingface`) — standard `HFLM` adapter with `device=cpu` and `dtype=bfloat16`, correct on any machine without Spyre.
- **`local-completions`** — lm-eval's native OpenAI-compatible HTTP backend. Use this when a vLLM server is already running: lm-eval sends its requests to that server (via `lm_base_url`) instead of loading its own copy of the model.

This path can run standalone or alongside quality metrics in a single pipeline invocation as well.

### 3.5 Embedding Evaluation

The embedding runner wraps the `mteb` library to evaluate any HuggingFace sentence-embedding or bi-encoder model. It runs across all MTEB task types (Retrieval, STS, Classification, Clustering, Reranking, BitextMining) and emits the same top-level JSON schema as the generative framework, with `model_type: "encoder"` and task-appropriate metrics (nDCG@10, Spearman ρ, V-measure, etc.).

Two backends are supported:

- **vllm** (primary) — delegates all encoding to a running vLLM server (on Spyre or GPU, declared with `platform`) via `/v1/embeddings`. The `VLLMEmbeddingModel` class implements the MTEB `EncoderProtocol` interface over HTTP, with no torch or sentence-transformers dependency in the eval process. Set `encoder.backend: "vllm"` and `encoder.base_url` in the config (see Section 3.2).
- **local** (fallback) — loads the model in-process via `sentence-transformers` (`SentenceTransformer`) and runs inference locally. Use when a vLLM server is not available or the model is not supported behind `/v1/embeddings`.


`encoder.batch_size` is enforced by `sentence-transformers` (via MTEB) in the `local` backend, and by client-side batching in `VLLMEmbeddingModel` in the vLLM backends, which sends one `/v1/embeddings` request per batch.

**Backend compatibility note:** Results from the `local` and `vllm` backends for the same model may not always be directly comparable — vLLM uses its own tokenization and pooling logic which may differ from `sentence-transformers`. The `vllm` backend also requires the model to be served behind `/v1/embeddings`; decoder-only models or models not configured for embedding in vLLM will return an HTTP error on this endpoint and must use the `local` backend.

### 3.6 Results Manifest and Index

The results index module maintains an append-only `results_index.json` manifest. Every completed run adds one entry. The dashboard reads this file to discover all available results without scanning the filesystem.

**Concurrency:** Parallel evaluation jobs on the same machine are safe. Concurrent jobs on different nodes (e.g. k8s pods sharing a path) are not supported; each job should write to its own result directory and the indexes merged afterwards (see Section 9).

The index entry shape is:

```json
{
  "timestamp": "2025-09-01T19:00:00Z",
  "model": "ibm-granite/granite-3.3-8b-instruct",
  "model_type": "decoder",
  "task_category": "summarization",
  "dataset": "cnn_dailymail",
  "backend": "vllm",
  "platform": "spyre",
  "num_samples": 200,
  "metrics": { "rouge1": 0.412, "bleu_4": 12.3 },
  "result_file": "results/granite-3.3-8b-instruct_spyre_cnn_dailymail.json",
  "status": "ok",
  "error": null
}
```

---

## 4. Dependencies

| Category | Package | Purpose | Scope |
|---|---|---|---|
| **Core** | `torch`, `pyyaml`, `datasets` | Tensor ops, config parsing, HuggingFace dataset loading | `cpu` and `spyre` backends |
| **Generative Eval** | `transformers` | `AutoModelForCausalLM`, tokenizers | Decoder runs |
| | `rouge-score`, `sacrebleu`, `nltk` | Standard quality metrics (ROUGE, BLEU, METEOR) | `rouge`, `bleu`, `meteor` |
| | `bert-score` | Semantic similarity metric | Optional (`bertscore`) |
| **Benchmark Harness** | `lm-eval>=0.4` | EleutherAI benchmark harness (MMLU, ARC) | Academic benchmarks |
| **Embedding Eval** | `mteb>=1.1`, `sentence-transformers>=2.7` | MTEB benchmark suite & embedding models (validated against `mteb==1.7.8`, `sentence-transformers==3.0.1`) | Encoder `local` backend only |
| **Hardware Backend** | `torch_spyre`, `hf_adapters` | IBM Spyre hardware acceleration & model loading | `spyre` backend only |
| **vLLM Backend** | `vllm` (external server process) | OpenAI-compatible inference server; runs on Spyre via `torch_spyre` internally | `vllm` backend only |

All packages except `torch_spyre`, `hf_adapters`, and `vllm` are publicly available on PyPI. `torch_spyre` is the low-level IBM Spyre hardware backend (lives in the `torch-spyre` repo). `hf_adapters` is the HuggingFace-compatible model loading layer for Spyre (lives in the `hf-adapters` repo). Both must be installed from their respective internal repos before running Spyre-backend evaluations. `vllm` is installed in the `torch-spyre` venv on the Spyre machine and runs as a separate server process — the eval code itself has no Python dependency on vLLM and communicates with it purely over HTTP using only the standard library (`urllib`).

---

## 5. Correctness and Reproducibility

### 5.1 Sampling Reproducibility

All dataset loaders shuffle with a fixed `seed=42` and cache the selected sample indices locally. Every re-run with the same config selects exactly the same N samples, making runs comparable across model versions, backends and dates.

### 5.2 Error Isolation

The multi-dataset loop catches exceptions at the per-dataset level. A dataset load failure or metric computation error does **not** abort the run - it is logged, registered as `status: "error"` in the index, and the remaining datasets continue. This ensures a transient HuggingFace Hub timeout or a missing optional dependency (`bert-score`) does not cancel an otherwise valid run.

### 5.3 Metric Fidelity

No custom scoring logic is introduced in the metric computation layer. Every metric delegates to the canonical library:

- ROUGE → Google `rouge-score`
- BLEU → `sacrebleu` (the ACL standard implementation)
- METEOR → `nltk`
- BERTScore → `bert-score` (Zhang et al. 2020, `roberta-large` by default)
- lm-eval accuracy → EleutherAI `lm-evaluation-harness`
- MTEB metrics → `mteb` library

This means metric computation is directly comparable to published numbers that use the same libraries. However, this does not extend to output parsing - for lm-eval benchmarks, different models may require different output parsers to correctly extract answers from generated responses. lm-eval handles this per task, but some models may need additional parsing adjustments to avoid artificially low scores. This is a known challenge when evaluating a variety of models across diverse datasets.

### 5.4 Framework Validation and Reference Outputs

The following results from Spyre runs are provided for reference to demonstrate the framework's output format and metric reporting.

#### 1. Decoder Model: `google/gemma-4-26B-A4B-it` - vLLM backend on IBM Spyre

| Evaluation Stream | Dataset / Task | Samples | Metric | Value |
|---|---|---|---|---|
| **Free-form Generation** | SQuAD | 200 | Exact Match | 0.5850 |
| | | | ROUGE-1 | 0.8266 |
| | | | ROUGE-L | 0.8248 |
| | | | BLEU-4 | 38.99 |
| | | | METEOR | 0.5715 |
| | TriviaQA | 200 | Exact Match | 0.4850 |
| | | | ROUGE-1 | 0.6216 |
| | | | METEOR | 0.4342 |
| | XSum | 200 | ROUGE-1 | 0.2736 |
| | | | ROUGE-L | 0.2003 |
| | | | METEOR | 0.2144 |
| | GSM8K | 200 | Exact Match | 0.5050 |
| **Academic Benchmarks** | ARC Easy | 200 | Accuracy (norm) | 0.6250 |
| | ARC Challenge | 200 | Accuracy (norm) | 0.4250 |
| | HellaSwag | 200 | Accuracy (norm) | 0.5150 |
| | TruthfulQA MC1 | 200 | Accuracy | 0.3250 |
| | MMLU (7 subjects) | 200 each | Mean Accuracy | 0.5485 |

> **Note:** Academic benchmarks use `lm_backend: "local-completions"` routed to the same vLLM server (`lm_limit: 200` per task, 5-shot; TruthfulQA MC1 is 0-shot). MMLU covers 7 subjects (abstract algebra, college mathematics, college physics, clinical knowledge, professional law, moral scenarios, philosophy) — not the full 57-subject suite. Benchmark scores should only be compared between runs that use the same `lm_backend`, since tokenization and numerics can differ slightly between backends.

#### 2. Encoder Model: `ibm-granite/granite-embedding-278m-multilingual` - vLLM backend

| Task Category | Evaluated Tasks | Primary Metric | Value |
|---|---|---|---|
| **Retrieval** | NFCorpus, SciFact | Mean nDCG@10 | 0.4616 |
| **STS** | STS12, STSBenchmark | Mean Spearman ρ | 0.7677 |
| **Classification** | Banking77Classification | Mean Accuracy | 0.7806 |
| **Clustering** | ArxivClusteringS2S | Mean V-measure | 0.3290 |

#### 3. Output Schema Verification

The pipeline writes consistent, self-describing JSON records ingested by the shared results index:

**Sample Decoder Result Snippet:**
```json
{
  "model": "google/gemma-4-26B-A4B-it",
  "model_type": "decoder",
  "task_category": "qa",
  "backend": "vllm",
  "platform": "spyre",
  "dataset": "squad",
  "metrics": {
    "exact_match": 0.585,
    "rouge1": 0.8266,
    "rougeL": 0.8248,
    "bleu_4": 38.99,
    "meteor": 0.5715
  },
  "metric_metadata": {
    "exact_match": { "scale": "0–1", "higher_is_better": true },
    "rouge1":      { "scale": "0–1", "higher_is_better": true },
    "rougeL":      { "scale": "0–1", "higher_is_better": true },
    "bleu_4":      { "scale": "0–100", "higher_is_better": true },
    "meteor":      { "scale": "0–1", "higher_is_better": true }
  },
  "metadata": { "num_samples": 200, "seed": 42, "backend": "vllm", "platform": "spyre" }
}
```

**Sample Encoder Result Snippet:**
```json
{
  "model": "ibm-granite/granite-embedding-278m-multilingual",
  "model_type": "encoder",
  "task_category": "retrieval",
  "metrics": {
    "mean_ndcg_at_10_retrieval": 0.4616,
    "mean_spearman_sts": 0.7677,
    "mean_accuracy_classification": 0.7806,
    "mean_v_measure_clustering": 0.329
  },
  "metric_metadata": {
    "ndcg_at_10":  { "scale": "0–1",  "higher_is_better": true, "task_type": "Retrieval" },
    "spearman":    { "scale": "-1–1", "higher_is_better": true, "task_type": "STS" },
    "accuracy":    { "scale": "0–1",  "higher_is_better": true, "task_type": "Classification" },
    "v_measure":   { "scale": "0–1",  "higher_is_better": true, "task_type": "Clustering" }
  },
  "metadata": {
    "tasks": ["SciFact", "NFCorpus", "STS12", "STSBenchmark", "Banking77Classification", "ArxivClusteringS2S"],
    "backend": "vllm",
    "platform": "spyre"
  },
  "per_task_metrics": {
    "SciFact":               { "task_type": "Retrieval",       "task_category": "retrieval",       "ndcg_at_10": 0.6387 },
    "NFCorpus":              { "task_type": "Retrieval",       "task_category": "retrieval",       "ndcg_at_10": 0.2845 },
    "STS12":                 { "task_type": "STS",             "task_category": "sts",             "spearman": 0.7516 },
    "STSBenchmark":          { "task_type": "STS",             "task_category": "sts",             "spearman": 0.7838 },
    "Banking77Classification": { "task_type": "Classification","task_category": "classification",  "accuracy": 0.7806 },
    "ArxivClusteringS2S":    { "task_type": "Clustering",      "task_category": "clustering",      "v_measure": 0.329 }
  }
}
```

> **Note:** `task_category` is the most common MTEB category among the tasks run. `metrics` holds one aggregate key per task type — e.g. `mean_ndcg_at_10_retrieval` is the mean nDCG@10 over SciFact and NFCorpus. Per-task scores are in `per_task_metrics` (truncated here; the full output includes all metric variants).

---

## 6. Design Decisions

### 6.1 Single YAML Entry Point

**Decision:** All configuration lives in one YAML file; the pipeline reads `model_type` and dispatches accordingly.

**Rationale:** Eliminates per-model bespoke scripts. Any engineer can run a full evaluation by editing one file and running one command. CLI `--set` overrides allow quick one-off changes without touching the file.

### 6.2 Metric Metadata in JSON Output

**Decision:** Every result file carries a `metric_metadata` block encoding `scale` and `higher_is_better` for each computed metric.

**Rationale:** If this is only in the UI, it becomes a presentation detail that can get out of sync with the framework. Encoding it in the JSON makes it machine-readable: any future dashboard, CLI tool, or automated regression system gets the semantics for free without hardcoding them. The `scale` field in particular enables the dashboard to display metric values with context — as a labeled range, a normalized progress bar, or a common-axis comparison chart — without needing a per-metric lookup table.

### 6.3 Two Complementary Evaluation Paradigms

**Decision:** The framework runs complementary evaluation paradigms for each model type, optionally in a single command.

**Decoder models:**
- *Free-form generation quality* (ROUGE, BLEU, METEOR, exact match) — tests whether the model produces accurate, fluent output for real tasks such as summarization, QA and translation.
- *Log-likelihood benchmark accuracy* (MMLU, ARC, HellaSwag) — tests knowledge and reasoning using the same methodology as published leaderboards. lm-eval scores each answer choice by log-likelihood. The reported metrics are `acc_norm` (length-normalized accuracy) for ARC and HellaSwag, and `acc` for MMLU and TruthfulQA.

**Encoder models:**
- *MTEB task quality* (nDCG@10, Spearman ρ, accuracy, V-measure) — tests embedding quality across retrieval, STS, classification and clustering tasks.

**Rationale:** For decoder models, neither paradigm subsumes the other — a model that scores well on MMLU can still degrade on summarization on Spyre if quantization affects generation quality, and vice versa. Both are needed for a complete picture.

---

## 7. Relationship to Existing Tooling



The **[E2E Performance Testing RFC](https://github.com/torch-spyre/RFCs/blob/main/1633-E2EModelPerf/1633-E2EModelPerf.md)** notes that quality evals may be redundant if correctness tests already confirm matching output against a CPU reference. This framework complements that view: correctness tests are a fast regression gate on token-level agreement, while quality evals measure task-level fitness at scale — catching degradation from padding, truncation or generation parameter differences that token-matching alone may not surface. Both are valuable and intended to be run together.

---

## 8. Alternative Approaches

### OLMES (AllenAI)

**Approach:** Use OLMES as the standardization layer on top of lm-eval.

**Advantages:**
- Reproducible prompt formats (5 canonical variants per task)
- Decontamination checking
- Leaderboard-compatible configs

**Disadvantages:**
- Adds an external dependency with enforced prompt formats
- OLMES uses lm-eval under the hood for task orchestration — our current lm-eval integration already wires lm-eval directly to the Spyre/vLLM backend without duplicating any lm-eval logic. Adding OLMES would not reduce what we build; it would add a layer on top
- Its main value-add — canonical 5-variant prompt formats and leaderboard-compatible configs — is not needed for cross-platform consistency comparisons. What matters is that we use the **same prompts and config on both platforms**, which our current setup already guarantees
- Only relevant if the goal becomes publishing numbers against external leaderboards, which is not our goal
- Does not add value for custom dataset evaluation paths which are not covered by OLMES

**Conclusion:** OLMES is worth revisiting if the goal becomes publishing benchmark numbers against public leaderboards. For Spyre platform correctness validation (vLLM on Spyre vs vLLM on GPU), the current lm-eval-direct integration is sufficient and avoids an unnecessary dependency.

### DeepEval

**Approach:** Use DeepEval as the evaluation layer, leveraging its LLM-as-judge metrics (hallucination detection, answer relevancy, faithfulness, contextual precision).

**Advantages:**
- Rich LLM-as-judge metrics beyond n-gram overlap
- Active open-source community with a broad metric library
- Supports custom metrics and CI integration

**Disadvantages:**
- LLM-as-judge metrics require a separate judge model, adding infra overhead and cost
- Not designed for direct Spyre/HuggingFace backend integration — would require a wrapper
- Overkill for the current use case of Spyre-vs-CPU quality comparison using standard reference-based metrics

**Conclusion:** Worth considering if the evaluation scope expands to include RAG pipelines or conversational quality assessment where reference-based metrics are insufficient.

### AWS fmeval

**Approach:** Use Amazon's `fmeval` library for quality evaluation, which supports ROUGE, METEOR, BERTScore, exact match, and toxicity/stereotyping checks.

**Advantages:**
- Covers the same reference-based metrics as this framework
- Includes built-in toxicity and prompt stereotyping checks
- Well-documented with support for custom datasets

**Disadvantages:**
- AWS-centric design — not straightforward to integrate with `hf_adapters` or Spyre backends
- Adds an external managed dependency with its own data format requirements
- No academic benchmark support (MMLU, ARC) — would still require lm-eval alongside it

**Conclusion:** Metric coverage overlaps significantly with this framework but the integration cost with Spyre is high. No compelling reason to adopt it over the current approach.

---

## 9. Future Work

- **Multimodal evaluation** — the framework currently covers text-in/text-out decoder models and text embedding models. VLMs (vision-language models) are a gap. The vLLM backend already supports `/v1/chat/completions` with image content blocks for VLMs; adding multimodal eval requires: (a) a multimodal dataset loader (e.g. `TextVQA`, `MMMU`), (b) a prompt builder that encodes image+text inputs in the OpenAI vision message format, and (c) extending the result schema for multimodal task metrics.
- **Tool-calling / function-calling evaluation** — extend the prompt builder and dataset layer to test structured output and special token handling for tool-use scenarios (e.g. using `ToolBench` or a custom tool-call dataset).
- **Multi-turn evaluation** — extend the prompt builder and dataset layer to support MT-Bench and AlpacaEval for instruction-following quality assessment.
- **Scenario coverage expansion** — add explicit long-context datasets (e.g. `SCROLLS`, `LongBench`) and special-character/multilingual stress sets to systematically cover the inference scenario matrix in Section 2.
- **OLMES integration** — only if the goal becomes publishing benchmark numbers against public leaderboards, which is not the current objective.
- **Cross-node index writes** — the results index is safe for parallel jobs on one machine only. In a k8s or multi-node setup, each job should write to its own result directory and the indexes merged afterwards. A shared-safe index (e.g. a database or per-job index files merged by the dashboard) is future work.
- **WMT dataset naming** — `src_lang`/`tgt_lang` in the config are not arbitrary; only pairs available in WMT14 are valid. A cleaner approach would be to use `wmt-de-en` as the dataset name directly, consistent with how other datasets are named, and derive the language pair from the name. This would also remove a config parameter that applies only to WMT.



---
