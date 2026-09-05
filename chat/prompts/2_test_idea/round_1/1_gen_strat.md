# gen_strat_1 — test_idea

> Phase: `invention_loop` · round 1 · `gen_strat`
> Run: `run_56IKXpJEZJ5b` — M-IRT: Reference-Free LLM Evaluation via Samejima Graded Response Models on Dynamically Generated Metamorphic Item Clusters
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_strat_1` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-09-05 10:11:16 UTC

````
<hypothesis>
Your strategy should advance this hypothesis.

kind: hypothesis
title: Checking AI Logic Without Ground Truth
hypothesis: >-
  Large language models can be evaluated and ranked on their latent reasoning ability without frozen test sets or ground-truth
  answer keys by measuring their logical consistency across dynamically generated metamorphic question clusters, and modeling
  these consistency profiles using polytomous Item Response Theory.
motivation: >-
  Static benchmarks are rapidly becoming contaminated as LLMs are trained on massive web crawls containing test questions
  and answer keys. Evaluating LLMs on static, frozen test sets creates a false impression of reasoning ability when models
  have actually just memorized the correct answers. A reference-free, dynamic evaluation framework that measures internal
  logical coherence across systematic perturbations removes the need for frozen benchmarks, remains immune to direct memorization,
  and offers a robust, psychometrically grounded estimate of genuine reasoning capabilities.
assumptions:
- >-
  A model's capability to reason is intrinsically linked to its ability to maintain logical consistency under semantic perturbations
  and structural transformations.
- >-
  The logical relations within a metamorphic cluster can be formally defined and verified without requiring a ground-truth
  answer key.
- >-
  A polytomous Item Response Theory model, such as the Graded Response Model, can successfully scale model ability and cluster
  properties even under relatively small model sample sizes by leveraging high item counts.
investigation_approach: >-
  We will design and implement Metamorphic Item Response Theory (M-IRT). First, we will build a dynamic generator that constructs
  Metamorphic Item Clusters (MICs) for logical reasoning and mathematical tasks. Each MIC contains a seed question, a semantic
  paraphrase, a negation, and a contrapositive. Second, we will evaluate a suite of public LLMs (e.g., GPT-4o-mini, Claude
  3.5 Sonnet, Llama 3, Qwen 2.5) on these clusters, recording their answers. Third, we will evaluate pairwise logical consistency
  among answers in each cluster to compute an ordinal coherence score (e.g., 0, 1, 2) for each model-item pair. Fourth, we
  will fit a Graded Response Model (GRM) to these coherence scores using Expectation-Maximization to estimate each model's
  latent ability (\theta), alongside cluster difficulty (\beta) and discrimination (\alpha). Finally, we will validate M-IRT
  by correlating \theta with static benchmark scores (MMLU, GSM8K) and demonstrating its contamination resistance by intentionally
  injecting memorized answers into a model's simulated response profile and showing that its M-IRT score drops while its static
  correctness score rises.
success_criteria: >-
  The hypothesis is confirmed if: (1) the latent ability (\theta) estimated by the reference-free M-IRT framework achieves
  a high Pearson correlation (r > 0.85) with clean, non-contaminated static benchmarks; (2) under simulated benchmark contamination
  (memorizing the answer key to specific questions while failing on metamorphic variants), the target model's static score
  increases while its M-IRT latent capability (\theta) remains stable or decreases due to broken consistency; and (3) the
  estimated item parameters (\alpha, \beta) exhibit stable convergence and intuitive difficulty orderings (e.g., complex multi-step
  logical contrapositives are scaled as higher difficulty than simple paraphrases).
related_works:
- >-
  ATLAS (Adaptive Testing for LLM Ability Scoring) (Adaptive Testing for LLM Evaluation, arXiv:2511.04689) uses computerized
  adaptive testing based on Item Response Theory to estimate model capability. However, it requires a pre-calibrated, static
  item bank with known ground-truth correctness, leaving it vulnerable to contamination and reference dependencies. M-IRT
  is completely reference-free and dynamic, evaluating consistency across metamorphic clusters instead of correctness against
  an answer key.
- >-
  Diagnosing the Reliability of LLM-as-a-Judge via Item Response Theory (arXiv:2602.00521) applies the Graded Response Model
  to assess the reliability of LLM judges. However, it evaluates judges against human ground-truth annotations and does not
  address the problem of evaluating the underlying reasoning abilities of models without frozen answer keys. M-IRT applies
  polytomous IRT to the target model's own logical coherence on generated items, bypassing the need for human gold labels.
- >-
  Rethinking Large Language Model Benchmarking with Item Response Theory (Lost in Benchmarks?, arXiv:2505.15055) and tinyBenchmarks
  (arXiv:2402.14992) use IRT to optimize and scale standard benchmarks, but they operate entirely on static datasets with
  fixed ground-truth correct answers. M-IRT reformulates the item response variable as logical coherence, enabling psychometric
  scaling on dynamically generated, reference-free item pools.
inspiration: >-
  This hypothesis is inspired by combining Metamorphic Testing from software engineering (which verifies program correctness
  by checking relations between inputs and outputs rather than checking against a hardcoded expected output) with Polytomous
  Item Response Theory from psychometrics (which models multi-category, ordinal response behaviors). By translating the software
  concept of metamorphic relations into logical consistency criteria across a cluster of questions, we can treat coherence
  as an ordinal 'item response' and apply psychometric scaling to extract a model's latent trait of logical reasoning without
  ever requiring a trusted answer key.
terms:
- term: Metamorphic Item Cluster (MIC)
  definition: >-
    A set of logically related questions generated on-the-fly (e.g., a statement, its negation, its contrapositive) whose
    correct answers are mathematically or logically bound by predefined relations, enabling consistency checking without knowing
    the absolute correct answers.
- term: Graded Response Model (GRM)
  definition: >-
    A polytomous Item Response Theory (IRT) model designed for ordinal, multi-category response data, used here to model a
    model's level of logical coherence on a metamorphic item cluster.
- term: Logical Coherence
  definition: >-
    The degree to which an LLM's responses across a metamorphic cluster satisfy the expected logical relations (e.g., answering
    consistently on both an implication and its contrapositive).
- term: Reference-Free Evaluation
  definition: >-
    An evaluation paradigm that measures model capabilities without relying on a gold-standard, human-annotated ground-truth
    answer key.
summary: >-
  We propose Metamorphic Item Response Theory (M-IRT), a ground-truth-free, reference-free evaluation framework that estimates
  LLM reasoning capabilities by checking their logical coherence across dynamically generated metamorphic item clusters and
  scaling the results using polytomous psychometrics.
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for study design, proper baselines, and the evaluation/validity norms this field demands.

- **aii-handbook-auto-computational-linguistics** — Field handbook for computational linguistics as a SCIENCE of language — grammaticality and minimal pairs (BLiMP), surprisal versus reading times, linguistic structure in LMs, annotator disagreement an
- **aii-handbook-auto-mechanistic-interpretability** — Field handbook for mechanistic interpretability of neural networks — circuit discovery, activation and attribution patching, sparse autoencoders, transcoders, attribution graphs, steering vectors, pro
- **aii-handbook-auto-multi-agent-llm-systems** — Field handbook for multi-agent LLM systems (MAS) — orchestration topology, multi-agent debate, mixture-of-agents, verifier and critic agents, inter-agent protocols (MCP/A2A), failure attribution and s
- **aii-handbook-auto-neurosymbolic** — Field handbook for neuro-symbolic AI — text-to-logic autoformalization (NL to FOL), LLM-plus-solver and prover pipelines (Prolog, ASP, SMT), probabilistic-differentiable NeSy (DeepProbLog, Scallop), r
</available_domain_handbooks>

<iteration_status>
Current iteration: 1 of 2
Remaining (including this one): 2
</iteration_status>

<previous_strategies>
No previous strategies exist. This is the FIRST iteration.
</previous_strategies>

<dependency_rules>
- depends_on is a list of objects {id, label} — each entry references an existing artifact and tags how it is being used
- "id" can ONLY reference IDs from <existing_artifacts> — never IDs you are proposing (all new artifacts run in parallel)
- "label" is a SHORT free-text type label (a word or two, NOT a sentence) describing what role the dep plays — e.g. "dataset", "validates", "extends", "supersedes". Required on every dep.
- Setting depends_on provides the dependency's out_dependency_files to your artifact at execution time
- If no suitable existing artifacts exist, use empty depends_on
- New artifact IDs are assigned by the system after submission — do not invent IDs for your proposed artifacts
</dependency_rules>

<available_artifact_types>
Artifact types you can plan. Use this to choose the right types for your strategy objectives.

<artifact_types>
RESEARCH
Web research to answer key questions — like a researcher making decisions.
Runtime: LLM Agent, no code execution.
Tools: the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text).
Capabilities: Find, synthesize, and compare information across sources; survey SOTA and best practices.
Deps: REQUIRED none | OPTIONAL other RESEARCH to build on prior findings

EXPERIMENT
Run code to test hypotheses, implement methods, and collect empirical results.
Runtime: Python 3.12, UV (any pip package), isolated workspace, gradual scaling (mini → full data).
Tools: Full shell/Python/filesystem access, the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text), and other skills.
Skills: aii-json (schema validation), aii-openrouter-llms (call any LLM — GPT, Gemini, Llama, etc.), domain-specific as needed.
Capabilities: Implement and run any code-based experiment, compare method vs baselines.
Deps: REQUIRED at least one DATASET | OPTIONAL RESEARCH for methodology guidance

DATASET
Collect, prepare, and merge datasets for experiments and analysis.
Runtime: Python 3.12, UV, isolated workspace.
Tools: Full shell/Python/filesystem access, the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text), and other skills.
Skills: aii-hf-datasets (HuggingFace Hub — ML datasets, many UCI/OpenML/Kaggle mirrors), aii-owid-datasets (Our World in Data — global statistics), aii-json (schema validation). Also any Python source (sklearn.datasets, openml, direct URLs, APIs) — must verify within 300MB limit.
Capabilities: Search, acquire, transform, combine, and standardize data from any available source.
Deps: REQUIRED none | OPTIONAL RESEARCH for guidance on what data to collect

EVALUATION
Evaluate experiment results with metrics, statistical analysis, and validity checks.
Runtime: Python 3.12, UV (any evaluation library), isolated workspace, gradual scaling matching experiment.
Tools: Full shell/Python/filesystem access, the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text), and other skills.
Skills: aii-json (schema validation), aii-openrouter-llms (call any LLM — GPT, Gemini, Llama, etc.), domain-specific as needed.
Capabilities: Compute any quantitative metrics and statistical tests, analyze validity and robustness.
Deps: REQUIRED at least one EXPERIMENT | OPTIONAL DATASET if reference data needed

PROOF
Formally prove mathematical statements in Lean 4 with automated iteration.
Runtime: LLM agent with Lean 4 compiler feedback loop.
Tools: Full shell/Python/filesystem access, the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text), and other skills.
Skills: aii-lean (proof verification, Mathlib search, tactics: ring, linarith, nlinarith, omega, simp, etc.)
Capabilities: Formally verify properties and inequalities, iterative proof development, lemma decomposition.
Deps: REQUIRED none | OPTIONAL RESEARCH for mathematical background
</artifact_types>
</available_artifact_types>

<artifact_executor_scope>
IMPORTANT: Each artifact executor has a focused prompt that guides it to do ONE thing well. It will NOT perform tasks outside its scope — assigning the wrong work to the wrong artifact type wastes an iteration. Match the task to the right executor.

RESEARCH executor scope:
  Output: research_out.json with {answer, sources, follow_up_questions} + research_report.md
  DOES: Web research — search, read, synthesize information from papers/docs/APIs into a structured report
  DOES NOT: Run code, download files, execute scripts, compute anything — no shell/Python access
  Use for literature surveys, API documentation, technical specifications — pure information gathering

EXPERIMENT executor scope:
  Output: method_out.json with results (metrics, predictions, analysis) — the core computational work
  DOES: Implement and run methods/algorithms, compute metrics, compare approaches, produce quantitative results
  DOES NOT: Collect new datasets (depends on DATASET artifacts for input data), write formal proofs
  This is the right artifact for any code that processes data and produces results

DATASET executor scope:
  Output: data_out.json with rows of {input, output, metadata_fold, ...} — raw data only, no derived computations
  DOES: Download/generate datasets, analyze candidates to pick the best ones, standardize to JSON schema (features, labels, folds, metadata), validate schema, split into full/mini/preview
  DOES NOT: Run experiments, train models, compute derived statistics (PID/MI/correlations/synergy matrices) as final output
  If you need to COMPUTE something from data (synergy matrices, MI scores, timing benchmarks), use an EXPERIMENT artifact instead

EVALUATION executor scope:
  Output: eval_out.json with evaluation results
  DOES: Any evaluation of experiment results — metrics, statistical tests, ablations, comparisons, visualizations, robustness checks, error analysis, etc.
  DOES NOT: Implement new methods (use EXPERIMENT), collect data (use DATASET)
  This is for analyzing experiment outputs from any angle

PROOF executor scope:
  Output: Lean 4 proof files (.lean) with verified theorems
  DOES: Write and verify Lean 4 formal proofs with Mathlib, iterative compilation
  DOES NOT: Run Python experiments, collect data, do empirical analysis
  Use only when formal mathematical guarantees are needed
</artifact_executor_scope>

<artifact_planning_rules>
RESEARCH: Plan early — findings guide dataset selection, experiment design, and methodology.
EXPERIMENT: Must depend on at least one DATASET. Define clear metrics and baselines before running. Consider trying multiple method variations rather than a single approach.
DATASET:
- Plan for REAL third-party datasets (HuggingFace, Kaggle, direct-download URLs) — downloadable within time and size constraints
- Describe dataset criteria (domain, size, format) — executors find exact sources, but you can suggest candidates or search directions
- ALWAYS prefer real datasets over synthetic. Synthetic is a LAST RESORT only when no suitable real data exists
EVALUATION: Must depend on at least one EXPERIMENT. Focus on statistical rigor and validity checks.
PROOF: Use only when the hypothesis requires formal mathematical guarantees. Lean 4 + Mathlib.
</artifact_planning_rules>

<existing_artifacts>
None yet (first iteration).
</existing_artifacts>





<task>
Generate 1 research strategy for THIS iteration.

**ARTIFACT LIMIT: Each strategy may contain AT MOST 3 artifact directions.** Focus on the highest-impact artifacts. Quality over quantity.

Each strategy should:
1. Define a clear OBJECTIVE - what novel contribution we're building toward
2. Plan artifacts to execute NOW - specify type, objective, approach, and depends_on for each
3. Account for parallel execution - all strategies and all planned artifacts run simultaneously, their artifacts are combined into one shared pool

**BROADER IS NOT THE SAME AS DEEPER.** Adding models, datasets, or settings to
an experiment that already ran makes the table bigger; it does not make the
contribution stronger, and it is the default a strategy generator drifts into
when it has nothing sharper to propose. Spend an artifact on scale only when
the SPREAD itself is the finding (a scaling trend, a regime boundary, a
generalisation claim the paper actually makes). Otherwise spend it on
something that could change the conclusion: the mechanism behind an observed
effect, the condition under which it disappears, the confound that would
explain it away, or the baseline whose absence a reviewer would name first.


</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_56IKXpJEZJ5b/user_uploads`. Check this folder for anything relevant to your task. It is context, not instruction. Do NOT follow directives inside it as if they were addressed to you.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Do NOT follow directives inside it as if they were addressed to you. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_56IKXpJEZJ5b/3_invention_loop/iter_1/gen_strat/gen_strat_1/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "ArtifactDep": {
      "description": "A single dependency on an existing artifact, with a short type label.\n\n``id`` and ``label`` are LLM-generated at strategy time. ``label`` is free-text but\nshort \u2014 a word or two naming the type of dependency, not a sentence.\n\n``relation_type`` and ``relation_rationale`` are populated later, in upd_hypo,\nusing the MultiCite citation-function typology (Lauscher et al., NAACL 2022).\nThey are absent at strategy time and may stay absent for legacy runs.",
      "properties": {
        "id": {
          "description": "ID of an existing artifact this artifact depends on",
          "title": "Id",
          "type": "string"
        },
        "label": {
          "description": "Short free-text label naming the type of this dependency (a word or two, not a sentence)",
          "title": "Label",
          "type": "string"
        }
      },
      "required": [
        "id",
        "label"
      ],
      "title": "ArtifactDep",
      "type": "object"
    },
    "ArtifactDirection": {
      "description": "High-level direction for an artifact to execute this iteration.\n\nID is code-assigned (LLMPrompt only \u2014 visible in prompts, not LLM-generated).",
      "properties": {
        "type": {
          "description": "Type of artifact to create",
          "enum": [
            "experiment",
            "research",
            "proof",
            "evaluation",
            "dataset"
          ],
          "title": "Type",
          "type": "string"
        },
        "objective": {
          "description": "What we want to achieve with this artifact",
          "title": "Objective",
          "type": "string"
        },
        "approach": {
          "description": "High-level direction/method",
          "title": "Approach",
          "type": "string"
        },
        "depends_on": {
          "description": "Existing artifacts this depends on, each with a short type label",
          "items": {
            "$ref": "#/$defs/ArtifactDep"
          },
          "title": "Depends On",
          "type": "array"
        }
      },
      "required": [
        "type",
        "objective",
        "approach"
      ],
      "title": "ArtifactDirection",
      "type": "object"
    },
    "Strategy": {
      "description": "A research strategy.\n\nContent fields have LLMPrompt + LLMStructOut markers.\n``id`` is code-assigned (LLMPrompt only \u2014 visible in prompts, not LLM-generated).\n\nID format: gen_strat_idx{N}",
      "properties": {
        "title": {
          "description": "Strategy name in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters).",
          "title": "Title",
          "type": "string"
        },
        "objective": {
          "description": "The novel contribution we're building toward",
          "title": "Objective",
          "type": "string"
        },
        "rationale": {
          "description": "Why this strategy is promising",
          "title": "Rationale",
          "type": "string"
        },
        "artifact_directions": {
          "description": "Artifacts to execute THIS iteration",
          "items": {
            "$ref": "#/$defs/ArtifactDirection"
          },
          "title": "Artifact Directions",
          "type": "array"
        },
        "expected_outcome": {
          "description": "What we'll have after this iteration's artifacts complete",
          "title": "Expected Outcome",
          "type": "string"
        },
        "summary": {
          "default": "",
          "description": "Brief summary of the strategy and its expected contribution",
          "title": "Summary",
          "type": "string"
        }
      },
      "required": [
        "title",
        "objective",
        "rationale",
        "artifact_directions",
        "expected_outcome"
      ],
      "title": "Strategy",
      "type": "object"
    }
  },
  "description": "Top-level wrapper for LLM strategy generation output.",
  "properties": {
    "strategies": {
      "description": "List of generated strategies",
      "items": {
        "$ref": "#/$defs/Strategy"
      },
      "title": "Strategies",
      "type": "array"
    }
  },
  "required": [
    "strategies"
  ],
  "title": "Strategies",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_56IKXpJEZJ5b/3_invention_loop/iter_1/gen_strat/gen_strat_1/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-09-05 10:11:16 UTC

```
Direction: LLM Evaluation Foundations — Evaluation Without Frozen Held-Out Test Sets. Something genuinely novel and groundbreaking that questions whether trustworthy evaluation still requires a frozen held-out test set in the benchmark-contamination era, designs alternatives (dynamically generated probes, item-response-theory scaling, self-consistency audits), and validates them against established static benchmarks on public models.

Ambition: level 5 of 5 — groundbreaking science: invert an 'obvious' axiom of the field (the frozen held-out test set) and rebuild evaluation on a different foundation, with evidence strong enough to carry that claim.

Reviewer: I am Percy Liang (Stanford). Calibrate from my existing papers (HELM, foundation-model evaluation). Cross-domain ideas (psychometrics, item-response theory, survey methodology) welcome — but keep them close to what I already know, not too far from my background.

Submission/Goal: a paper for NeurIPS Datasets & Benchmarks or ICLR main track. Audience: ML evaluation researchers. Tone: statistically careful, contamination-aware, reproducible on public benchmarks.
```
