# gen_plan_dataset_1 — test_idea

> Phase: `invention_loop` · round 1 · `gen_plan`
> Run: `run_6uOr5GlpaMfR` — Evaluating Embedding-Based Semantic Coherence for Readability Assessment: An Empirical Study
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_plan_dataset_1` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-08 23:24:25 UTC

````
<hypothesis>
kind: hypothesis
title: Semantic Control Energy for Readability
hypothesis: >-
  Text readability can be quantified by the minimum 'control energy' required to traverse the semantic trajectory of a text,
  where readable texts require minimal energy to follow their semantic progression while unreadable texts require large energy
  corrections due to jarring semantic jumps or excessive repetition.
motivation: >-
  Current readability formulas (Flesch-Kincaid, etc.) rely on surface features like sentence length and word complexity, missing
  the dynamic flow of meaning. Information-theoretic approaches (compression/Kolmogorov complexity) capture static complexity
  but not the cognitive effort of semantic navigation. By treating text as a dynamical system trajectory through semantic
  space and measuring the optimal control energy needed to follow it, we can capture a fundamental aspect of readability:
  how much cognitive 'work' a reader must expend to track the evolving meaning.
assumptions:
- >-
  Text can be meaningfully represented as a trajectory in a continuous semantic embedding space
- >-
  Human reading comprehension requires cognitive resources proportional to the 'control effort' needed to track semantic changes
- >-
  Optimal control theory provides a valid framework for quantifying the minimum effort needed to navigate semantic transitions
- >-
  The energy cost of semantic transitions correlates with subjective reading difficulty
investigation_approach: >-
  1. Map sentences to embeddings (using SBERT or similar) to create a semantic trajectory. 2. Model the trajectory as a dynamical
  system: x(t+1) = x(t) + u(t) + noise, where x is the semantic state and u is the 'control input'. 3. Compute the LQR (Linear
  Quadratic Regulator) cost: sum of squared deviations from optimal path + control effort. 4. Alternative: compute the cumulative
  Wasserstein distance or semantic 'work' along the trajectory. 5. Compare against traditional readability formulas and human
  judgments on standard datasets (CLEAR corpus, WeeBit, etc.). 6. Evaluate whether SCE captures aspects of readability that
  traditional formulas miss (e.g., texts with simple words but jarring topic shifts).
success_criteria: >-
  1. SCE scores should correlate with human readability judgments at least as well as traditional formulas (Flesch-Kincaid,
  SMOG). 2. SCE should better predict reading comprehension scores than surface-based formulas on texts with simple vocabulary
  but poor semantic flow. 3. Ablation studies should show that the 'energy' component (penalizing large semantic jumps) is
  necessary for predictive power. 4. The method should be computationally feasible: <1 second per document on standard hardware.
related_works:
- >-
  Kolmogorov complexity using compression (Ehret 2018): Also uses information theory but measures static complexity of entire
  text rather than dynamic semantic navigation cost. Our approach is fundamentally different - we measure the optimal control
  energy of the semantic trajectory, not compression ratio.
- >-
  Bigram Semantic Distance (Kenett et al. 2017): Measures semantic distance between consecutive words/sentences. Our approach
  extends this by considering the optimal control effort over the ENTIRE trajectory (not just pairwise distances) and incorporates
  a dynamical systems framework.
- >-
  Coh-Metrix and coherence measures: Measure local coherence and connectivity. Our approach is global - measuring the total
  'energy' needed to follow the semantic flow, which captures both local coherence and global trajectory smoothness.
- >-
  Word Mover's Distance (Kusner et al. 2015): Uses optimal transport for document similarity. Our approach is different: we
  measure the control energy needed to follow a trajectory, not the transport cost between two static distributions.
inspiration: >-
  The hypothesis combines insights from three distant fields: (1) Control Theory - specifically Linear Quadratic Regulator
  (LQR) theory which minimizes energy for trajectory tracking, (2) Optimal Transport theory - which provides Wasserstein distance
  for measuring semantic transition costs, and (3) Physics/Dynamical Systems - which views readability as the 'work' required
  to move through semantic space. The core insight is that readable text should have a 'smooth' semantic trajectory requiring
  minimal control corrections, analogous to how a well-designed controller keeps a system on a desired path with minimal energy
  expenditure.
terms:
- term: Semantic Trajectory
  definition: >-
    The path traced by sequential units of text (sentences or paragraphs) when mapped to a continuous vector space representing
    meaning (e.g., through sentence embeddings).
- term: Control Energy
  definition: >-
    In control theory, the cumulative effort (measured as squared control inputs) required to make a system follow a desired
    trajectory. In our context, it represents the cognitive work needed to track semantic changes in text.
- term: LQR (Linear Quadratic Regulator)
  definition: >-
    An optimal control method that finds the control inputs minimizing a quadratic cost function of state deviations and control
    effort, commonly used in engineering to design stable, efficient controllers.
- term: Semantic Embedding Space
  definition: >-
    A high-dimensional vector space where words, sentences, or documents are mapped such that semantic similarity corresponds
    to geometric proximity (e.g., cosine similarity in the embedding space).
- term: Optimal Transport (Wasserstein Distance)
  definition: >-
    A mathematical framework for measuring the distance between probability distributions by computing the minimum 'cost'
    to transform one distribution into another, often visualized as moving 'mass' from one configuration to another.
summary: >-
  This hypothesis proposes a novel readability metric based on control theory: readable text requires minimal 'control energy'
  to follow its semantic trajectory. By modeling text as a dynamical system in embedding space and computing the optimal control
  cost, we can quantify readability as the cognitive work needed for semantic navigation.
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for the methods, proper baselines, and evaluation this field demands.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>

<artifact_direction>
Make this direction concrete and actionable. Keep the same type and respect dependencies.

id: dataset_iter1_dir2
type: dataset
objective: >-
  Acquire and standardize 2-3 standard readability datasets with human judgments or grade-level annotations for evaluating
  the SCE method.
approach: >-
  Download and standardize: (1) CLEAR corpus (if available) or WeeBit dataset from HuggingFace or direct sources - contains
  texts with human readability ratings, (2) Newsela dataset or similar with leveled texts (same content at different reading
  levels), (3) Standard readability benchmark like OneStopEnglish. Transform to JSON format with fields: {text, readability_score/grade_level,
  metadata}. Create train/validation/test splits. Prioritize datasets with human judgment data over surface-level features.
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
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`

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

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-08 23:24:25 UTC

