# gen_paper_text — test_idea

> Phase: `invention_loop` · round 1 · `gen_paper_text`
> Run: `iter1_924aa01cf43b` — Knowledge Redundancy as a Predictor of Open-Source Project Survival: A Methodological Validation Study
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_text` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-08-21 15:55:21 UTC

````
<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for related-work positioning and how this field frames a genuinely novel contribution.

- **aii-handbook-auto-computational-linguistics** — Verified field handbook for computational linguistics as a SCIENCE of language (not NLP engineering).
- **aii-handbook-auto-mechanistic-interpretability** — Verified field handbook for mechanistic-interpretability research.
- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
- **aii-handbook-auto-neurosymbolic** — Verified field handbook for neuro-symbolic AI research (LLM+solver, autoformalization, text2logic).
</available_domain_handbooks>
<hypothesis>
The research hypothesis.

kind: hypothesis
title: Knowledge redundancy predicts OSS survival after founder leaves
hypothesis: >-
  The relationship between knowledge redundancy (overlap in contributor expertise) and open-source project survival after
  founder departure is inverted-U shaped: projects with moderate knowledge redundancy survive at higher rates than both those
  with zero redundancy (all critical knowledge held by founder) and those with excessive redundancy (all contributors know
  the same things, with no specialization).
motivation: >-
  Open-source projects frequently depend on a small number of core developers, and founder departure is a major threat to
  project continuity. While 'bus factor' (the minimal number of developers whose departure would stall a project) is well-studied,
  it fails to capture an important dimension: the DEGREE OF OVERLAP in what contributors know. Two projects could both have
  bus factor = 2, but in one the two contributors know completely different things (low redundancy) while in the other they
  know largely the same things (high redundancy). This hypothesis identifies knowledge redundancy as a distinct, measurable
  predictor of post-founder survival, with a non-monotonic relationship that reveals an optimal level of redundancy for project
  resilience.
assumptions:
- >-
  Knowledge redundancy can be measured from observable contribution patterns (code commits, file modifications, issue discussions)
  as the degree of overlap in contributor expertise areas
- >-
  Founder departure can be identified as the point where the original creator/main contributor stops making commits for an
  extended period (12+ months)
- >-
  Project survival can be measured as continued development activity (commits, releases, issue resolutions) after founder
  departure, beyond what would be expected from pre-departure trends
- >-
  The effect of knowledge redundancy is separable from bus factor, project size, popularity, and other known predictors, allowing
  for controlled analysis
investigation_approach: >-
  1. DATA COLLECTION: Mine GitHub API to identify ~2000 popular open-source projects (100+ stars, 2+ years active), extract
  commit histories, file modification records, and contributor metadata. 2. FOUNDER DEPARTURE IDENTIFICATION: Define founder
  as the contributor with highest initial authorship; mark departure as 12+ months without commits after a period of activity.
  3. KNOWLEDGE REDUNDANCY MEASUREMENT: Compute redundancy as the average pairwise overlap in file modification patterns among
  top contributors (using Jaccard similarity of file sets modified by each contributor). 4. SURVIVAL MEASUREMENT: Define survival
  as continued development activity (commits, releases) for 12+ months after founder departure at levels statistically indistinguishable
  from pre-departure trends. 5. ANALYSIS: Fit survival models (Cox proportional hazards) with knowledge redundancy as key
  predictor, including quadratic term to test inverted-U prediction, controlling for bus factor, project size, age, popularity,
  programming language, and contributor count.
success_criteria: >-
  The hypothesis is confirmed if: (1) The quadratic term for knowledge redundancy in survival models is statistically significant
  (p < 0.05) and negative, indicating an inverted-U relationship; (2) Projects with moderate redundancy (25th-75th percentile)
  show 20%+ higher survival rates than projects with very low redundancy (bottom 10th percentile); (3) Projects with very
  high redundancy (top 10th percentile) show 10%+ LOWER survival rates than those with moderate redundancy, confirming the
  non-monotonic prediction. The hypothesis is disconfirmed if knowledge redundancy shows only a linear relationship with survival
  or no significant relationship after controlling for bus factor.
related_works:
- >-
  Avelino et al. (2019) 'On the abandonment and survival of open source projects: An empirical investigation' - This paper
  studies bus/truck factor and finds that 41% of projects survive founder departure through new core developers. However,
  it measures only the NUMBER of critical contributors (bus factor), not the OVERLAP in their knowledge. My hypothesis introduces
  knowledge redundancy as a distinct construct that predicts survival beyond bus factor alone.
- >-
  Cosentino et al. (2016) 'Assessing the bus factor from repository data' - Proposes algorithms to compute bus factor from
  git repositories. My work differs by focusing on knowledge REDUNDANCY (overlap) rather than just the MINIMAL set of critical
  contributors, and by predicting survival outcomes rather than just measuring risk.
- >-
  Write access provisioning and organizational ownership in open source software projects (2025) - This recent paper explores
  how write access affects project novelty and survival. My hypothesis differs by focusing on the STRUCTURE of knowledge distribution
  (redundancy) rather than governance mechanisms (who has commit access), though these may interact.
- >-
  The State of Survival in OSS: The Impact of Diversity (ESEC/FSE 2023) - Studies demographic and motivational diversity among
  contributors. My hypothesis focuses on KNOWLEDGE diversity/redundancy (what contributors know) rather than demographic diversity
  (who they are), and predicts a non-monotonic rather than linear relationship.
inspiration: >-
  This hypothesis draws from three cross-disciplinary inspirations: (1) FROM INFORMATION THEORY: Error-correcting codes use
  controlled redundancy to enable recovery from data loss - too little redundancy fails to correct errors, too much wastes
  bandwidth. This inspired the inverted-U hypothesis for knowledge redundancy in projects. (2) FROM ORGANIZATIONAL PSYCHOLOGY:
  Research on team redundancy shows that some overlap in expertise enables backup behavior during member absence, but excessive
  overlap reduces specialization benefits. (3) FROM ECOLOGY: The diversity-stability hypothesis suggests ecosystems with moderate
  redundancy in species roles are most resilient to disturbance - neither completely specialized (vulnerable to keystone species
  loss) nor completely redundant (wastes resources).
terms:
- term: Knowledge redundancy
  definition: >-
    The degree of overlap in expertise areas among project contributors, measured as the average pairwise similarity in the
    sets of files, modules, or code areas that contributors modify. High redundancy means contributors work on the same things;
    low redundancy means each contributor has unique areas of expertise.
- term: Founder departure
  definition: >-
    The event where a project's original creator or primary contributor (identified by highest initial code authorship) stops
    making commits for an extended period (12+ months), marking their effective exit from active development.
- term: Bus factor
  definition: >-
    The minimal number of contributors whose simultaneous departure would render a project unable to continue development.
    A bus factor of 1 means a single person holds all critical knowledge; higher values indicate more distributed knowledge.
- term: Project survival
  definition: >-
    The continuation of active development (commits, releases, issue resolutions) after a disruption event (founder departure)
    at levels statistically consistent with pre-disruption activity patterns, sustained for a minimum period (12+ months).
- term: Inverted-U relationship
  definition: >-
    A non-monotonic relationship where the dependent variable (survival) first increases then decreases as the independent
    variable (knowledge redundancy) increases, forming an upside-down U shape. This indicates an optimal intermediate level
    rather than a linear benefit.
summary: >-
  This hypothesis predicts that open-source projects survive founder departure best when knowledge is moderately redundant
  among contributors - not completely concentrated in the founder (zero redundancy) nor completely overlapping across all
  contributors (excessive redundancy). This inverted-U relationship is distinct from bus factor and reveals an optimal structure
  for post-founder resilience.
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 3 research artifacts across all iterations.

--- Item 1 ---
id: art_hCV89wVDpKcQ
type: research
title: 'OSS Survival Literature Review: Knowledge Redundancy and Bus Factor'
summary: >-
  Comprehensive literature review examining OSS project survival prediction, bus factor measurement, knowledge redundancy
  constructs, and methodological approaches. Synthesized findings from 25+ key papers spanning software engineering, organizational
  psychology, and survival analysis. Key findings: (1) 16% of popular OSS projects experience abandonment, 41% survive through
  new maintainer adoption; (2) Bus factor measurement validated with 77-100% precision across multiple algorithms; (3) Knowledge
  redundancy is a novel construct not directly measured in OSS literature; (4) Cox proportional hazards models standard for
  survival analysis; (5) Inverted-U hypothesis theoretically grounded in organizational psychology literature but untested
  in OSS context. Identified 5+ methodological gaps and 3+ alternative theoretical frameworks (community smells, death spiral,
  social capital). Provides methodological recommendations for measuring knowledge redundancy using Jaccard similarity on
  developer file ownership vectors, survival definitions, control variables, and statistical analysis plans.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 2 ---
id: art_5yxZHBH-Wwc_
type: dataset
title: GitHub OSS founder departure survival dataset
summary: >-
  GitHub OSS survival dataset with 1000 repositories containing: (1) Knowledge redundancy scores computed via Jaccard similarity
  of file modification patterns among top contributors, (2) Founder departure events identified by 12+ months of inactivity,
  (3) Pre/post-departure activity metrics, (4) Repository metadata including stars, language, and creation date. The dataset
  enables analysis of whether knowledge redundancy predicts project survival after founder departure. Output classes: survived
  (601 repos), died (167 repos), no_departure (232 repos). All plan criteria met: 1000 repos, 768 with departures, 601 survivals,
  file size 0.61MB under 300MB limit, valid redundancy scores in [0,1] range, schema validation passed. Exhaustive search
  completed: 15+ HuggingFace queries, 13+ web searches, 4+ candidate datasets evaluated, real API collection attempted. No
  pre-collected dataset matches all requirements. Synthetic dataset is methodology-valid and suitable for research.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 3 ---
id: art_FDgSH3zFKh6_
type: research
title: >-
  Knowledge redundancy measurement and survival analysis validation for OSS projects
summary: >-
  Comprehensive validation of technical approach for measuring knowledge redundancy from git commit data using Jaccard similarity
  and testing inverted-U hypothesis about OSS project survival after founder departure using Cox proportional hazards models.
  Research covers all six phases of investigation: (1) Knowledge redundancy measurement validation with Jaccard similarity,
  cosine similarity, Shannon entropy, and Herfindahl-Hirschman Index as alternative measures, including weighted variants
  and implementation code examples; (2) Cox proportional hazards model specification with quadratic term interpretation for
  inverted-U hypothesis testing, including hazard ratio calculations and turning point formulas; (3) Bus factor algorithm
  comparison between Avelino et al. and Cosentino et al. approaches with detailed implementation steps, parameter specifications,
  and validation results from precision/recall comparison studies; (4) Survival time definition and censoring approaches based
  on empirical evidence from 1,932 GitHub projects, including founder departure identification algorithms and 1-year inactivity
  threshold validation; (5) GitHub API data collection feasibility assessment including rate limits of 5,000 requests per
  hour for authenticated users, time estimates for 2,000 projects, GraphQL optimization strategies, and GHTorrent status evaluation;
  (6) Statistical power requirements and sample size calculations using the 10 events per variable rule of thumb, confirming
  that 2,000 projects provides sufficient power exceeding 80% for detecting moderate effect sizes. Key validated findings
  include 41% survival rate after founder departure from Aveline et al. (2019), Jaccard similarity appropriateness for knowledge
  redundancy measurement with weighting recommendations, Cox model quadratic term interpretation guidelines showing negative
  coefficient indicates inverted-U relationship, GitHub API constraints and optimization strategies, and Avelino et al. bus
  factor algorithm recommendation based on empirical comparison studies. The research provides actionable validation for downstream
  artifact execution with validated formulas, algorithm specifications, API constraints, statistical power calculations, and
  diagnostic check procedures.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/3_invention_loop/iter_1/gen_art/gen_art_research_2
out_expected_files:
- research_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 3 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

title: 'OSS Survival Literature Review: Knowledge Redundancy and Bus Factor'
type: research
id: art_hCV89wVDpKcQ
summary: >-
  Comprehensive literature review examining OSS project survival prediction, bus factor measurement, knowledge redundancy
  constructs, and methodological approaches. Synthesized findings from 25+ key papers spanning software engineering, organizational
  psychology, and survival analysis. Key findings: (1) 16% of popular OSS projects experience abandonment, 41% survive through
  new maintainer adoption; (2) Bus factor measurement validated with 77-100% precision across multiple algorithms; (3) Knowledge
  redundancy is a novel construct not directly measured in OSS literature; (4) Cox proportional hazards models standard for
  survival analysis; (5) Inverted-U hypothesis theoretically grounded in organizational psychology literature but untested
  in OSS context. Identified 5+ methodological gaps and 3+ alternative theoretical frameworks (community smells, death spiral,
  social capital). Provides methodological recommendations for measuring knowledge redundancy using Jaccard similarity on
  developer file ownership vectors, survival definitions, control variables, and statistical analysis plans.

title: GitHub OSS founder departure survival dataset
type: dataset
id: art_5yxZHBH-Wwc_
summary: >-
  GitHub OSS survival dataset with 1000 repositories containing: (1) Knowledge redundancy scores computed via Jaccard similarity
  of file modification patterns among top contributors, (2) Founder departure events identified by 12+ months of inactivity,
  (3) Pre/post-departure activity metrics, (4) Repository metadata including stars, language, and creation date. The dataset
  enables analysis of whether knowledge redundancy predicts project survival after founder departure. Output classes: survived
  (601 repos), died (167 repos), no_departure (232 repos). All plan criteria met: 1000 repos, 768 with departures, 601 survivals,
  file size 0.61MB under 300MB limit, valid redundancy scores in [0,1] range, schema validation passed. Exhaustive search
  completed: 15+ HuggingFace queries, 13+ web searches, 4+ candidate datasets evaluated, real API collection attempted. No
  pre-collected dataset matches all requirements. Synthetic dataset is methodology-valid and suitable for research.

title: >-
  Knowledge redundancy measurement and survival analysis validation for OSS projects
type: research
id: art_FDgSH3zFKh6_
summary: >-
  Comprehensive validation of technical approach for measuring knowledge redundancy from git commit data using Jaccard similarity
  and testing inverted-U hypothesis about OSS project survival after founder departure using Cox proportional hazards models.
  Research covers all six phases of investigation: (1) Knowledge redundancy measurement validation with Jaccard similarity,
  cosine similarity, Shannon entropy, and Herfindahl-Hirschman Index as alternative measures, including weighted variants
  and implementation code examples; (2) Cox proportional hazards model specification with quadratic term interpretation for
  inverted-U hypothesis testing, including hazard ratio calculations and turning point formulas; (3) Bus factor algorithm
  comparison between Avelino et al. and Cosentino et al. approaches with detailed implementation steps, parameter specifications,
  and validation results from precision/recall comparison studies; (4) Survival time definition and censoring approaches based
  on empirical evidence from 1,932 GitHub projects, including founder departure identification algorithms and 1-year inactivity
  threshold validation; (5) GitHub API data collection feasibility assessment including rate limits of 5,000 requests per
  hour for authenticated users, time estimates for 2,000 projects, GraphQL optimization strategies, and GHTorrent status evaluation;
  (6) Statistical power requirements and sample size calculations using the 10 events per variable rule of thumb, confirming
  that 2,000 projects provides sufficient power exceeding 80% for detecting moderate effect sizes. Key validated findings
  include 41% survival rate after founder departure from Aveline et al. (2019), Jaccard similarity appropriateness for knowledge
  redundancy measurement with weighting recommendations, Cox model quadratic term interpretation guidelines showing negative
  coefficient indicates inverted-U relationship, GitHub API constraints and optimization strategies, and Avelino et al. bus
  factor algorithm recommendation based on empirical comparison studies. The research provides actionable validation for downstream
  artifact execution with validated formulas, algorithm specifications, API constraints, statistical power calculations, and
  diagnostic check procedures.
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

FIGURE TYPE — set `figure_type` on every figure. One test decides it: does the figure plot numbers?
  "data"    — a DATA FIGURE: bars, curves, scatter, heatmaps, confusion matrices, scaling
              laws, distributions, Pareto fronts, ablation deltas. Rendered deterministically
              from the values you supply, so every bar is exactly the height of its number.
  "concept" — a CONCEPT FIGURE: conceptual artwork, architecture and flow diagrams, anything
              with no underlying dataset. Drawn by an image model.
If the figure has real numbers behind it, ALWAYS use "data". An image model only approximates
values: the bars come back close to, but not equal to, the numbers you asked for, and nothing
downstream detects it.

Example in paper_text:
  "...our method achieves state-of-the-art results as shown below.\n\n[FIGURE:fig3]\n\nThe results demonstrate..."

Example in figures array (results comparison — plots numbers, so a data figure):
  {"id": "fig3", "title": "Performance Comparison", "figure_type": "data", "caption": "Comparison of geometric mean query latency across optimizers.", "image_gen_detailed_description": "Grouped bar chart. Categories: PostgreSQL, Bao, RLQOpt. One series 'Latency'. Values: 4.6, 2.8, 2.0 seconds. Errors: 0.8, 0.5, 0.3. X-axis label 'Optimizer'. Y-axis label 'Latency (s)', range 0-5.", "aspect_ratio": "16:9", "summary": "Compares latency across optimizers"}

Example in figures array (architecture diagram, hero — no dataset, so a concept figure):
  {"id": "fig1", "title": "System Architecture", "figure_type": "concept", "caption": "End-to-end pipeline: encoder feeds latents into the planner, which queries the value head before emitting actions.", "image_gen_detailed_description": "Horizontal flow diagram, left to right. Five labeled boxes: 'Input' (gray), 'Encoder' (blue), 'Latent (z, 256-dim)' (light blue, narrow), 'Planner' (green), 'Action Head' (orange). Arrows labeled with shapes. Value head as separate green box below 'Planner', bidirectional arrow. Sans-serif font, clean white background, no 3D.", "aspect_ratio": "21:9", "summary": "Hero architecture diagram"}

CRITICAL: Before writing figure specs, look through artifact workspace output files (*_out.json)
and code to find ALL the exact values. The figure generator cannot read files — every exact number
and value MUST be in the image_gen_detailed_description. For a "data" figure, list the values per series
plus the axis labels and units; the renderer needs the numbers themselves, not a description of
what they look like.
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
actual image/figure files. Do NOT emit your structured output when the draft is done — TODO 5 is a
separate revision pass that runs over the finished draft first.
TODO 5. REVISION PASS — start this ONLY once TODO 4's draft is complete, and treat it as a distinct
pass over the finished text rather than something folded into the writing. Read
`REVISION_CHECKLIST.md` in the aii-paper-writing skill's own directory and apply every item to the
full draft.

Writing and revising are different jobs and cannot be done at the same time. The defects that
checklist targets — prose denser than the field needs, an abstract dumped full of numbers, sections
that leak into one another, a Figure 1 that shows a side result instead of the main idea, close
prior work that only the draft's FINAL vocabulary would have surfaced, a study of N things that
plots eight of them, section names that mean nothing to someone who has not read the section,
implementation filenames cited in the prose, numbers that disagree between the abstract, the text
and the tables — are all invisible while drafting, because you are holding your intent rather than
the text. Every one is obvious to the first outside reader.

Work the items one at a time against the ACTUAL text, not from memory of what you meant to write.
For each item, either fix the draft or state in one line why it already holds. The checklist's
consistency section is several SEPARATE sweeps of the whole paper, one concern per sweep — run them
that way, and repeat any sweep that produced an edit, since a fix in one place routinely breaks
agreement somewhere else. Expect this pass to change the draft; one that produces no edits was not
really run.

Only when the checklist is fully worked through, emit the structured JSON — that is your ONLY
output. Do NOT compile LaTeX or generate image/figure files at any point.
</todos><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`

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
        "figure_type": {
          "description": "Which generator draws this figure. Decide by ONE test: does the figure plot numbers? 'data' \u2014 a DATA FIGURE: bars, curves, scatter, heatmaps, confusion matrices, scaling laws, distributions, Pareto fronts, ablation deltas. Rendered deterministically from the numbers, so every bar is exactly the height of its value. 'concept' \u2014 a CONCEPT FIGURE: conceptual artwork, architecture and flow diagrams, anything with no underlying dataset. When a figure has real numbers behind it, ALWAYS choose 'data': an image model only approximates values, producing bars that disagree with their own labels.",
          "enum": [
            "data",
            "concept"
          ],
          "title": "Figure Type",
          "type": "string"
        },
        "image_gen_detailed_description": {
          "description": "The generator's ONLY input \u2014 it cannot read files. For figure_type='data': every numeric value to plot, per series, with axis labels and units, category names, and what the figure has to make the reader see \u2014 the comparison, trend, trade-off or distribution that is the point. Name a chart type only if you actually want a specific one: the figure generator reads its own catalogue of chart types and picks the one that fits, so an enumeration here would only go stale as that catalogue grows. For figure_type='concept': the composition \u2014 what appears where, colours, labels, and what to leave out.",
          "title": "Image Gen Detailed Description",
          "type": "string"
        },
        "aspect_ratio": {
          "default": "21:9",
          "description": "Shape of the figure. '21:9' for architecture diagrams / pipelines / flow charts (the paper's hero diagram is usually one of these), '16:9' for side-by-side comparisons and multi-panel results, '4:3' for dense charts, '1:1' for heatmaps / confusion matrices / scatter plots, '3:4' or '9:16' for vertical layouts.",
          "enum": [
            "1:1",
            "4:3",
            "3:2",
            "16:9",
            "21:9",
            "3:4",
            "9:16"
          ],
          "title": "Aspect Ratio",
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
        "figure_type",
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

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_qtJqn5LVU5LN/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-08-21 15:55:21 UTC

```
What determines whether an open-source project survives its founder stepping away?
```

### [3] SKILL-INPUT — aii-paper-writing · 2026-08-21 15:55:27 UTC

The agent loaded the **aii-paper-writing** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-paper-writing
description: "Writes the PROSE of an AI research paper: abstract, introduction, related work, methods, experiments, discussion and conclusion, with a page budget, the 5-paragraph intro pattern, writing-quality rules, inline [FIGURE:fig_id] markers plus a structured figures array, and a MANDATORY REVISION_CHECKLIST.md pass over every finished draft. Use whenever a paper, abstract, section, or full write-up is being drafted or rewritten for a venue such as NeurIPS, ICML, ICLR or ACL. Triggers: write a paper, paper structure, abstract, introduction, related work, methods, experiments, contributions, figure caption and placement, revision pass, academic prose. NOT for: assembling or compiling .tex (use aii-paper-to-latex), rendering the figure image files (aii-data-fig-gen, aii-concept-fig-gen), fetching BibTeX (use aii-semscholar-bib), or critiquing a finished draft's logic (use amg-paper-verification)."
---

## MANDATORY: the final revision pass

**`REVISION_CHECKLIST.md`, in this skill's own directory, MUST be read and
applied to every finished draft, always, as a separate pass after the writing
is done.** It is not optional, not conditional on how the draft looks, and not
something to fold into the writing itself.

Writing and revising are different jobs and cannot be done in one pass. The
defects that checklist targets — dense prose, a number-dumped abstract, sections
that leak into each other, a Figure 1 that shows a side result, prior work the
final vocabulary would have found, results mentioned but never plotted,
inconsistencies between abstract and tables — are all invisible while drafting,
because the author is holding the intent rather than the text. Every one of them
is obvious to the first outside reader. Reading the checklist before writing
does not substitute: the pass has to run against a finished draft.

So the order is always: write the complete draft → read `REVISION_CHECKLIST.md`
→ work its items against the full text, fixing as you go → only then emit the
output.

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

### [4] SKILL-INPUT — aii-semscholar-bib · 2026-08-21 15:55:27 UTC

The agent loaded the **aii-semscholar-bib** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-semscholar-bib
description: "Fetches real BibTeX entries in one batch from Semantic Scholar by DOI, ArXiv ID or title via aii_semscholar_bib__fetch, normalises citation keys to AuthorYYYY, injects DOIs, and writes the result into references.bib, with a mandatory web-search fallback for anything not found. ALWAYS use whenever a bibliography, reference list or .bib file is being built or extended, and whenever a citation needs a verified entry instead of an invented one — never hand-write BibTeX first. Triggers: bibliography, references.bib, bibtex, citation key, DOI, arXiv id, Semantic Scholar, reference list, cite these papers, natbib entries. NOT for: writing the text around the citations (use aii-paper-writing), running bibtex and compiling (use aii-paper-to-latex), judging whether cited work supports the claims (use amg-paper-verification), or open-ended literature search and PDF mining (use aii-web-tools)."
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

### [5] SKILL-INPUT — aii-web-tools · 2026-08-21 15:55:33 UTC

The agent loaded the **aii-web-tools** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-web-tools
description: "Runs web search, page fetch as markdown, and regex grep over full HTML or PDF text via this skill's own scripts (aii_fast_web_search.py, aii_fast_web_fetch.py) — a free-first keyless search stack with Serper fallback that works even where built-in WebSearch and WebFetch are absent. Use when a query, page, or paper must be searched, read, or mined for an exact quote, number, table value, or methodology sentence, and whenever a lossy summary would lose the detail. Triggers: web search, scholarly search, OpenAlex, Crossref, Serper, fetch a URL as markdown, read a PDF, arXiv, regex grep a page, exact quote, table value, citation check. NOT for: planning a broad multi-source literature review or mass verification campaign — use aii-web-research-tools; NOT for a PDF file already on disk — extraction, form filling, merging and PDF creation are anthropic-pdf; NOT for driving a browser or testing a UI."
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
   implementations — free-first web search (keyless general/scholarly engines,
   Serper fallback), html2text + PyMuPDF for fetch, and regex grep over the full
   document text. They work without any built-in web tools.

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

### 1. Search the web (free-first: general or scholarly)

```bash
# general web (default): keyless engines (ddgs, marginalia); Serper only if they miss
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation LLM" --max-results 10
# scholarly mode: OpenAlex + Crossref (DOIs, citation counts)
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation" --mode scholarly
```

Returns ranked title / URL / snippet lines. `--mode general` (default) uses
keyless general engines; `--mode scholarly` uses academic APIs. Both fall back
to Serper (paid) only when the free engines miss. Use search first to scan the
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
