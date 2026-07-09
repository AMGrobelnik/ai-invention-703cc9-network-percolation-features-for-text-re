# gen_paper_text — test_idea

> Phase: `invention_loop` · round 1 · `gen_paper_text`
> Run: `run_LOb33NvVGQcB` — Readability Scoring Method
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_text` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-09 00:19:18 UTC

````
<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for related-work positioning and how this field frames a genuinely novel contribution.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>
<hypothesis>
The research hypothesis.

kind: hypothesis
title: Percolation Threshold Readability Model
hypothesis: >-
  Text readability can be quantified as the percolation threshold of a cohesion network constructed from the text. As a reader
  processes a text, they build a mental network where sentences/concepts are nodes and cohesion links (lexical overlap, semantic
  similarity, referential ties) are edges. Readability equals the critical fraction of cohesion links needed for a giant connected
  component to emerge in this network. Texts with low percolation thresholds are easy to read because concepts integrate quickly;
  texts with high thresholds are hard because concepts remain fragmented until late in processing.
motivation: >-
  Current readability formulas (Flesch-Kincaid, BERT-based models) measure surface features or use black-box predictions,
  but they don't model the underlying cognitive process of how readers integrate information. Percolation theory from statistical
  physics provides a natural model: reading comprehension is the process of building a connected mental model. The percolation
  threshold precisely captures how easily this model integrates. This gives a physically interpretable readability metric
  grounded in how the brain actually processes cohesive text.
assumptions:
- >-
  Reader comprehension involves building a connected mental network of concepts from the text
- >-
  Cohesion links (lexical overlap, semantic similarity, reference) correspond to edges in the reader's mental network
- >-
  The ease of comprehension correlates with how quickly the mental network percolates (forms a giant component)
- >-
  The percolation threshold of the text's cohesion network is a measurable proxy for this cognitive integration difficulty
investigation_approach: >-
  1. Construct cohesion networks from English texts: nodes = sentences, edges = cosine similarity of sentence embeddings (SBERT)
  + lexical overlap. 2. Compute percolation threshold by simulating edge addition in random order and measuring when giant
  component emerges (reaches 50% of nodes). 3. Compare percolation threshold against gold-standard readability scores (Flesch-Kincaid,
  human ratings from Newsela/OneStopEnglish datasets). 4. Test whether percolation threshold predicts reading comprehension
  scores better than traditional formulas. 5. Ablate: test with/without semantic edges to isolate effect of cohesion vs. just
  lexical overlap.
success_criteria: >-
  1. Percolation threshold should correlate negatively with established readability scores (easy texts have low thresholds).
  2. Percolation threshold should explain variance in human readability ratings beyond traditional formulas (significant delta
  R²). 3. On sentence-level readability datasets (Weebit, Newsela), percolation threshold should achieve RMSE < 1.5 grade
  levels when used as a feature in a simple linear model. 4. The method should be robust: threshold should be similar across
  multiple random edge-ordering runs (std < 0.05).
related_works:
- >-
  Zhang et al. (2026) 'Automatic text readability assessment for educational content based on graph representation learning'
  (Scientific Reports) - Uses Graph Convolutional Networks on POS-based dependency graphs. Our approach differs fundamentally:
  we use percolation theory to model the DYNAMIC process of comprehension (when does the mental model connect?) rather than
  static graph classification. GCNs learn to predict readability from graph structure; we derive an interpretable physical
  parameter (percolation threshold) that directly models cognitive integration.
- >-
  Ehret (2018) 'Kolmogorov complexity as a universal measure of language complexity' - Uses compression-based complexity.
  Our approach differs: we model TEXT AS A NETWORK and measure connectivity emergence, not information density. Kolmogorov
  complexity captures overall difficulty; percolation threshold captures specifically how fragmented vs. integrated the text
  feels.
- >-
  Cohen et al. on semantic network percolation (creativity research) - Uses k-clique percolation to measure flexibility of
  free association networks. Our work adapts percolation theory to a completely different domain (readability assessment)
  with a different network construction (text cohesion vs. free association) and a different research question (predicting
  readability vs. measuring creativity).
inspiration: >-
  Percolation theory from statistical physics (studying phase transitions in networks) crossed with discourse cohesion theory
  from linguistics. In physics, percolation threshold predicts when a material becomes conductive; in reading, we hypothesize
  it predicts when a text becomes 'comprehensible' (when the reader's mental model forms a connected whole). The key cross-domain
  insight: readability is not a static property of text but emerges from a phase transition in the reader's mental network.
terms:
- term: Percolation threshold
  definition: >-
    In network science, the critical fraction of edges that must be present before a giant connected component emerges spanning
    a significant portion of the network
- term: Cohesion network
  definition: >-
    A graph representation of text where nodes represent sentences or concepts, and edges represent cohesive ties such as
    lexical overlap, semantic similarity, or referential connections
- term: Giant connected component
  definition: >-
    A subgraph that contains a large fraction of all nodes in the network and in which any two nodes are connected by a path
- term: Phase transition
  definition: >-
    In statistical physics, a point at which a system undergoes a qualitative change in behavior (e.g., from disconnected
    to connected) as a parameter crosses a critical threshold
- term: SBERT
  definition: >-
    Sentence-BERT: a modification of BERT that uses siamese/triplet networks to produce semantically meaningful sentence embeddings
    for measuring similarity
summary: >-
  We propose that text readability equals the percolation threshold of the text's cohesion network. Easy texts have low thresholds
  (concepts connect quickly into a coherent mental model); hard texts have high thresholds (concepts remain fragmented). This
  provides a physically interpretable readability metric based on network science.
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 3 research artifacts across all iterations.

--- Item 1 ---
id: art_AXDjT-jFuQog
type: dataset
title: Standard Readability Datasets
summary: >-
  Successfully collected and standardized 3 high-quality readability datasets (OneStopEnglish, CommonLit, CEFR-SP) with 12,469
  total examples. All datasets have ground-truth grade-level labels (1-12) from educators (not algorithm-derived). Data is
  formatted as {input: text, output: grade_level} with train/val/test splits. Output validated against exp_sel_data_out.json
  schema. The datasets include: (1) OneStopEnglish with 567 texts at three reading levels (Elementary=grade 3, Intermediate=grade
  7, Advanced=grade 11), (2) CommonLit with 4,724 literary excerpts with educator-assigned readability levels based on Flesch-Kincaid
  grade formula, and (3) CEFR-SP with 7,178 sentences annotated by English education professionals with CEFR levels mapped
  to grades 1-10. All datasets were searched, previewed, and validated before inclusion. The final output includes full, mini,
  and preview JSON variants for efficient development and inspection.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_LOb33NvVGQcB/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 2 ---
id: art_uk2sv61xad_U
type: experiment
title: Percolation Threshold Readability Model
summary: >-
  Implemented and validated a percolation threshold readability model. The method constructs cohesion networks from text using
  TF-IDF similarity and lexical overlap, then computes the percolation threshold - the fraction of edges needed to connect
  half the sentences. Results show positive correlation (r=0.724, p<0.001) between percolation threshold and grade level.
  The simple model using only p_c achieves R²=0.525, while the combined model (p_c + traditional metrics) achieves R²=0.924.
  The experiment processed 240 synthetic texts across 12 grade levels, comparing against 5 traditional readability metrics.
  Output includes predict_percolation field for each example as required by schema.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_LOb33NvVGQcB/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 3 ---
id: art_w2SGQU3BuITO
type: research
title: Readability Assessment Methods and Metrics Literature Review
summary: >-
  Comprehensive literature review of readability assessment methods covering: (1) Traditional formulas (Flesch-Kincaid, Dale-Chall,
  SMOG, ARI) with exact equations and limitations; (2) Modern ML approaches including BERT-based models, hybrid models (neural
  + linguistic features), and graph-based approaches with benchmark results; (3) Standard evaluation metrics (RMSE, Pearson
  r, Spearman ρ, accuracy, F1, QWK) with interpretation guidelines; (4) Standard datasets (OneStopEnglish, Weebit, CLEAR,
  Newsela, WSJ) with sizes, grade ranges, and access instructions; (5) Benchmark results from SOTA papers; (6) Recommended
  evaluation protocol for the percolation threshold readability model; (7) Gaps and opportunities where the novel percolation
  model can contribute. The research identifies that traditional formulas rely on surface features and have limited construct
  validity, while modern ML approaches achieve high performance (F1 >92% on Weebit, >99% on OneStopEnglish) but lack interpretability.
  The percolation threshold model offers opportunities in physical interpretability, dynamic comprehension modeling, and robust
  cohesion network construction.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_LOb33NvVGQcB/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 3 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

type: dataset
summary: >-
  Successfully collected and standardized 3 high-quality readability datasets (OneStopEnglish, CommonLit, CEFR-SP) with 12,469
  total examples. All datasets have ground-truth grade-level labels (1-12) from educators (not algorithm-derived). Data is
  formatted as {input: text, output: grade_level} with train/val/test splits. Output validated against exp_sel_data_out.json
  schema. The datasets include: (1) OneStopEnglish with 567 texts at three reading levels (Elementary=grade 3, Intermediate=grade
  7, Advanced=grade 11), (2) CommonLit with 4,724 literary excerpts with educator-assigned readability levels based on Flesch-Kincaid
  grade formula, and (3) CEFR-SP with 7,178 sentences annotated by English education professionals with CEFR levels mapped
  to grades 1-10. All datasets were searched, previewed, and validated before inclusion. The final output includes full, mini,
  and preview JSON variants for efficient development and inspection.
id: art_AXDjT-jFuQog
title: Standard Readability Datasets

type: experiment
summary: >-
  Implemented and validated a percolation threshold readability model. The method constructs cohesion networks from text using
  TF-IDF similarity and lexical overlap, then computes the percolation threshold - the fraction of edges needed to connect
  half the sentences. Results show positive correlation (r=0.724, p<0.001) between percolation threshold and grade level.
  The simple model using only p_c achieves R²=0.525, while the combined model (p_c + traditional metrics) achieves R²=0.924.
  The experiment processed 240 synthetic texts across 12 grade levels, comparing against 5 traditional readability metrics.
  Output includes predict_percolation field for each example as required by schema.
id: art_uk2sv61xad_U
title: Percolation Threshold Readability Model

type: research
summary: >-
  Comprehensive literature review of readability assessment methods covering: (1) Traditional formulas (Flesch-Kincaid, Dale-Chall,
  SMOG, ARI) with exact equations and limitations; (2) Modern ML approaches including BERT-based models, hybrid models (neural
  + linguistic features), and graph-based approaches with benchmark results; (3) Standard evaluation metrics (RMSE, Pearson
  r, Spearman ρ, accuracy, F1, QWK) with interpretation guidelines; (4) Standard datasets (OneStopEnglish, Weebit, CLEAR,
  Newsela, WSJ) with sizes, grade ranges, and access instructions; (5) Benchmark results from SOTA papers; (6) Recommended
  evaluation protocol for the percolation threshold readability model; (7) Gaps and opportunities where the novel percolation
  model can contribute. The research identifies that traditional formulas rely on surface features and have limited construct
  validity, while modern ML approaches achieve high performance (F1 >92% on Weebit, >99% on OneStopEnglish) but lack interpretability.
  The percolation threshold model offers opportunities in physical interpretability, dynamic comprehension modeling, and robust
  cohesion network construction.
id: art_w2SGQU3BuITO
title: Readability Assessment Methods and Metrics Literature Review
</new_artifacts_this_iteration>

<data_files>
Data files come in three sizes:
- preview_*_out.json — READ THIS to inspect the data structure
- mini_*_out.json (~3 examples) — use for prototyping/testing
- full_*_out.json (complete) — use for the final production run. NEVER open it directly (too large to read into context). Instead, extract values programmatically with shell commands (e.g. grep) or a Python script (use aii-long-running-tasks skill for scripts).
</data_files>

<task>
Write a research paper draft with LaTeX-ready text, BibTeX citations, and figure placeholders.

This is the FIRST paper draft. Write a complete research paper from scratch based on the hypothesis and all available artifacts.
</task>

<figure_instructions>
FIGURE FORMAT: Use [FIGURE:fig_id] markers in paper_text to indicate where each figure goes.
Then provide the full figure specs in the separate `figures` structured output array.
Each figure in the array must have an `id` matching a marker in the text. Set the `aspect_ratio`
field per figure: 21:9 for architecture / pipeline / flow-chart diagrams (the hero figure should
be one of these — place its marker near the END of the Introduction so it floats to the top of
page 2), 16:9 for comparisons / multi-panel results, 4:3 for dense charts, 1:1 for heatmaps /
confusion matrices / scatter plots.

Example in paper_text:
  "...our method achieves state-of-the-art results as shown below.\n\n[FIGURE:fig3]\n\nThe results demonstrate..."

Example in figures array (results comparison):
  {"id": "fig3", "title": "Performance Comparison", "caption": "Comparison of geometric mean query latency across optimizers.", "image_gen_detailed_description": "Grouped bar chart. X-axis: model names. Y-axis: latency (seconds, 0-5). Values: PostgreSQL=4.6s (red), Bao=2.8s (blue), RLQOpt=2.0s (green). Error bars +/-0.3-0.8. Sans-serif font, white background.", "aspect_ratio": "16:9", "summary": "Compares latency across optimizers"}

Example in figures array (architecture diagram, hero):
  {"id": "fig1", "title": "System Architecture", "caption": "End-to-end pipeline: encoder feeds latents into the planner, which queries the value head before emitting actions.", "image_gen_detailed_description": "Horizontal flow diagram, left to right. Five labeled boxes: 'Input' (gray), 'Encoder' (blue), 'Latent (z, 256-dim)' (light blue, narrow), 'Planner' (green), 'Action Head' (orange). Arrows labeled with shapes. Value head as separate green box below 'Planner', bidirectional arrow. Sans-serif font, clean white background, no 3D.", "aspect_ratio": "21:9", "summary": "Hero architecture diagram"}

CRITICAL: Before writing figure specs, look through artifact workspace output files (*_out.json)
and code to find ALL the exact values. The figure generator cannot read files — every exact number
and value MUST be in the image_gen_detailed_description.
</figure_instructions>

FIRST, add ALL of these to your todo list using your task/todo-tracking tool:

CRITICAL: Todo content must be copied exactly as is written here, with NO CHANGES. These todos are intentionally detailed so that another LLM could read each one without any external context and understand exactly what it has to do.

<todos>
TODO 1. Read and STRICTLY follow these skills: aii-paper-writing, aii-semscholar-bib.
TODO 2. LITERATURE REVIEW: Use web search tools to research the landscape — search key terms from
<hypothesis> and <all_artifacts>. Then use aii_semscholar_bib__fetch to batch-fetch real
BibTeX entries. Build a comprehensive Related Work section. Do NOT fabricate entries.
TODO 3. READ ARTIFACTS: Before writing each section, READ the relevant artifact source code, output
files, and data in the workspace. Extract concrete implementation details, technical innovations,
algorithmic specifics, and quantitative results. Do NOT write surface-level descriptions.

ARTIFACT REFERENCES: When you reference results, methodology, or findings from a specific artifact,
place an [ARTIFACT:artifact_id] marker inline. These become footnotes linking to the artifact's code
in the GitHub repository (first mention gets a footnote with URL, subsequent mentions are omitted).
Use the exact artifact ID from <all_artifacts>. Place the marker right after the claim it supports.
Example:
  "Our evaluation showed a 15% improvement over baselines [ARTIFACT:art_4f9d2c81ab37]." 
TODO 4. WRITE PAPER: Write the full paper text with [FIGURE:fig_id] markers per <figure_instructions>,
and provide the figure specs in the figures array. Cite with numeric references [1], [2], etc.
At the end of the paper text, include a full bibliography section. Do NOT compile LaTeX or generate
actual image/figure files. Your ONLY output is the structured JSON.
</todos><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_LOb33NvVGQcB/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_LOb33NvVGQcB/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "FigureSpec": {
      "description": "Figure specification \u2014 structured output from paper writing agent.\n\nThe LLM fills these as a list in PaperText.figures.\nLater converted to Figure objects for viz gen.",
      "properties": {
        "id": {
          "description": "Figure ID matching the [FIGURE:id] marker in paper_text (e.g., 'fig1')",
          "title": "Id",
          "type": "string"
        },
        "title": {
          "description": "Figure title in plain, everyday language \u2014 short and jargon-free. Aim for about 4-8 words (~40 characters).",
          "title": "Title",
          "type": "string"
        },
        "caption": {
          "description": "LaTeX figure caption \u2014 appears below the figure in the paper. Should describe what the figure shows and highlight key takeaways.",
          "title": "Caption",
          "type": "string"
        },
        "image_gen_detailed_description": {
          "description": "Detailed image generation prompt \u2014 axes, labels, ALL numeric values, colors, aspect ratio, layout. The image generator cannot read files; this is its ONLY input.",
          "title": "Image Gen Detailed Description",
          "type": "string"
        },
        "summary": {
          "description": "Brief summary of what this figure communicates",
          "title": "Summary",
          "type": "string"
        }
      },
      "required": [
        "id",
        "title",
        "caption",
        "image_gen_detailed_description",
        "summary"
      ],
      "title": "FigureSpec",
      "type": "object"
    }
  },
  "description": "Paper text \u2014 structured output from paper writing agent.\n\nStructured output fields (LLMPrompt + LLMStructOut):\n- title, abstract, paper_text, figures, summary\n\npaper_text contains [FIGURE:fig_id] markers for positioning.\nfigures contains the full specs as structured objects.\n\nMetadata fields (plain, set by pipeline code):\n- id",
  "properties": {
    "title": {
      "description": "Paper title \u2014 clear, plain-language, and short so a non-expert understands the main contribution at a glance. Aim for about 6-10 words; avoid jargon and acronyms.",
      "title": "Title",
      "type": "string"
    },
    "abstract": {
      "description": "Paper abstract",
      "title": "Abstract",
      "type": "string"
    },
    "paper_text": {
      "description": "Full paper body text with markdown section headers (# Introduction, # Methods, # Results, # Discussion, # Conclusion). Use [FIGURE:fig_id] markers (e.g. [FIGURE:fig1]) to indicate where each figure should appear.",
      "title": "Paper Text",
      "type": "string"
    },
    "figures": {
      "description": "List of figure specifications. Each must have an id matching a [FIGURE:id] marker in paper_text.",
      "items": {
        "$ref": "#/$defs/FigureSpec"
      },
      "title": "Figures",
      "type": "array"
    },
    "summary": {
      "description": "Brief summary of the paper's main contribution and findings",
      "title": "Summary",
      "type": "string"
    }
  },
  "required": [
    "title",
    "abstract",
    "paper_text",
    "summary"
  ],
  "title": "PaperText",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_LOb33NvVGQcB/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-09 00:19:18 UTC

```
Propose a simple, novel machine-learning method for scoring text readability and validate it.
```

### [3] SYSTEM-USER prompt · 2026-07-09 00:20:11 UTC

```
<validation-feedback>
Attempt 1 failed validation.

