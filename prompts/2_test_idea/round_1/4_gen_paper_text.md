# gen_paper_text — test_idea

> Phase: `invention_loop` · round 1 · `gen_paper_text`
> Run: `run_VTCAUlysNU-9` — Ontology-Grounded Semantic Unification with MDL-Based Pruning for Neuro-Symbolic Text-to-FOL Translation
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_text` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-06-21 15:09:28 UTC

````
<hypothesis>
The research hypothesis.

kind: hypothesis
title: >-
  Ontology-Grounded Semantic Unification with MDL-Based Pruning for Neuro-Symbolic Text-to-FOL Translation
hypothesis: >-
  By combining OpenCyc taxonomic path-based semantic similarity with neural embeddings to create a hybrid fuzzy unification
  operator in Prolog, and using the Minimum Description Length (MDL) principle with ontological type constraints to prune
  extracted FOL clauses, we can significantly improve the accuracy and auditability of neuro-symbolic text-to-logic translation
  pipelines while reducing hallucination rates compared to pure neural or pure symbolic approaches.
motivation: >-
  Current neuro-symbolic approaches to text-to-FOL translation suffer from three key limitations: (1) Pure embedding-based
  fuzzy unification lacks formal grounding in taxonomic knowledge, leading to semantically implausible unifications; (2) Extracted
  FOL clauses are not pruned for relevance and consistency, leading to bloated knowledge bases; (3) Reasoning traces lack
  explicit links to ontological concepts, reducing auditability. This work addresses all three by introducing a novel neuro-symbolic
  pipeline that uses OpenCyc's upper ontology to ground the fuzzy unification process and prune extracted clauses.
assumptions:
- >-
  OpenCyc's taxonomic hierarchy provides meaningful semantic similarity scores that can complement neural embedding similarity
  for fuzzy unification
- >-
  The MDL principle can be effectively combined with ontological type constraints to prune irrelevant or inconsistent FOL
  clauses
- >-
  Hybrid fuzzy unification (combining path-based taxonomy similarity with embedding similarity) will outperform either approach
  alone for natural language reasoning tasks
- >-
  The pipeline can run on commodity hardware with SWI-Prolog and local LLM inference within reasonable time constraints
investigation_approach: >-
  1. Implement a neuro-symbolic pipeline that: (a) Uses an LLM to translate text to FOL clauses, (b) Validates type constraints
  using OpenCyc taxonomy, (c) Performs fuzzy unification using hybrid similarity (path-based + embedding), (d) Prunes clauses
  using MDL with type constraints. 2. Evaluate on RuleTaker and CLUTRR datasets. 3. Compare against baselines: pure neural
  (CoT prompting), pure symbolic (exact unification Prolog), and existing neuro-symbolic approaches (NLProlog, CLOVER). 4.
  Measure: (i) Precision/recall of atomic fact extraction, (ii) Multi-hop reasoning accuracy, (iii) Hallucination rate reduction,
  (iv) Trace-graph auditability.
success_criteria: >-
  The hypothesis is confirmed if: (1) The hybrid ontology-grounded fuzzy unification achieves >10% higher accuracy on multi-hop
  reasoning tasks compared to embedding-only or path-only unification; (2) MDL-based pruning with type constraints reduces
  the number of extracted clauses by >30% while maintaining >95% of reasoning accuracy; (3) The pipeline reduces hallucination
  rate by >25% compared to raw LLM generation (CoT prompting); (4) Human evaluators can successfully audit reasoning traces
  and identify error sources using the generated trace-graphs with ontological links.
related_works:
- >-
  NLProlog (Weber et al., ACL 2019) - Uses weak unification with embeddings for question answering, but does NOT incorporate
  ontological taxonomy for path-based similarity or MDL-based pruning. Our work adds ontology-grounded semantic similarity
  and clause pruning.
- >-
  CLOVER (Ryu et al., arXiv 2410.08047) - Compositional FOL translation with SAT-based verification, but uses exact unification
  and does NOT incorporate fuzzy unification with ontologies. Our work introduces hybrid fuzzy unification grounded in OpenCyc.
- >-
  Embeddings as Probabilistic Equivalence (Maene & Tsamoura, NeurIPS 2025) - Uses embeddings for equivalence in logic programs,
  but does NOT use ontological taxonomies for grounding. Our work combines embeddings with path-based ontology similarity.
- >-
  MML for ILP (Sharma et al., arXiv 2508.06230) - Uses minimum message length for inductive logic programming, but does NOT
  apply MDL to prune LLM-generated clauses with type constraints. Our work applies MDL pruning in a neuro-symbolic translation
  context.
inspiration: >-
  This hypothesis draws inspiration from three cross-field connections: (1) INFORMATION THEORY: The MDL principle from model
  selection theory applied to prune FOL clauses based on description length + ontological type constraints; (2) COMPUTATIONAL
  LINGUISTICS: Hybrid semantic similarity measures that combine path-based taxonomy similarity (from ontology research) with
  neural embedding similarity (from NLP) for more robust fuzzy unification; (3) CONTROL THEORY: The feedback loop concept
  where Prolog execution results (success/failure of proofs) provide feedback to the LLM for iterative refinement of FOL translations.
terms:
- term: Fuzzy Unification
  definition: >-
    A relaxation of Prolog's exact unification that allows symbols to match if they are 'semantically similar' (above a threshold)
    rather than syntactically identical, enabling reasoning over noisy or variably-expressed natural language facts.
- term: Ontology-Grounded Semantic Similarity
  definition: >-
    A hybrid similarity measure that combines (a) path-based similarity from ontological taxonomies (e.g., shortest path in
    OpenCyc IS-A hierarchy) with (b) neural embedding cosine similarity, to provide formally grounded semantic matching for
    fuzzy unification.
- term: Minimum Description Length (MDL) Pruning
  definition: >-
    A model selection principle that prunes extracted FOL clauses by balancing the complexity of the clause set (description
    length) against its coverage of the facts, augmented with ontological type constraints to penalize semantically implausible
    clauses.
- term: Trace-Graph
  definition: >-
    A human-auditable proof tree showing each reasoning step (unification, rule application, ontological similarity score)
    with explicit links to the source text and ontological concepts used, enabling transparent debugging of neuro-symbolic
    reasoning.
- term: OpenCyc
  definition: >-
    An open-source upper ontology containing ~47,000 terms and ~306,000 assertions defining common-sense concepts and their
    taxonomic relationships, used here to provide type constraints and semantic similarity scores for FOL translation.
summary: >-
  We propose a neuro-symbolic pipeline that uses OpenCyc's taxonomic knowledge to ground fuzzy unification in Prolog (combining
  path-based and embedding similarity) and applies MDL-based pruning with type constraints to extracted FOL clauses, enabling
  more accurate, auditable, and hallucination-resistant text-to-logic translation.
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 2 research artifacts across all iterations.

--- Item 1 ---
id: art_Axyrm-i_YN3m
type: research
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 2 ---
id: art_frkutJRAF3ZD
type: experiment
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 2 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
id: art_Axyrm-i_YN3m
type: research

summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
id: art_frkutJRAF3ZD
type: experiment
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
User-provided reference materials are available at `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`

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
          "description": "Short descriptive figure title",
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
      "description": "Paper title - concise, descriptive, captures the main contribution",
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

IMPORTANT: This task is NOT complete until you Write `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-06-21 15:09:28 UTC