```
Propose a simple, novel machine-learning method for scoring text readability and validate it.
```

### [3] SKILL-INPUT — aii-web-tools · 2026-07-08 23:24:30 UTC

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

### [4] SKILL-INPUT — aii-hf-datasets · 2026-07-08 23:25:42 UTC

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

### [5] SYSTEM-USER prompt · 2026-07-08 23:37:07 UTC

````
YOUR PREVIOUS SESSION WAS INTERRUPTED: A single operation exceeded the 720s message timeout. Each individual operation must complete within 720s. Do NOT mock, skip, or compromise your execution — still do the real work. Try to make operations run faster if possible. If a command genuinely takes longer than 720s, split it into sequential parts that each complete within the time limit.

Last messages before interruption:
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "File created successfully at: /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/research_readability_datasets.py"}], "is_error": false, "command": "create", "path": "
  - [agent_response]: I need to research the specific readability datasets mentioned in the artifact direction to create a detailed plan. Let me use the web search tools to find information about dataset availability and access methods. I'll search for each dataset systematically.
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "create",
  "path": "/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/gather_dataset_info.py",
  "file_text": "#!/usr/bin/env python3\n\"\"\"\nResearch script to gather information about readability datasets\nfor the Sem
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "File created successfully at: /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/gather_dataset_info.py"}], "is_error": false, "command": "create", "path": "/ai-invent
  - [agent_think]: The user wants me to create a detailed plan for a DATASET artifact. Let me review what I need to do:

1. I'm a planner, not an executor - I need to create a plan that tells the executor what to do
2. The artifact direction is to acquire and standardize 2-3 standard readability datasets with human ju
  - [agent_response]: I realize I've been trying to execute searches directly, but as a planner, I should create a detailed plan based on my knowledge and make it actionable for the executor. Let me create the plan directly now, incorporating specific details about the datasets mentioned in the artifact direction.
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "create",
  "path": "/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": "{\n  \"title\": \"Readability Datasets for SCE Evaluation\",\n  \"summary\": \"Collect and stan
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "File created successfully at: /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json"}], "is_error": false, "command": "create", "path
  - [agent_think]: The user asked me to create a detailed plan for a dataset artifact. I've created a JSON file with the plan, but I should verify it's complete and properly formatted. Let me review what I've created and ensure it meets all the requirements.

