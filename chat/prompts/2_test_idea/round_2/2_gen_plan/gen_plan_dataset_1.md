# gen_plan_dataset_1 — test_idea

> Phase: `invention_loop` · round 2 · `gen_plan`
> Run: `run_RiHQW43yNEvO` — Simple Readability Score
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_plan_dataset_1` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-08 11:23:01 UTC

````
<hypothesis>
kind: hypothesis
title: Readability as Circuit Resistance
hypothesis: >-
  Text readability can be modeled through effective electrical resistance of discourse graphs with SEMANTIC edges between
  sentences. The Kirchhoff index of graphs where edges are weighted by semantic similarity (cosine distance between SBERT
  embeddings) provides a readability metric that captures discourse coherence beyond sentence count. Unlike sequential-only
  graphs (which reduce to sentence counting and produce trivially few distinct values), semantic edges enable the metric to
  capture meaningful variance in discourse structure. The first experiment using sequential edges and synthetic data with
  limited sentence counts (1-3 sentences) was invalid and must be repeated with rich discourse graphs and established benchmarks
  containing real human judgments.
motivation: >-
  Current readability formulas rely on surface features (sentence length, word difficulty) or black-box ML models that don't
  explicitly model the cognitive process of reading. Drawing from electrical network theory, we propose that readable text
  should allow 'easy information flow' through semantic connections, analogous to current flowing through a low-resistance
  circuit. This provides a theoretically grounded, interpretable metric that captures discourse-level coherence in a way surface
  features cannot.
assumptions:
- >-
  Text can be meaningfully represented as a graph where sentences are nodes and edges represent discourse connections (semantic
  similarity, rhetorical relations, or sequential adjacency)
- >-
  The cognitive effort of reading correlates with the 'resistance' to information flow through the discourse graph
- >-
  Edge weights (resistances) can be meaningfully assigned based on semantic distance or discourse relation strength
- >-
  The effective graph resistance (Kirchhoff index) computed from this weighted graph correlates with human judgments of readability
investigation_approach: >-
  1. Construct discourse graphs from texts: nodes=sentences, edges=semantic connections weighted by cosine distance between
  sentence embeddings (or simplified: sequential edges with weights based on position). 2. Compute the effective graph resistance
  (trace of Laplacian pseudoinverse) as the readability score. 3. Evaluate on standard readability datasets (e.g., Weebit,
  CLEAR) by correlating with human ratings. 4. Compare against traditional formulas (Flesch-Kincaid, SMOG) and ML baselines.
  5. Perform ablation: test different graph construction methods (sequential only, similarity-thresholded, full RST parsing).
success_criteria: >-
  The effective resistance metric should: (1) Achieve Pearson correlation r > 0.7 with human readability ratings on standard
  benchmarks, (2) Outperform or match traditional readability formulas (Flesch-Kincaid, etc.) in predictive accuracy, (3)
  Show significant correlation (p < 0.01) with reading time/eye-tracking measures if available, (4) Be computationally feasible
  (< 1s per document for typical lengths). A tiny experiment (N=50 texts with human ratings) showing r > 0.5 would support
  proceeding to full evaluation.
related_works:
- >-
  Mesgar & Strube (2015) 'Graph-based Coherence Modeling For Assessing Readability' - Uses entity grids and discourse relation
  graphs with features like outdegree and frequent subgraphs, but does NOT use effective resistance. Our approach differs
  by using the actual electrical network resistance as the direct readability metric, which captures global information flow
  rather than local graph patterns.
- >-
  Zhang et al. (2026) 'Automatic text readability assessment for educational content based on graph representation learning'
  - Uses GCNs on POS-based dependency graphs. This is a deep learning approach that learns features implicitly, whereas our
  method uses a specific, interpretable graph metric (effective resistance) derived from network theory.
- >-
  Guinaudeau & Strube (2013) 'Graph-based coherence modeling' - Introduces entity graphs and one-mode projections for coherence
  modeling. Our work differs by using effective resistance (a global spectral graph property) rather than local features like
  edge weights or components.
- >-
  Ehret (2018) 'Kolmogorov complexity as a universal measure of language complexity' - Uses compression-based complexity.
  While both approaches use information theory concepts, effective resistance captures discourse-level connectivity while
  Kolmogorov complexity captures lexical/syntactic redundancy.
- >-
  Klein et al. (2025) 'Surprisal Takes It All: Eye Tracking Based Cognitive Evaluation of Text Readability Measures' - Finds
  surprisal (from language models) predicts reading ease. Our approach is complementary: effective resistance models discourse
  structure while surprisal models lexical predictability.
inspiration: >-
  The hypothesis draws from electrical network theory (Kirchhoff's laws, effective resistance) and its application to graph
  analysis. In electrical engineering, the effective resistance between nodes in a network captures how easily current can
  flow. We adapt this to text by treating discourse connections as electrical pathways: coherent, well-connected text has
  low 'resistance' to information flow, while disjointed or complex text has high resistance. This cross-domain transfer from
  circuit theory to readability assessment is, to our knowledge, novel.
terms:
- term: Effective resistance (Kirchhoff index)
  definition: >-
    The sum of resistance distances between all pairs of nodes in a graph, equivalent to the trace of the pseudoinverse of
    the graph Laplacian. In electrical networks, this represents the total resistance 'seen' by current flowing through the
    network.
- term: Graph Laplacian
  definition: >-
    A matrix representation of a graph L = D - A, where D is the degree matrix and A is the adjacency matrix. The pseudoinverse
    of L is used to compute effective resistances between nodes.
- term: Discourse graph
  definition: >-
    A graph representation of text where nodes represent sentences or discourse units, and edges represent rhetorical relations,
    semantic connections, or sequential adjacency.
- term: Resistance distance
  definition: >-
    A graph metric derived from electrical network theory that measures the effective electrical resistance between two nodes
    if unit resistors are placed on each edge. It captures both direct and indirect pathways between nodes.
- term: Kirchhoff index
  definition: >-
    The sum of all pairwise resistance distances in a graph. It is a global graph invariant that measures the overall 'connectivity'
    or 'flow capacity' of the network.
summary: >-
  We propose a novel readability metric based on effective electrical resistance of discourse graphs. By modeling text as
  a circuit where sentences are connected by semantic pathways, the total resistance to information flow (Kirchhoff index)
  provides a physically-motivated, interpretable measure of readability that captures discourse-level coherence beyond surface
  features.
_relation_rationale: >-
  First experiment invalid (only 2 values); refining to require semantic edges, not just sequential.
_confidence_delta: decreased
_key_changes:
- >-
  Added REQUIREMENT for semantic edges (SBERT embeddings) instead of just sequential edges
- >-
  Acknowledged first experiment was invalid: only 2 distinct values, correlation = sentence count
- >-
  Added success criterion: metric must produce continuous range of values across diverse texts
- >-
  Added success criterion: partial correlation controlling for sentence count must remain significant
- >-
  Changed evaluation to use established benchmarks (CLEAR, WeeBit) with REAL human judgments
- >-
  Added ablation comparing sequential-only vs. semantic edges to quantify discourse contribution
- Emphasized edge weights must be based on semantic distance, not uniform
- Noted normalization scheme needs theoretical justification
relation_type: evolution
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for the methods, proper baselines, and evaluation this field demands.

- **aii-handbook-multi-llm-agents** — Guide for implementing Multi-LLM Agent Systems research using Mirascope orchestration, HuggingFace datasets/evaluation, and proven multi-agent patterns.
</available_domain_handbooks>

<artifact_direction>
Make this direction concrete and actionable. Keep the same type and respect dependencies.

id: dataset_iter2_dir1
type: dataset
objective: >-
  Acquire the CLEAR corpus (CommonLit Ease of Readability) with real human readability judgments for experiment validation
approach: >-
  Download the CLEAR corpus from GitHub (https://github.com/scrosseye/CLEAR-Corpus). The corpus contains ~4000 texts with
  human readability ratings from multiple raters on a 1-100 scale. Also download the ratings file which contains the actual
  human judgments. Standardize to JSON format with fields: text, sentence_boundaries, human_readability_score (original 1-100
  scale preserved), text_id, metadata, rater_agreement. Create full/mini/preview splits. The CLEAR corpus is essential because
  it has genuine human judgments, unlike synthetic data or algorithmically-labeled datasets used previously. Save to data_out.json
  in standardized schema.
depends_on: []
</artifact_direction>



<instructions>
YOUR ROLE: Write a detailed PLAN for the artifact. A separate executor agent runs the actual artifact later.

You are a PLANNER, not an executor. Your output is a plan that tells the executor what to do and how.
Do NOT execute the artifact itself — a separate agent handles that. Your job is to plan it so well that the executor can follow your plan step by step.

You CAN and SHOULD: search the web, read papers, and explore library docs to make your plan concrete.
You CANNOT run shell commands or scripts — code execution is disabled. Research via web tools only.

Do NOT do the executor's job: don't download datasets, don't implement code, don't run experiments, don't write proofs, don't compute evaluations.

<artifact_executor_scope>
IMPORTANT: Each artifact executor has a focused prompt that guides it to do ONE thing well. It will NOT perform tasks outside its scope — assigning the wrong work to the wrong artifact type wastes an iteration. Match the task to the right executor.

DATASET executor scope:
  Output: data_out.json with rows of {input, output, metadata_fold, ...} — raw data only, no derived computations
  DOES: Download/generate datasets, analyze candidates to pick the best ones, standardize to JSON schema (features, labels, folds, metadata), validate schema, split into full/mini/preview
  DOES NOT: Run experiments, train models, compute derived statistics (PID/MI/correlations/synergy matrices) as final output
  If you need to COMPUTE something from data (synergy matrices, MI scores, timing benchmarks), use an EXPERIMENT artifact instead
</artifact_executor_scope>

<artifact_planning_rules>
DATASET:
- Plan for REAL third-party datasets (HuggingFace, Kaggle, direct-download URLs) — downloadable within time and size constraints
- Describe dataset criteria (domain, size, format) — executors find exact sources, but you can suggest candidates or search directions
- ALWAYS prefer real datasets over synthetic. Synthetic is a LAST RESORT only when no suitable real data exists
</artifact_planning_rules>

<compute_profiles>
Choose the compute profile this artifact needs for execution.
Available profiles for dataset artifacts:
  - gpu: 1x NVIDIA RTX A4500, 20GB VRAM, 7 vCPUs, 29GB RAM — ML training, CUDA, large models (fallback: GPUs cheap→expensive: 2000 Ada → A4000 → 4000 Ada → L4 → 4090 → 5090)
  - cpu_heavy: 4 vCPUs, 32GB RAM — large datasets, memory-intensive processing (fallback: CPUs cheap→expensive, then GPU hosts cheap→expensive (all ≥32GB RAM))

Set runpod_compute_profile to one of these exact tier names.
</compute_profiles>
GOOD PLANS: specific, actionable, consider failure scenarios, build on the suggested approach.
BAD PLANS: vague hand-waving, ignoring the suggested approach, missing critical executor details.
</instructions><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "description": "Plan for a DATASET artifact.",
  "properties": {
    "title": {
      "description": "Plan title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters).",
      "title": "Title",
      "type": "string"
    },
    "summary": {
      "default": "",
      "description": "Brief summary",
      "title": "Summary",
      "type": "string"
    },
    "runpod_compute_profile": {
      "anyOf": [
        {
          "type": "string"
        },
        {
          "type": "null"
        }
      ],
      "default": "cpu_light",
      "description": "Compute tier for execution \u2014 pick from the available profiles list (e.g., 'gpu', 'cpu_heavy', 'cpu_light'). Only used in RunPod mode.",
      "title": "Runpod Compute Profile"
    },
    "ideal_dataset_criteria": {
      "description": "What makes an ideal dataset for this purpose - size, format, content requirements",
      "title": "Ideal Dataset Criteria",
      "type": "string"
    },
    "dataset_search_plan": {
      "description": "Step-by-step plan for finding/creating this dataset - sources to check, fallback options",
      "title": "Dataset Search Plan",
      "type": "string"
    },
    "target_num_datasets": {
      "description": "How many individual datasets should be delivered. Count each dataset separately, not collections \u2014 a benchmark suite of N datasets counts as N. This controls how broadly the executor searches, so setting it too low will under-collect.",
      "title": "Target Num Datasets",
      "type": "integer"
    }
  },
  "required": [
    "title",
    "ideal_dataset_criteria",
    "dataset_search_plan",
    "target_num_datasets"
  ],
  "title": "DatasetPlan",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-08 11:23:01 UTC

```
Propose a simple, novel, testable ML method for scoring text readability and validate it with a tiny experiment.
```

### [3] SKILL-INPUT — aii-web-tools · 2026-07-08 11:23:17 UTC

The agent loaded the **aii-web-tools** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-web-tools
description: "Web research toolkit: web search (Serper/Google), web page fetch as markdown (HTML and PDF), and regex grep over full page/PDF text. Use whenever a task needs to search the web, read a page, mine a paper/PDF, verify citations, or extract exact quotes, numbers, or methodology from a URL."
---

## Web tools

You have three web capabilities: **search**, **fetch**, and **grep** (exact
regex extraction over a full page or PDF).

**Pick where they come from, in this order:**

1. **If you have built-in `WebSearch` / `WebFetch` tools, PREFER those over the
   scripts below.** They may be **deferred tools** (listed by name but with
   schemas not yet loaded) — if so, call `ToolSearch("select:WebSearch,WebFetch")`
   ONCE to load them, then use them normally. Do not skip them just because they
   need that one extra load step; they are the preferred path. Pair them with the
   `aii_web_tools__fetch_grep` script below when you need exact text / numbers /
   methodology that a summary would miss, or when reading a PDF.
2. **Only if you have NO built-in `WebSearch` / `WebFetch`** (e.g. the OpenHands
   backend), use the scripts in this skill (below). They are our own
   implementations — Serper.dev for search, html2text + PyMuPDF for fetch, and
   regex grep over the full document text. They work without any built-in web
   tools.

Workflow either way: **search** (discover) → **fetch** (read for the gist) →
**grep** (pull exact details / read PDFs).

---

## Running the scripts

Run every script with the skill's pre-provisioned interpreter (it already has
`requests`, `html2text`, `pymupdf`, `python-dotenv`). Set `PY` once:

```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-web-tools"
export PY="$SKILL_DIR/../.ability_client_venv/bin/python"
```

### 1. Search the web (Serper.dev / Google)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation LLM" --max-results 10
```