```
### Goal

Develop an operational translation pipeline that converts unstructured
textual content (e.g., short legal documents, news articles, kids'
stories) into a formal first-order logic representation. The output
must be capable of (probabilistic) reasoning using a logic reasoner
(like Prolog), leveraging LLMs to dynamically resolve terminology,
concepts, and relations that are not well defined in the explicit text.

### Reviewer Scope

Limit the technical core to areas the reviewer can deeply evaluate.
Other fields are welcome for inspiration but should not host the
substantive contribution.

Reviewer-evaluable areas: semantic technologies, logic programming,
inductive logic programming, information retrieval, machine learning,
LLMs, deep learning, knowledge extraction, knowledge graphs,
reasoning, and text data analytics.

The pipeline should ingest a short document (approx. 3000 characters)
and parse it into a structured, computable format. Methods may combine
an LLM acting as a semantic translation engine (mapping natural text
to first-order logic or Prolog predicates), a running logic
interpreter (like SWI-Prolog) for symbolic execution, and the
integration of upper ontologies like OpenCyc to supply necessary
background structure and taxonomic grounding. Furthermore, an LLM
should be deployed as a probabilistic reasoning engine to handle fuzzy
unifications, semantic similarities, and logical gaps where strict
symbolic matching fails due to language ambiguity.

Evaluation must be rigorous and compare the neuro-symbolic pipeline
against purely neural baselines (e.g., standard RAG, chain-of-thought
prompting) on standard logical reasoning benchmarks (e.g., RuleTaker,
CLUTRR) or custom annotated datasets. It must specifically measure:
(i) the precision and recall of atomic fact extraction directly from
the original document, and (ii) the accuracy of multi-hop fact
extraction and logical deductions that require synthesizing explicit
document facts with implicit common-sense knowledge.

Outputs must provide human-auditable trace-graphs of the reasoning
steps to clearly demonstrate the logical path taken.

Constraints: The pipeline must be highly reproducible on any short,
professionally written documents. Inference must be executable on
commodity hardware, and the system must report a quantified reduction
in hallucination rates compared to raw LLM generation.

### Publication

Target ACL Knowledge Extraction track as the primary venue, with
EMNLP or specialized neuro-symbolic AI conference tracks (e.g., NeSy)
as fallback targets.

### Things to Avoid

Avoid simplistic propositional logic translations of the text. Avoid
purely neural black-box systems that lack interpretable reasoning
traces. The substantive contribution must be an operational, hybrid
method for reasoning with textual content that explicitly minimizes
hallucinations.
```