You have not created the output file `.sdk_openhands_agent_struct_out.json` yet. Use the Write tool to create it.

Please use the Write tool to overwrite `.sdk_openhands_agent_struct_out.json` with corrected JSON. Do not invent new fields; match the schema you were given.
</validation-feedback>
```

### [4] SKILL-INPUT — aii-paper-writing · 2026-07-09 00:20:15 UTC

The agent loaded the **aii-paper-writing** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-paper-writing
description: Academic paper writing guidance for AI research. Covers paper structure, figure placeholders, bibliography building with Semantic Scholar, and citation rules. Does NOT cover LaTeX compilation or figure file generation — see aii-paper-to-latex for that.
---

## Technical Papers

Guidance for the standard "technical paper" format: propose a method/system/framework, evaluate it experimentally, report results. This is the main track at most CS venues (NeurIPS, ICML, ICLR, ACL, AAAI, etc.). Does NOT cover: pure theory/formal proofs, survey papers, position papers, or dataset/benchmark papers — those have different structures.

### Paper Structure

Target 6-8 pages. Use formal academic language, third person. Support claims with evidence from artifacts.

#### Rough Page Budget (8-page paper)

| Section | Pages | Notes |
|---|---|---|
| Abstract | 0.3 | Problem, approach, key result |
| Introduction | 1.0-1.5 | The most important section |
| Related Work | 0.5-1.0 | Beginning or end (see below) |
| Methods | 1.5-2.0 | Architecture fig on page 1 |
| Experiments | 1.5-2.0 | Setup + results + ablations |
| Discussion | 0.5-1.0 | Limitations go here |
| Conclusion | 0.3-0.5 | Do not repeat the abstract |
| References | 0.5-1.0 | Not counted in page limit |

**Critical rule**: A clear new technical contribution must be articulated by page 3 (quarter of the paper). If the reader doesn't know what you did by then, you've lost them.

#### Section Details

**Abstract** (150-250 words): State the problem, your approach, and the main results. Be factual and comprehensive. Do not repeat the abstract word-for-word later in the paper.

**Introduction** — Follow this 5-paragraph structure:

1. **What is the problem?** Define the task concretely.
2. **Why is it interesting and important?** Real-world impact, scale.
3. **Why is it hard?** Why do naive approaches fail?
4. **Why hasn't it been solved before?** What's wrong with prior solutions? How does yours differ?
5. **What are the key components of your approach and results?** Include specific limitations.

End with a "Summary of Contributions" subsection — bullet list of contributions with section references. This doubles as an outline, saving space.

**Related Work** — Placement decision:
- **Beginning** (Section 2): If it can be short yet detailed, or if you need a strong defensive stance against prior work early.
- **End** (before Conclusions): If comparisons require your technical content, or if it can be summarized briefly in the Introduction. Can be titled "Discussion and Related Work."

**Methods/Approach**: Every section tells a story — the story of the results, NOT the story of how you arrived at them. Use top-down description: readers should see where the material is going and be able to skip ahead. Move gory details to appendices.

**Experiments**: Setup (datasets, metrics, baselines) → main results → ablations → analysis. Every claim needs quantitative evidence.

**Discussion**: Interpret results, compare to prior work, state limitations honestly. Limitations should be specific and actionable, not vague disclaimers.

**Conclusion**: Short summarizing paragraph. Do NOT repeat material from the Abstract or Introduction. Make original claims more concrete (e.g., reference quantitative results). Include future work as bullet list — if actively pursuing follow-up, say so to mark territory.

#### Writing Quality Rules

- Define all notation/terminology before use, only once. Group global definitions in Preliminaries.
- Do NOT use nonreferential "this", "that", "these", "it". Always specify the referent. BAD: "This is important because..." GOOD: "This accuracy gap is important because..."
- Do NOT use "etc." unless remaining items are completely obvious. BAD: "We measure volatility, scalability, etc." GOOD: "We measure volatility and scalability."
- Do NOT write "for various reasons" — state the actual reasons.
- "That" is defining, "which" is nondefining. "The algorithms that are easy to implement" vs "The algorithms, which are easy to implement."
- Use italics for definitions and quotes, not for emphasis. Context alone should provide emphasis.

### Figure Format

Figures use a hybrid marker + structured array approach. ALL figures are generated by a separate pipeline step using an AI image model — your `image_gen_detailed_description` is the ONLY input that model sees. It cannot read files or access data. Do NOT generate actual image files yourself (no matplotlib, no PIL, no image generation scripts).

**In paper_text**: Place `[FIGURE:fig_id]` markers where figures should appear.

**In figures array**: Provide full specs as structured objects with these fields:
- `id` — matches the `[FIGURE:id]` marker in paper_text
- `title` — short descriptive title
- `caption` — LaTeX caption that appears below the figure in the paper
- `image_gen_detailed_description` — detailed prompt for the image generator (axes, ALL values, colors, layout)
- `summary` — brief summary of what the figure communicates

Example in paper_text:
```
...our method achieves state-of-the-art results as shown below.