Returns ranked title / URL / snippet lines. Use it first to scan the
landscape; snippets are for discovery only — fetch a page before judging it.

### 2. Fetch a page as markdown (HTML or PDF)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" fetch --url "https://arxiv.org/abs/2303.11366" --max-chars 10000
```

`--max-chars` caps output (default 10000); `--char-offset N` pages further in.
Handles PDFs transparently via PyMuPDF.

### 3. Grep a page or PDF (exact regex extraction)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" grep --url "https://arxiv.org/pdf/2303.11366" --pattern "verbal reinforcement" --max-matches 20 --context-chars 200
```

Returns only the matching sections with surrounding context — the right tool
for exact numbers, table values, methodology, or long PDFs where a summary
would lose the detail. `-i` for case-insensitive.

**Parallelize** independent searches/fetches in one turn; only sequence a
fetch after the search that produced its URL.

---

## Notes

- The scripts call our ability server. If a script prints
  `Ability service not available`, the server is down — say so rather than
  silently improvising a different search method.
- Do **not** hand-roll your own `requests`/scraping for search when these
  tools are available: Serper returns clean Google results and the fetch/grep
  scripts already handle HTML, PDFs, and encoding.
````

### [4] SKILL-INPUT — aii-hf-datasets · 2026-07-08 11:28:49 UTC

