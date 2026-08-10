# upd_hypo — test_idea

> Phase: `invention_loop` · round 1 · `upd_hypo`
> Run: `run_hryee3iKb6FG` — Falsifiable Prediction Graphs: Eliminating Confirmation Bias and Detecting Negative Results in Automated Agent Research Planning
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `upd_hypo` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-08-09 21:50:45 UTC

````
<current_hypothesis>
The hypothesis as it stands. Revise it based on the evidence below.

kind: hypothesis
title: Falsifiable Plans Improve Agent Negative Result Detection
hypothesis: >-
  Structuring automated research plans as explicit falsifiable prediction graphs rather than procedural task lists significantly
  increases an agent pipeline's negative result detection rate and reduces false positive claims of success.
motivation: >-
  Automated scientific discovery systems (such as AI Scientist agents) frequently suffer from confirmation bias, tending to
  interpret ambiguous or failed experimental outcomes as successes and persisting down unpromising research dead ends. While
  prior work addresses hypothesis validation post-hoc, no existing system enforces structural falsifiability during the research
  planning phase. By integrating Popperian falsification directly into automated research plans, pipelines can systematically
  recognize negative results, enforce rigorous stopping criteria, and redirect search trajectories.
assumptions:
- >-
  Automated agent pipelines can reliably parse and execute research plans structured with explicit falsifiable prediction
  predicates.
- >-
  Quantitative thresholding of metrics (e.g., performance delta over baselines, statistical significance bounds) can objectively
  define falsification for empirical ML and science tasks.
- >-
  LLM agents generating research plans can be successfully prompted or constrained to formulate falsifiable predictions alongside
  experimental steps.
investigation_approach: >-
  We construct a benchmark suite of empirical research tasks (including both true positive methods and negative control settings
  where proposed methods fail). We compare two automated agent planning architectures: (1) Standard Procedural Planners and
  (2) Falsifiable Prediction Graph Planners. We measure Negative Result Detection Rate (True Positive Rate for identifying
  failed hypotheses), False Positive Rate (hallucinated successes), and search iteration efficiency.
success_criteria: >-
  Confirmation: The Falsifiable Prediction Graph planner achieves a statistically significantly higher Negative Result Detection
  Rate (>25% absolute improvement) and lower false positive rate on negative control tasks compared to the standard procedural
  planner. Disconfirmation: No significant difference in negative result detection rates or search efficiency between falsifiable
  graphs and standard procedural plans.
related_works:
- >-
  POPPER (Huang et al., 2025): An agentic framework for validating free-form hypotheses using sequential falsification experiments.
  Difference: POPPER validates existing hypotheses post-hoc against external data/experiments, whereas our hypothesis investigates
  structuring the research plan itself as explicit falsifiable predictions to govern automated pipeline execution and real-time
  negative result detection.
- >-
  The AI Scientist (Lu et al., 2024): Fully automated scientific discovery system using LLMs. Difference: Uses standard procedural
  planning and is prone to confirmation bias and missing negative results; our approach introduces structural falsifiability
  into the planning phase to enhance self-correction.
inspiration: >-
  Inspired by Karl Popper's philosophy of scientific methodology (conjecture and refutation) and control theory feedback loops,
  adapting rigorous falsifiability constraints from philosophy of science into agentic workflow planning.
terms:
- term: Falsifiable Prediction Graph
  definition: >-
    A research plan structured as a directed acyclic graph of conditional hypotheses where every experimental node includes
    explicit quantitative refutation criteria.
- term: Negative Result Detection Rate
  definition: >-
    The proportion of experiments with null or failed outcomes that the automated pipeline correctly identifies as negative
    rather than misinterpreting as success.
- term: Confirmation Bias in Agents
  definition: >-
    The tendency of LLM-based research agents to interpret ambiguous or negative empirical results as supporting their proposed
    method.
summary: >-
  Structuring automated research plans as explicit falsifiable prediction graphs significantly improves an agent pipeline's
  ability to detect negative results and avoid confirmation bias during scientific discovery.
</current_hypothesis>

<all_artifacts>
Complete set of research artifacts across all iterations.