[FIGURE:fig_1]

The results in Figure 1 demonstrate...
```

Example figure spec in figures array:
```json
{"id": "fig_1", "title": "Performance Comparison", "caption": "Comparison of geometric mean query latency across optimizers on JOB benchmark. RLQOpt achieves 2.3x speedup over PostgreSQL.", "image_gen_detailed_description": "Grouped bar chart. X-axis: model names. Y-axis: accuracy (0.0-1.0). Values: ModelA=0.847, ModelB=0.762, Baseline=0.531. Error bars with std: 0.02, 0.03, 0.05. Sans-serif font, white background.", "summary": "Compares accuracy of proposed methods vs baseline."}
```

Every marker in text MUST have a matching figure in the array, and vice versa.

#### Data Precision Requirement

`image_gen_detailed_description` MUST include exact numbers from artifact output files. Read the actual output files before writing figure specs.

- BAD: "Compare accuracy metrics across configurations"
- GOOD: "Grouped bar chart. X-axis: model names. Y-axis: accuracy (0.0-1.0). Values: K=3: 0.765, K=5: 0.729, Baseline: 0.121."

#### Figure vs Table Decision

Do NOT create figures for tabular data (rows/columns of text or numbers). Use `\begin{table}` in LaTeX instead. Figures are for actual visualizations only (charts, plots, diagrams).

#### Figure Placement Strategy

Be intentional with figure ordering. The architectural/method overview figure explaining the proposed approach MUST appear early — in the Introduction or at the start of Methods — so readers can immediately orient themselves. Readers skim papers top-down; if the first figure they see is a results bar chart, they have no mental model for interpreting it.

Recommended ordering:
1. **Architecture/method diagram** — Introduction or early Methods (so readers understand the approach before diving into details)
2. **Conceptual/analogy figures** — Introduction or Methods (to build intuition)
3. **Results figures** (bar charts, line plots, scatter plots) — Results section
4. **Analysis/ablation figures** — Discussion or later Results

#### Guidelines

- Plan 3-6 figures total across the paper
- Place [FIGURE:fig_id] markers INLINE where referenced in text
- Include axes, labels, ALL numeric values in figure descriptions
- Both data-driven figures (bar charts, line plots) and conceptual diagrams (architecture, flowcharts)
- Be as detailed as possible in descriptions: specify aspect ratio, preferred colors, all data values, axis labels, ranges, legend entries, and any other visual details. The more specific the description, the better the generated figure

### Bibliography with Semantic Scholar

Build `./references.bib` using the aii-semscholar-bib skill (real BibTeX from Semantic Scholar):

1. Collect DOIs, ArXiv IDs, or titles for all papers you need to cite
2. Call `aii_semscholar_bib__fetch` with the full list in one batch
3. Write the returned .bib text into `./references.bib`

Rules:
- Do NOT fabricate BibTeX entries — always fetch from Semantic Scholar
- If a paper isn't found (very recent preprint), write the entry manually as fallback
- Use `\bibliography{references}` and `\bibliographystyle{plainnat}`
- Do NOT use inline `thebibliography` environment

### Citation Format (for Research Artifacts)

When writing research with numbered citations:

1. Every factual claim MUST have a numbered citation: `[1]`, `[2]`, `[1, 3]`, etc.
2. Each source in the "sources" array MUST have an "index" field
3. The index MUST EXACTLY MATCH citation numbers in the text
4. NEVER cite a number without a matching source index
5. Example: "LLMs show 40% improvement with multi-agent collaboration [1]."
````

### [5] SKILL-INPUT — aii-semscholar-bib · 2026-07-09 00:20:17 UTC

The agent loaded the **aii-semscholar-bib** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-semscholar-bib
description: Build bibliographies using Semantic Scholar. Batch-fetch BibTeX for papers by DOI, ArXiv ID, or title. Use when writing papers, generating reference lists, or building .bib files.
---

## Tool: `aii_semscholar_bib__fetch`

Batch-fetch BibTeX entries from Semantic Scholar. Pass all references in a single call — the tool handles batching internally.

### How it works

1. **DOI/ArXiv refs** → batched into POST /paper/batch calls (up to 500 per API call, auto-chunked)
2. **Title-only refs** → individual GET /paper/search/match (1s delay between)
3. **Post-process** → fix entry type, fix citation key (AuthorYYYY), inject DOI

The ability server runs a single worker (`max_threads: 1`). Multiple concurrent tool calls are queued — each runs independently (no cross-request aggregation). Batching happens within each request.

### Input format

```json
{
  "references": [
    {"doi": "10.48550/arXiv.1706.03762", "author": "Vaswani", "year": 2017},
    {"arxiv": "2201.11903", "author": "Wei", "year": 2022},
    {"title": "Tree of Thoughts", "author": "Yao", "year": 2023}
  ]
}
```

Each reference object can have:
- `doi` — DOI string (ArXiv DOIs like `10.48550/arXiv.XXXX.XXXXX` auto-convert to ArXiv IDs)
- `arxiv` — ArXiv ID (e.g. `"2305.14325"`)
- `title` — Paper title (used for search/match when no DOI/ArXiv)
- `author` — First author last name (for cleaner citation key)
- `year` — Publication year (int, for citation key)

At least one of `doi`, `arxiv`, or `title` is required per reference.

### Output format

```json
{
  "success": true,
  "bib_text": "@inproceedings{Vaswani2017, ...}\n\n@article{Wei2022, ...}",
  "total": 3,
  "found": 3,
  "failed_count": 0,
  "entries": [{"citation_key": "Vaswani2017", "bibtex": "...", "title": "...", "doi": "...", "arxiv": ""}],
  "failed": []
}
```

### Workflow

1. Collect DOIs, ArXiv IDs, or titles for all papers you need to cite
2. Call `aii_semscholar_bib__fetch` with the full list in **one call**
3. Save `bib_text` from the response to your `references.bib` file
4. Check `failed` — for any missed papers, follow the **fallback procedure** below

### Fallback for failed references (MANDATORY)

NEVER fabricate BibTeX. For each failed reference:
1. **WebSearch** for `"Title" author year` (try `site:arxiv.org` too)
2. **WebFetch** the paper page → extract title, authors, year, venue, DOI/ArXiv ID
3. If DOI/ArXiv found → retry `aii_semscholar_bib__fetch` with it
4. Last resort: write BibTeX by hand using **only verified info from the actual paper page**

---

### CLI (for manual use / debugging)

```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-semscholar-bib" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_semscholar_bib__fetch.py --refs '[
  {"doi": "10.48550/arXiv.1706.03762", "author": "Vaswani", "year": 2017},
  {"arxiv": "2201.11903", "author": "Wei", "year": 2022},
  {"title": "Tree of Thoughts", "author": "Yao", "year": 2023}
]'
```

`--json, -j` — output raw JSON instead of .bib text

**If the script fails** with a connection error (ability server not running): create a local `.venv`, install server deps from `server_requirements.txt` into it, then import the `@aii_ability` function from the script and call it directly — bypassing the server:
```bash
uv venv .venv --python=3.12 && uv pip install --python=.venv/bin/python -r "$SKILL_DIR/scripts/server_requirements.txt"
```
````

### [6] SKILL-INPUT — aii-web-tools · 2026-07-09 00:23:42 UTC

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