The agent loaded the **aii-hf-datasets** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-hf-datasets
description: Searches, previews, and downloads datasets from HuggingFace Hub. Use when user needs machine learning datasets, training data, HuggingFace datasets, dataset discovery, or .parquet/.json exports.
---

## Contents

- Workflow (3-phase dataset discovery)
- Scripts (Search, Preview, Download)

**IMPORTANT - Parallel execution:** GNU `parallel` subshells do NOT inherit `source activate`. Use `export` for variables and **single-quoted** command templates so parallel's subshells can resolve them:
```
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets"
export PY="$SKILL_DIR/../.ability_client_venv/bin/python"
```

---

## Workflow: 3-Phase Dataset Discovery

### Phase 1: Search for Datasets
Find datasets with metadata (configs, splits, features, sizes)
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_search_datasets.py --query "sentiment analysis" --limit 5
```

### Phase 2: Preview Dataset (if promising)
Inspect metadata AND sample rows in one call
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_preview_datasets.py openai/gsm8k
```

### Phase 3: Download Dataset (if suitable)
Download after reviewing the preview
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_download_datasets.py openai/gsm8k --config main --split train
```

---

## Scripts

### Search HuggingFace Datasets (aii_hf_search_datasets.py)

Search and discover datasets on HuggingFace Hub.

**Example input:**
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_search_datasets.py --query "text classification" --limit 5
```