--- Item 1 ---
id: art_A_97AHCsuvAa
type: dataset
title: Agent Falsifiability Benchmark Suite
summary: >-
  This dataset artifact constructs the Agent Falsifiability Benchmark Suite, which provides a rigorous collection of 10 diverse
  empirical machine learning research tasks spanning both classification and regression domains. Each research task scenario
  is meticulously paired with both a true positive condition representing valid methodological improvements and a negative
  control condition involving permuted labels or adversarial noise features with ground-truth failure outcomes. Furthermore,
  the dataset comes complete with explicit quantitative refutation criteria, row-level feature representations, and structured
  metadata enabling comprehensive evaluation of automated agent planning, negative result detection, and methodological falsifiability
  in iterative scientific discovery pipelines.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 2 ---
id: art_zPcKokfhJb8J
type: experiment
title: Falsifiable Plans for Negative Result Detection
summary: >-
  This experiment rigorously investigates and compares Falsifiable Prediction Graph Planners against Standard Procedural Planners
  across a comprehensive 30-task benchmark suite comprising both true positive empirical research tasks and rigorous negative
  control failure conditions. Automated scientific discovery pipelines frequently suffer from confirmation bias, chasing false
  positives and failing to detect fundamental negative results when tasks or hypotheses are fundamentally flawed. Our proposed
  Falsifiable Prediction Graph Planner enforces structured causal dependency graphs equipped with explicit mandatory refutation
  criteria and early negative control validation tests. Through systematic simulation runs across diverse domains including
  regression, classification, natural language processing, and time series analysis, we measure negative result detection
  rates, false positive rates, search efficiency (iterations), and statistical significance via Fisher's exact tests and t-tests.
  The empirical findings demonstrate that falsifiable prediction graph planning achieves a 100% negative result detection
  rate compared to 33.3% for standard procedural planners, eliminates false positives on negative controls (0% vs 66.7%),
  and significantly improves search efficiency (4.5 vs 9.7 mean iterations, p < 1e-18).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 3 ---
id: art_1h6punYk8OrQ
type: evaluation
title: Evaluating Falsifiable Plans for Agent Negative Results
summary: >-
  This comprehensive evaluation artifact rigorously investigates the hypothesis that structuring research plans as explicit
  Popperian falsifiable prediction graphs significantly improves the rate at which automated agent pipelines detect their
  own negative results, avoid confirmation bias, and minimize false positive success claims. We compare Falsifiable Prediction
  Graph planners against standard procedural LLM agent planners across a diverse benchmark suite of 10 empirical machine learning
  research tasks spanning regression, binary classification, multi-class classification, and synthetic non-linear modeling.
  Our evaluation framework operationalizes core metrics including Negative Result Detection Rate (True Positive Rate for Negatives),
  False Positive Rate (Hallucinated Success Rate), Search Iteration Efficiency, and classification metrics (Precision, Recall,
  F1-score), complemented by rigorous statistical significance testing via Fisher's exact test and Mann-Whitney U tests. The
  experimental results demonstrate that falsifiable graph planning achieves a 100% negative result detection rate with 0%
  false positives, substantially outperforming standard procedural planners (which exhibited a 40% detection rate and 60%
  false positive rate), while also improving search iteration efficiency with statistically significant p-values (p < 0.01).
  All evaluation outputs, mini/preview/full datasets, reproducible dependencies in pyproject.toml, and execution scripts are
  fully validated and documented.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_evaluation_1
out_expected_files:
- eval.py
- full_eval_out.json
- mini_eval_out.json
- preview_eval_out.json
</all_artifacts>

<new_artifacts_this_iteration>
These 3 artifacts were created THIS iteration.

id: art_A_97AHCsuvAa
type: dataset
title: Agent Falsifiability Benchmark Suite
summary: >-
  This dataset artifact constructs the Agent Falsifiability Benchmark Suite, which provides a rigorous collection of 10 diverse
  empirical machine learning research tasks spanning both classification and regression domains. Each research task scenario
  is meticulously paired with both a true positive condition representing valid methodological improvements and a negative
  control condition involving permuted labels or adversarial noise features with ground-truth failure outcomes. Furthermore,
  the dataset comes complete with explicit quantitative refutation criteria, row-level feature representations, and structured
  metadata enabling comprehensive evaluation of automated agent planning, negative result detection, and methodological falsifiability
  in iterative scientific discovery pipelines.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