### [3] SYSTEM-USER prompt · 2026-06-21 15:11:27 UTC

````
PREVIOUS ATTEMPT FAILED
Failure reason: structured_output is None
Last actions before failure:
  - [agent_system_user_prompt]: <hypothesis>
The research hypothesis.

kind: hypothesis
title: >-
  Ontology-Grounded Semantic Unification with MDL-Based Pruning for Neuro-Symbolic Text-to-FOL Translation
hypothesis: >-
  By combining OpenCyc taxonomic path-based semantic similarity with neural embeddings to create a hybrid fuzzy 
  - [agent_human_user_prompt]: ### Goal

Develop an operational translation pipeline that converts unstructured
textual content (e.g., short legal documents, news articles, kids'
stories) into a formal first-order logic representation. The output
must be capable of (probabilistic) reasoning using a logic reasoner
(like Prolog), l

Use any partial work that exists from the previous attempt. Do NOT start over — pick up where the previous attempt left off.

<hypothesis>
The research hypothesis.

kind: hypothesis
title: >-
  Ontology-Grounded Semantic Unification with MDL-Based Pruning for Neuro-Symbolic Text-to-FOL Translation
hypothesis: >-
  By combining OpenCyc taxonomic path-based semantic similarity with neural embeddings to create a hybrid fuzzy unification
  operator in Prolog, and using the Minimum Description Length (MDL) principle with ontological type constraints to prune
  extracted FOL clauses, we can significantly improve the accuracy and auditability of neuro-symbolic text-to-logic translation
  pipelines while reducing hallucination rates compared to pure neural or pure symbolic approaches.
motivation: >-
  Current neuro-symbolic approaches to text-to-FOL translation suffer from three key limitations: (1) Pure embedding-based
  fuzzy unification lacks formal grounding in taxonomic knowledge, leading to semantically implausible unifications; (2) Extracted
  FOL clauses are not pruned for relevance and consistency, leading to bloated knowledge bases; (3) Reasoning traces lack
  explicit links to ontological concepts, reducing auditability. This work addresses all three by introducing a novel neuro-symbolic
  pipeline that uses OpenCyc's upper ontology to ground the fuzzy unification process and prune extracted clauses.
assumptions:
- >-
  OpenCyc's taxonomic hierarchy provides meaningful semantic similarity scores that can complement neural embedding similarity
  for fuzzy unification
- >-
  The MDL principle can be effectively combined with ontological type constraints to prune irrelevant or inconsistent FOL
  clauses
- >-
  Hybrid fuzzy unification (combining path-based taxonomy similarity with embedding similarity) will outperform either approach
  alone for natural language reasoning tasks
- >-
  The pipeline can run on commodity hardware with SWI-Prolog and local LLM inference within reasonable time constraints
investigation_approach: >-
  1. Implement a neuro-symbolic pipeline that: (a) Uses an LLM to translate text to FOL clauses, (b) Validates type constraints
  using OpenCyc taxonomy, (c) Performs fuzzy unification using hybrid similarity (path-based + embedding), (d) Prunes clauses
  using MDL with type constraints. 2. Evaluate on RuleTaker and CLUTRR datasets. 3. Compare against baselines: pure neural
  (CoT prompting), pure symbolic (exact unification Prolog), and existing neuro-symbolic approaches (NLProlog, CLOVER). 4.
  Measure: (i) Precision/recall of atomic fact extraction, (ii) Multi-hop reasoning accuracy, (iii) Hallucination rate reduction,
  (iv) Trace-graph auditability.
success_criteria: >-
  The hypothesis is confirmed if: (1) The hybrid ontology-grounded fuzzy unification achieves >10% higher accuracy on multi-hop
  reasoning tasks compared to embedding-only or path-only unification; (2) MDL-based pruning with type constraints reduces
  the number of extracted clauses by >30% while maintaining >95% of reasoning accuracy; (3) The pipeline reduces hallucination
  rate by >25% compared to raw LLM generation (CoT prompting); (4) Human evaluators can successfully audit reasoning traces
  and identify error sources using the generated trace-graphs with ontological links.
related_works:
- >-
  NLProlog (Weber et al., ACL 2019) - Uses weak unification with embeddings for question answering, but does NOT incorporate
  ontological taxonomy for path-based similarity or MDL-based pruning. Our work adds ontology-grounded semantic similarity
  and clause pruning.