**Parallel execution (multiple queries):**

IMPORTANT: Use full python path with GNU parallel (venv activate does NOT work in parallel subshells):
```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
export PY="$SKILL_DIR/../.ability_client_venv/bin/python" && \
export S="$SKILL_DIR/scripts/aii_hf_search_datasets.py" && \
parallel -j 10 -k --group --will-cite '$PY $S --query {} --limit 3' ::: 'sentiment' 'classification' 'translation'
```

**Example output:**
```
Found 5 dataset(s) for query='text classification'

============================================================
Dataset 1: stanfordnlp/imdb
Downloads: 2,500,000 | Likes: 1,234
Description: Large Movie Review Dataset for binary sentiment classification...
Tags: text-classification, en, sentiment-analysis
```

**Result fields per dataset:**

Each entry in ``results`` carries:

- ``id`` / ``downloads`` / ``likes`` / ``tags`` / ``description`` — standard
  HF metadata
- ``has_loader_script`` (bool) — repo ships a top-level ``<repo>.py`` loader.
  ``datasets>=3`` won't run these directly; the dataset is reachable only
  via the Datasets Server's pre-converted parquet shards. Treat as a yellow
  flag.
- ``loadable`` (bool) — **prefer datasets where this is ``True``.** Means
  the dataset is reachable via *some* path: either native parquet (no
  script) or HF auto-converted the script's output to parquet. When
  ``False``, the script needs deps HF can't install (e.g. ``conllu``,
  custom audio decoders) and ``aii_hf_datasets__download_datasets`` will
  fail — pick a different candidate.

**Parameters:**

`--query` (optional)
- Search query string
- Example: `--query "sentiment analysis"`

`--limit` (optional)
- Maximum number of results (default: 5)

`--tags` (optional)
- Filter by tags (comma-separated)
- Format: `category:value`
- Examples: `language:en`, `task_categories:text-classification`

`--sort` (optional)
- Sort by field: `downloads`, `likes` (default: downloads)

**Tips:**
- Search displays full dataset metadata
- Use tags to filter: `--tags "language:en,task_categories:translation"`

---

### Preview HuggingFace Dataset (aii_hf_preview_datasets.py)

Inspect a specific dataset - shows metadata AND sample rows.