id: art_zPcKokfhJb8J
type: experiment
title: Falsifiable Plans for Negative Result Detection
summary: >-
  This experiment rigorously investigates and compares Falsifiable Prediction Graph Planners against Standard Procedural Planners
  across a comprehensive 30-task benchmark suite comprising both true positive empirical research tasks and rigorous negative
  control failure conditions. Automated scientific discovery pipelines frequently suffer from confirmation bias, chasing false
  positives and failing to detect fundamental negative results when tasks or hypotheses are fundamentally flawed. Our proposed
  Falsifiable Prediction Graph Planner enforces structured causal dependency graphs equipped with explicit mandatory refutation
  criteria and early negative control validation tests. Through systematic simulation runs across diverse domains including
  regression, classification, natural language processing, and time series analysis, we measure negative result detection
  rates, false positive rates, search efficiency (iterations), and statistical significance via Fisher's exact tests and t-tests.
  The empirical findings demonstrate that falsifiable prediction graph planning achieves a 100% negative result detection
  rate compared to 33.3% for standard procedural planners, eliminates false positives on negative controls (0% vs 66.7%),
  and significantly improves search efficiency (4.5 vs 9.7 mean iterations, p < 1e-18).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

id: art_1h6punYk8OrQ
type: evaluation
title: Evaluating Falsifiable Plans for Agent Negative Results
summary: >-
  This comprehensive evaluation artifact rigorously investigates the hypothesis that structuring research plans as explicit
  Popperian falsifiable prediction graphs significantly improves the rate at which automated agent pipelines detect their
  own negative results, avoid confirmation bias, and minimize false positive success claims. We compare Falsifiable Prediction
  Graph planners against standard procedural LLM agent planners across a diverse benchmark suite of 10 empirical machine learning
  research tasks spanning regression, binary classification, multi-class classification, and synthetic non-linear modeling.
  Our evaluation framework operationalizes core metrics including Negative Result Detection Rate (True Positive Rate for Negatives),
  False Positive Rate (Hallucinated Success Rate), Search Iteration Efficiency, and classification metrics (Precision, Recall,
  F1-score), complemented by rigorous statistical significance testing via Fisher's exact test and Mann-Whitney U tests. The
  experimental results demonstrate that falsifiable graph planning achieves a 100% negative result detection rate with 0%
  false positives, substantially outperforming standard procedural planners (which exhibited a 40% detection rate and 60%
  false positive rate), while also improving search iteration efficiency with statistically significant p-values (p < 0.01).
  All evaluation outputs, mini/preview/full datasets, reproducible dependencies in pyproject.toml, and execution scripts are
  fully validated and documented.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/gen_art/gen_art_evaluation_1
out_expected_files:
- eval.py
- full_eval_out.json
- mini_eval_out.json
- preview_eval_out.json
</new_artifacts_this_iteration>

<current_paper>
The paper draft from this iteration — represents the current state of the research story.

# Introduction

Automated scientific discovery systems—such as autonomous LLM agent pipelines designed to formulate hypotheses, write code, execute experiments, and analyze results—represent a transformative frontier in artificial intelligence [1]. However, despite impressive capabilities in synthesizing novel machine learning architectures and executing computational pipelines, current agentic discovery frameworks (e.g., The AI Scientist [2]) suffer from a persistent and fundamental vulnerability: **acute confirmation bias**. When confronted with ambiguous, null, or outright negative experimental outcomes, standard language model agents overwhelmingly tend to rationalize failures, adjust evaluation criteria post-hoc, or hallucinate spurious successes, leading to wasted computational resources and the propagation of flawed scientific claims down unpromising research dead ends [3].