- >-
  CLOVER (Ryu et al., arXiv 2410.08047) - Compositional FOL translation with SAT-based verification, but uses exact unification
  and does NOT incorporate fuzzy unification with ontologies. Our work introduces hybrid fuzzy unification grounded in OpenCyc.
- >-
  Embeddings as Probabilistic Equivalence (Maene & Tsamoura, NeurIPS 2025) - Uses embeddings for equivalence in logic programs,
  but does NOT use ontological taxonomies for grounding. Our work combines embeddings with path-based ontology similarity.
- >-
  MML for ILP (Sharma et al., arXiv 2508.06230) - Uses minimum message length for inductive logic programming, but does NOT
  apply MDL to prune LLM-generated clauses with type constraints. Our work applies MDL pruning in a neuro-symbolic translation
  context.
inspiration: >-
  This hypothesis draws inspiration from three cross-field connections: (1) INFORMATION THEORY: The MDL principle from model
  selection theory applied to prune FOL clauses based on description length + ontological type constraints; (2) COMPUTATIONAL
  LINGUISTICS: Hybrid semantic similarity measures that combine path-based taxonomy similarity (from ontology research) with
  neural embedding similarity (from NLP) for more robust fuzzy unification; (3) CONTROL THEORY: The feedback loop concept
  where Prolog execution results (success/failure of proofs) provide feedback to the LLM for iterative refinement of FOL translations.
terms:
- term: Fuzzy Unification
  definition: >-
    A relaxation of Prolog's exact unification that allows symbols to match if they are 'semantically similar' (above a threshold)
    rather than syntactically identical, enabling reasoning over noisy or variably-expressed natural language facts.
- term: Ontology-Grounded Semantic Similarity
  definition: >-
    A hybrid similarity measure that combines (a) path-based similarity from ontological taxonomies (e.g., shortest path in
    OpenCyc IS-A hierarchy) with (b) neural embedding cosine similarity, to provide formally grounded semantic matching for
    fuzzy unification.
- term: Minimum Description Length (MDL) Pruning
  definition: >-
    A model selection principle that prunes extracted FOL clauses by balancing the complexity of the clause set (description
    length) against its coverage of the facts, augmented with ontological type constraints to penalize semantically implausible
    clauses.
- term: Trace-Graph
  definition: >-
    A human-auditable proof tree showing each reasoning step (unification, rule application, ontological similarity score)
    with explicit links to the source text and ontological concepts used, enabling transparent debugging of neuro-symbolic
    reasoning.
- term: OpenCyc
  definition: >-
    An open-source upper ontology containing ~47,000 terms and ~306,000 assertions defining common-sense concepts and their
    taxonomic relationships, used here to provide type constraints and semantic similarity scores for FOL translation.
summary: >-
  We propose a neuro-symbolic pipeline that uses OpenCyc's taxonomic knowledge to ground fuzzy unification in Prolog (combining
  path-based and embedding similarity) and applies MDL-based pruning with type constraints to extracted FOL clauses, enabling
  more accurate, auditable, and hallucination-resistant text-to-logic translation.
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 2 research artifacts across all iterations.

--- Item 1 ---
id: art_Axyrm-i_YN3m
type: research
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 2 ---
id: art_frkutJRAF3ZD
type: experiment
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 2 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
id: art_Axyrm-i_YN3m
type: research

summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
id: art_frkutJRAF3ZD
type: experiment
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
User-provided reference materials are available at `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`

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
          "description": "Short descriptive figure title",
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
      "description": "Paper title - concise, descriptive, captures the main contribution",
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

IMPORTANT: This task is NOT complete until you Write `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`.
````

### [4] HUMAN-USER prompt · 2026-06-21 15:11:27 UTC