**Example input:**
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_preview_datasets.py openai/gsm8k --num-rows 5
```

**Parallel execution (multiple datasets):**

IMPORTANT: Use full python path with GNU parallel:
```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
export PY="$SKILL_DIR/../.ability_client_venv/bin/python" && \
export S="$SKILL_DIR/scripts/aii_hf_preview_datasets.py" && \
parallel -j 10 -k --group --will-cite '$PY $S {} --num-rows 3' ::: 'openai/gsm8k' 'imdb' 'squad'
```

**Example output:**
```
============================================================
Dataset: openai/gsm8k
============================================================
Downloads: 425,109 | Likes: 1,102

Description: GSM8K (Grade School Math 8K) is a dataset of 8.5K high quality
linguistically diverse grade school math word problems...

Configs: main, socratic

--- Sample Rows (train) ---
Columns: question, answer

Row 1:
  question: Natalia sold clips to 48 of her friends in April...
  answer: Natalia sold 48/2 = <<48/2=24>>24 clips in May...
```

**Parameters:**

`dataset_id` (required, positional)
- HuggingFace dataset ID
- Examples: `openai/gsm8k`, `glue`, `imdb`

`--config` (optional)
- Dataset configuration/subset name
- Auto-detects first config if not specified

`--split` (optional)
- Split to preview (default: `train`)

`--num-rows` (optional)
- Number of sample rows (default: 5, max: 20)

**Tips:**
- Use after search to verify data structure
- Streaming mode - doesn't download full dataset

---

### Download HuggingFace Dataset (aii_hf_download_datasets.py)

Download datasets and save to files.

**Example input:**
```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_hf_download_datasets.py openai/gsm8k --config main --split train
```

**Parallel execution (multiple datasets):**

IMPORTANT: Use full python path with GNU parallel. Use `eval {}` pattern when datasets need different flags (e.g. `--config`):
```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-hf-datasets" && \
export PY="$SKILL_DIR/../.ability_client_venv/bin/python" && \
export S="$SKILL_DIR/scripts/aii_hf_download_datasets.py" && \
parallel -j 10 -k --group --will-cite 'eval {}' ::: '$PY $S openai/gsm8k --config main --split train' '$PY $S imdb --split train' '$PY $S squad --split train'
```

**Example output:**
```
Downloaded: openai/gsm8k

  train:
    Rows: 7,473
    Preview: temp/datasets/preview_openai_gsm8k_main_train.json
    Mini: temp/datasets/mini_openai_gsm8k_main_train.json
    Full: temp/datasets/full_openai_gsm8k_main_train.json