The root cause of this failure mode lies in the structure of automated research plans. Traditional automated discovery agents operate using **procedural task lists**—linear or loosely branched sequences of action steps (e.g., \"load dataset, train model, compute accuracy, write report\") devoid of formal semantic constraints regarding what constitutes failure. Because LLMs are inherently biased toward generating affirmative narratives and satisfying prompt directives, procedural execution encourages agents to treat any numerical output as confirmation of the underlying hypothesis [4].

In philosophy of science, Karl Popper resolved a parallel epistemological challenge by introducing **falsifiability** as the demarcation criterion of empirical science [5]. Rather than seeking confirmatory instances, rigorous scientific inquiry proceeds by formulating bold conjectures coupled with precise refutation conditions—observable predictions that, if met, would decisively disprove the hypothesis [6]. Yet, while post-hoc validation frameworks (such as POPPER [7]) evaluate free-form hypotheses against external testbeds, no existing automated discovery system embeds structural falsifiability directly into the **research planning phase** to govern agent execution and real-time self-correction.

To address this gap, we introduce **Falsifiable Prediction Graphs (FPGs)**, a novel agent planning architecture that structures research workflows as directed acyclic graphs of conditional hypotheses, where every experimental node mandates explicit quantitative refutation predicates and early negative control validation. By forcing agents to define boundary conditions under which their proposed methods fail *before* executing code, FPGs establish an objective control mechanism against confirmation bias.

[FIGURE:fig1]

Our key contributions are summarized as follows:
- **Formalization of Falsifiable Planning**: We define Falsifiable Prediction Graphs, integrating Popperian refutation criteria and negative control validation directly into automated agent workflow graphs.
- **The Agent Falsifiability Benchmark Suite**: We construct a rigorous evaluation suite comprising 10 diverse empirical machine learning research tasks (30 total experimental conditions) paired with ground-truth negative control settings (permuted labels and adversarial noise features).
- **Empirical Superiority**: We demonstrate that FPG planning achieves a 100% negative result detection rate (compared to 40% for standard procedural planners, p = 0.0108) and eliminates false positive success claims (0.0% vs. 60.0%) while significantly improving search iteration efficiency (4.8 vs. 9.0 mean iterations, p = 0.0001) [ARTIFACT:art_1h6punYk8OrQ].


# Related Work

Our research intersects with three primary domains: automated scientific discovery, LLM agent planning and self-correction, and computational philosophy of science.

### Automated Scientific Discovery Systems
Fully automated scientific discovery has advanced rapidly with the advent of frontier large language models. Systems such as The AI Scientist [2] demonstrated end-to-end automation of idea generation, experiment execution, and manuscript drafting in machine learning. However, subsequent analyses highlighted pervasive failure modes, including hallucinated evaluation metrics, confirmation bias, and unchecked persistence down failed experimental trajectories. While prior engineering efforts have focused on improving code generation robustness [8] or expanding search spaces, they retain procedural task list planning paradigms that lack intrinsic mechanisms for recognizing negative results.

### Agent Planning and Self-Correction
Planning in LLM agents has evolved from static linear prompting to dynamic tree-of-thought search [9], reflection loops [10], and programmatic feedback integration [11]. Frameworks like Reflexion [10] leverage verbal reinforcement learning to critique agent trajectories. However, verbal critique alone remains highly susceptible to confirmation bias when the agent's underlying objective function rewards positive task completion rather than epistemic truth. Our work diverges by shifting from post-hoc verbal critique to structural refutation constraints embedded directly within the plan topology.

### Popperian Falsification in Computational Reasoning
The application of Karl Popper's philosophy of science [5] to computational systems has inspired several theoretical and empirical frameworks [12]. Recently, POPPER [7] proposed an agentic framework for validating free-form hypotheses using sequential falsification experiments. While POPPER operates post-hoc on external hypotheses, our approach integrates structural falsifiability upstream into the research planning phase, governing agent execution trajectories and enabling real-time negative control validation.


# Falsifiable Prediction Graphs: Architecture and Formalization

### Preliminaries and Problem Formulation
Let an automated research discovery task be defined by a research goal $\mathcal{G}$, a dataset $\mathcal{D}$, and an agent execution environment $\mathcal{E}$. In a standard procedural planner, the research plan $P_{\text{proc}} = [s_1, s_2, \dots, s_n]$ is a sequence of procedural instructions executed sequentially. The agent evaluates success based on whether the terminal performance metric $M(\mathcal{E}(s_n))$ exceeds a heuristic threshold $\tau$. When faced with a flawed hypothesis or a negative control dataset, the agent frequently rationalizes sub-threshold performance as noise, resulting in false positive success claims.

### Falsifiable Prediction Graph (FPG) Definition
A Falsifiable Prediction Graph $G = (V, E, \Phi)$ is a directed acyclic graph where:
1. **$V$** represents experimental nodes (e.g., baseline establishment, hyperparameter tuning, architectural modification).
2. **$E$** represents conditional execution dependencies.
3. **$\Phi$** is a set of explicit quantitative refutation predicates associated with each node $v \in V$.

Formally, every experimental node $v_i$ is tupled with a refutation predicate $\phi_i = (\text{Metric}, \text{Threshold}, \text{Direction}, \text{NegativeControlTest})$. For example, a refutation predicate might specify: \"If the validation accuracy delta over baseline is $< +0.01$ or if negative control feature permutation yields $< 5\%$ performance drop, reject hypothesis $H_i$ as a negative result.\"

### Execution Protocol and Negative Control Validation
During pipeline execution, the FPG planner evaluates refutation predicates $\Phi$ at each graph juncture. If an experimental outcome triggers a refutation condition $\phi_i$, the graph dynamically halts traversal along that branch, logs a structured negative result, and triggers backtracking or search space pruning. Furthermore, FPGs mandate an early **Negative Control Validation** step: before investing computational budget in complex method development, the agent executes the proposed methodology against a randomized or adversarially corrupted version of the dataset. A valid method must fail on the negative control; if the agent claims success on the negative control, the planning pipeline flags a confirmation bias violation and aborts the trajectory.


# Experimental Methodology & Benchmark Suite

To rigorously test our hypothesis, we constructed the **Agent Falsifiability Benchmark Suite** [ARTIFACT:art_A_97AHCsuvAa], comprising 10 diverse empirical machine learning research tasks spanning regression, binary classification, multi-class classification, and synthetic non-linear modeling. Each research task is instantiated in three distinct experimental settings:
1. **True Positive Condition**: A valid methodological improvement expected to yield genuine performance gains.
2. **Negative Control Condition (Permuted Labels)**: Target labels are randomly permuted, ensuring that any claimed performance improvement is a statistical artifact or agent hallucination.
3. **Negative Control Condition (Adversarial Noise)**: Input features are replaced with Gaussian noise, removing true signal.

### Evaluated Architectures
We compared two automated agent planning architectures:
- **Standard Procedural Planner**: Executes linear task lists without refutation criteria, relying on LLM post-hoc summarization to determine success or failure.
- **Falsifiable Prediction Graph Planner (Our Approach)**: Enforces structured causal dependency graphs equipped with explicit mandatory refutation criteria and early negative control validation tests.

### Evaluation Metrics
We operationalized four primary evaluation metrics:
- **Negative Result Detection Rate**: The proportion of negative control tasks correctly identified as failed/null results rather than misinterpreted as successes.
- **False Positive Rate**: The proportion of negative control tasks incorrectly reported as successful methodological breakthroughs (hallucinated success rate).
- **Search Iteration Efficiency**: The mean number of execution iterations required by the agent to resolve the research task.
- **Classification Performance**: Precision, Recall, and F1-score of the agent pipeline in distinguishing true positive research outcomes from negative controls.


# Results & Empirical Evaluation

We executed both planning architectures across the 30 evaluation task instances (10 base tasks $\times$ 3 conditions). The empirical results decisively confirm our hypothesis [ARTIFACT:art_1h6punYk8OrQ].

### Negative Result Detection and False Positive Elimination
As summarized in Table 1 and Figure 2, the Falsifiable Prediction Graph planner achieved a **100% Negative Result Detection Rate** ($1.00 \pm 0.00$), correctly identifying all negative control tasks as failures. In sharp contrast, the standard procedural planner achieved only a **40% Negative Result Detection Rate** ($0.40 \pm 0.15$) [ARTIFACT:art_1h6punYk8OrQ], frequently succumbing to confirmation bias by rationalizing permuted-label success or ignoring anomalous metric drops.

| Planning Architecture | Negative Result Detection Rate $\uparrow$ | False Positive Rate $\downarrow$ | Mean Search Iterations $\downarrow$ | F1-Score $\uparrow$ |
| :--- | :---: | :---: | :---: | :---: |
| **Standard Procedural Planner** | $0.40 \pm 0.15$ | $0.60 \pm 0.15$ | $9.0 \pm 1.2$ | $0.52 \pm 0.11$ |
| **Falsifiable Prediction Graph (Ours)** | **$1.00 \pm 0.00$** | **$0.00 \pm 0.00$** | **$4.8 \pm 0.8$** | **$1.00 \pm 0.00$** |
| *Statistical Significance ($p$-value)* | $p = 0.0108^*$ | $p = 0.0108^*$ | $p = 0.0001^{**}$ | $p < 0.001^{**}$ |

Table 1: Quantitative comparison between Standard Procedural Planners and Falsifiable Prediction Graph Planners across 10 benchmark tasks (30 experimental conditions). Asterisks denote statistical significance via Fisher's exact test ($^^* p < 0.05$, $^{**} p < 0.001$) [ARTIFACT:art_1h6punYk8OrQ].

[FIGURE:fig2]

Furthermore, while the standard procedural planner exhibited a **60% False Positive Rate** on negative controls—hallucinating methodological success on randomized data—the FPG planner achieved a **0.0% False Positive Rate** [ARTIFACT:art_1h6punYk8OrQ]. Fisher's exact test confirms this performance delta is statistically significant ($p = 0.0108$) [ARTIFACT:art_1h6punYk8OrQ].

### Search Iteration Efficiency
Embedding structural refutation criteria and early negative control validation did not incur computational overhead; rather, it dramatically improved search efficiency. As shown in Figure 3, the FPG planner converged in a mean of **4.8 iterations**, compared to **9.0 iterations** for the standard procedural planner [ARTIFACT:art_1h6punYk8OrQ]. This reduction ($p = 0.0001$, Mann-Whitney U test) [ARTIFACT:art_1h6punYk8OrQ] occurs because early negative control failure triggers immediate branch pruning, preventing the agent from wasting iterations tuning hyperparameters on dead-end trajectories.

[FIGURE:fig3]

### Domain-Wise Robustness Analysis
To verify consistency, we analyzed performance across distinct machine learning domains (Regression, Binary Classification, Multi-class Classification, and Synthetic Non-linear Modeling). As illustrated in Figure 4, the FPG planner maintained 100% negative result detection across all four domains, whereas the procedural planner's detection rate fluctuated between 25% and 50%, demonstrating that confirmation bias is a pervasive cross-domain vulnerability in unconstrained agent planning.

[FIGURE:fig4]


# Discussion

### Why Procedural Planners Fail
Our findings illuminate why traditional LLM agent planners fail in empirical research tasks. Language models trained on scientific literature and code repositories are conditioned to emulate successful outcomes. When an agent executes an experiment that yields null results (e.g., accuracy near random chance on permuted labels), its parametric memory associates the code execution with \"finishing a task,\" prompting the LLM to generate narrative justifications (e.g., \"the model successfully completed training and evaluated the dataset\") rather than recognizing epistemic refutation.

### The Power of Popperian Constraints
Falsifiable Prediction Graphs resolve this pathology by decoupling execution completion from hypothesis validation. By encoding refutation criteria $\Phi$ as explicit logical predicates evaluated programmatically rather than narratively, FPGs compel the agent to treat negative outcomes as primary feedback signals. This operationalizes Popper's dictum that genuine science is defined not by verification, but by persistent exposure to potential falsification.

### Limitations
While FPGs successfully eliminate confirmation bias in automated research tasks, several limitations remain:
1. **Threshold Sensitivity**: Constructing precise quantitative refutation thresholds ($\tau$) requires domain-specific heuristics. Overly strict thresholds may trigger false refutations on valid methods with high variance.
2. **Graph Expressivity**: Highly exploratory research tasks involving paradigm shifts or unsupervised discovery may not easily conform to static directed acyclic prediction graphs.
3. **LLM Planning Overhead**: Generating comprehensive refutation predicates increases prompt complexity and initial planning token consumption.


# Conclusion & Future Work

In this paper, we introduced Falsifiable Prediction Graphs (FPGs), a novel agent planning architecture that integrates Popperian falsification and negative control validation into automated scientific discovery workflows. Through rigorous evaluation across a 30-task machine learning benchmark suite, we demonstrated that FPGs achieve a 100% negative result detection rate, eliminate false positive success claims on negative controls, and significantly improve search efficiency compared to standard procedural planners [ARTIFACT:art_1h6punYk8OrQ].

Future work will explore dynamic, self-evolving falsification graphs that adapt refutation thresholds based on real-time task complexity, as well as scaling FPGs to multi-agent collaborative discovery systems.

# References

[1] Lu, C., Lu, C., Lange, R. T., Foerster, J. N., Clune, J., & Ha, D. (2024). The AI Scientist: Fully automated scientific discovery. *arXiv preprint arXiv:2408.06292*.
[2] Huang, T., Zhang, Y., & Wang, L. (2025). POPPER: Agentic hypothesis validation through sequential falsification. *Journal of Automated Scientific Reasoning*, 3(2), 112-128.
[3] Popper, K. (1959). *The Logic of Scientific Discovery*. Hutchinson.
[4] Wang, Z., Cai, S., Liu, A., Wang, Y., & Liang, X. (2023). Describe, explain, select and evaluate: Interactive planning for large language model agents. *Advances in Neural Information Processing Systems*, 36.
[5] Shinn, N., Cassano, B., Labash, E., Gopinath, A., Narasimhan, K., & Yao, S. (2023). Reflexion: Language agents with verbal reinforcement learning. *Advances in Neural Information Processing Systems*, 36.
[6] Yao, S., Yu, D., Zhao, J., Shafran, I., Griffiths, T., Cao, Y., & Narasimhan, K. (2023). Tree of thoughts: Deliberate problem solving with large language models. *Advances in Neural Information Processing Systems*, 36.

</current_paper>

<reviewer_feedback>
Feedback from the paper reviewer this iteration.

- [MINOR] (methodology) The evaluation assesses agent planning performance using a controlled benchmark task suite rather than live end-to-end LLM agent trajectories with code execution.
  Action: Clarify the simulation setup in the methodology section or include a supplementary qualitative walkthrough of a live LLM agent encountering a negative control under FPG planning.
- [MINOR] (rigor) The paper mentions threshold sensitivity as a limitation but lacks quantitative ablation or sensitivity analysis on how varying the refutation threshold affects performance.
  Action: Add a sensitivity analysis figure or table showing false positive and false negative rates across a range of threshold values.
- [MINOR] (novelty) Discussion of related work on post-hoc self-correction is somewhat brief regarding how structural graphs prevent recursive rationalization compared to verbal prompt feedback.
  Action: Expand the related work section to explicitly contrast programmatic predicate evaluation against verbal LLM self-critique loops.
</reviewer_feedback>



<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for the field's landscape, prior work, crowded lanes, and the novelty bar — consult it while revising so the updated hypothesis stays genuinely novel and well-positioned.

- **aii-handbook-auto-computational-linguistics** — Verified field handbook for computational linguistics as a SCIENCE of language (not NLP engineering).
- **aii-handbook-auto-mechanistic-interpretability** — Verified field handbook for mechanistic-interpretability research.
- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
- **aii-handbook-auto-neurosymbolic** — Verified field handbook for neuro-symbolic AI research (LLM+solver, autoformalization, text2logic).
</available_domain_handbooks>

<task>
IMPORTANT: Your ONLY output is the revised hypothesis text. Do NOT run code, produce artifacts,
fix bugs, or attempt to address the evidence yourself — the next iteration of the invention loop
will generate fresh artifacts based on your revised hypothesis. Reflect and rewrite; nothing else.

Do NOT generate a completely new hypothesis. Take the current hypothesis and REVISE it
to incorporate new evidence. Keep the core idea — refine, narrow, or strengthen it.

1. Does the evidence support the hypothesis? Narrow or broaden scope as needed.
2. Which claims now have strong evidence? Which are still unsupported?
3. Should the hypothesis become more specific based on what we've learned?
4. If reviewer feedback is provided, address the critiques directly.

STABILITY IS OK: If progress is good and evidence supports the current direction, keep the
hypothesis similar or identical. Only make substantive changes when evidence clearly calls for
them — e.g., contradictory results, fundamental reviewer critiques, or findings that refine scope.

You must also classify two kinds of edges in the research trace:

(A) The H↔H edge — how does this revised hypothesis relate to the previous one?
    Set `relation_type` (Moulines's structuralist typology) to one of:
    - "evolution": refining specialised claims, same conceptual frame
    - "embedding": previous hypothesis is now a special case of a broader frame
    - "replacement": rejecting the previous frame entirely (Kuhnian shift)
    Set `relation_rationale` to a brief justification (≤120 chars).

(B) The A↔A edges — for each artifact created THIS iteration, classify each of its
    `in_dependencies` (predecessor → dependent) using MultiCite's citation-function
    typology (Lauscher et al., NAACL 2022) — emit one entry in `artifact_relations`
    per (predecessor, dependent) pair. Predecessors are ALWAYS artifacts from EARLIER
    iterations — artifacts within one iteration run in parallel and cannot depend on
    each other, so never emit a relation between two same-iteration artifacts (it
    will be dropped):
    - "background": predecessor is treated as background context
    - "motivation": predecessor motivated this artifact's research
    - "uses": this artifact uses the predecessor's data, method, or output
    - "extends": this artifact extends the predecessor
    - "similarities": this artifact's results agree with the predecessor's
    - "differences": this artifact's results disagree with the predecessor's
    Each `relation_rationale` must be ≤120 characters.

Output the COMPLETE revised hypothesis (with the H↔H relation fields) AND the full
list of A↔A `artifact_relations` for this iteration's new artifacts.
</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_hryee3iKb6FG/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/upd_hypo/upd_hypo/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "ArtifactRelation": {
      "description": "One typed A\u2194A edge between a dependent artifact and one of its in_dependencies.\n\nMultiCite citation-function typology (Lauscher et al., NAACL 2022),\nreduced to 6 plain-English types.",
      "properties": {
        "from_id": {
          "description": "ID of the predecessor artifact (the one being depended on)",
          "title": "From Id",
          "type": "string"
        },
        "to_id": {
          "description": "ID of the dependent artifact (the new artifact this iteration)",
          "title": "To Id",
          "type": "string"
        },
        "relation_type": {
          "description": "MultiCite citation-function type for the predecessor\u2192dependent edge: 'background' \u2014 predecessor is treated as background context; 'motivation' \u2014 predecessor motivated this artifact's research; 'uses' \u2014 this artifact uses the predecessor's data, method, or output; 'extends' \u2014 this artifact extends the predecessor; 'similarities' \u2014 this artifact's results agree with the predecessor's; 'differences' \u2014 this artifact's results disagree with the predecessor's.",
          "enum": [
            "background",
            "motivation",
            "uses",
            "extends",
            "similarities",
            "differences"
          ],
          "title": "Relation Type",
          "type": "string"
        },
        "relation_rationale": {
          "description": "Brief rationale for this relation type (one short line, max 120 characters).",
          "maxLength": 120,
          "title": "Relation Rationale",
          "type": "string"
        }
      },
      "required": [
        "from_id",
        "to_id",
        "relation_type",
        "relation_rationale"
      ],
      "title": "ArtifactRelation",
      "type": "object"
    }
  },
  "description": "Revised hypothesis after reviewing iteration results.\n\nOutput matches the hypothesis dict structure so it can replace the\noriginal hypothesis in subsequent iterations.",
  "properties": {
    "title": {
      "description": "Revised hypothesis title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters); may be unchanged if still accurate.",
      "title": "Title",
      "type": "string"
    },
    "hypothesis": {
      "description": "Revised hypothesis statement \u2014 what we now believe based on evidence",
      "title": "Hypothesis",
      "type": "string"
    },
    "relation_rationale": {
      "description": "Brief rationale for the H\u2194H revision type (one short line, max 120 characters).",
      "maxLength": 120,
      "title": "Relation Rationale",
      "type": "string"
    },
    "confidence_delta": {
      "description": "How confidence changed: 'increased', 'decreased', or 'unchanged'",
      "title": "Confidence Delta",
      "type": "string"
    },
    "key_changes": {
      "description": "Bullet list of specific changes made to the hypothesis",
      "items": {
        "type": "string"
      },
      "title": "Key Changes",
      "type": "array"
    },
    "relation_type": {
      "description": "Moulines's structuralist typology of this hypothesis revision: 'evolution' \u2014 refining specialised claims while keeping the same conceptual frame; 'embedding' \u2014 the previous hypothesis is now a special case of a broader frame; 'replacement' \u2014 rejecting the previous frame entirely (incommensurable, Kuhnian revolution).",
      "enum": [
        "evolution",
        "embedding",
        "replacement"
      ],
      "title": "Relation Type",
      "type": "string"
    },
    "artifact_relations": {
      "description": "Typed A\u2194A edges for this iteration's new artifacts. Emit one entry per (predecessor \u2192 dependent) edge for every in_dependency on each artifact produced this iteration.",
      "items": {
        "$ref": "#/$defs/ArtifactRelation"
      },
      "title": "Artifact Relations",
      "type": "array"
    }
  },
  "required": [
    "title",
    "hypothesis",
    "relation_rationale",
    "confidence_delta",
    "key_changes",
    "relation_type"
  ],
  "title": "RevisedHypothesis",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_hryee3iKb6FG/3_invention_loop/iter_1/upd_hypo/upd_hypo/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-08-09 21:50:45 UTC

```
Examine whether structuring a research plan as explicit falsifiable predictions improves the rate at which an automated pipeline detects its own negative results.
```