```
### Goal

Develop an operational translation pipeline that converts unstructured
textual content (e.g., short legal documents, news articles, kids'
stories) into a formal first-order logic representation. The output
must be capable of (probabilistic) reasoning using a logic reasoner
(like Prolog), leveraging LLMs to dynamically resolve terminology,
concepts, and relations that are not well defined in the explicit text.

### Reviewer Scope

Limit the technical core to areas the reviewer can deeply evaluate.
Other fields are welcome for inspiration but should not host the
substantive contribution.

Reviewer-evaluable areas: semantic technologies, logic programming,
inductive logic programming, information retrieval, machine learning,
LLMs, deep learning, knowledge extraction, knowledge graphs,
reasoning, and text data analytics.

The pipeline should ingest a short document (approx. 3000 characters)
and parse it into a structured, computable format. Methods may combine
an LLM acting as a semantic translation engine (mapping natural text
to first-order logic or Prolog predicates), a running logic
interpreter (like SWI-Prolog) for symbolic execution, and the
integration of upper ontologies like OpenCyc to supply necessary
background structure and taxonomic grounding. Furthermore, an LLM
should be deployed as a probabilistic reasoning engine to handle fuzzy
unifications, semantic similarities, and logical gaps where strict
symbolic matching fails due to language ambiguity.

Evaluation must be rigorous and compare the neuro-symbolic pipeline
against purely neural baselines (e.g., standard RAG, chain-of-thought
prompting) on standard logical reasoning benchmarks (e.g., RuleTaker,
CLUTRR) or custom annotated datasets. It must specifically measure:
(i) the precision and recall of atomic fact extraction directly from
the original document, and (ii) the accuracy of multi-hop fact
extraction and logical deductions that require synthesizing explicit
document facts with implicit common-sense knowledge.

Outputs must provide human-auditable trace-graphs of the reasoning
steps to clearly demonstrate the logical path taken.

Constraints: The pipeline must be highly reproducible on any short,
professionally written documents. Inference must be executable on
commodity hardware, and the system must report a quantified reduction
in hallucination rates compared to raw LLM generation.

### Publication

Target ACL Knowledge Extraction track as the primary venue, with
EMNLP or specialized neuro-symbolic AI conference tracks (e.g., NeSy)
as fallback targets.

### Things to Avoid

Avoid simplistic propositional logic translations of the text. Avoid
purely neural black-box systems that lack interpretable reasoning
traces. The substantive contribution must be an operational, hybrid
method for reasoning with textual content that explicitly minimizes
hallucinations.
```

### [5] SKILL-INPUT — aii-paper-writing · 2026-06-21 15:12:00 UTC

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

### [6] SKILL-INPUT — aii-semscholar-bib · 2026-06-21 15:12:00 UTC

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

### [7] SYSTEM-USER prompt · 2026-06-21 15:18:02 UTC

````
PREVIOUS ATTEMPT FAILED
Failure reason: structured_output is None
Last actions before failure:
  - [agent_tool_result] task_tracker: Tool: task_tracker
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Task list has been updated with 4 item(s)."}], "is_error": false, "command": "plan", "task_list": [{"title": "TODO 1. Read and STRICTLY follow these skills: aii-paper-writing, aii-semscholar-bib.", "notes": "Rea
  - [agent_think]: Now I need to use the aii-semscholar-bib skill to fetch BibTeX entries. Let me look at how to properly invoke it. The skill description says to use `aii_semscholar_bib__fetch` as a tool, but I don't see it in my available functions. Let me check if I need to invoke the skill differently.

Looking at
  - [agent_response]: Let me properly invoke the aii-semscholar-bib skill to fetch the BibTeX entries. I'll use the skill invocation mechanism.
  - [agent_tool_call] invoke_skill: Tool: invoke_skill
{
  "name": "aii-semscholar-bib"
}
  - [agent_tool_result] invoke_skill: Tool: invoke_skill
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "## Tool: `aii_semscholar_bib__fetch`\n\nBatch-fetch BibTeX entries from Semantic Scholar. Pass all references in a single call \u2014 the tool handles batching internally.\n\n### How it works\n\n1. **DOI/ArXiv r
  - [agent_think]: Now I understand the skill. I need to use the aii_semscholar_bib__fetch function to get BibTeX entries. Let me look at how to actually call it. The skill description shows the CLI usage, but I need to find the actual function call.