```

**Parameters:**

`dataset_id` (required, positional)
- HuggingFace dataset ID
- Examples: `openai/gsm8k`, `imdb`

`--config` (optional)
- Dataset configuration/subset name
- Use preview to see available configs

`--split` (optional)
- Specific split to load (e.g., `train`, `test`)
- If not specified, loads all splits

`--output-dir` (optional)
- Output directory (default: `temp/datasets/`)

**Output files (auto-saved):**
1. **Preview**: `preview_{dataset}_{split}.json` - 3 truncated rows - **READ THIS** for quick inspection
2. **Mini**: `mini_{dataset}_{split}.json` - 3 full rows - for development/testing
3. **Full**: `full_{dataset}_{split}.json` - All rows - **DO NOT READ directly** - use as input path for code

**Tips:**
- Only read preview file directly with Read tool
- Mini and full are input paths for processing code

**If the script fails** with a connection error (ability server not running): create a local `.venv`, install server deps from `server_requirements.txt` into it, then import the `@aii_ability` function from the script and call it directly — bypassing the server:
```bash
uv venv .venv --python=3.12 && uv pip install --python=.venv/bin/python -r "$SKILL_DIR/scripts/server_requirements.txt"
```
````

### [5] SYSTEM-USER prompt · 2026-07-08 11:35:40 UTC

````
YOUR PREVIOUS SESSION WAS INTERRUPTED: A single operation exceeded the 720s message timeout. Each individual operation must complete within 720s. Do NOT mock, skip, or compromise your execution — still do the real work. Try to make operations run faster if possible. If a command genuinely takes longer than 720s, split it into sequential parts that each complete within the time limit.

Last messages before interruption:
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the result of running `cat -n` on /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json:\n     1\t{\n     2\t  \"title\": \"Ac
  - [agent_response]: I see the issue - there's a tab character on line 7 before "target_num_datasets". The file has invalid JSON. Let me fix this by using the str_replace more carefully. The issue is that the `"target_num_datasets"` line has a tab character before it. Let me try to match the exact text:
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "str_replace",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": null,
  "old_str": "  \"target_num_datasets\": 1\n}",
  "new_str": "  \"target_num_datasets
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Invalid `new_str` parameter:   \"target_num_datasets\": 1\n}. No replacement was performed. `new_str` and `old_str` must be different."}], "is_error": true, "command": "str_replace", "path": null, "prev_exist": t
  - [agent_response]: Let me try a different approach - use the create command to overwrite the file. First let me delete the file by creating a new version:
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "create",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/plan_json_corrected.json",
  "file_text": "{\n  \"title\": \"Acquire CLEAR Corpus for Readability Validation\",\n  \"summary\": \"Download and standar
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "File created successfully at: /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/plan_json_corrected.json"}], "is_error": false, "command": "create", "path": "/ai-inve
  - [agent_response]: Now let me verify this new file is valid JSON and then replace the old file:
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "view",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/plan_json_corrected.json",
  "file_text": null,
  "old_str": null,
  "new_str": null,
  "insert_line": null,
  "view_range": null
}
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the result of running `cat -n` on /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/plan_json_corrected.json:\n     1\t{\n     2\t  \"title\": \"Acquire CLEAR 
  - [agent_response]: The new file has the same issue - there's a tab before "target_num_datasets" on line 7. This is strange. Let me look at the raw content. Actually, I think the issue is that the content I'm pasting has tabs in it. Let me try a completely different approach - use Python to write the JSON file directly
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "create",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/final_write_plan.py",
  "file_text": "#!/usr/bin/env python3\n\"\"\"\nWrite the plan JSON with proper formatting\n\"\"\"\nimport json\nimport os\n\n# 
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "File created successfully at: /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/final_write_plan.py"}], "is_error": false, "command": "create", "path": "/ai-inventor/
  - [agent_response]: Let me now try to run this Python script to write the JSON file properly. But wait - I realize I should just write the output file directly. Let me use a simpler approach - just write the JSON file content directly using bash:
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "create",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": "{\n  \"title\": \"Acquire CLEAR Corpus for Readability Validation\",\n  \"summary\": \"Download
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Invalid `path` parameter: /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json. File already exists at: /ai-inventor/aii_data/runs/r
  - [agent_response]: I need to delete the old file first or use str_replace. Let me try to fix just the problematic line. Let me look more carefully at what's on line 7:
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "view",
  "path": "/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": null,
  "old_str": null,
  "new_str": null,
  "insert_line": null,
  "view_range": [
    5,
    8

  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the result of running `cat -n` on /ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json:\n     5\t  \"ideal_dataset_criteria\"
  - [status_public_warning]: [PauseEvent]

CONTINUE FOLLOWING THESE INSTRUCTIONS:

<hypothesis>
kind: hypothesis
title: Readability as Circuit Resistance
hypothesis: >-
  Text readability can be modeled through effective electrical resistance of discourse graphs with SEMANTIC edges between
  sentences. The Kirchhoff index of graphs where edges are weighted by semantic similarity (cosine distance between SBERT
  embeddings) provides a readability metric that captures discourse coherence beyond sentence count. Unlike sequential-only
  graphs (which reduce to sentence counting and produce trivially few distinct values), semantic edges enable the metric to
  capture meaningful variance in discourse structure. The first experiment using sequential edges and synthetic data with
  limited sentence counts (1-3 sentences) was invalid and must be repeated with rich discourse graphs and established benchmarks
  containing real human judgments.
motivation: >-
  Current readability formulas rely on surface features (sentence length, word difficulty) or black-box ML models that don't
  explicitly model the cognitive process of reading. Drawing from electrical network theory, we propose that readable text
  should allow 'easy information flow' through semantic connections, analogous to current flowing through a low-resistance
  circuit. This provides a theoretically grounded, interpretable metric that captures discourse-level coherence in a way surface
  features cannot.
assumptions:
- >-
  Text can be meaningfully represented as a graph where sentences are nodes and edges represent discourse connections (semantic
  similarity, rhetorical relations, or sequential adjacency)
- >-
  The cognitive effort of reading correlates with the 'resistance' to information flow through the discourse graph
- >-
  Edge weights (resistances) can be meaningfully assigned based on semantic distance or discourse relation strength
- >-
  The effective graph resistance (Kirchhoff index) computed from this weighted graph correlates with human judgments of readability
investigation_approach: >-
  1. Construct discourse graphs from texts: nodes=sentences, edges=semantic connections weighted by cosine distance between
  sentence embeddings (or simplified: sequential edges with weights based on position). 2. Compute the effective graph resistance
  (trace of Laplacian pseudoinverse) as the readability score. 3. Evaluate on standard readability datasets (e.g., Weebit,
  CLEAR) by correlating with human ratings. 4. Compare against traditional formulas (Flesch-Kincaid, SMOG) and ML baselines.
  5. Perform ablation: test different graph construction methods (sequential only, similarity-thresholded, full RST parsing).
success_criteria: >-
  The effective resistance metric should: (1) Achieve Pearson correlation r > 0.7 with human readability ratings on standard
  benchmarks, (2) Outperform or match traditional readability formulas (Flesch-Kincaid, etc.) in predictive accuracy, (3)
  Show significant correlation (p < 0.01) with reading time/eye-tracking measures if available, (4) Be computationally feasible
  (< 1s per document for typical lengths). A tiny experiment (N=50 texts with human ratings) showing r > 0.5 would support
  proceeding to full evaluation.
related_works:
- >-
  Mesgar & Strube (2015) 'Graph-based Coherence Modeling For Assessing Readability' - Uses entity grids and discourse relation
  graphs with features like outdegree and frequent subgraphs, but does NOT use effective resistance. Our approach differs
  by using the actual electrical network resistance as the direct readability metric, which captures global information flow
  rather than local graph patterns.
- >-
  Zhang et al. (2026) 'Automatic text readability assessment for educational content based on graph representation learning'
  - Uses GCNs on POS-based dependency graphs. This is a deep learning approach that learns features implicitly, whereas our
  method uses a specific, interpretable graph metric (effective resistance) derived from network theory.
- >-
  Guinaudeau & Strube (2013) 'Graph-based coherence modeling' - Introduces entity graphs and one-mode projections for coherence
  modeling. Our work differs by using effective resistance (a global spectral graph property) rather than local features like
  edge weights or components.
- >-
  Ehret (2018) 'Kolmogorov complexity as a universal measure of language complexity' - Uses compression-based complexity.
  While both approaches use information theory concepts, effective resistance captures discourse-level connectivity while
  Kolmogorov complexity captures lexical/syntactic redundancy.
- >-
  Klein et al. (2025) 'Surprisal Takes It All: Eye Tracking Based Cognitive Evaluation of Text Readability Measures' - Finds
  surprisal (from language models) predicts reading ease. Our approach is complementary: effective resistance models discourse
  structure while surprisal models lexical predictability.
inspiration: >-
  The hypothesis draws from electrical network theory (Kirchhoff's laws, effective resistance) and its application to graph
  analysis. In electrical engineering, the effective resistance between nodes in a network captures how easily current can
  flow. We adapt this to text by treating discourse connections as electrical pathways: coherent, well-connected text has
  low 'resistance' to information flow, while disjointed or complex text has high resistance. This cross-domain transfer from
  circuit theory to readability assessment is, to our knowledge, novel.
terms:
- term: Effective resistance (Kirchhoff index)
  definition: >-
    The sum of resistance distances between all pairs of nodes in a graph, equivalent to the trace of the pseudoinverse of
    the graph Laplacian. In electrical networks, this represents the total resistance 'seen' by current flowing through the
    network.
- term: Graph Laplacian
  definition: >-
    A matrix representation of a graph L = D - A, where D is the degree matrix and A is the adjacency matrix. The pseudoinverse
    of L is used to compute effective resistances between nodes.
- term: Discourse graph
  definition: >-
    A graph representation of text where nodes represent sentences or discourse units, and edges represent rhetorical relations,
    semantic connections, or sequential adjacency.
- term: Resistance distance
  definition: >-
    A graph metric derived from electrical network theory that measures the effective electrical resistance between two nodes
    if unit resistors are placed on each edge. It captures both direct and indirect pathways between nodes.
- term: Kirchhoff index
  definition: >-
    The sum of all pairwise resistance distances in a graph. It is a global graph invariant that measures the overall 'connectivity'
    or 'flow capacity' of the network.
summary: >-
  We propose a novel readability metric based on effective electrical resistance of discourse graphs. By modeling text as
  a circuit where sentences are connected by semantic pathways, the total resistance to information flow (Kirchhoff index)
  provides a physically-motivated, interpretable measure of readability that captures discourse-level coherence beyond surface
  features.
_relation_rationale: >-
  First experiment invalid (only 2 values); refining to require semantic edges, not just sequential.
_confidence_delta: decreased
_key_changes:
- >-
  Added REQUIREMENT for semantic edges (SBERT embeddings) instead of just sequential edges
- >-
  Acknowledged first experiment was invalid: only 2 distinct values, correlation = sentence count
- >-
  Added success criterion: metric must produce continuous range of values across diverse texts
- >-
  Added success criterion: partial correlation controlling for sentence count must remain significant
- >-
  Changed evaluation to use established benchmarks (CLEAR, WeeBit) with REAL human judgments
- >-
  Added ablation comparing sequential-only vs. semantic edges to quantify discourse contribution
- Emphasized edge weights must be based on semantic distance, not uniform
- Noted normalization scheme needs theoretical justification
relation_type: evolution
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for the methods, proper baselines, and evaluation this field demands.

- **aii-handbook-multi-llm-agents** — Guide for implementing Multi-LLM Agent Systems research using Mirascope orchestration, HuggingFace datasets/evaluation, and proven multi-agent patterns.
</available_domain_handbooks>

<artifact_direction>
Make this direction concrete and actionable. Keep the same type and respect dependencies.

id: dataset_iter2_dir1
type: dataset
objective: >-
  Acquire the CLEAR corpus (CommonLit Ease of Readability) with real human readability judgments for experiment validation
approach: >-
  Download the CLEAR corpus from GitHub (https://github.com/scrosseye/CLEAR-Corpus). The corpus contains ~4000 texts with
  human readability ratings from multiple raters on a 1-100 scale. Also download the ratings file which contains the actual
  human judgments. Standardize to JSON format with fields: text, sentence_boundaries, human_readability_score (original 1-100
  scale preserved), text_id, metadata, rater_agreement. Create full/mini/preview splits. The CLEAR corpus is essential because
  it has genuine human judgments, unlike synthetic data or algorithmically-labeled datasets used previously. Save to data_out.json
  in standardized schema.
depends_on: []
</artifact_direction>



<instructions>
YOUR ROLE: Write a detailed PLAN for the artifact. A separate executor agent runs the actual artifact later.

You are a PLANNER, not an executor. Your output is a plan that tells the executor what to do and how.
Do NOT execute the artifact itself — a separate agent handles that. Your job is to plan it so well that the executor can follow your plan step by step.

You CAN and SHOULD: search the web, read papers, and explore library docs to make your plan concrete.
You CANNOT run shell commands or scripts — code execution is disabled. Research via web tools only.

Do NOT do the executor's job: don't download datasets, don't implement code, don't run experiments, don't write proofs, don't compute evaluations.

<artifact_executor_scope>
IMPORTANT: Each artifact executor has a focused prompt that guides it to do ONE thing well. It will NOT perform tasks outside its scope — assigning the wrong work to the wrong artifact type wastes an iteration. Match the task to the right executor.

DATASET executor scope:
  Output: data_out.json with rows of {input, output, metadata_fold, ...} — raw data only, no derived computations
  DOES: Download/generate datasets, analyze candidates to pick the best ones, standardize to JSON schema (features, labels, folds, metadata), validate schema, split into full/mini/preview
  DOES NOT: Run experiments, train models, compute derived statistics (PID/MI/correlations/synergy matrices) as final output
  If you need to COMPUTE something from data (synergy matrices, MI scores, timing benchmarks), use an EXPERIMENT artifact instead
</artifact_executor_scope>

<artifact_planning_rules>
DATASET:
- Plan for REAL third-party datasets (HuggingFace, Kaggle, direct-download URLs) — downloadable within time and size constraints
- Describe dataset criteria (domain, size, format) — executors find exact sources, but you can suggest candidates or search directions
- ALWAYS prefer real datasets over synthetic. Synthetic is a LAST RESORT only when no suitable real data exists
</artifact_planning_rules>

<compute_profiles>
Choose the compute profile this artifact needs for execution.
Available profiles for dataset artifacts:
  - gpu: 1x NVIDIA RTX A4500, 20GB VRAM, 7 vCPUs, 29GB RAM — ML training, CUDA, large models (fallback: GPUs cheap→expensive: 2000 Ada → A4000 → 4000 Ada → L4 → 4090 → 5090)
  - cpu_heavy: 4 vCPUs, 32GB RAM — large datasets, memory-intensive processing (fallback: CPUs cheap→expensive, then GPU hosts cheap→expensive (all ≥32GB RAM))

Set runpod_compute_profile to one of these exact tier names.
</compute_profiles>
GOOD PLANS: specific, actionable, consider failure scenarios, build on the suggested approach.
BAD PLANS: vague hand-waving, ignoring the suggested approach, missing critical executor details.
</instructions><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "description": "Plan for a DATASET artifact.",
  "properties": {
    "title": {
      "description": "Plan title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters).",
      "title": "Title",
      "type": "string"
    },
    "summary": {
      "default": "",
      "description": "Brief summary",
      "title": "Summary",
      "type": "string"
    },
    "runpod_compute_profile": {
      "anyOf": [
        {
          "type": "string"
        },
        {
          "type": "null"
        }
      ],
      "default": "cpu_light",
      "description": "Compute tier for execution \u2014 pick from the available profiles list (e.g., 'gpu', 'cpu_heavy', 'cpu_light'). Only used in RunPod mode.",
      "title": "Runpod Compute Profile"
    },
    "ideal_dataset_criteria": {
      "description": "What makes an ideal dataset for this purpose - size, format, content requirements",
      "title": "Ideal Dataset Criteria",
      "type": "string"
    },
    "dataset_search_plan": {
      "description": "Step-by-step plan for finding/creating this dataset - sources to check, fallback options",
      "title": "Dataset Search Plan",
      "type": "string"
    },
    "target_num_datasets": {
      "description": "How many individual datasets should be delivered. Count each dataset separately, not collections \u2014 a benchmark suite of N datasets counts as N. This controls how broadly the executor searches, so setting it too low will under-collect.",
      "title": "Target Num Datasets",
      "type": "integer"
    }
  },
  "required": [
    "title",
    "ideal_dataset_criteria",
    "dataset_search_plan",
    "target_num_datasets"
  ],
  "title": "DatasetPlan",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_RiHQW43yNEvO/3_invention_loop/iter_2/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`.

Propose a simple, novel, testable ML method for scoring text readability and validate it with a tiny experiment.
````