Looking at the artifact direction:
- Type: DATASET
- Object
  - [agent_response]: I've created a comprehensive plan for acquiring and standardizing readability datasets. Let me verify the plan is complete and properly formatted by viewing the output file.
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "view",
  "path": "/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": null,
  "old_str": null,
  "new_str": null,
  "insert_line": null,
  "view_range": null
}
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the result of running `cat -n` on /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json:\n     1\t{\n     2\t  \"title\": \"Re
  - [agent_response]: The plan looks comprehensive, but I should verify that the JSON is valid and ensure it matches the required schema. Let me also check if I need to clean up the temporary research files I created. Let me validate the JSON structure and make sure it's complete.
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "view",
  "path": "/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1",
  "file_text": null,
  "old_str": null,
  "new_str": null,
  "insert_line": null,
  "view_range": null
}
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the files and directories up to 2 levels deep in /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1, excluding hidden items:\n/ai-inventor/aii_data/runs/run_6uO
  - [agent_think]: The user asked me to create a plan for a dataset artifact. I've created the JSON output file at the required location. Now I should:

1. Verify the JSON is valid and complete
2. Clean up the temporary files I created (the research scripts)
3. Mark the task as complete

Let me check if the JSON file 
  - [agent_response]: I've created a comprehensive plan for the dataset artifact. Let me clean up the temporary research files I created during the planning process, then verify the output is complete.
  - [agent_tool_call] file_editor: Tool: file_editor
{
  "command": "view",
  "path": "/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json",
  "file_text": null,
  "old_str": null,
  "new_str": null,
  "insert_line": null,
  "view_range": null
}
  - [agent_tool_result] file_editor: Tool: file_editor
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Here's the result of running `cat -n` on /ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json:\n     1\t{\n     2\t  \"title\": \"Re
  - [status_public_warning]: [PauseEvent]

CONTINUE FOLLOWING THESE INSTRUCTIONS:

<hypothesis>
kind: hypothesis
title: Semantic Control Energy for Readability
hypothesis: >-
  Text readability can be quantified by the minimum 'control energy' required to traverse the semantic trajectory of a text,
  where readable texts require minimal energy to follow their semantic progression while unreadable texts require large energy
  corrections due to jarring semantic jumps or excessive repetition.
motivation: >-
  Current readability formulas (Flesch-Kincaid, etc.) rely on surface features like sentence length and word complexity, missing
  the dynamic flow of meaning. Information-theoretic approaches (compression/Kolmogorov complexity) capture static complexity
  but not the cognitive effort of semantic navigation. By treating text as a dynamical system trajectory through semantic
  space and measuring the optimal control energy needed to follow it, we can capture a fundamental aspect of readability:
  how much cognitive 'work' a reader must expend to track the evolving meaning.
assumptions:
- >-
  Text can be meaningfully represented as a trajectory in a continuous semantic embedding space
- >-
  Human reading comprehension requires cognitive resources proportional to the 'control effort' needed to track semantic changes
- >-
  Optimal control theory provides a valid framework for quantifying the minimum effort needed to navigate semantic transitions
- >-
  The energy cost of semantic transitions correlates with subjective reading difficulty
investigation_approach: >-
  1. Map sentences to embeddings (using SBERT or similar) to create a semantic trajectory. 2. Model the trajectory as a dynamical
  system: x(t+1) = x(t) + u(t) + noise, where x is the semantic state and u is the 'control input'. 3. Compute the LQR (Linear
  Quadratic Regulator) cost: sum of squared deviations from optimal path + control effort. 4. Alternative: compute the cumulative
  Wasserstein distance or semantic 'work' along the trajectory. 5. Compare against traditional readability formulas and human
  judgments on standard datasets (CLEAR corpus, WeeBit, etc.). 6. Evaluate whether SCE captures aspects of readability that
  traditional formulas miss (e.g., texts with simple words but jarring topic shifts).