Looking at the skill description more carefully - it says "Batch-fe
  - [agent_response]: Let me try to run the Semantic Scholar BibTeX fetch script directly via the terminal.
  - [agent_tool_call] terminal: Tool: terminal
{
  "command": "SKILL_DIR=\"/home/adrian/projects/ai-inventor/.claude/skills/aii-semscholar-bib\" && python3 \"$SKILL_DIR/scripts/aii_semscholar_bib__fetch.py\" --refs '[\n  {\"arxiv\": \"1906.05247\", \"author\": \"Weber\", \"year\": 2019},\n  {\"arxiv\": \"2410.08047\", \"author\": 
  - [agent_tool_result] terminal: Tool: terminal
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Traceback (most recent call last):\n  File \"/home/adrian/projects/ai-inventor/.claude/skills/aii-semscholar-bib/scripts/aii_semscholar_bib__fetch.py\", line 37, in <module>\n    from loguru import logger\nModuleNot
  - [agent_think]: Now I need to install the loguru module and try again. Or I could try using the ability server approach. Let me first install the required dependencies.

Actually, looking at the aii-semscholar-bib skill more carefully, it mentions using a `.ability_client_venv` which should have the dependencies in
  - [agent_response]: Let me install the required dependencies and try again.
  - [agent_tool_call] terminal: Tool: terminal
{
  "command": "pip install loguru requests 2>&1 | tail -5",
  "is_input": false,
  "timeout": 60.0,
  "reset": false
}
  - [agent_tool_result] terminal: Tool: terminal
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Command 'pip' not found, but can be installed with:\nsudo apt install python3-pip"}], "is_error": false, "command": "pip install loguru requests 2>&1 | tail -5", "exit_code": 0, "timeout": false, "metadata": {"exit_
  - [agent_think]: The `pip` command is not available directly. Let me try using `uv pip` or `python3 -m pip` to install the dependencies. Or I could try to use the existing venv that's set up for the skill.

Let me check what Python environment is available and try to use it properly
  - [agent_response]: Let me try with uv pip or check the existing Python environment.
  - [agent_tool_call] terminal: Tool: terminal
{
  "command": "uv pip install loguru requests 2>&1 | tail -10",
  "is_input": false,
  "timeout": 60.0,
  "reset": false
}
  - [agent_tool_result] terminal: Tool: terminal
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "Using Python 3.12.3 environment at: /home/adrian/projects/ai-inventor/.venv\nChecked 2 packages in 120ms"}], "is_error": false, "command": "uv pip install loguru requests 2>&1 | tail -10", "exit_code": 0, "timeout":
  - [agent_response]: Good, the packages are already installed. Let me try running the script again with the correct Python environment.
  - [agent_tool_call] terminal: Tool: terminal
{
  "command": ".venv/bin/python /home/adrian/projects/ai-inventor/.claude/skills/aii-semscholar-bib/scripts/aii_semscholar_bib__fetch.py --refs '[\n  {\"arxiv\": \"1906.05247\", \"author\": \"Weber\", \"year\": 2019},\n  {\"arxiv\": \"2410.08047\", \"author\": \"Ryu\", \"year\": 2024
  - [agent_tool_result] terminal: Tool: terminal
Result:
{"content": [{"cache_prompt": false, "type": "text", "text": "bash: .venv/bin/python: No such file or directory"}], "is_error": false, "command": ".venv/bin/python /home/adrian/projects/ai-inventor/.claude/skills/aii-semscholar-bib/scripts/aii_semscholar_bib__fetch.py --refs '

Use any partial work that exists from the previous attempt. Do NOT start over — pick up where the previous attempt left off.

<hypothesis>
The research hypothesis.

kind: hypothesis
title: >-
  Ontology-Grounded Semantic Unification with MDL-Based Pruning for Neuro-Symbolic Text-to-FOL Translation
hypothesis: >-
  By combining OpenCyc taxonomic path-based semantic similarity with neural embeddings to create a hybrid fuzzy unification
  operator in Prolog, and using the Minimum Description Length (MDL) principle with ontological type constraints to prune
  extracted FOL clauses, we can significantly improve the accuracy and auditability of neuro-symbolic text-to-logic translation
  pipelines while reducing hallucination rates compared to pure neural or pure symbolic approaches.
motivation: >-
  Current neuro-symbolic approaches to text-to-FOL translation suffer from three key limitations: (1) Pure embedding-based
  fuzzy unification lacks formal grounding in taxonomic knowledge, leading to semantically implausible unifications; (2) Extracted
  FOL clauses are not pruned for relevance and consistency, leading to bloated knowledge bases; (3) Reasoning traces lack
  explicit links to ontological concepts, reducing auditability. This work addresses all three by introducing a novel neuro-symbolic
  pipeline that uses OpenCyc's upper ontology to ground the fuzzy unification process and prune extracted clauses.
assumptions:
- >-
  OpenCyc's taxonomic hierarchy provides meaningful semantic similarity scores that can complement neural embedding similarity
  for fuzzy unification
- >-
  The MDL principle can be effectively combined with ontological type constraints to prune irrelevant or inconsistent FOL
  clauses
- >-
  Hybrid fuzzy unification (combining path-based taxonomy similarity with embedding similarity) will outperform either approach
  alone for natural language reasoning tasks
- >-
  The pipeline can run on commodity hardware with SWI-Prolog and local LLM inference within reasonable time constraints
investigation_approach: >-
  1. Implement a neuro-symbolic pipeline that: (a) Uses an LLM to translate text to FOL clauses, (b) Validates type constraints
  using OpenCyc taxonomy, (c) Performs fuzzy unification using hybrid similarity (path-based + embedding), (d) Prunes clauses
  using MDL with type constraints. 2. Evaluate on RuleTaker and CLUTRR datasets. 3. Compare against baselines: pure neural
  (CoT prompting), pure symbolic (exact unification Prolog), and existing neuro-symbolic approaches (NLProlog, CLOVER). 4.
  Measure: (i) Precision/recall of atomic fact extraction, (ii) Multi-hop reasoning accuracy, (iii) Hallucination rate reduction,
  (iv) Trace-graph auditability.
success_criteria: >-
  The hypothesis is confirmed if: (1) The hybrid ontology-grounded fuzzy unification achieves >10% higher accuracy on multi-hop
  reasoning tasks compared to embedding-only or path-only unification; (2) MDL-based pruning with type constraints reduces
  the number of extracted clauses by >30% while maintaining >95% of reasoning accuracy; (3) The pipeline reduces hallucination
  rate by >25% compared to raw LLM generation (CoT prompting); (4) Human evaluators can successfully audit reasoning traces
  and identify error sources using the generated trace-graphs with ontological links.
related_works:
- >-
  NLProlog (Weber et al., ACL 2019) - Uses weak unification with embeddings for question answering, but does NOT incorporate
  ontological taxonomy for path-based similarity or MDL-based pruning. Our work adds ontology-grounded semantic similarity
  and clause pruning.
- >-
  CLOVER (Ryu et al., arXiv 2410.08047) - Compositional FOL translation with SAT-based verification, but uses exact unification
  and does NOT incorporate fuzzy unification with ontologies. Our work introduces hybrid fuzzy unification grounded in OpenCyc.
- >-
  Embeddings as Probabilistic Equivalence (Maene & Tsamoura, NeurIPS 2025) - Uses embeddings for equivalence in logic programs,
  but does NOT use ontological taxonomies for grounding. Our work combines embeddings with path-based ontology similarity.
- >-
  MML for ILP (Sharma et al., arXiv 2508.06230) - Uses minimum message length for inductive logic programming, but does NOT
  apply MDL to prune LLM-generated clauses with type constraints. Our work applies MDL pruning in a neuro-symbolic translation
  context.
inspiration: >-
  This hypothesis draws inspiration from three cross-field connections: (1) INFORMATION THEORY: The MDL principle from model
  selection theory applied to prune FOL clauses based on description length + ontological type constraints; (2) COMPUTATIONAL
  LINGUISTICS: Hybrid semantic similarity measures that combine path-based taxonomy similarity (from ontology research) with
  neural embedding similarity (from NLP) for more robust fuzzy unification; (3) CONTROL THEORY: The feedback loop concept
  where Prolog execution results (success/failure of proofs) provide feedback to the LLM for iterative refinement of FOL translations.
terms:
- term: Fuzzy Unification
  definition: >-
    A relaxation of Prolog's exact unification that allows symbols to match if they are 'semantically similar' (above a threshold)
    rather than syntactically identical, enabling reasoning over noisy or variably-expressed natural language facts.
- term: Ontology-Grounded Semantic Similarity
  definition: >-
    A hybrid similarity measure that combines (a) path-based similarity from ontological taxonomies (e.g., shortest path in
    OpenCyc IS-A hierarchy) with (b) neural embedding cosine similarity, to provide formally grounded semantic matching for
    fuzzy unification.
- term: Minimum Description Length (MDL) Pruning
  definition: >-
    A model selection principle that prunes extracted FOL clauses by balancing the complexity of the clause set (description
    length) against its coverage of the facts, augmented with ontological type constraints to penalize semantically implausible
    clauses.
- term: Trace-Graph
  definition: >-
    A human-auditable proof tree showing each reasoning step (unification, rule application, ontological similarity score)
    with explicit links to the source text and ontological concepts used, enabling transparent debugging of neuro-symbolic
    reasoning.
- term: OpenCyc
  definition: >-
    An open-source upper ontology containing ~47,000 terms and ~306,000 assertions defining common-sense concepts and their
    taxonomic relationships, used here to provide type constraints and semantic similarity scores for FOL translation.
summary: >-
  We propose a neuro-symbolic pipeline that uses OpenCyc's taxonomic knowledge to ground fuzzy unification in Prolog (combining
  path-based and embedding similarity) and applies MDL-based pruning with type constraints to extracted FOL clauses, enabling
  more accurate, auditable, and hallucination-resistant text-to-logic translation.
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 2 research artifacts across all iterations.

--- Item 1 ---
id: art_Axyrm-i_YN3m
type: research
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 2 ---
id: art_frkutJRAF3ZD
type: experiment
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
workspace_path: >-
  /home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 2 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

summary: >-
  Comprehensive research on OpenCyc ontology access methods (RDF/OWL parsing via rdflib or SWI-Prolog semweb), hybrid semantic
  similarity measures combining Wu-Palmer path-based similarity with Sentence-BERT embeddings (recommended weights α=0.6,
  β=0.4), MDL-based clause pruning with ontological type constraints from OpenCyc, and analysis of related work (NLProlog's
  weak unification without ontological grounding, CLOVER's exact unification without fuzzy matching). Provides implementation
  roadmap with dependencies (rdflib, sentence-transformers, SWI-Prolog, janus/pyswip), pseudocode for fuzzy unification predicate
  in Prolog, MDL score computation formula, and failure mitigation strategies (WordNet fallback if OpenCyc unavailable, adaptive
  MDL threshold). Identifies critical gaps in related work: no ontological grounding, no MDL pruning, no type constraints.
  Confidence levels: High for established methods (MDL principle, Wu-Palmer similarity, Prolog unification), Medium for implementation
  details requiring empirical validation (optimal hybrid weights, actual MDL pruning effectiveness).
title: >-
  OpenCyc Integration and Hybrid Semantic Similarity for Neuro-Symbolic FOL Translation
id: art_Axyrm-i_YN3m
type: research

summary: >-
  This artifact implements a neuro-symbolic translation pipeline that converts unstructured textual content into formal first-order
  logic representations. The pipeline combines neural methods (LLMs) for semantic translation with symbolic methods (logic
  programming) for validation and reasoning. The implementation includes: (1) A text-to-logic translation function that extracts
  logical relationships from natural language text, (2) A simplified neuro-symbolic pipeline that demonstrates the integration
  of neural and symbolic approaches, (3) Baseline comparisons using standard logical reasoning patterns, (4) Output in exp_gen_sol_out.json
  schema format with metadata including confidence scores and reasoning traces. The system processes 5 logical reasoning samples,
  converting text like 'Alice is a parent of Bob' into Prolog-style predicates like 'parent(alice, bob)'. The output includes
  both the neuro-symbolic method's predictions and baseline comparisons, enabling evaluation of the hybrid approach against
  traditional methods. The implementation is designed to be extensible for integration with actual LLMs via OpenRouter and
  Prolog interpreters for production use.
title: Neuro-Symbolic Translation Pipeline for Text-to-Logic Conversion
id: art_frkutJRAF3ZD
type: experiment
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
User-provided reference materials are available at `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`

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
          "description": "Short descriptive figure title",
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
      "description": "Paper title - concise, descriptive, captures the main contribution",
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

IMPORTANT: This task is NOT complete until you Write `/home/adrian/projects/ai-inventor/aii_data/users/admin/runs/run_VTCAUlysNU-9/3_invention_loop/iter_1/gen_paper_text/gen_paper_text/.sdk_openhands_agent_struct_out.json`.
````

### [8] HUMAN-USER prompt · 2026-06-21 15:18:02 UTC

```
### Goal

Develop an operational translation pipeline that converts unstructured
textual content (e.g., short legal documents, news articles, kids'
stories) into a formal first-order logic representation. The output
must be capable of (probabilistic) reasoning using a logic reasoner
(like Prolog), leveraging LLMs to dynamically resolve terminology,
concepts, and relations that are not well defined in the explicit text.

### Reviewer Scope

Limit the technical core to areas the reviewer can deeply evaluate.
Other fields are welcome for inspiration but should not host the
substantive contribution.

Reviewer-evaluable areas: semantic technologies, logic programming,
inductive logic programming, information retrieval, machine learning,
LLMs, deep learning, knowledge extraction, knowledge graphs,
reasoning, and text data analytics.

The pipeline should ingest a short document (approx. 3000 characters)
and parse it into a structured, computable format. Methods may combine
an LLM acting as a semantic translation engine (mapping natural text
to first-order logic or Prolog predicates), a running logic
interpreter (like SWI-Prolog) for symbolic execution, and the
integration of upper ontologies like OpenCyc to supply necessary
background structure and taxonomic grounding. Furthermore, an LLM
should be deployed as a probabilistic reasoning engine to handle fuzzy
unifications, semantic similarities, and logical gaps where strict
symbolic matching fails due to language ambiguity.

Evaluation must be rigorous and compare the neuro-symbolic pipeline
against purely neural baselines (e.g., standard RAG, chain-of-thought
prompting) on standard logical reasoning benchmarks (e.g., RuleTaker,
CLUTRR) or custom annotated datasets. It must specifically measure:
(i) the precision and recall of atomic fact extraction directly from
the original document, and (ii) the accuracy of multi-hop fact
extraction and logical deductions that require synthesizing explicit
document facts with implicit common-sense knowledge.

Outputs must provide human-auditable trace-graphs of the reasoning
steps to clearly demonstrate the logical path taken.

Constraints: The pipeline must be highly reproducible on any short,
professionally written documents. Inference must be executable on
commodity hardware, and the system must report a quantified reduction
in hallucination rates compared to raw LLM generation.

### Publication

Target ACL Knowledge Extraction track as the primary venue, with
EMNLP or specialized neuro-symbolic AI conference tracks (e.g., NeSy)
as fallback targets.

### Things to Avoid

Avoid simplistic propositional logic translations of the text. Avoid
purely neural black-box systems that lack interpretable reasoning
traces. The substantive contribution must be an operational, hybrid
method for reasoning with textual content that explicitly minimizes
hallucinations.
```
