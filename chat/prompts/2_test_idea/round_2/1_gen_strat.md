# gen_strat_1 — test_idea

> Phase: `invention_loop` · round 2 · `gen_strat`
> Run: `run_nOuUUSNqdMp4` — The Uniformity Principle: How Within-Sentence Consistency Predicts Readability
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_strat_1` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-21 15:06:41 UTC

````
<hypothesis>
Your strategy should advance this hypothesis.

kind: hypothesis
title: Uniformity Improves Sentence Readability
hypothesis: >-
  The readability of a sentence is predicted not only by average linguistic complexity (e.g., mean word length, mean sentence
  length) but also by the uniformity of linguistic features within the sentence. Specifically, sentences with lower coefficient
  of variation (CV) of word-level features—such as word length in characters, syllable count, and word frequency—are easier
  to read than sentences with the same average values but higher CV. Initial experiments on 13,129 sentences from WeeBIT and
  CEFR-SP datasets show that adding uniformity features (CV of word length, syllables, frequency) to traditional average features
  yields statistically significant R² improvements of +0.138 (WeeBIT) and +0.042 (CEFR-SP), both p < 0.0001. However, uniformity
  features alone perform similarly to average features alone on WeeBIT (R² = 0.226 vs 0.226), suggesting they provide complementary
  rather than standalone predictive power. The 'Uniformity Principle' operates because uniform information density allows
  readers to establish a consistent processing rhythm, reducing peak cognitive load. To fully confirm this hypothesis, subsequent
  experiments must: (1) use high-quality word frequency norms (SUBTLEX-US rather than NLTK Gutenberg), (2) compare against
  modern baselines (BERT-based models, LingFeat), (3) provide bootstrap confidence intervals for R² improvements, and (4)
  evaluate on additional datasets.
motivation: >-
  Classic readability formulas (Flesch-Kincaid, etc.) rely exclusively on average values of surface features. However, cognitive
  load theory suggests that the brain processes information more efficiently when the rate of information delivery is consistent.
  If confirmed, this hypothesis would provide a new theoretical foundation for readability assessment and enable the development
  of lightweight, interpretable readability formulas that outperform classic methods by incorporating uniformity measures.
  This is particularly valuable for applications requiring fast, explainable readability scoring without large language models.
assumptions:
- >-
  Human readers process sentences as sequential information streams where cognitive load accumulates locally based on word-level
  difficulty.
- >-
  Uniform information density (low variance in word-level features) reduces the peak cognitive load compared to fluctuating
  density, even when averages are identical.
- >-
  Surface linguistic features (word length, syllable count, word frequency) serve as valid proxies for word-level processing
  difficulty.
- >-
  The coefficient of variation (standard deviation divided by mean) is an appropriate measure of uniformity that generalizes
  across sentences of different lengths and difficulty levels.
investigation_approach: >-
  1. Extract classic surface features from sentences in a public readability dataset (e.g., CommonLit CLEAR corpus or WSJ
  dataset): word length in characters, syllable count, and word frequency for each word. 2. Compute sentence-level uniformity
  metrics: coefficient of variation (CV) of word lengths, CV of syllable counts, and CV of word frequencies within each sentence.
  3. Train lightweight regression models to predict readability scores using: (a) only traditional average features, (b) only
  uniformity features, and (c) combined features. 4. Evaluate whether uniformity features provide significant additional predictive
  power beyond averages using cross-validation. 5. Analyze feature importance and ablation studies to quantify the independent
  contribution of uniformity.
success_criteria: >-
  The hypothesis is confirmed if: (1) Uniformity features (CV of word-level features) are statistically significant predictors
  of readability scores (p < 0.05) in regression models; (2) Adding uniformity features to traditional average features yields
  a statistically significant improvement in predictive performance (e.g., R² increase > 0.02 or MAE decrease > 5%); (3) The
  improvement holds across multiple public datasets and readability scoring systems. The hypothesis is disconfirmed if uniformity
  features provide no significant predictive power beyond traditional features, or if the coefficient of variation shows near-zero
  correlation with readability scores.
related_works:
- >-
  Feng et al. (2010) 'A Comparison of Features for Automatic Readability Assessment' - This paper evaluates various features
  for readability assessment including shallow features like average word length and sentence length. However, it does not
  investigate the variance or coefficient of variation of these features within sentences as a predictor. Our hypothesis differs
  by claiming that uniformity (low CV) within a sentence is a separate, independent predictor from averages.
- >-
  Courtis (2004) 'Corporate report obfuscation: artefact or phenomenon?' - This paper uses coefficient of variation to measure
  readability variability ACROSS sentences in corporate reports, finding that high variability indicates obfuscation. Our
  hypothesis differs by applying the uniformity principle WITHIN individual sentences, claiming that low within-sentence variance
  of word properties improves readability.
- >-
  Eltanbouly et al. (2025) 'Trait-Specific Rubric-Assisted Cross-Prompt Essay Scoring' - This paper uses 'word_var: Variance
  of word length' as one of many features in a machine learning model. However, it does not test the specific theoretical
  claim that uniformity is an independent predictor, nor does it use the coefficient of variation (normalized measure) or
  test across multiple word-level features (syllables, frequency). Our hypothesis provides a theoretical framework and systematic
  evaluation.
- >-
  Genzel & Charniak (2002) 'Entropy Rate Constancy in Text' - This paper proposes that speakers maintain a constant entropy
  rate across sentences. While related to information uniformity, it operates at the sentence-level entropy rate rather than
  within-sentence uniformity of surface features. Our hypothesis focuses on within-sentence uniformity of surface linguistic
  features as a cognitive processing principle.
inspiration: >-
  The hypothesis is inspired by three cross-domain insights: (1) From COGNITIVE SCIENCE and Cognitive Load Theory: consistent
  information processing rates reduce peak working memory load compared to fluctuating rates. (2) From INFORMATION THEORY:
  uniform information density (constant bit rate) is easier to process than variable bit rate in streaming systems. (3) From
  ECONOMICS: the Gini coefficient and coefficient of variation measure inequality/non-uniformity, which in other domains predicts
  system efficiency. The core insight is that reading is a sequential processing task where uniformity of difficulty within
  a sentence allows the reader to establish a consistent 'processing rhythm', reducing cognitive effort compared to sentences
  with 'bursty' difficulty patterns.
terms:
- term: Coefficient of Variation (CV)
  definition: >-
    A normalized measure of dispersion calculated as the ratio of the standard deviation to the mean (CV = σ/μ). It measures
    the relative variability of a feature independent of its absolute scale, allowing comparison across sentences of different
    lengths and difficulty levels.
- term: Surface Linguistic Features
  definition: >-
    Readily observable textual properties that do not require deep linguistic analysis, such as word length in characters,
    number of syllables per word, sentence length in words, and word frequency counts.
- term: Within-Sentence Uniformity
  definition: >-
    The degree to which word-level properties (length, syllables, frequency) are consistent throughout a sentence, measured
    by the coefficient of variation of these properties across all words in the sentence.
- term: Cognitive Rhythm
  definition: >-
    A hypothesized cognitive processing state where the reader establishes a consistent pace of processing when encountering
    uniformly difficult text, leading to reduced peak cognitive load compared to processing text with fluctuating difficulty.
- term: Sentence-Level Readability
  definition: >-
    The assessment of reading difficulty for individual sentences independently, as opposed to document-level readability
    which averages across multiple sentences.
summary: >-
  This hypothesis proposes that sentence readability depends not only on average linguistic complexity but also on the uniformity
  of word-level features within the sentence. Sentences with consistent word lengths, syllable counts, and word frequencies
  (low coefficient of variation) are predicted to be easier to read because they allow readers to maintain a steady cognitive
  processing rhythm, reducing peak cognitive load.
_relation_rationale: >-
  Added initial experimental results; specified methodological requirements for full confirmation
_confidence_delta: increased
_key_changes:
- >-
  Added specific experimental results: R² improvements of +0.138 and +0.042, both p < 0.0001
- >-
  Noted that uniformity-only features perform similarly to average-only on WeeBIT, suggesting complementary rather than standalone
  value
- >-
  Added requirement for high-quality word frequency norms (SUBTLEX-US) based on reviewer feedback
- >-
  Added requirement to compare against modern baselines (BERT-based, LingFeat) to establish contribution beyond current methods
- >-
  Added requirement for bootstrap confidence intervals for R² improvements (currently only p-values reported)
- >-
  Added requirement for evaluation on additional datasets beyond WeeBIT and CEFR-SP
- >-
  Specified that cv_syllables was the most predictive uniformity feature (coefficient +0.150 on WeeBIT)
relation_type: evolution
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for study design, proper baselines, and the evaluation/validity norms this field demands.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>

<iteration_status>
Current iteration: 2 of 2
Remaining (including this one): 1
</iteration_status>

<previous_strategies>
Strategies from the PREVIOUS iteration. You can CONTINUE these directions,
ADAPT based on what worked and what didn't in the artifacts produced, or PIVOT if results suggest a better path.

--- Strategy 1 ---
kind: strategy
id: gen_strat_1_idx1
title: Test Uniformity Principle for Sentence Readability
objective: >-
  Establish the data foundation and methodological approach for testing whether within-sentence uniformity of linguistic features
  (low coefficient of variation) is a significant predictor of sentence readability beyond traditional average features.
rationale: >-
  The hypothesis proposes a novel 'Uniformity Principle' - that sentences with consistent word-level properties (length, syllables,
  frequency) are easier to read due to reduced peak cognitive load. Classic readability formulas (Flesch-Kincaid, etc.) use
  only averages and ignore within-sentence variance. Confirming this would provide a new theoretical foundation for lightweight,
  interpretable readability assessment. This first iteration must secure the right dataset and understand feature computation
  methods before modeling can begin in Iteration 2.
artifact_directions:
- id: dataset_iter1_dir1
  type: dataset
  objective: >-
    Acquire and prepare a public dataset with sentence-level readability scores and raw text for feature computation
  approach: >-
    Search for and download the CommonLit CLEAR corpus, WSJ dataset, or similar public readability dataset that provides (1)
    individual sentences and (2) human-rated or expert-labeled readability scores. Standardize to JSON format with fields:
    sentence_id, text, readability_score, source_metadata. Create full/mini/preview splits. Prioritize datasets with 1000+
    sentences to ensure statistical power for regression modeling. If CommonLit CLEAR is not publicly accessible, identify
    and acquire alternatives like Newsela, OneStopEnglish, or extracted portions of the WSJ corpus with readability annotations.
  depends_on: []
- id: research_iter1_dir2
  type: research
  objective: >-
    Survey methods for computing word-level linguistic features and understand the landscape of sentence-level readability
    assessment
  approach: >-
    Conduct targeted literature review on: (1) Methods for computing syllable count in English (libraries like textstat, syllables,
    or CMU pronouncing dictionary approaches), (2) Sources of word frequency norms (SUBTLEX-US, KF-NAP, Google Books Ngrams,
    or modern alternatives), (3) Existing sentence-level readability datasets and their properties, (4) Features used in previous
    readability assessment research (Feng et al. 2010 and related work), (5) Statistical approaches for testing incremental
    predictive power of new features (nested model comparison, AIC/BIC, cross-validated R² difference tests). Produce a methodology
    guide for feature computation and experimental design.
  depends_on: []
expected_outcome: >-
  By the end of Iteration 1, we will have: (1) A prepared dataset with sentences and readability scores in standardized JSON
  format, ready for feature computation, and (2) A clear methodology for computing word-level features (syllables, frequency)
  and testing the uniformity hypothesis statistically. This foundation enables Iteration 2 to focus on feature engineering,
  model training, and statistical evaluation of the Uniformity Principle.
summary: >-
  Establish foundation for testing the Uniformity Principle by acquiring sentence-level readability dataset and surveying
  feature computation methods.
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
--- Item 1 ---
id: art_nzHCg3npeffO
type: dataset
title: Sentence-Level Readability Datasets
summary: >-
  Successfully collected and standardized 2 sentence-level readability datasets for the artifact objective of computing uniformity
  features (CV of word length, syllables, word frequency). Dataset 1: WeeBIT (3,125 sentences) - established benchmark with
  5 age intervals from Vajjala & Meurers (2012). Dataset 2: CEFR-SP (10,004 sentences) - sentences annotated with CEFR levels
  (A1-C2) by English education professionals, published at EMNLP 2022. Both datasets were loaded from HuggingFace Hub, standardized
  to exp_sel_data_out.json schema with input (sentence text) and output (readability score as string) fields, and validated
  against the schema. The readability scores were normalized to 0-1 scale (0=easy, 1=hard). Output files include full_data_out.json
  (13,129 examples total), mini_data_out.json (3 examples for development), and preview_data_out.json (3 examples for inspection).
  Additional files: data_out_1.json and data_out_2.json for individual datasets, temp/datasets/ with full/mini/preview versions,
  and README.md with documentation.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_nOuUUSNqdMp4/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json
out_dependency_files:
  file_list:
  - data.py
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json
  data_file_paths:
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json

--- Item 2 ---
id: art_zKX1_wXmedjn
type: research
title: Word features and readability methods research
summary: |-
  This research artifact provides a comprehensive methodological guide for computing word-level linguistic features (syllable count, word frequency) and understanding the sentence-level readability assessment landscape. The research was conducted to inform experimental design for testing the 'Uniformity Principle' hypothesis, which posits that variance/uniformity measures of linguistic properties within sentences may improve readability prediction beyond traditional average-based features.

  Key findings across 5 research phases:

  1. SYLLABLE COUNTING: Three main approaches exist - (a) CMU Pronouncing Dictionary via 'pronouncing' library (high accuracy, research-grade), (b) 'syllables' package (fast heuristic, lower accuracy), (c) textstat library (uses Pyphen, only 54% accurate per GitHub issues). Recommendation: Use CMUdict as primary with heuristic fallback.

  2. WORD FREQUENCY: SUBTLEX-US norms (based on 51M subtitle words) significantly outperform older norms (Kucera & Francis, Celex) in predicting word processing times. Available as free download from Ghent University. Google Books Ngrams is secondary option.

  3. SENTENCE-LEVEL DATASETS: (a) CLEAR corpus (~5,000 excerpts, grades 3-12, multiple readability metrics + teacher ratings, MIT license), (b) WSJ dataset (1,200 sentences, 20 annotators, grades 1-7), (c) OneStopEnglish (189 texts × 3 levels). CLEAR recommended as primary for hypothesis testing.

  4. FEATURE LANDSCAPE: Feng et al. (2010) evaluated 5 categories - discourse, language modeling, syntactic, POS, and shallow features. Their Table 5 lists 8 shallow features. Critical finding: ALL existing features are means/averages (e.g., 'average syllables per word'). NO variance/uniformity measures were found, suggesting the 'Uniformity Principle' hypothesis has novelty.

  5. STATISTICAL METHODS: For testing incremental predictive power - (a) Cross-validated R² difference with bootstrap CI (most robust), (b) AIC/BIC comparison (model selection), (c) Nested F-test (linear models). Recommendations provided with Python implementation examples.

  The artifact includes: (1) Detailed methodology guide with installation commands and code snippets, (2) Dataset catalog with properties and access methods, (3) Feature catalog from Feng et al. (2010), (4) Statistical methodology guide, (5) Novelty assessment for uniformity features, (6) Experimental design recommendations.

  Sources: 14 references covering PyPI packages, academic papers (Feng et al. 2010, Liu & Lee 2023), dataset documentation (CLEAR, WSJ, OneStopEnglish), and statistical methods resources. All sources accessed and verified via web research tools.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_nOuUUSNqdMp4/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json
out_dependency_files:
  file_list:
  - research_out.json
</existing_artifacts>

<current_paper>
The current paper draft — represents the research story so far.

Use this to understand what's working, what's not, and what gaps remain.
Gaps and weak results signal what to try differently — not what to conclude.

# The Uniformity Principle: How Within-Sentence Consistency Predicts Readability

## Abstract

Classic readability formulas (e.g., Flesch-Kincaid) rely exclusively on average values of surface linguistic features. This paper introduces the Uniformity Principle: readability is predicted not only by these averages but also by the uniformity (consistent difficulty) of word-level features within a sentence. We evaluate this hypothesis on 13,129 sentences from two public benchmarks (WeeBIT and CEFR-SP). Using Ridge regression with 5-fold cross-validation, we find that uniformity features (coefficient of variation of word length, syllable count, and word frequency) are statistically significant predictors of readability scores (p < 0.001), yielding R-squared improvements of +0.138 and +0.042 beyond traditional average features. The coefficient of variation of syllable counts is the most predictive uniformity feature (coefficient +0.150 on WeeBIT). These findings suggest that the Uniformity Principle captures a previously unrecognized aspect of readability, providing a lightweight and interpretable enhancement to traditional readability assessment.

---

# 1 Introduction

Readability assessment—the task of predicting how difficult a text is to read—has practical applications in education, content creation, and accessibility. Classic readability formulas such as Flesch Reading Ease and Flesch-Kincaid Grade Level operate by computing averages of surface linguistic features: average word length in characters, average sentence length in words, and average syllables per word. These formulas assume that a sentence's difficulty can be reduced to its mean properties.

However, reading is a sequential information processing task. Cognitive load theory suggests that the human brain processes information more efficiently when the rate of information delivery is consistent. In streaming systems, uniform bit rate is easier to decode than variable bit rate. Similarly, in economics, inequality measures like the Gini coefficient predict system efficiency. We hypothesize that a similar principle applies to reading: sentences with uniform word-level difficulty allow readers to establish a consistent processing rhythm, reducing peak cognitive load compared to sentences with bursty difficulty patterns.

We call this the **Uniformity Principle**: the readability of a sentence is predicted not only by average linguistic complexity but also by the uniformity (consistency) of linguistic features within the sentence. Specifically, we propose that sentences with lower coefficient of variation (CV = standard deviation / mean) of word-level features are easier to read than sentences with the same average values but higher CV.

[FIGURE:fig1]

This paper makes the following contributions:

1. **Theoretical contribution**: We formulate the Uniformity Principle as a novel predictor of sentence-level readability, grounded in cognitive load theory and information theory.
2. **Empirical evaluation**: We conduct a systematic evaluation on 13,129 sentences from two established benchmarks (WeeBIT and CEFR-SP).
3. **Significant findings**: We show that uniformity features provide statistically significant predictive power beyond traditional features (p < 0.001), with R-squared improvements of +0.138 and +0.042.
4. **Practical impact**: The Uniformity Principle enables lightweight, interpretable readability formulas that outperform classic methods.

---

# 2 Related Work

## 2.1 Readability Assessment

Readability assessment has a long history in natural language processing. Classic formulas rely on shallow surface features. Feng et al. conducted a comprehensive comparison of features for automatic readability assessment, evaluating discourse, language modeling, syntactic, part-of-speech, and shallow features. Their Table 5 lists 8 shallow features, all of which are means or averages. To our knowledge, no prior work has investigated the variance or coefficient of variation of these features within sentences as a predictor of readability.

## 2.2 Variance and Uniformity in Text

Courtis used the coefficient of variation to measure readability variability across sentences in corporate reports. However, this work operates at the document level. Our hypothesis is fundamentally different: we claim that within-sentence uniformity of word properties improves readability.

## 2.3 Cognitive Load Theory

Cognitive load theory posits that working memory has limited capacity. In reading, cognitive load accumulates locally based on word-level difficulty. We hypothesize that uniform information density reduces peak cognitive load.

---

# 3 The Uniformity Principle

## 3.1 Hypothesis

The Uniformity Principle states that sentence readability depends not only on average linguistic complexity but also on the uniformity of word-level features within the sentence.

Formally, for a word-level feature f, we define: (1) Average: μf = (1/n) Σ fi, (2) Uniformity (CV): CVf = σf / μf.

The Uniformity Principle predicts that readability score R is a function of both μf and CVf.

## 3.2 Cognitive Motivation

The hypothesis is motivated by: (1) Cognitive Load Theory—consistent processing reduces peak load, (2) Information Theory—uniform bit rate is easier to decode, (3) Gini Coefficient—inequality reduces efficiency.

## 3.3 Feature Definitions

We compute three classes of word-level features: (1) Word length in characters, (2) Syllable count (using CMU Pronouncing Dictionary), (3) Word frequency (log-transformed, from NLTK Gutenberg corpus). For each feature, we compute: Average (traditional) and Coefficient of variation (uniformity).

---

# 4 Experiments

## 4.1 Datasets

We evaluate on two public sentence-level readability datasets.

**WeeBIT**: 3,125 sentences annotated with 5 age intervals. Scores normalized to [0, 1].

**CEFR-SP**: 10,004 sentences annotated with CEFR levels (A1-C2). Levels mapped to 0.0-1.0.

[FIGURE:fig2]

## 4.2 Experimental Setup

Feature computation: Syllable counting uses CMU Pronouncing Dictionary (123,455 words). Word frequency uses NLTK Gutenberg corpus (42,339 words). Models: Ridge regression (alpha=1.0) with 5-fold cross-validation. Three feature sets: (1) Average only, (2) Uniformity only, (3) Combined.

## 4.3 Results

[FIGURE:fig3]

Key findings: (1) Uniformity features are predictive (R² > 0.22 on WeeBIT, > 0.40 on CEFR-SP), (2) Adding uniformity features yields significant improvements (p < 0.001), (3) MSE reduction of 17.8% (WeeBIT) and 8.9% (CEFR-SP).

## 4.4 Feature Importance

[FIGURE:fig4]

All three uniformity features have positive coefficients, indicating that higher within-sentence variance is associated with higher reading difficulty. On WeeBIT, top features: cv_syllables (+0.150), avg_word_len (-0.117), num_words (+0.108), cv_freq (+0.103).

---

# 5 Discussion

## 5.1 Interpretation of Results

The results confirm the Uniformity Principle hypothesis. The effect is particularly strong for cv_syllables (+0.150 on WeeBIT), suggesting sentences with varying syllable counts are more difficult.

## 5.2 Comparison to Classic Formulas

Classic readability formulas can be viewed as linear combinations of average features. Our results suggest these formulas are incomplete—they miss the uniformity signal that explains an additional 1.8-13.8% of variance.

## 5.3 Limitations

Word frequency uses Gutenberg corpus (not SUBTLEX-US). WeeBIT has only 5 readability levels. No direct cognitive validation (eye-tracking data).



[FIGURE:fig5]

## 5.4 Practical Applications

The Uniformity Principle enables: (1) Lightweight readability scoring, (2) Text simplification guidance, (3) Curriculum design.

---

# 6 Conclusion

This paper introduced the Uniformity Principle: the hypothesis that within-sentence uniformity of word-level linguistic features predicts readability independently of traditional average features. Through systematic evaluation on 13,129 sentences from two public benchmarks, we demonstrated that uniformity features are statistically significant predictors (p < 0.001), adding uniformity features yields R² improvements of +0.138 and +0.042, and the coefficient of variation of syllable counts is the most predictive uniformity feature.

These findings suggest that the Uniformity Principle captures a previously unrecognized aspect of readability. We hope this work inspires further research into uniformity-based features for readability assessment.

---

# References

[12] Feng, L., Jansche, M., Huenerfauth, M. (2010). A Comparison of Features for Automatic Readability Assessment. COLING 2010.

[13] Courtis, J. K. (2004). Corporate report obfuscation: artefact or phenomenon? Journal of Business Communication.

[19] Vajjala, S., Meurers, D. (2012). WeeBIT: A Corpus of Alphabetical Texts for Readability Research. LREC 2012.

[20] Xia, M. et al. (2023). CEFR-SP: A Sentence-Level Corpus for CEFR Level Prediction. EMNLP 2023.

</current_paper>

<reviewer_feedback>
Paper reviewer feedback from the previous iteration. Your strategy MUST address these critiques.
Prioritize major issues — these are the most impactful improvements to make.

- [MAJOR] (methodology) The paper uses NLTK Gutenberg corpus for word frequency computation, which the authors' own research artifact (art_zKX1_wXmedjn) identifies as suboptimal. The artifact states: 'SUBTLEX-US norms (based on 51M subtitle words) significantly outperform older norms (Kucera & Francis, Celex) in predicting word processing times.' Using Gutenberg corpus (42,339 words from books) instead of SUBTLEX-US likely reduces the quality of the frequency-based uniformity features.
  Action: Replace NLTK Gutenberg corpus with SUBTLEX-US word frequency norms. The SUBTLEX-US data is freely available from Ghent University. Use the Zipf scale values or SUBTL WF (word frequency per million) for computing word frequency uniformity. This change is straightforward and will improve the quality of the frequency features.
- [MAJOR] (methodology) The paper only uses Ridge regression as the evaluation model. This is a weak baseline that does not represent the current state of readability assessment. Recent work (Deutsch et al. 2020, Liu & Lee 2023) has shown that neural models and comprehensive feature sets (e.g., LingFeat with 255 features) achieve much higher performance. Without comparing to these stronger baselines, it's unclear whether uniformity features provide value beyond what's already captured by modern methods.
  Action: Add experiments with at least one modern neural baseline (e.g., BERT-based readability assessment) and one comprehensive feature-based baseline (e.g., LingFeat or the feature set from Deutsch et al. 2020). Show whether adding uniformity features to these stronger baselines still yields improvements. If the improvement disappears with stronger baselines, the contribution is much weaker than claimed.
- [MAJOR] (evidence) The paper reports R² improvements of +0.138 and +0.042 but does not provide effect sizes, confidence intervals, or detailed breakdown of these improvements. The p-values (< 0.001) are reported but p-values alone are insufficient for evaluating practical significance. Additionally, the paper claims 'MSE reduction of 17.8% (WeeBIT) and 8.9% (CEFR-SP)' but it's unclear whether this is on training or test set, and whether the reduction is statistically significant.
  Action: Report cross-validated R² differences with bootstrap confidence intervals (as recommended in the research artifact). Provide a table with mean, standard deviation, and confidence intervals for R² on test sets for all three feature sets (average only, uniformity only, combined). Also report whether the MSE reduction is statistically significant using a paired bootstrap test.
- [MINOR] (novelty) The paper states 'To our knowledge, no prior work has investigated the variance or coefficient of variation of these features within sentences as a predictor of readability.' While this appears true for word-level features, the paper should acknowledge that Courtis (1998) investigated readability VARIABILITY at the document level (using coefficient of variation across sentences in corporate reports). The paper correctly distinguishes this but could be more explicit about the relationship to this prior work.
  Action: In Section 2.2, add a more detailed discussion of Courtis (1998) and explicitly state that while Courtis operated at the document level (variance across sentences), this paper is the first to investigate within-sentence variance of word-level features. This strengthens rather than weakens the paper's novelty claim.
- [MAJOR] (scope) The evaluation is limited to only 2 sentence-level datasets (WeeBIT and CEFR-SP). Both datasets have limitations: WeeBIT has only 5 readability levels and was originally designed for document-level assessment; CEFR-SP sentences are annotated based on document-level CEFR ratings, not direct sentence-level annotation. The generalizability of the results to other datasets, to document-level readability, and to languages other than English is not established.
  Action: Add evaluation on at least one more dataset, preferably at the document level (e.g., CLEAR corpus or Newsela). If document-level evaluation is not possible, at least add evaluation on a third sentence-level dataset (e.g., WSJ dataset from Liu & Lee 2023). Also discuss the limitations of the current evaluation more explicitly in Section 5.3.
- [MINOR] (rigor) The paper does not report out-of-vocabulary (OOV) rates for the CMU Pronouncing Dictionary. The research artifact mentions that CMUdict has 123,455 words, but typical readability assessment texts may contain words not in this dictionary (e.g., domain-specific terms, named entities, rare words). The handling of OOV words for syllable counting and the OOV rate should be reported.
  Action: Report the OOV rate for CMUdict on both datasets. Implement and document a fallback strategy for OOV words (e.g., using the 'syllables' package heuristic or a simple rule like counting vowel groups). Sensitivity analysis showing the impact of OOV handling on results would further strengthen the paper.
- [MINOR] (clarity) Figure references (FIGURE:fig1 through FIGURE:fig5) are placeholders without actual figures or detailed captions. While the instructions state that figures should be assumed to show exactly what the caption describes, having no figures or detailed captions makes it difficult to evaluate whether the results are presented clearly and whether the figures effectively communicate the findings.
  Action: Generate actual figures or provide detailed figure captions specifying what each figure shows, what the axes are, what the error bars represent, etc. At minimum, provide mock-ups or detailed descriptions of what each figure should contain so that reviewers can evaluate whether the visualization effectively communicates the results.
- [MINOR] (methodology) Section 4.2 states that syllable counting uses CMU Pronouncing Dictionary (123,455 words) and word frequency uses NLTK Gutenberg corpus (42,339 words), but it's unclear how word frequency is computed for out-of-vocabulary words (words not in Gutenberg). Are they assigned a default frequency? Removed? This should be documented.
  Action: Document the handling of OOV words for word frequency computation. If using a default frequency for OOV words, justify the choice (e.g., assigning frequency = 0 or 1 for unseen words). If removing OOV words, report the percentage of words removed and show that results are robust to this choice.
- [MINOR] (evidence) The paper reports positive coefficients for all three uniformity features, indicating that higher within-sentence variance is associated with higher reading difficulty. This is plausible but the paper does not provide error bars or significance tests for individual feature coefficients. It's possible that some uniformity features are not significant predictors when controlling for others.
  Action: Add a table or discussion of the statistical significance of individual feature coefficients. Report standard errors or confidence intervals for the Ridge regression coefficients. This will help readers understand which uniformity features are most robust and whether all three contribute uniquely to predictability.
- [MINOR] (scope) The paper claims practical applications in 'Lightweight readability scoring, Text simplification guidance, Curriculum design' (Section 5.4) but does not demonstrate or evaluate any of these applications. The paper is purely an empirical evaluation of whether uniformity features predict readability, without demonstrating end-to-end utility.
  Action: Either add a demonstration of one practical application (e.g., show how uniformity features can guide text simplification by identifying sentences with high CV that should be simplified) or tone down the claims about practical applications in Section 5.4. A short demonstration or case study would substantially strengthen the paper.
</reviewer_feedback>

<task>
Generate 1 research strategy for THIS iteration.

**ARTIFACT LIMIT: Each strategy may contain AT MOST 3 artifact directions.** Focus on the highest-impact artifacts. Quality over quantity.

Each strategy should:
1. Define a clear OBJECTIVE - what novel contribution we're building toward
2. Plan artifacts to execute NOW - specify type, objective, approach, and depends_on for each
3. Account for parallel execution - all strategies and all planned artifacts run simultaneously, their artifacts are combined into one shared pool


</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_nOuUUSNqdMp4/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_nOuUUSNqdMp4/3_invention_loop/iter_2/gen_strat/gen_strat_1/.sdk_openhands_agent_struct_out.json`

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

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_nOuUUSNqdMp4/3_invention_loop/iter_2/gen_strat/gen_strat_1/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-21 15:06:41 UTC

```
A lightweight sentence-level readability scoring model for English text using classic surface linguistic features, evaluated on a small public dataset.
```

### [3] SYSTEM-USER prompt · 2026-07-21 15:07:48 UTC

```
<verification_results>
Your previous response had issues that need fixing:

DEPENDENCY ERRORS (depends_on can ONLY reference IDs from <existing_artifacts>):
  - Strategy 1: Artifact 'dataset_iter2_dir1' (dataset): dependency 'art_nzHCg3npeffO' has type 'dataset' which is not allowed (allowed: {'research'})

</verification_results>

<task>
Fix ALL issues above and regenerate your strategies:

1. Fix dependency errors:
   - depends_on is a list of {id, label} objects — every entry MUST have a non-empty short label
   - id can ONLY reference IDs from <existing_artifacts>
   - You CANNOT reference artifacts you are proposing in this strategy as dependencies (they all run in parallel)
   - Follow the dependency type rules (e.g., experiments require datasets)
   - If no suitable existing artifacts exist, use depends_on: []

Output the corrected JSON with the fixed strategies.
</task>
```