success_criteria: >-
  1. SCE scores should correlate with human readability judgments at least as well as traditional formulas (Flesch-Kincaid,
  SMOG). 2. SCE should better predict reading comprehension scores than surface-based formulas on texts with simple vocabulary
  but poor semantic flow. 3. Ablation studies should show that the 'energy' component (penalizing large semantic jumps) is
  necessary for predictive power. 4. The method should be computationally feasible: <1 second per document on standard hardware.
related_works:
- >-
  Kolmogorov complexity using compression (Ehret 2018): Also uses information theory but measures static complexity of entire
  text rather than dynamic semantic navigation cost. Our approach is fundamentally different - we measure the optimal control
  energy of the semantic trajectory, not compression ratio.
- >-
  Bigram Semantic Distance (Kenett et al. 2017): Measures semantic distance between consecutive words/sentences. Our approach
  extends this by considering the optimal control effort over the ENTIRE trajectory (not just pairwise distances) and incorporates
  a dynamical systems framework.
- >-
  Coh-Metrix and coherence measures: Measure local coherence and connectivity. Our approach is global - measuring the total
  'energy' needed to follow the semantic flow, which captures both local coherence and global trajectory smoothness.
- >-
  Word Mover's Distance (Kusner et al. 2015): Uses optimal transport for document similarity. Our approach is different: we
  measure the control energy needed to follow a trajectory, not the transport cost between two static distributions.
inspiration: >-
  The hypothesis combines insights from three distant fields: (1) Control Theory - specifically Linear Quadratic Regulator
  (LQR) theory which minimizes energy for trajectory tracking, (2) Optimal Transport theory - which provides Wasserstein distance
  for measuring semantic transition costs, and (3) Physics/Dynamical Systems - which views readability as the 'work' required
  to move through semantic space. The core insight is that readable text should have a 'smooth' semantic trajectory requiring
  minimal control corrections, analogous to how a well-designed controller keeps a system on a desired path with minimal energy
  expenditure.
terms:
- term: Semantic Trajectory
  definition: >-
    The path traced by sequential units of text (sentences or paragraphs) when mapped to a continuous vector space representing
    meaning (e.g., through sentence embeddings).
- term: Control Energy
  definition: >-
    In control theory, the cumulative effort (measured as squared control inputs) required to make a system follow a desired
    trajectory. In our context, it represents the cognitive work needed to track semantic changes in text.
- term: LQR (Linear Quadratic Regulator)
  definition: >-
    An optimal control method that finds the control inputs minimizing a quadratic cost function of state deviations and control
    effort, commonly used in engineering to design stable, efficient controllers.
- term: Semantic Embedding Space
  definition: >-
    A high-dimensional vector space where words, sentences, or documents are mapped such that semantic similarity corresponds
    to geometric proximity (e.g., cosine similarity in the embedding space).
- term: Optimal Transport (Wasserstein Distance)
  definition: >-
    A mathematical framework for measuring the distance between probability distributions by computing the minimum 'cost'
    to transform one distribution into another, often visualized as moving 'mass' from one configuration to another.
summary: >-
  This hypothesis proposes a novel readability metric based on control theory: readable text requires minimal 'control energy'
  to follow its semantic trajectory. By modeling text as a dynamical system in embedding space and computing the optimal control
  cost, we can quantify readability as the cognitive work needed for semantic navigation.
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for the methods, proper baselines, and evaluation this field demands.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>

<artifact_direction>
Make this direction concrete and actionable. Keep the same type and respect dependencies.

id: dataset_iter1_dir2
type: dataset
objective: >-
  Acquire and standardize 2-3 standard readability datasets with human judgments or grade-level annotations for evaluating
  the SCE method.
approach: >-
  Download and standardize: (1) CLEAR corpus (if available) or WeeBit dataset from HuggingFace or direct sources - contains
  texts with human readability ratings, (2) Newsela dataset or similar with leveled texts (same content at different reading
  levels), (3) Standard readability benchmark like OneStopEnglish. Transform to JSON format with fields: {text, readability_score/grade_level,
  metadata}. Create train/validation/test splits. Prioritize datasets with human judgment data over surface-level features.
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
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`

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

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_6uOr5GlpaMfR/3_invention_loop/iter_1/gen_plan/gen_plan_dataset_1/.sdk_openhands_agent_struct_out.json`.

Propose a simple, novel machine-learning method for scoring text readability and validate it.
````
