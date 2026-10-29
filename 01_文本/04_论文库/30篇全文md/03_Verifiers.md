---
title: "The Art of Building Verifiers for Computer Use Agents"
arxiv_html: https://arxiv.org/html/2604.06240v1
downloaded: 2026-10-29
converted: arxiv LaTeXML HTML -> Markdown（本地图片 + alttext 公式还原）
---

# The Art of Building Verifiers for Computer Use Agents

- **Corby Rosset** · Microsoft Research · corbyrosset@microsoft.com
- **Pratyusha Sharma** · Microsoft Research · pratysharma@microsoft.com
- **Andrew Zhao** · Microsoft Research · andrewzhao@microsoft.com
- **Miguel Gonzalez-Fernandez** · Browserbase · ahmed.awadallah@microsoft.com
- **Ahmed Awadallah** · Microsoft Research

###### Abstract

Verifying the success of computer use agent (CUA) trajectories is a critical challenge: without reliable verification, neither evaluation nor training signal can be trusted. In this paper, we present lessons learned from building a best-in-class verifier for web tasks we call the Universal Verifier.
We design the Universal Verifier around four key principles: 1) constructing rubrics with meaningful, non-overlapping criteria to reduce noise; 2) separating process and outcome rewards that yield complementary signals, capturing cases where an agent follows the right steps but gets blocked or succeeds through an unexpected path; 3) distinguishing between controllable and uncontrollable failures scored via a cascading-error-free strategy for finer-grained failure understanding; and 4) a divide-and-conquer context management scheme that attends to all screenshots in a trajectory, improving reliability on longer task horizons.
We validate these findings on CUAVerifierBench, a new set of CUA trajectories with both process and outcome human labels, showing that our Universal Verifier agrees with humans as often as humans agree with each other. We report a reduction in false positive rates to near zero compared to baselines like WebVoyager ( $\geq$ 45%) and WebJudge ( $\geq$ 22%). We emphasize that these gains stem from the cumulative effect of the design choices above. We also find that an auto-research agent achieves 70% of expert quality in 5% of the time, but fails to discover all strategies required to replicate the Universal Verifier. We open-source our Universal Verifier system along with CUAVerifierBench11
1
Code and Data will be available at <https://github.com/microsoft/fara>.

|  |
| --- |
|  |

![](images/03_Verifiers/kappa_progression_outcome.svg)


Figure 1: We compare whether an auto-research system can design a CUA trajectory verifier as well as the expert human-designed Universal Verifier, as measured in agreement with human labels. The human expert iterated over 32 experiments across three weeks; the auto-research agent completed the same in roughly one day. Qualitatively, auto-research edits tended to be conservative and incremental, missing the design intuition behind the human’s highest-impact structural decisions (tagged)

## 1 Introduction

The ability of AI agents to operate computers autonomously—browsing the web, filling forms, navigating interfaces—has advanced rapidly [Zhou et al. (2024)](#bib.bib3); [He et al. (2024a)](#bib.bib4); [Zheng et al. (2024)](#bib.bib5); [Koh et al. (2024)](#bib.bib6); [Xie et al. (2024)](#bib.bib7); [OpenAI (2025)](#bib.bib8); [Agashe et al. (2025)](#bib.bib9); [Awadallah and others (2025)](#bib.bib10); [Gupta and others (2026)](#bib.bib11). Yet progress in training and evaluating these systems is bottlenecked by a deceptively difficult question: *did the agent actually succeed?* Unlike text generation tasks where outputs can be compared directly, computer use trajectories are long, visually rich, and ambiguous, making human annotation both challenging and expensive. The notion of success itself is nuanced: a task may be partially completed; success may be achieved through unexpected paths; and failures may be subtle, appearing only transiently in a screenshot buried deep in a multi-step interaction. Building a verifier that reliably answers this question is far from straightforward—and the consequences of getting it wrong compound, corrupting both benchmarks and training data.

In this paper, we document the lessons learned from building a verifier for computer use agents, structured as a set of actionable design principles. Our approach rests on four core ideas. First, a good verifier requires well-designed rubrics with specific, non-overlapping criteria that enable consistent scoring across diverse tasks. Second, it must report both process and outcome rewards—these provide complementary signals that differ primarily in whether the environment prevented success despite correct agent behavior, or allowed success via an unexpected but valid path. Third, it must distinguish controllable failures from uncontrollable ones and score trajectories with a cascading-error-free rubric, so that a single early obstacle does not unfairly penalize all downstream steps. Fourth, it must attend effectively to all screenshot evidence in a trajectory, not just the most recent frames; longer tasks contain critical state changes that are systematically missed when context is truncated.

To support rigorous evaluation of these principles, we release CUAVerifierBench, a benchmark of human-labeled CUA trajectories. To our knowledge, CUAVerifierBench is the first benchmark designed specifically to measure verifier quality for both process and outcome rewards, enabling the community to compare verifier alignment with human judgment in a standardized way. We show that our verifier—which we call the *Universal Verifier*—substantially improves alignment with human labels over existing WebJudge, WebVoyager as measured by Cohen’s $\kappa$ , while reducing false positive rates from 30%+ to 1-8%.

Crucially, building a high-quality verifier is not a one-shot problem but an iterative development process, and this process is only possible when grounded in a reliable evaluation procedure. CUAVerifierBench serves exactly this role: each candidate verifier design can be scored against human judgments using Cohen’s $\kappa$ , providing a clear and immediate signal for what works and what does not. Figure [1](#S0.F1) traces this iterative journey over 96 experiments. The expert-designed verifier begins with near-zero agreement and steadily improves through principled experimentation, reaching $\kappa\approx 0.7$ by experiment 32 as the four design principles are incrementally discovered and integrated.

We also explored whether an automated research agent could replicate this process. Starting from a blank slate, the auto-research-designed verifier follows a similar upward trend but consistently underperforms, with $\kappa$ plateauing around $0.55$ —roughly 70% of expert-level quality. Qualitatively, the auto-research agent’s edits tended to be conservative and incremental, struggling to encode the kind of evaluative judgment behind the large structural changes that drove the expert-designed verifier’s step-function improvements. However, when initialized from the expert’s best verifier configuration, the auto-research agent surpasses the expert-designed peak, suggesting that human expertise and automated optimization play complementary roles: the former is essential for discovering core design principles, while the latter excels at the fine-grained tuning that extracts remaining performance.

In summary, our contributions are as follows: (1) We identify and validate four design principles for building reliable CUA verifiers, showing that their cumulative effect yields a verifier that agrees with humans as often as humans agree with each other. (2) We release CUAVerifierBench, the first benchmark specifically designed to evaluate verifier quality for computer use agents, providing the community with a standardized way to measure verifier alignment with human judgment.

## 2 Background and Related Work

Several systems have been proposed for automatically evaluating CUA, differing primarily in what inputs they consume and whether they rely on prompted LLMs or trained models. WebVoyager ([He et al., 2024b](#bib.bib12)) uses a GPT-4V-based evaluator that receives all trajectory screenshots (but not all action history) alongside the agent’s stated final answer to produce a binary outcome judgment. Validated against human annotations on 300 tasks, the GPT-4V variant achieves 85.3% agreement ( $\kappa{=}0.70$ ), matching human inter-annotator agreement. WebJudge ([Xue et al., 2025](#bib.bib32)) addresses two known failure modes of this approach: reliance on the agent’s potentially hallucinated final answer, and token overload from passing all screenshots unfiltered. It employs a three-step pipeline that first extracts key points from the task description, scores each screenshot for relevance, and judges success using only the top- $k$ selected screenshots and the full action history. Under the same evaluation setting, WebJudge (o4-mini) achieves 85.7% human-agreement compared to 78.7% for WebVoyager.

Shifting from outcome prediction to failure diagnosis, AgentRx ([Barke et al., 2026](#bib.bib2)) identifies the *critical failure step* and assigns it a root cause from a nine-category taxonomy.

AgentRewardBench ([Lù et al., 2025](#bib.bib14)) provides 1,302 expert-annotated trajectories across five benchmarks (WebArena ([Zhou et al., 2023](#bib.bib24)), VisualWebArena ([Koh et al., 2024](#bib.bib6)), AssistantBench ([Yoran et al., 2024](#bib.bib25)), WorkArena ([Drouin et al., 2024](#bib.bib26)), WorkArena++ ([Boisvert et al., 2024](#bib.bib27))) and four agent LLMs (GPT-4o ([OpenAI, 2024](#bib.bib28)), Claude 3.7 Sonnet ([Anthropic, 2025](#bib.bib29)), Llama-3.3-70B ([Grattafiori et al., 2024](#bib.bib30)), and Qwen2.5-VL ([Bai et al., 2025](#bib.bib31))). They introduce a Simplified Judge that, in a single LLM completion, predicts three binary labels—task success, side effects, and repetition cycles.
Their key finding is that no LLM-based judge exceeds 70% precision: including NNetNav ([Murty et al., 2025](#bib.bib15)) and AER ([Pan et al., 2024](#bib.bib16)).
Human inter-annotator agreement was 89.3%.

Several works debated whether process or outcome rewards are more effective for scenarios such as solving math problems ([Lightman et al., 2023](#bib.bib13); [Uesato et al., 2022](#bib.bib18));  [Wang et al. (2024)](#bib.bib19) trains their own process reward model.  [Zhang et al. (2025b)](#bib.bib21) distill lessons for building process verifiers for math. Others extend to agentic RAG domains ([Zhang et al., 2025a](#bib.bib22)). We refer the reader to additional surveys ([Zheng and others, 2025](#bib.bib23); [Stuhlmüller and Byun, 2022](#bib.bib17)).

## 3 What is True of Good Verifiers?

| Verifier | LLM | Rubric | Screenshots | Action hist. | Final ans. |
| --- | --- | --- | --- | --- | --- |
| WebJudge (OM2W) | o4-mini | ✗ Not used | ✓ Top- $k$ most relevant | ✓ Full | ✗ |
| (scored 1–5, kept if |  |  |  |  |  |
| $\geq$ threshold; capped at 5) |  |  |  |  |  |
| WebVoyager GPT eval | gpt-4o | ✗ Not used | ✓ All screenshots | ✗ | ✓ |
| (last $N$ if over limit; |  |  |  |  |  |
| default $N{=}30$ ) |  |  |  |  |  |
| Universal Verifier (Ours) | gpt-5.2 | ✓ Per-task | ✓ Top- $k$ most | ✓ Full | ✓ |
| success criteria | relevant per criterion |  |  |  |  |

Table 1: Comparison of different computer use trajectory verifiers’ characteristics

We distill principles we believe are critical to the construction of a reliable verifier based on our extensive hands-on experience with CUA trajectory logs.

### 3.1 Good Rubrics have Specific and Non-Overlapping Criteria

The root of the pipeline is rubric generation: flawed rubrics produce errors that cascade through the pipeline and cannot be easily corrected downstream.
Anecdotally, Figure [1](#S0.F1) shows that the good rubric design *alone* accounted for roughly half of the Cohen’s $\kappa$ gains.
Through iterative development, we identified four systematic failure modes and corresponding fixes:

1. 1.

   Phantom criteria. LLM-generated rubrics frequently introduce requirements never stated in the task (e.g., in Appendix [A.2](#A1.SS2), Table [4](#A1.T4)), inflating the denominator and over-penalizing agents that completed the actual task.
2. 2.

   Cascading errors. When rubric criteria are not logically independent, a single upstream error propagates into downstream criteria, multiplying the point penalty.
3. 3.

   Separate Generation and Scoring Generating the rubric and scoring it in a single LLM call leads the model to create criteria tailored to the agent’s behavior. We separate rubric generation (from the task alone, without seeing the trajectory) from scoring.
4. 4.

   Hallucination detection. We score the whole rubric in two passes—with and without evidence from the relevant screenshots—to surface discrepancies.
5. 5.

   Conditional Criteria: Some criteria may not apply depending on reality (e.g., *“buy organic blueberries, or if unavailable, buy non-organic”*). Hence, at rubric-generation time, we mark some criteria as “conditional” to be updated once the task is attempted. Conditions that are not met are excluded, ensuring that mutually exclusive criteria do not interfere. See Appendix [A.2](#A1.SS2), Table [5](#A1.T5) for details and examples.

The remaining sub-sections discuss the scoring of rubrics. Sometimes, the rubric is modified for e.g. updating conditional criteria, or adding new criteria for unsolicited side-effects.

### 3.2 Separate Process and Outcome Rewards

In computer use settings, the environment plays an out-sized role in the success of a task, especially if an agent is blocked or can’t access necessary resources. Hence, a central design principle of our verification framework is the separation of *how well the agent executed* in the context of the environment from *whether the user’s goal was achieved*. These two questions have fundamentally different answers in many real-world scenarios, and conflating them leads to reward signals that are either too lenient (crediting agents for apparent effort when the user is left empty-handed) or too harsh (penalizing agents for factors outside their control).
We formalize this separation through two
two independent signals per trajectory: a process reward (a fine-grained rubric whose score reflects execution across sub-goals) and an outcome reward (a binary success/failure judgment on whether the goal was achieved).

##### Process Label (Rubric Score):

This is a scored rubric of criteria, each of which is weighted by a maximum number of earnable points. It is reported as a normalized score from 0.0 to 1.0 reflecting how well the agent executed each sub-goal of the task. It is computed as:

|  | 

$$
r_{\text{proc}}=\frac{\sum_{i\in\mathcal{A}}\text{earned\_points}_{i}}{\sum_{i\in\mathcal{A}}\text{max\_points}_{i}}
$$

 |  | (1) |
| --- | --- | --- | --- |

where $\mathcal{A}$ is the set of *applicable* rubric criteria—those whose conditions are met (for conditional criteria) or that are unconditional. The process label evaluates the quality of the agent’s execution at each step, independent of whether those steps ultimately produced a successful outcome. While it is technically a scalar score, the rubric also contains specific justifications as to why points were earned or lost based on evidence from the full action history and screenshots.
An agent that, for example, navigated to the correct product, and but was blocked by a login wall before it could add-to-cart would full process credit, even though the user’s goal was not achieved. Example rubrics can be seen in Figures [2](#A1.F2), and [3](#A1.F3).

##### Outcome Label (Binary Success/Failure)

The outcome label is a binary yes/no judgment answering: would a reasonable user consider the task done? This is evaluated from the perspective of a user who issued the task and is examining the end state. This is intrinsically challenging, because users may have different notions of success under ambiguity (e.g. is it acceptable to omit NeurIPS’s secondary venue in Mexico City when asked *“where is NeurIPS 2025 being hosted?”*) and different preferences as for what constraints are strict vs flexible (e.g. is ok to book a table using opentable.com when the user asked to use resy.com?).

In order to make progress, we assume that the outcome label should focus on *primary intent* – if the primary intent is to book a table, then the user would be flexible on which platform it is booked unless otherwise stated. We also believe most users are forgiving of nitpicks like rounding $5.95 to $6, etc. However, we assume users would *not* be forgiving of unsolicited side-effects e.g. buying a warranty when they only wanted to buy the product itself, or hallucinations like those described in Table [7](#A1.T7). We summarize the process and outcome rewards for computer use scenarios in Table [6](#A1.T6) – notice they only disagree in the second row.

### 3.3 Discern Controllable vs. Uncontrollable Factors

Since the main difference between a trajectory being a process success but an outcome failure involves the environment, we explicitly define which of these aspects are controllable vs. uncontrollable from the perspective of the agent. Each rubric’s criteria description fields attempt to anticipate these factors and give guidance on how to award partial credit.

Uncontrollable factors: Conditions beyond the agent’s control; *not* penalized in *process*.

- •

  Platform/infrastructure issues: CAPTCHA, login walls without credentials, etc.
- •

  Entity non-existence: product discontinued, business closed, service not available.
- •

  Availability constraints: out of stock, no reservations on requested date, sold out.
- •

  Search result limitations: no results matching all specified criteria.

Controllable factors: Avoidable mistakes the agent *should* be penalized for in *process*.

- •

  Intent Mis-match: Choosing an entirely wrong product, location, person, service, etc.
- •

  Reasoning Errors: Incorrect reasoning about the task e.g. Figure [4](#A1.F4).
- •

  Hallucinations: claiming success without evidence, fabricating information.
- •

  Insufficient effort: giving up after a single failed attempt.
- •

  Execution errors: not using available filters, skipping required steps.

### 3.4 Effective Context Management of Screenshot Evidence

Our main contribution is a verifier designed to combat hallucinations22
2
We define the anatomy of hallucinations Section [A.5](#A1.SS5), Table [7](#A1.T7), and give an example in Figure [5](#A1.F5) through better management of visual screenshot evidence. Both WebVoyager ([He et al., 2024b](#bib.bib12)) and WebJudge ([Xue et al., 2025](#bib.bib32)) assess a large amount of screenshots in one LLM context window – WebVoyager includes all screenshots, whereas WebJudge ranks the top $~\approx 30-50$ . Other verifiers only analyze the last ones ([Pan et al., 2024](#bib.bib16)). Too many screenshots over-exerts the LLM by forcing it to solve a needle-in-a-haystack problem, which scales poorly with longer trajectories, whereas restricting to the last few risks missing task-relevant evidence.
To address these problems, our design scores each screenshot against every rubric criterion to produce a relevance matrix, grouping the top- $k$ most relevant *per criterion* to send for further analysis, which is both more scalable to longer trajectories and more focused. We elaborate on our screenshot-scoring design in Appendix [A.3.1](#A1.SS3.SSS1) with an example in Figure [6](#A1.F6).

### 3.5 Unsolicited Side-Effects

Extraneous actions with material side effects—such as adding unrequested items to a cart (e.g. see Figure [7](#A1.F7)) or enrolling in unrequested services—constitute often cannot be anticipated before the task is attempted because rubrics are not designed to enumerate all the ways a task can go wrong. To catch such cases, a dedicated pass over a trajectory is needed. While unsolicited side-effects almost always result in outcome failure, they only partially penalize the process score, weighted by how serious the side-effect is.

## 4 Universal Verifier System

We model a computer use task as a tuple $(g,\mathcal{E})$ , where $g$ is a natural language goal (e.g., “book the cheapest available flight from Seattle to Boston on June 3rd”) and $\mathcal{E}$ is a computer environment with an observable graphical interface. An agent interacts with $\mathcal{E}$ over $T$ discrete timesteps, producing a trajectory $\tau=(s_{0},a_{1},s_{1},a_{2},\ldots,a_{T},s_{T})$ , where $s_{t}\in\mathcal{S}$ is a screenshot observation at time $t$ and $a_{t}\in\mathcal{A}$ is an action (e.g., click, type, scroll). The length $T$ varies across tasks from a handful of steps for form-filling to hundreds of steps for multi-stage workflows.

We define a verifier as a function $V:(g,\tau)\to\mathcal{R}$ that maps a goal and trajectory to a structured scoring response $r\in\mathcal{R}$ . In the simplest case $\mathcal{R}=\{0,1\}$ (binary success), but we argue and our design reflects—that $\mathcal{R}$ should be richer: a tuple $(r_{\text{proc}},r_{\text{out}},d)$ comprising a process score $r_{\text{proc}}\in[0,1]$ , an outcome score $r_{\text{out}}\in\{0,1\}$ , and a diagnostic report $d$ that classifies and localizes failures within $\tau$ . The process score captures the quality of the agent’s execution, while the outcome score reflects whether the goal $g$ was ultimately satisfied.

The central challenge is that $V$ must operate over the full observation sequence $\{s_{0},\ldots,s_{T}\}$ , which can be long, visually dense, and contain critical state changes at arbitrary timesteps. We define verifier quality as agreement with a human oracle $V^{*}:(g,\tau)\to\mathcal{R}$ , measured by precision, recall, and Cohen’s $\kappa$ over a labeled set of trajectories ([Artstein and Poesio, 2008](#bib.bib1)). A verifier that inspects only $s_{T}$ or a fixed subset $\{s_{t_{1}},\ldots,s_{t_{k}}\}\subset\tau$ is a strict approximation of $V^{*}$ and, as we show empirically, systematically underperforms on trajectories where $T$ is large. Reliable verification therefore requires attending to all $T+1$ observations.

Algorithm 1  Universal Verifier

1:
agent trajectory $\tau$ , observations $\{s_{0},\dots,s_{T}\}$ , user goal $g$

2:
Process score $r_{\text{proc}}$ , Outcome score $r_{\text{out}}$ , diagnostic report $d$

3:
Generate Rubric
$\mathcal{C}=\{c_{1},\dots,c_{N}\}$ of $N$ disjoint, meaningful criteria from $g$ . See [A.2](#A1.SS2)

4:
Multimodal Relevance Scoring.
Score each screenshot against every criterion to produce relevance matrix
$\mathbf{R}\in\mathbb{R}^{(T+1)\times N}$ . See Appendix [A.3.1](#A1.SS3.SSS1) for more details.

5:
Top- $k$ Grouping.
For each $c_{j}$ , select the $k$ most relevant
$\mathcal{S}_{j}\subseteq\{s_{0},\dots,s_{T}\},\;|\mathcal{S}_{j}|\leq k$ .

6:
Evidence Analysis.
For each pair $(c_{j},\,s_{i})$ with $s_{i}\in\mathcal{S}_{j}$ , extract visual evidence $e_{ij}$ .

7:
Conditional Disambiguation.
Resolve conflicts among conditional criteria using $\{e_{ij}\}$ .

8:
Reality Check.
Reconcile rubric assumptions against screenshot evidence;
produce interpretive reality notes and action-only score $r_{\text{proc\_action\_only}}$ .

9:
Multimodal Rescoring.
Rescore $\mathcal{C}$ holistically using screenshot evidence (which takes precedence over agent claims) following Tables [6](#A1.T6) and [7](#A1.T7).

10:
Side-Effect Detection.
Detect and include unsolicited agent actions with material side effects not already penalized by $\mathcal{C}$ , return procedural score $r_{\text{proc}}$ . (see example Figure [7](#A1.F7))

11:
Outcome Verification.
run and return outcome score $r_{\text{out}}$ .

12:
Failure Diagnosis.
Identify and localize all failures points from Table [10](#A1.T10) and return $d$ .

The Universal Verifier (UV) we create incorporates the principles from Section [3](#S3) and operates in three phases: rubric creation, *multimodal scoring* incorporating screenshot evidence to ascertain $r_{\text{proc}}$ , and produce a final outcome judgment $r_{\text{out}}$ , and error diagnosis $d$ as shown in Algorithm [1](#alg1).
The key design invariant is that no relevant screenshot evidence can go undetected in the pipeline, specifically to not miss any hallucinations.
To reduce variance, Steps 7–9 in Algorithm [1](#alg1) can be run as multiple parallel instances, with process score determined by median of rubric scores, and outcome by majority vote.

Finally, we conduct an error analysis on $\tau$ to categorize failure modes and identify the step $t$ at which each failure occurred in a trajectory. We hand-crafted an error taxonomy with 7 categories and 24 subcodes as shown in Table [10](#A1.T10), covering categories such as intent missmatches, hallucinations, critical point violations, etc.

## 5 Experiments

We treat the Universal Verifier as an annotator like any other human, and compute inter-annotator agreements throughout our studies: (1) agreement with human trajectory labels on two independently annotated datasets, (2) agreement between native benchmark verifiers and UV at scale, and (3) an auto-research study exploring whether an AI agent can replace or augment human expertise in verifier design. We describe each experimental setup below.

### CUAVerifierBench: Human-Labeled Datasets

Since the UV’s innovation of verifying both process and outcome labels is novel in the computer use domain, no existing benchmarks provide both labels.

We sampled 140 trajectories from WebTailBench using Fara-7B([Awadallah et al., 2025](#bib.bib36)). In-house expert annotators labeled each trajectory for both process success and outcome success following the guidelines in §[3](#S3). This dataset is used for all ablation studies (§[6](#S6)–[6](#S6)) and the auto-research experiments (§[6](#S6.SS0.SSS0.Px1)). We call this the Internal dataset.

Furthermore, we contracted external annotators managed by Browserbase33
3
<https://www.browserbase.com/> to label 106 trajectories sampled from Fara-7B ([Awadallah et al., 2025](#bib.bib36)) on Online-Mind2Web for both process and outcome success, with $2\times$ annotator overlap per trajectory. Annotators were first calibrated on 10 practice trajectories with gold annotations. They then judged each evaluation trajectory in a two-stage process:
1) UV-blind stage: Annotators saw only the input task, the un-scored rubric criteria, and the agent’s trajectory. They independently judged outcome and process success and provided a continuous rubric score per trajectory.
2) UV-informed stage: Annotators were shown the UV’s outcome verdict and rubric scores, and asked whether they *agreed*/*disagreed* with the UV’s outcome and process.

For task-level aggregation, outcome labels are computed as the majority vote of the annotators’ binary judgments, and process labels are the median of the annotators’ continuous rubric scores, then binarized at a $\geq 0.8$ threshold. Ties are broken by a third.
We report agreement metrics from both stages: *UV-blind* agreement measures how often human judgments independently align with the UV, while *UV-informed* agreement measures how often humans endorse the UV’s verdict after reviewing its reasoning. We further measure inter-annotator agreement, and how often their labels flipped once seeing the UV’s output.

##### Agreement on Canonical Benchmarks’ Verifiers

The human-labeled datasets above are small by design (expert annotation is expensive). To assess verifier behavior at scale, we re-score several agent trajectories across several canonical benchmarks like with Universal Verifier and compute agreement between that benchmark’s “native” verifier and UV. We select three benchmarks – WebVoyager, Online-Mind2Web (OM2W), and WebTailBench – and two agent models – Fara-7B and GPT-5 as a Set-of-Marks Agent ([Yang et al., 2023](#bib.bib20)).

##### Auto-Research Study

The Universal Verifier comprises approximately 3,000 lines of code and 2,000 lines of prompts—including rubric generation templates, scoring instructions, outcome verification logic, and error classification rules—all designed iteratively by a human expert (the first author). To investigate whether an AI agent can replicate or augment this human expertise, we designed an auto-research system using Claude Code v2.1.87 with Claude Opus 4.6 (1M context) on a Claude Max subscription. The system is given the same principles from Section [3](#S3), and reuses the same experimental infrastructure as the human expert (running the UV on the internal set, computing agreement metrics, and committing prompt changes to version control). We evaluate two settings:

- •

  From-blank prompts: All ${\sim}2{,}000$ lines of prompts are replaced with // TODO placeholders, leaving only the code scaffold. The agent is given high-level design principles but no access to prior prompt versions, previous commits, or other branches. A separate compliance agent audits each iteration to prevent memorization of test examples into prompts. The optimization rule is: *maximize Cohen’s $\kappa$ without increasing FPR*; any FPR-increasing change is automatically rolled back.
- •

  Continuing expert work: The agent starts from the human expert’s best prompts and continues with the same optimization objective.

## 6 Results

Agreement with Human Labels: UV vs. Existing Verifiers: In Table [2](#S6.T2) we compare UV against two prominent existing trajectory judges—WebVoyager ([He et al., 2024b](#bib.bib12)) and WebJudge ([Xue et al., 2025](#bib.bib32))—on CUAVerifierBench. The UV substantially outperforms both baselines across nearly every metric on both datasets. On outcome labels, the UV achieves a Cohen’s $\kappa$ of 0.64 (internal) and 0.58 (Browserbase), compared to 0.44/0.26 for WebJudge and 0.31/0.13 for WebVoyager. Strikingly, the UV achieves an FPR near zero (0.01 internal, 0.08 Browserbase) on outcome labels, meaning it almost never credits a trajectory with success when a human annotator would mark it as a failure. A version of this table with standard deviation error bars computed from three independent runs is included in Table [15](#A2.T15).

To test whether the UV’s advantage stems from simply from using a stronger backbone model, we report four additional columns in Table [2](#S6.T2), where we upgrade WebVoyager’s GPT-4o and WebJudge’s o4-mini to GPT-5.2. While this does reduce FPR substantially (e.g., WebVoyager outcome FPR drops from 0.45 to 0.10 on Internal), it also dramatically increases FNR (0.24 $\to$ 0.44), and overall $\kappa$ improves only modestly. We conclude UV’s advantage stems from its screenshot scoring design, not merely from using a stronger model

|  | Internal Dataset ( $n{=}140$ ) |  |  |  |  | Browserbase OM2W ( $n{=}106$ ) |  |  |  |  |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
|  | WebVoy. |  | WebJudge |  | UV | WebVoy. |  | WebJudge |  | UV |
|  | GPT-4o | GPT-5.2 | o4-mini | GPT-5.2 | GPT-5.2 | GPT-4o | GPT-5.2 | o4-mini | GPT-5.2 | GPT-5.2 |
| Agreement with outcome human labels |  |  |  |  |  |  |  |  |  |  |
| Accuracy ( $\uparrow$ ) | $0.67$ | $0.70$ | $0.72$ | $0.64$ | ${0.81}$ | $0.48$ | $0.74$ | $0.64$ | $0.74$ | ${0.88}$ |
| F1 ( $\uparrow$ ) | $0.73$ | $0.69$ | $0.74$ | $0.58$ | ${0.81}$ | $0.35$ | $0.50$ | $0.44$ | $0.46$ | ${0.65}$ |
| Cohen’s $\kappa$ ( $\uparrow$ ) | $0.31$ | $0.43$ | $0.44$ | $0.33$ | $0.64$ | $0.13$ | $0.36$ | $0.26$ | $0.31$ | $0.58$ |
| FNR ( $\downarrow$ ) | $0.24$ | $0.44$ | $0.33$ | $0.57$ | $0.32$ | $0.12$ | $0.18$ | $0.12$ | $0.29$ | $0.31$ |
| FPR ( $\downarrow$ ) | $0.45$ | $0.10$ | $0.22$ | $0.07$ | $0.01$ | $0.60$ | $0.28$ | $0.40$ | $0.26$ | $0.08$ |
| Agreement with process human labels |  |  |  |  |  |  |  |  |  |  |
| Accuracy ( $\uparrow$ ) | $0.62$ | $0.64$ | $0.66$ | $0.61$ | ${0.81}$ | $0.55$ | $0.75$ | $0.68$ | $0.73$ | ${0.78}$ |
| F1 ( $\uparrow$ ) | $0.70$ | $0.65$ | $0.70$ | $0.57$ | ${0.86}$ | $0.47$ | $0.56$ | $0.53$ | $0.49$ | ${0.57}$ |
| Cohen’s $\kappa$ ( $\uparrow$ ) | $0.17$ | $0.34$ | $0.32$ | $0.30$ | $0.59$ | $0.22$ | $0.40$ | $0.34$ | $0.32$ | $0.43$ |
| FNR ( $\downarrow$ ) | $0.31$ | $0.49$ | $0.40$ | $0.59$ | $0.24$ | $0.05$ | $0.23$ | $0.12$ | $0.36$ | $0.29$ |
| FPR ( $\downarrow$ ) | $0.52$ | $0.10$ | $0.25$ | $0.04$ | $0.04$ | $0.56$ | $0.26$ | $0.38$ | $0.25$ | $0.20$ |

Table 2: Agreement between three verifiers and humans in CUAVerifierBench. Upgrading external verifier to GPT-5.2 results in only modest improvement, confirming the UV’s advantage is architectural.

Browserbase Annotations:
Using the two-stage annotation protocol described in §[5](#S5.SSx1), we measure how agreement changes when annotators are shown the UV’s reasoning. The UV-informed stage substantially improves agreement: outcome Cohen’s $\kappa$ rises from 0.39 to 0.63, and outcome FNR drops from 0.62 to 0.35, while FPR remains near zero (0.04). On process labels, FNR drops sharply from 0.32 to 0.09. Only 16.6% of annotator outcome judgements flipped after seeing the UV’s reasoning, nearly all moving from success to failure after the UV identified a failure they initially missed.

We also plot a scatter plot of the rubric score the human annotators assigned to the trajectories vs what the UV assigned in Figure [11](#A2.F11). See in Appendix [B.2](#A2.SS2) including Table [13](#A2.T13) for full results.

Inter-annotator agreement: the Browserbase split contains at least two annotations per trajectory. The UV’s outcome $\kappa$ with human labels (0.58, Table [2](#S6.T2)) and process $\kappa$ (0.43) fall within the corresponding inter-annotator ranges (0.53–0.57 and 0.36–0.45, respectively; Table [14](#A2.T14)), indicating that the UV agrees with humans about as well as humans agree with each other on both dimensions (We report more details in Section [B.2](#A2.SS2)).

Ablations: Varying Rubric Generator and Scorer: We conduct two additional ablations of the Universal Verifier, reported in full in Appendix [B.1](#A2.SS1). In Table [11](#A2.T11) we vary the backbone LLMs of the UV end-to-end (each model generates and scores its own rubric), finding that GPT-5.2 achieves the lowest FPR while GPT-5 offers the best balanced agreement. In Table [12](#A2.T12) we again vary the backbone LLM, but isolate the scoring component by fixing the rubric (generated by GPT-5.2), showing that GPT-5.2 is the most conservative scorer while GPT-5.1 achieves the highest overall $\kappa$ .

Agreement Between UV and Native Benchmark Verifiers
We measure agreement between the UV and the *native verifiers* shipped with each of three benchmarks: WebVoyager, Online-Mind2Web (OM2W), and WebTailBench. Table [3](#S6.T3) shows that the native verifiers disagree substantially with the UV labels: false positive rates w.r.t UV outcome labels are consistently above 20%, with WebVoyager (GPT-4o) having the highest FPR and lowest Cohen’s $\kappa$ . Histograms of error taxonomies for these are shown in Figures [8](#A1.F8),  [9](#A1.F9), and  [10](#A1.F10).

|  | WebVoyager |  | OM2W |  | WebTailBench |  |
| --- | --- | --- | --- | --- | --- | --- |
|  | Fara-7B | GPT-5 | Fara-7B | GPT-5 | Fara-7B | GPT-5 |
| $N$ (tasks scored) | 594 | 593 | 298 | 276 | 599 | 597 |
| Unterminated (%) | 4.2 | 3.4 | 5.0 | 7.2 | 17.0 | 7.7 |
| Success rate (%) |  |  |  |  |  |  |
| Native verifier | 74.6 | 90.6 | 32.2 | 62.0 | 39.6 | 62.5 |
| UV Process | 49.0 | 79.4 | 25.8 | 64.9 | 39.6 | 63.5 |
| UV Outcome | 37.9 | 71.0 | 15.8 | 48.6 | 23.2 | 39.9 |
| Native vs. UV Process $\dagger$ |  |  |  |  |  |  |
| FNR ( $\downarrow$ ) | 0.06 | 0.04 | 0.26 | 0.27 | 0.30 | 0.23 |
| FPR ( $\downarrow$ ) | 0.56 | 0.68 | 0.18 | 0.42 | 0.20 | 0.37 |
| Accuracy ( $\uparrow$ ) | 0.69 | 0.83 | 0.80 | 0.67 | 0.76 | 0.72 |
| F1 ( $\uparrow$ ) | 0.75 | 0.90 | 0.66 | 0.74 | 0.70 | 0.78 |
| Cohen’s $\kappa$ ( $\uparrow$ ) | 0.38 | 0.36 | 0.52 | 0.30 | 0.50 | 0.40 |
| Native vs. UV Outcome |  |  |  |  |  |  |
| FNR ( $\downarrow$ ) | 0.01 | 0.02 | 0.17 | 0.24 | 0.14 | 0.17 |
| FPR ( $\downarrow$ ) | 0.60 | 0.72 | 0.23 | 0.49 | 0.25 | 0.49 |
| Accuracy ( $\uparrow$ ) | 0.63 | 0.78 | 0.78 | 0.63 | 0.77 | 0.64 |
| F1 ( $\uparrow$ ) | 0.68 | 0.86 | 0.55 | 0.67 | 0.64 | 0.65 |
| Cohen’s $\kappa$ ( $\uparrow$ ) | 0.33 | 0.33 | 0.42 | 0.27 | 0.49 | 0.31 |

Table 3: Agreement between native benchmark verifiers and the Universal Verifier (UV) across three benchmarks and two agent models. The UV is treated as the reference label.

##### Auto-Research: Can AI Replace Human Experts in Verifier Design?

A natural question is whether an AI auto-research agent can replicate—or even improve upon—the process of designing verifiers([Lu et al., 2026](#bib.bib33); [Karpathy, 2026](#bib.bib34); [Tie et al., 2025](#bib.bib35)).
Figure [1](#S0.F1) shows outcome Cohen’s $\kappa$ progression across experiments for the human expert and both auto-research settings (process $\kappa$ is in Figure [13](#A3.F13)), and Figures [14](#A3.F14)–[15](#A3.F15) show the corresponding FPR and FNR trajectories.
The blank-prompt auto-research agent reached about  70% of the quality of the human expert in only 5% of the time, and when given the best prompts and code the human had, it could still find improvements subject to the constraint of not increasing false positive rate.
Table [17](#A3.T17) in Appendix  [C.1](#A3.SS1) summarizes each continue-expert iteration’s purpose and whether it was committed or rolled back.

Regarding AgentRewardBench ([Lù et al., 2025](#bib.bib14)), in Appendix [B.4](#A2.SS4) we report that out of a sample of 30 trajectories that terminated within step budget and were labeled as successful by their human annotators, we consider 8 to be false positive according to our outcome guidelines (FPR $\approx 0.27$ ).

## 7 Conclusion

We presented the Universal Verifier and CUAVerifierBench, demonstrating that our four design principles cumulatively produce a verifier that 1) agrees with humans as often as humans agree with each other and 2) better than any other verifier we measured, while 3) reducing false positive rates to near zero compared to baselines like WebVoyager ( $\geq$ 45%) and WebJudge ( $\geq$ 22%). These gains are architectural rather than model-driven: upgrading baseline backbones to the same LLM used by the UV yields only modest improvements. Our auto-research experiment reveals that while an AI agent can reach 70% of expert-level verifier quality in 5% of the time, it struggles to independently discover the structural design decisions that drive the largest gains, suggesting that building reliable verifiers remains as much an art of encoding evaluative judgment as it is an engineering problem.

## 8 Ethics Statement

We disclose that we contracted human annotators via an external firm Browserbase, and they represented to us that those annotators were paid more than minimum wage applicable under local law. We also represent that some annotators gave us express written permission to quote qualitative feedback they gave us about their experience judging the tasks. We do no disclose any personally identifiable information about the judges. We did not give the judges any psychologically harmful, offensive, or adult-natured tasks.

Additionally, we disclose that parts of this work were produced by generative AI, including but not limited to auto-research studies, results, analysis, and code. We performed our best effort to verify the results were not hallucinated.

## References

- Agashe et al. (2025)
  S. Agashe, R. Assouel, F. Yang, J. Xu, B. Wang, X. E. Li, and C. Han
  Agent S2: a compositional generalist-specialist framework for computer use agents.
  arXiv preprint arXiv:2504.00906.
  External Links: [Link](https://arxiv.org/abs/2504.00906)
  Cited by: [§1](#S1.p1.1).
- Anthropic (2025)
  Anthropic
  The claude model spec.
  Note: Claude 3.7 Sonnet model card available at <https://assets.anthropic.com/m/785e231869ea8b3b/original/claude-3-7-sonnet-system-card.pdf>
  External Links: [Link](https://www.anthropic.com/news/claude-3-7-sonnet)
  Cited by: [§2](#S2.p3.1).
- Artstein and Poesio (2008)
  R. Artstein and M. Poesio
  Survey article: inter-coder agreement for computational linguistics.
  Computational Linguistics 34 (4), pp. 555–596.
  External Links: [Link](https://aclanthology.org/J08-4004/),
  [Document](https://dx.doi.org/10.1162/coli.07-034-R2)
  Cited by: [§4](#S4.p3.1).
- Awadallah et al. (2025)
  A. Awadallah, Y. Lara, R. Magazine, H. Mozannar, A. Nambi, Y. Pandya, A. Rajeswaran, C. Rosset, A. Taymanov, V. Vineet, S. Whitehead, and A. Zhao
  Fara-7b: an efficient agentic model for computer use.
  External Links: 2511.19663,
  [Link](https://arxiv.org/abs/2511.19663)
  Cited by: [§5](#S5.SSx1.p2.1),
  [§5](#S5.SSx1.p3.1).
- Awadallah et al. (2025)
  A. Awadallah et al.
  Fara-7B: an efficient agentic model for computer use.
  arXiv preprint arXiv:2511.19663.
  External Links: [Link](https://arxiv.org/abs/2511.19663)
  Cited by: [§1](#S1.p1.1).
- Bai et al. (2025)
  S. Bai, K. Chen, X. Liu, J. Wang, W. Ge, S. Song, K. Dang, P. Wang, S. Wang, J. Tang, et al.
  Qwen2.5-vl technical report.
  External Links: 2502.13923,
  [Link](https://arxiv.org/abs/2502.13923)
  Cited by: [§2](#S2.p3.1).
- Barke et al. (2026)
  S. Barke, A. Goyal, A. Khare, A. Singh, S. Nath, and C. Bansal
  AgentRx: diagnosing ai agent failures from execution trajectories.
  External Links: 2602.02475,
  [Link](https://arxiv.org/abs/2602.02475)
  Cited by: [§2](#S2.p2.1).
- Boisvert et al. (2024)
  L. Boisvert, M. Thakkar, M. Gasse, M. Caccia, T. L. S. D. Chezelles, Q. Cappart, N. Chapados, A. Lacoste, and A. Drouin
  WorkArena++: towards compositional planning and reasoning-based common knowledge work tasks.
  External Links: 2407.05291,
  [Link](https://arxiv.org/abs/2407.05291)
  Cited by: [§2](#S2.p3.1).
- Drouin et al. (2024)
  A. Drouin, M. Gasse, M. Caccia, I. H. Laradji, M. D. Verme, T. Marty, L. Boisvert, M. Thakkar, Q. Cappart, D. Vazquez, N. Chapados, and A. Lacoste
  WorkArena: how capable are web agents at solving common knowledge work tasks?.
  External Links: 2403.07718,
  [Link](https://arxiv.org/abs/2403.07718)
  Cited by: [§2](#S2.p3.1).
- Grattafiori et al. (2024)
  A. Grattafiori, A. Dubey, A. Jauhri, A. Pandey, A. Kadian, A. Al-Dahle, et al.
  The llama 3 herd of models.
  External Links: 2407.21783,
  [Link](https://arxiv.org/abs/2407.21783)
  Cited by: [§2](#S2.p3.1).
- Gupta et al. (2026)
  T. Gupta et al.
  MolmoWeb: open visual web agent and open data for the open web.
  arXiv preprint arXiv:2601.10611.
  External Links: [Link](https://arxiv.org/abs/2601.10611)
  Cited by: [§1](#S1.p1.1).
- He et al. (2024a)
  H. He, W. Yao, K. Ma, W. Yu, Y. Dai, H. Zhang, Z. Lan, and D. Yu
  WebVoyager: building an end-to-end web agent with large multimodal models.
  In Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (ACL),
  pp. 6864–6890.
  External Links: [Link](https://arxiv.org/abs/2401.13919)
  Cited by: [§1](#S1.p1.1).
- He et al. (2024b)
  H. He, W. Yao, K. Ma, W. Yu, Y. Dai, H. Zhang, Z. Lan, and D. Yu
  WebVoyager: building an end-to-end web agent with large multimodal models.
  External Links: 2401.13919,
  [Link](https://arxiv.org/abs/2401.13919)
  Cited by: [§2](#S2.p1.1),
  [§3.4](#S3.SS4.p1.1),
  [§6](#S6.p1.1).
- Karpathy (2026)
  A. Karpathy
  Autoresearch: AI agents running research on single-GPU nanochat training automatically.
  Note: <https://github.com/karpathy/autoresearch>Accessed: 2026-03-29
  Cited by: [§6](#S6.SS0.SSS0.Px1.p1.1).
- Koh et al. (2024)
  J. Y. Koh, R. Lo, L. Jang, V. Duvvur, M. C. Lim, P. Huang, G. Neubig, S. Zhou, R. Salakhutdinov, and D. Fried
  VisualWebArena: evaluating multimodal agents on realistic visually grounded web tasks.
  In Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (ACL),
  External Links: [Link](https://arxiv.org/abs/2401.13649)
  Cited by: [§1](#S1.p1.1),
  [§2](#S2.p3.1).
- Lightman et al. (2023)
  H. Lightman, V. Kosaraju, Y. Burda, H. Edwards, B. Baker, T. Lee, J. Leike, J. Schulman, I. Sutskever, and K. Cobbe
  Let’s verify step by step.
  External Links: 2305.20050,
  [Link](https://arxiv.org/abs/2305.20050)
  Cited by: [§2](#S2.p4.1).
- Lu et al. (2026)
  C. Lu, C. Lu, R. T. Lange, Y. Yamada, S. Hu, J. Foerster, D. Ha, and J. Clune
  Towards end-to-end automation of AI research.
  Nature 651 (8107), pp. 914–919.
  External Links: [Document](https://dx.doi.org/10.1038/s41586-026-10265-5),
  [Link](https://www.nature.com/articles/s41586-026-10265-5)
  Cited by: [§6](#S6.SS0.SSS0.Px1.p1.1).
- Lù et al. (2025)
  X. H. Lù, A. Kazemnejad, N. Meade, A. Patel, D. Shin, A. Zambrano, K. Stańczak, P. Shaw, C. J. Pal, and S. Reddy
  AgentRewardBench: evaluating automatic evaluations of web agent trajectories.
  External Links: 2504.08942,
  [Link](https://arxiv.org/abs/2504.08942)
  Cited by: [§2](#S2.p3.1),
  [§6](#S6.SS0.SSS0.Px1.p2.1).
- Murty et al. (2025)
  S. Murty, H. Zhu, D. Bahdanau, and C. D. Manning
  NNetNav: unsupervised learning of browser agents through environment interaction in the wild.
  External Links: 2410.02907,
  [Link](https://arxiv.org/abs/2410.02907)
  Cited by: [§2](#S2.p3.1).
- OpenAI (2024)
  OpenAI
  GPT-4o system card.
  External Links: 2410.21276,
  [Link](https://arxiv.org/abs/2410.21276)
  Cited by: [§2](#S2.p3.1).
- OpenAI (2025)
  OpenAI
  Computer-using agent.
  Technical report
  External Links: [Link](https://openai.com/index/computer-using-agent/)
  Cited by: [§1](#S1.p1.1).
- Pan et al. (2024)
  J. Pan, Y. Zhang, N. Tomlin, Y. Zhou, S. Levine, and A. Suhr
  Autonomous evaluation and refinement of digital agents.
  External Links: 2404.06474,
  [Link](https://arxiv.org/abs/2404.06474)
  Cited by: [§2](#S2.p3.1),
  [§3.4](#S3.SS4.p1.1).
- Stuhlmüller and Byun (2022)
  A. Stuhlmüller and J. Byun
  Supervise process, not outcomes.
  Note: Ought blog post
  External Links: [Link](https://ought.org/updates/2022-04-06-process)
  Cited by: [§2](#S2.p4.1).
- Tie et al. (2025)
  G. Tie, P. Zhou, and L. Sun
  A survey of AI scientists.
  External Links: 2510.23045,
  [Link](https://arxiv.org/abs/2510.23045)
  Cited by: [§6](#S6.SS0.SSS0.Px1.p1.1).
- Uesato et al. (2022)
  J. Uesato, N. Kushman, R. Kumar, F. Song, N. Siegel, L. Wang, A. Creswell, G. Irving, and I. Higgins
  Solving math word problems with process- and outcome-based feedback.
  External Links: 2211.14275,
  [Link](https://arxiv.org/abs/2211.14275)
  Cited by: [§2](#S2.p4.1).
- Wang et al. (2024)
  P. Wang, L. Li, Z. Shao, R. Xu, D. Dai, Y. Li, D. Chen, Y. Wu, and Z. Sui
  Math-shepherd: verify and reinforce llms step-by-step without human annotations.
  In Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics,
  Cited by: [§2](#S2.p4.1).
- Xie et al. (2024)
  T. Xie, D. Zhang, J. Chen, X. Li, S. Zhao, R. Cao, T. J. Hua, Z. Cheng, D. Shin, F. Lei, Y. Liu, Y. Deng, N. Jain, R. Maddila, K. Zou, Y. Lu, and T. Yu
  OSWorld: benchmarking multimodal agents for open-ended tasks in real computer environments.
  In Advances in Neural Information Processing Systems (NeurIPS),
  External Links: [Link](https://arxiv.org/abs/2404.07972)
  Cited by: [§1](#S1.p1.1).
- Xue et al. (2025)
  T. Xue, W. Qi, T. Shi, C. H. Song, B. Gou, D. Song, H. Sun, and Y. Su
  An illusion of progress? assessing the current state of web agents.
  External Links: 2504.01382,
  [Link](https://arxiv.org/abs/2504.01382)
  Cited by: [§2](#S2.p1.1),
  [§3.4](#S3.SS4.p1.1),
  [§6](#S6.p1.1).
- Yang et al. (2023)
  J. Yang, H. Zhang, F. Li, X. Zou, C. Li, and J. Gao
  Set-of-mark prompting unleashes extraordinary visual grounding in gpt-4v.
  External Links: 2310.11441,
  [Link](https://arxiv.org/abs/2310.11441)
  Cited by: [§5](#S5.SSx1.SSS0.Px1.p1.1).
- Yoran et al. (2024)
  O. Yoran, S. J. Amouyal, C. Malaviya, B. Bogin, O. Press, and J. Berant
  AssistantBench: can web agents solve realistic and time-consuming tasks?.
  External Links: 2407.15711,
  [Link](https://arxiv.org/abs/2407.15711)
  Cited by: [§2](#S2.p3.1).
- Zhang et al. (2025a)
  W. Zhang, X. Li, K. Dong, Y. Wang, P. Jia, X. Li, Y. Zhang, D. Xu, Z. Du, H. Guo, R. Tang, and X. Zhao
  Process vs. outcome reward: which is better for agentic rag reinforcement learning.
  External Links: 2505.14069
  Cited by: [§2](#S2.p4.1).
- Zhang et al. (2025b)
  Z. Zhang, C. Zheng, Y. Wu, B. Zhang, R. Lin, B. Yu, D. Liu, J. Zhou, and J. Lin
  The lessons of developing process reward models in mathematical reasoning.
  External Links: 2501.07301
  Cited by: [§2](#S2.p4.1).
- Zheng et al. (2024)
  B. Zheng, B. Gou, J. Kil, H. Sun, and Y. Su
  GPT-4V(ision) is a generalist web agent, if grounded.
  In Proceedings of the 41st International Conference on Machine Learning (ICML),
  External Links: [Link](https://arxiv.org/abs/2401.01614)
  Cited by: [§1](#S1.p1.1).
- Zheng et al. (2025)
  C. Zheng et al.
  A survey of process reward models: from outcome signals to process supervisions for large language models.
  External Links: 2510.08049
  Cited by: [§2](#S2.p4.1).
- Zhou et al. (2023)
  S. Zhou, F. F. Xu, H. Zhu, X. Zhou, R. Lo, A. Sridhar, X. Cheng, T. Ou, Y. Bisk, D. Fried, U. Alon, and G. Neubig
  WebArena: a realistic web environment for building autonomous agents.
  External Links: 2307.13854,
  [Link](https://arxiv.org/abs/2307.13854)
  Cited by: [§2](#S2.p3.1).
- Zhou et al. (2024)
  S. Zhou, F. F. Xu, H. Zhu, X. Zhou, R. Lo, A. Sridhar, X. Cheng, T. Ou, Y. Bisk, D. Fried, U. Alon, and G. Neubig
  WebArena: a realistic web environment for building autonomous agents.
  In Proceedings of the International Conference on Learning Representations (ICLR),
  External Links: [Link](https://arxiv.org/abs/2307.13854)
  Cited by: [§1](#S1.p1.1).

## Appendix A Universal Verifier Details

### A.1 Top-Level Rubric and Outcome Example

The output of our Universal Verifier is a rubric which shows scores for individual criteria based on action-history-only scoring, which are then updated with multimodal evidence. It also shows a separate Outcome result as shown in Figure [2](#A1.F2).

![Refer to caption](images/03_Verifiers/example_verifier_result.png)


Figure 2: An snapshot of our internal visualization tool for viewing verification results for a trajectory addressing the task “find the best men’s face wash according to GQ or Men’s Health, then buy it on Amazon”

We record details of how each individual criterion are scored, as shown in Figure [3](#A1.F3)

![Refer to caption](images/03_Verifiers/example_verifier_result_single_criterion.png)


Figure 3: A snapshot for the same example of how an individual criterion was scored, in this case, the model lost a point because it transcribed ”Cardon” incorrectly as ”Caron” in its action history based on multi-modal evidence. These kinds of meticulous analysis helps us detect hallucinations that otherwise would slip through.

### A.2 Rubric Failure Modes and Fixes

Rubric generation is the root of the verification pipeline, and flawed rubrics produce errors that cascade through scoring and outcome determination. Through iterative development (§[3](#S3)), we identified several systematic failure modes in LLM-generated rubrics and developed corresponding fixes. Table [4](#A1.T4) illustrates three representative examples comparing an old rubric verifier against the improved Universal Verifier.

| Old Rubric | Pts | Improved Rubric | Pts |
| --- | --- | --- | --- |
| Task A: On Eventbrite.com, find a live music event in Nashville, TN happening this upcoming Saturday. Then on Spotify.com, find songs by any of the performing artists from that event. |  |  |  |
| Event details Name, date & time, venue & location | 2/3 | Event details Name, date & time, venue & location | 2/3 |
| Ticket information Includes ticket price or free indicator | 0/1 | Performing artists list All performers named | 1/1 |
| Event link Direct URL to Eventbrite page | 0/1 | Spotify artist search Searches at least one artist | 1/1 |
| Performing artists list All performers named in event description | 1/1 | Song selection 3–5 song titles per artist searched | 1/1 |
| Spotify artist search Searches for at least one artist on Spotify | 1/1 |  |  |
| Song selection 3–5 song titles per artist searched | 1/1 |  |  |
| Spotify links URLs to songs or artist page on Spotify | 0/1 |  |  |
| 5/9 $\rightarrow$ FAILURE 3 phantom criteria |  | 5/6 $\rightarrow$ SUCCESS |  |
| Task B: On Booking.com, find the cheapest available 8/10+ scored hotel for a 3-night stay starting Dec 15, 2025 in Jakarta for 2 adults. Use the hotel’s address to find the closest coffee shop; output its name and address. |  |  |  |
| Hotel identification & rating Cheapest qualifying hotel with $\geq$ 8.0 rating | 0/2 | Search Booking.com correctly Jakarta, Dec 15–18, 2 adults, 8/10+ filter | 3/3 |
| Total price for stay Total 3-night price at selected hotel | 0/2 | Apply filter, identify cheapest Correctly finds lowest-priced hotel | 3/3 |
| Hotel street address Full street address from Booking.com | 0/2 | Find closest coffee shop Name and full address | 3/3 |
| Coffee shop name & address Name and full address of closest coffee shop | 2/2 |  |  |
| 2/8 $\rightarrow$ FAILURE 2 phantom criteria, $-4$ pts |  | 9/9 $\rightarrow$ SUCCESS |  |
| Task C: On LinkedIn.com, search for ‘Computer Vision Researcher’ roles in Seattle posted in the past week. Find the latest free Stanford computer vision course available online to prep. |  |  |  |
| LinkedIn search summary Search filters, result count, direct link | 2/2 | Access LinkedIn and configure search Keyword, location, past week filter | 2/2 |
| Detailed job listings (top 3–5) Title, company, location, date, requirements | 0/4 | Present search results Roles with title, company, posting date | 3/3 |
| Course identification and link Latest free Stanford CV course, title, platform, URL | 2/2 | Identify latest free Stanford CV course Course name, platform, free access link | 3/3 |
| Course details completeness Start date, self-paced status, syllabus, enrollment | 0/2 |  |  |
| Agent action log Lists navigation and search steps taken | 0/0 |  |  |
| 4/12 $\rightarrow$ FAILURE 3 phantom criteria, $-6$ pts |  | 8/8 $\rightarrow$ SUCCESS |  |

Table 4: Three examples of rubric failure modes of positive trajectories comparing old rubric generation (left) against the improved Universal Verifier’s (right). Red text indicates flawed rubric criteria that were e.g. never requested by the task.

We summarize the key failure modes and our fixes below:

Phantom criteria.
LLM-generated rubrics frequently introduce requirements that were never stated in the task nor necessary to complete it. For example, when asked to “find a live music event on Eventbrite and find songs by the artists on Spotify,” the old rubric added criteria for ticket information, event links, and Spotify URLs—none of which the user requested (Table [4](#A1.T4), Task A). These phantom criteria over-penalize trajectories by inflating the denominator, causing agents that completed the task to be marked as failures. Our fix instructs the rubric generator to anchor criteria strictly to what the task necessitates and explicitly forbids grading on information the user did not ask for.

Cascading errors.
When rubric criteria are not logically independent, an error in one criterion propagates into downstream criteria, multiplying the point penalty. For instance, if the rubric first asks “identify the correct neighbourhood” and then asks “search for hotels in that neighbourhood,” a single factual mis-label in the first criterion causes the agent to lose points on both criteria—even if the agent’s downstream actions were internally consistent with its (incorrect) upstream data. Another example is shown in more detail in Figure [4](#A1.F4). Our fix requires criteria to be evaluated independently: each criterion is graded based on whether the agent’s actions were reasonable given the information it had at that step, not whether upstream criteria were scored correctly.

![Refer to caption](images/03_Verifiers/justin_timberlake_controllable_error.png)


Figure 4: An example of how the model made a computation error for the task *“List all the members of the bands Nsync and BackStreet Boys. Find the net worth of the one with the longest last name.”* – it thought “Timberlake” was the longest when in fact “Kirkpatrick” is. This mistake was identified, but notably, the error did NOT cascade to the last criterion *“Find and report the net worth of the identified longest-last-name member”*

Separating rubric generation from scoring.
Early versions of the pipeline had a single LLM call both generate the rubric and score it simultaneously. This led to confirmation bias: the model would generate lenient criteria that it knew the agent could satisfy, or generate criteria tailored to match the agent’s actual behavior rather than the task requirements. Separating these into distinct stages—first generate the rubric from the task alone (without seeing the trajectory), then score the trajectory against the rubric—eliminated this coupling.

Conditional Criteria
Many real-world tasks contain contingencies: “do X, but if X is not possible, report that instead.”. It is not known at rubric-generation time whether X is possible or not, so we must wait until a trajectory has been executed to ascertain and hence whether to “count” or “activate” certain criteria. To handle these, the rubric generator creates *conditional criteria* whose contribution to the score depends on whether a condition is met during the trajectory. When the condition is not met, the criterion is excluded from both numerator and denominator of the process score, ensuring that agents are not penalized for outcomes they could not control. Table [5](#A1.T5) shows a concrete example.

Two-pass scoring: with and without screenshots.
Hallucinations are difficult to catch when the scorer has access to screenshots, because the model may inadvertently use visual evidence to “fill in” claims the agent made without basis. Our pipeline scores each criterion twice: once with access to only the agent’s text actions (to check whether claims are grounded in what the agent actually did), and once with full screenshot access (to verify visual state). Discrepancies between the two passes flag potential hallucinations for closer inspection, as shown in Appendix [A.3](#A1.SS3) and Figure [5](#A1.F5).

| Criterion | Pts |
| --- | --- |
| Task: How much does it cost to select a window seat on a direct AirAsia flight from Singapore to Langkawi from November 24 to November 27? If there are no available flights for those dates, please indicate that in your answer. |  |
| Access AirAsia booking flow and run the specified flight search Navigate to AirAsia, search for SIN $\rightarrow$ LGK on Nov 24 and LGK $\rightarrow$ SIN on Nov 27. | 2/2 |
| Determine direct-flight availability for both legs Check whether direct flights exist for each leg; report unavailability when applicable. | 7/7 |
| Report window-seat selection cost for the identified flights Select a window seat and report the cost for each eligible flight. Conditional: Only applies if $\geq$ 1 eligible direct AirAsia flight exists for Nov 24 (SIN $\rightarrow$ LGK) and Nov 27 (LGK $\rightarrow$ SIN). Condition met: Yes. | 1/4 |
| Total: 10/13 |  |

Table 5: Example of a conditional rubric criterion. The third criterion only contributes to the score if direct flights are available. If no flights existed, this criterion would be excluded from both numerator and denominator, preventing the agent from being penalized for not reporting a cost that is impossible to obtain. The condition is evaluated by the verifier based on screenshot evidence from the agent’s trajectory.

### A.3 Detecting Hallucinations

The key principle of our Universal Verifier design is to not miss any visual evidence which is important to the success of the task, including those that reveal hallucinations or fabrications by the agent. We were surprised how subtle yet critical the hallucinations the Universal Verifier caught. For instance, in Figure [5](#A1.F5), the task is *“Investigate the ’Salesforce/blip-image-captioning-base’ image-to-text model on Hugging Face to identify its main applications and notable performance comparisons.”*, which leads to the ArXiv page <https://arxiv.org/abs/2201.12086>. In the abstract, the authors state their model improves *image captioning (+2.8% in CIDEr)…*. However, the agent in this trajectory states “+6.2% CIDEr score”, which is a contradiction as defined in Table [7](#A1.T7) in Section [A.5](#A1.SS5).

![Refer to caption](images/03_Verifiers/hallucination_example.png)


Figure 5: An example of a hallucination caught by the Universal Verifier where the model claimed in its final answer that a model exhibited “+6.2% CIDEr score” when in fact it had “+2.8% in CIDEr” – and the agent did see the abstract of the model on ArXiv. This is a very subtle but critical failure mode that even humans are likely to miss.

#### A.3.1 Screenshot Relevance Matrix

Step 2 of the Universal verifier is to score which screenshots are most relevant to (or most indicative of success of) which criteria. In Figure [6](#A1.F6), we show an example of such a score matrix. Note the “staircase” shape characterizing how later screenshots make progress towards later criteria in the rubric; most trajectories are relatively linear.

We make several optimizations to speed up processing of relevance matrix computation, while also ensuring quality:

- •

  Parallelized: Each screenshot is scored against all criteria in the rubric in one LLM call (so there are exactly $M$ calls for $M$ screenshots in a trajectory, all issued in parallel. A smaller model like o4-mini can be used here).
- •

  Batching: If the same screenshot is relevant for more than one criteria, downstream analysis of those (screenshot, criterion) pairs are batched into one LLM call.
- •

  Pruning: when a criterion has highly relevant screenshots (score above 7), we can safely ignore those with score less than 5 that occured temporally before the relevant ones.
- •

  Tie Breaking: When choosing top-k screenshots and there are ties, the ones temporally later in the trajectory take precedence since they likely contain the most up-to-date information in the state.

![Refer to caption](images/03_Verifiers/relevance_matrix.png)


Figure 6: An example relevance matrix where 13 screenshots were scored against five criteria in the rubric for the task *“find the best men’s face wash according to GQ or Men’s Health, then buy it on Amazon”*

![Refer to caption](images/03_Verifiers/unsolicited_side_effect.png)


Figure 7: An example of an unsolicited side effect that was not anticipated when the rubric was generated. The task is *“Compare shipping options and delivery times for the TK Evolution APU coolant sensor between Amazon and AutoZone—make sure to check the actual product pages for the most up-to-date shipping costs and delivery estimates.”*, and the agent added the product to the cart instead of just answering the question.

### A.4 Scenario Behavior

The pipeline’s process and outcome signals are designed to diverge in principled ways across different failure modes. Table [6](#A1.T6) summarizes how each signal responds to representative scenarios.

| Scenario | Process Score | Outcome Label |
| --- | --- | --- |
| Agent solved task correctly, no blockers, no side effects | Success | Success |
| Environment blocker (CAPTCHA, login wall, site down, out of stock); agent reported clearly and did not attempt alternative | Success (best effort) | Failure (goal not achieved) |
| Agent overcame blocker via alternative source, delivered correct result | Success | Success |
| Controllable mistake (wrong product, wrong date, missed option) | Failure (deduct per criterion) | Failure (if mistake affects goal) |
| Correct approach but wrong final answer (computational or reasoning error) | Failure (moderate deduction) | Failure (wrong answer) |
| Unsolicited side effects (extraneous cart items, unauthorized substitutions) | Failure | Failure |
| Hallucination / grounding error (claims contradicted by screenshots) | Failure (visual evidence overrides) | Failure (wrong information) |
| Agent stopped at Critical Point (no permission given); correct behavior | Success | Success |
| Agent stopped at Critical Point but HAD permission to cross | Failure | Failure |
| Under-specified task: agent asks user to clarify missing information (no other issues) | Success | Success |
| Under-specified task: agent makes assumptions without asking | Failure (if assumptions led to errors) | Failure (if result does not match intent) |

Table 6: How the multimodal rubric verifier handles representative scenarios. The process score (Steps 0–7) and outcome label (Step 8) are independent signals that can diverge.

The key insight is that process and outcome diverge on *environment blockers*: the process score awards full credit for best-effort execution when the agent was blocked by factors outside its control, while the outcome label marks it as failure because the user’s real-world goal was not achieved. This means an agent can score 100% on process but fail on outcome if the environment prevented completion.

We note that for environment blockers, full credit is awarded only when the agent clearly reported the blocker *and did not attempt an alternative*. If the agent overcame the blocker via an alternative source and delivered a correct result, the outcome is Success—the system judges by the results delivered, not by whether the original platform was used.

### A.5 Visual Evidence Taxonomy

A critical component of the multimodal pipeline is the grounding of agent claims against visual evidence. Screenshots serve as ground truth: when there is a discrepancy between the agent’s claims and what screenshots show, the screenshots take precedence. Table [7](#A1.T7) defines the five categories used to evaluate agent claims against visual evidence in Steps 4 and 6.

| Category | Verdict | Example |
| --- | --- | --- |
| Contradiction : screenshots show $X$ , agent claims $\neg X$ | Failure | Screenshot shows a booking calendar exists; agent says “no booking system available” |
| Fabrication : agent claims $X$ with zero evidentiary basis | Failure | Agent states a price that appears nowhere in any screenshot |
| Omission : agent did not view everything needed; screenshots lack evidence of $X$ , but $X$ is commonly known to exist | Failure | Task: “highest ranked NHL team in Western Conference.” Agent only checked Central Division, never viewed Pacific Division |
| Supported inference from absence : screenshots show no evidence of $X$ across all pages, AND $X$ is not commonly known to exist | Success | No booking UI visible anywhere $\rightarrow$ agent reports “no online booking available” |
| Visual confirmation without explicit statement : agent omits justification but screenshots visually confirm the correct result | Success | Agent found female cardiologists but did not state “female”—photos in screenshots confirm they are female-presenting |

Table 7: Visual evidence taxonomy for evaluating agent claims against screenshot evidence. Only contradictions, fabrications, and omissions are penalized; supported inferences and visual confirmations are not.

### A.6 Cost Breakdown

The Universal Verifier can be configured to use any json-capable multimodal LLM available as an endpoint. Table [8](#A1.T8) summarizes the number of LLM calls per pipeline step for a given trajectory. Let $M$ denote the number of screenshots in the trajectory, $N$ the number of rubric criteria, $K$ the maximum screenshots per criterion, and $S$ the number of unique screenshots selected across all criteria in Step 3.

| Step | LLM Calls | Parallelism |
| --- | --- | --- |
| 1a: Initial Rubric Generation | 1 | — |
| 1b: Dependency Checking | 1 | — |
| 1c: Action-History-Only Scoring | 1 | — |
| 2: Screenshot-Criteria Relevance Scoring | $M$ | Fully parallel |
| 3: Group Top-k Screenshots by Criteria | 0 | — |
| 4a: Evidence Analysis (batched) | $S\leq K\times N$ | Fully parallel |
| 4b: Post-Evidence Condition Disentanglement | $\leq 1$ | — |
| 5: “Reality Check” Rubric Assumptions | 1 | — |
| 6: Multimodal Evidence-based Rescoring † | 1 | — |
| 7: Side-Effect Detection † | 1 | — |
| 8: Outcome Verification † | 1 | — |

Table 8: LLM calls per pipeline step. Steps marked with $\dagger$ are run $N_{\text{vote}}$ times when majority voting is enabled.

For a typical trajectory from our logs with e.g. $M{=}47$ screenshots, $N{=}3$ criteria, $K{=}5$ , and $S{=}10$ unique screenshots, the pipeline made $3+47+10+1+1+1+1+1=65$ LLM calls (without majority voting), with the heaviest steps executing in parallel.

| Benchmark | Model | Selection | Hallucination | Exec. & Strategy | Critical Point | Side-Effect | Tool Interaction |
| --- | --- | --- | --- | --- | --- | --- | --- |
| WebVoyager | Fara-7B | 0.442 | 0.821 | 0.740 | 0.000 | 0.002 | 0.019 |
|  | GPT-5 | 0.206 | 0.424 | 0.382 | 0.000 | 0.002 | 0.040 |
| OM2W | Fara-7B | 0.724 | 0.905 | 1.456 | 0.007 | 0.007 | 0.046 |
|  | GPT-5 | 0.331 | 0.404 | 0.879 | 0.000 | 0.007 | 0.026 |
| WebTailBench | Fara-7B | 0.785 | 1.078 | 0.988 | 0.000 | 0.010 | 0.036 |
|  | GPT-5 | 0.485 | 0.495 | 1.054 | 0.000 | 0.020 | 0.047 |

Table 9: Failure points normalized by number of trajectories per error category by benchmark and
model.


| Error Type | Description |
| --- | --- |
| 1. Selection |  |
| 1.1 Missing intent | Choosing an entirely wrong product, location, person, service, etc. |
| 1.2 Unauthorized substitution | Silently swapping an unavailable item for a similar alternative without reporting |
| 1.3 Wrong action type | Performing the wrong interaction on the correct entity |
| 1.4 Wrong values / constraint violation | Incorrect parameters, unsatisfied constraints, or results not matching stated requirements |
| 1.5 Other | Selection error not covered above |
| 2. Hallucination |  |
| 2.1 Output contradiction | Evidence shows X, but agent claims not-X; includes misinterpreting page/tool content |
| 2.2 Action contradiction | Agent claims action was performed but evidence contradicts; action was achievable |
| 2.3 Output fabrication | Agent claims a fact with zero evidentiary basis; complete invention |
| 2.4 Action fabrication | Agent claims action occurred but no evidence it was even possible; includes fabricating user info |
| 2.5 Other | Hallucination error not covered above |
| 3. Execution & Strategy |  |
| 3.1 Computational mistakes | Correct methodology but wrong answer due to miscounting, arithmetic, or misreading |
| 3.2 Platform non-compliance | Not attempting the specified platform or silently switching sources |
| 3.3 Incomplete delivery | Had all necessary intermediate information but failed to deliver final output |
| 3.4 Environment failure | Correct intent but blocked by environment (page failure, CAPTCHA, login wall) |
| 3.5 Incomplete task execution | Did not perform all sub-goals, stopped prematurely, or skipped steps |
| 3.6 Other | Execution error not covered above |
| 4. Critical Point |  |
| 4.1 Premature stop | Stopped at critical point despite user explicitly granting permission |
| 4.2 Violation | Crossed transactional boundary without permission |
| 4.3 Other | Critical point error not covered above |
| 5. Task Ambiguity |  |
| 5.1 Underspecified | Task omits essential parameters required for execution |
| 5.2 Ambiguous | Task or environment state admits multiple valid interpretations or targets |
| 5.3 Unsafe | Task asks for action that could cause harm or violate policies |
| 5.4 Other | Task ambiguity error not covered above |
| 6. Side-Effect |  |
| 6.1 Unsolicited | Any lasting modification, enrollment, or addition not requested |
| 6.2 Other | Side-effect error not covered above |
| 7. Tool Interaction |  |
| 7.1 Invalid invocation | Tool call with wrong arguments (action exists but args are incorrect) |
| 7.2 Hallucinated action | Agent invokes a tool/action that does not exist in the action space |
| 7.3 Intent–action mismatch | Agent’s stated intent differs from tool call issued in the same message. |
| 7.4 Other | Tool interaction error not covered above |

Table 10: Error taxonomy for computer-use agent failures.

![](images/03_Verifiers/side_by_side_WebVoyager_error_taxonomy_histogram.svg)


Figure 8: Fara-7B + GPT -5 side-by-side on WebVoyager. The histogram counts are normalized by number of trajectories

![](images/03_Verifiers/side_by_side_om2w_error_taxonomy_histogram.svg)


Figure 9: Fara-7B + GPT -5 side-by-side on Online-Mind2Web. The histogram counts are normalized by number of trajectories

![](images/03_Verifiers/side_by_side_webtailbench_error_taxonomy_histogram.svg)


Figure 10: Fara-7B + GPT -5 side-by-side on WebTailBench. The histogram counts are normalized by number of trajectories

## Appendix B Results

### B.1 Ablation: Varying Rubric Generator and Scorer

We ran two ablations varying which model generated the rubrics and which model scored them in the Universal Verifier system, and compared agreement with process and outcome human labels on the internal dataset.

Table [11](#A2.T11) evaluates the full pipeline end-to-end, where each model both generates its own rubric and scores it. GPT-5.2 achieves the lowest FPR (0.03 / 0.0), confirming that its advantage is not solely due to scoring a rubric it generated itself. GPT-5 achieves the highest accuracy on process (0.84) and ties with o3 on outcome Cohen’s $\kappa$ (0.72), making it a strong all-around choice when FPR is less critical than balanced agreement.

| Rubric Creation | Scoring | FNR ( $\downarrow$ ) | FPR ( $\downarrow$ ) | Acc ( $\uparrow$ ) | F1 ( $\uparrow$ ) | Cohen’s $\kappa$ ( $\uparrow$ ) |
| --- | --- | --- | --- | --- | --- | --- |
| GPT-4o | GPT-4o | 0.16 / 0.12 | 0.41 / 0.36 | 0.78 / 0.78 | 0.85 / 0.82 | 0.42 / 0.53 |
| o4-mini | o4-mini | 0.28 / 0.25 | 0.24 / 0.15 | 0.73 / 0.79 | 0.80 / 0.81 | 0.40 / 0.59 |
| o3 | o3 | 0.26 / 0.20 | 0.21 / 0.068 | 0.76 / 0.86 | 0.82 / 0.87 | 0.45 / 0.72 |
| GPT-5 | GPT-5 | 0.17 / 0.21 | 0.12 / 0.051 | 0.84 / 0.86 | 0.89 / 0.87 | 0.63 / 0.72 |
| GPT-5.1 | GPT-5.1 | 0.15 / 0.15 | 0.29 / 0.17 | 0.81 / 0.84 | 0.87 / 0.86 | 0.52 / 0.68 |
| GPT-5.2 | GPT-5.2 | 0.23 / 0.28 | 0.03 / 0.00 | 0.82 / 0.84 | 0.87 / 0.84 | 0.61 / 0.68 |
| GPT-5.4 | GPT-5.4 | 0.13 / 0.21 | 0.26 / 0.068 | 0.84 / 0.85 | 0.89 / 0.86 | 0.57 / 0.70 |

$\dagger$ Process predictions binarized with a 0.8 threshold.

Table 11: Agreement with human labels when each model both generates its own rubric and scores it. Metrics are reported as process $\dagger$  / outcome. GPT-5.2 achieves the lowest false positive rate when tasked with deriving its own rubric and scoring it.

Table [12](#A2.T12) isolates the effect of the scoring model by holding the rubric fixed (generated by GPT-5.2) and varying only which model scores it. GPT-5.2 achieves the lowest false positive rate (0.03 / 0.0 for process / outcome), indicating it is the most conservative scorer—rarely marking a failed trajectory as successful. GPT-5.1 achieves the highest F1 and Cohen’s $\kappa$ on outcome (0.89 / 0.74), suggesting it best balances precision and recall overall.

| Rubric Creation | Scoring | FNR ( $\downarrow$ ) | FPR ( $\downarrow$ ) | Acc ( $\uparrow$ ) | F1 ( $\uparrow$ ) | Cohen’s $\kappa$ ( $\uparrow$ ) |
| --- | --- | --- | --- | --- | --- | --- |
| GPT-5.2 | GPT-4o | 0.20 / 0.14 | 0.32 / 0.34 | 0.77 / 0.78 | 0.84 / 0.82 | 0.43 / 0.54 |
| GPT-5.2 | o4-mini | 0.23 / 0.25 | 0.21 / 0.068 | 0.78 / 0.83 | 0.84 / 0.84 | 0.49 / 0.66 |
| GPT-5.2 | o3 | 0.26 / 0.20 | 0.09 / 0.068 | 0.78 / 0.86 | 0.83 / 0.87 | 0.52 / 0.72 |
| GPT-5.2 | GPT-5 | 0.22 / 0.24 | 0.059 / 0.034 | 0.82 / 0.85 | 0.87 / 0.86 | 0.60 / 0.70 |
| GPT-5.2 | GPT-5.1 | 0.19 / 0.14 | 0.12 / 0.12 | 0.83 / 0.87 | 0.88 / 0.89 | 0.60 / 0.74 |
| GPT-5.2 | GPT-5.2 | 0.23 / 0.28 | 0.03 / 0.00 | 0.82 / 0.84 | 0.87 / 0.84 | 0.61 / 0.68 |
| GPT-5.2 | GPT-5.4 | 0.19 / 0.26 | 0.088 / 0.034 | 0.84 / 0.84 | 0.88 / 0.84 | 0.62 / 0.68 |

$\dagger$ Process predictions binarized with a 0.8 threshold.

Table 12: Agreement with human labels when rubrics are fixed (generated by GPT-5.2) and only the scoring model varies. Metrics are reported as process $\dagger$  / outcome. GPT-5.2 achieves the lowest FPR while GPT-5 is also competitive.

### B.2 CUAVerifierBench: Browserbase Results

|  | UV-Blind | UV-Informed |
| --- | --- | --- |
| Agreement with outcome human labels |  |  |
| Accuracy ( $\uparrow$ ) | 0.79 | 0.91 |
| F1 ( $\uparrow$ ) | 0.50 | 0.69 |
| Cohen’s $\kappa$ ( $\uparrow$ ) | 0.39 | 0.63 |
| FNR ( $\downarrow$ ) | 0.62 | 0.35 |
| FPR ( $\downarrow$ ) | 0.05 | 0.04 |
| Agreement with process human labels |  |  |
| Accuracy ( $\uparrow$ ) | 0.74 | 0.78 |
| F1 ( $\uparrow$ ) | 0.64 | 0.63 |
| Cohen’s $\kappa$ ( $\uparrow$ ) | 0.43 | 0.50 |
| FNR ( $\downarrow$ ) | 0.32 | 0.09 |
| FPR ( $\downarrow$ ) | 0.23 | 0.25 |

Table 13: Universal Verifier’s agreement with human labels on the Browserbase-OM2W dataset ( $n{=}106$ ) trajectories of Fara-7B on Online-Mind2Web, each labeled by two independent annotators). In the *UV-Blind* stage, annotators judged outcome and process success without seeing the UV’s output; in the *UV-Informed* stage, annotators were shown the UV’s verdict and asked whether they agreed. Outcome human labels are aggregated as majority vote; process human labels are the median rubric score binarized at $\geq 0.8$ .

Label-flip details – UV-Blind to UV-Informed:
A label-flip analysis reveals that 16.6% of annotator-level outcome judgments changed after seeing the UV’s reasoning: of the 34 outcome flips, 31 moved from success $\to$ failure (agreeing with UV-identified failures), 2 moved to agree with UV-identified successes, and 1 flipped to disagree with a UV failure call. For process, 21 of 25 flips moved to agree with UV-identified failures, 3 to agree with UV-identified successes, and 1 to disagree with a UV success call. In both cases, the UV’s reasoning disproportionately helped annotators identify failures they had initially missed.

In Table [13](#A2.T13) we show agreement metrics between humans and UV labels in the UV-blind and UV-informed setting, showing the impact that the judge’s flips had on e.g. Cohen’s $\kappa$ . Overall, the judges agreed more with the UV once they saw it’s output.

This evidence further validates the design of the Universal Verifier as being a detailed-oriented verifier that can reliably detect hallucinations and subtle mistakes. In fact, one of the judge’s feedback says exactly this (Quoting one of the annotators):

> “A recurring pattern was that I initially gave too much credit for
> workflows that looked mostly correct, even when the final answer missed
> the core requirement. One example was the Brooklyn neighborhood maps
> task (New–4091bdd3): the agent clearly reached the right MTA page and
> extracted the map names internally, so on first pass it felt close to
> correct. But the AI judge highlighted that the final answer never
> actually returned the list to the user, which made me more careful about
> distinguishing ‘found the info’ from ‘delivered the info’.‘
>
> Another strong example was a Porsche task (Porsche–c3a33396) asking for
> the cheapest certified pre-owned 911 meeting multiple constraints. The
> workflow looked good at first because the agent applied the right
> filters (CPO, 2019+, 200-mile radius, price low-to-high). My initial
> instinct was to trust the process because the setup was correct. But the
> AI judge caught that a cheaper listing was still visible in the
> filtered results, meaning the final selection was wrong even though the
> filtering looked reasonable. That changed how I thought about these
> tasks: a workflow can look methodical and still fail on the final
> selection step.
>
> The UPS Access Point task (Ups–9b5dfe54) was also a big one for me. I
> initially gave more credit because the locations themselves were clearly
> identified and the listed services sounded like normal UPS services.
> But after reading the AI judge reasoning and rechecking the screenshots,
> I realized none of those services were actually shown anywhere in the
> evidence. That was a useful reminder that I was sometimes filling in
> gaps with ‘likely true’ background knowledge instead of sticking to what
> was explicitly supported.
>
> Similarly, in the house-cleaning task (Thumbtack–c2153fc0), a weekly
> filter had been selected in one platform flow, which initially made me
> feel the weekly requirement was satisfied. But the final provider
> recommendation came from a different source, and there was no
> provider-specific confirmation that weekly recurring cleaning was
> actually offered. The AI judge helped surface the difference between
> platform-level filtering and provider-level verification.
>
> Overall, the most useful thing for me was seeing how often the miss
> happened in the ‘last mile’: not returning the requested information,
> overclaiming from incomplete evidence, or choosing the wrong final
> answer despite a mostly correct process. Those reviews made me more
> cautious about rewarding plausibility over verified completion.”
>
> —Annotator A

Continuous rubric score agreement.
Recall that the annotators of the Browserbase-OM2W also scored the same UV-generated rubric criteria (albeit “UV-Blind”, before seeing how the UV scored those criteria itself). In Figure [11](#A2.F11) we plot the UV’s scores of its rubric against each human annotator’s score for all 215 annotator–task pairs (106 tasks $\times$ ${\sim}$ 2 annotators) in the Browserbase-OM2W set of CUAVerifierBench. Each dot is colored by the annotator’s final (UV-informed) process verdict: green indicates the annotator ultimately judged the process as successful.

The Pearson correlation between UV and human rubric scores is $r=0.61$ ( $p<10^{-22}$ ) and the Spearman rank correlation is $\rho=0.58$ ( $p<10^{-20}$ ), confirming strong monotonic agreement between the two continuous scores. When binarized at the 0.8 threshold (dashed lines), this continuous agreement manifests as the Cohen’s $\kappa=0.43$ reported for process labels in Table [2](#S6.T2). The upper-right quadrant (both scores $\geq 0.8$ ) is dominated by green dots, while the lower-left quadrant is predominantly red, indicating that the UV and human annotators largely agree on both the successes and failures.

![](images/03_Verifiers/rubric_scatter.svg)


Figure 11: UV rubric score vs. human process score on the Browserbase OM2W dataset (215 annotator–task pairs). Each dot is colored by the annotator’s final UV-informed process verdict: green = process success, red = process failure. Dashed lines mark the 0.8 binarization threshold. The Pearson correlation is $r=0.61$ and Spearman $\rho=0.58$ .

Inter-annotator agreement.
To contextualize the UV–human agreement numbers, we measure how well the two human annotators agree with *each other* on the 106 tasks. Of the 106 tasks, 22 had annotator disagreements on UV-blind outcome and 18 on UV-informed outcome; 29 disagreed on UV-blind process and 28 on UV-informed process.

Table [14](#A2.T14) reports percent agreement and Cohen’s $\kappa$ for both UV-Blind and UV-Informed stages. In the UV-blind stage, outcome agreement ( $\kappa=0.57$ ) is substantially higher than process agreement whether measured as a binary correct/incorrect judgment ( $\kappa=0.45$ ) or via the continuous rubric score binarized at the 0.8 threshold ( $\kappa=0.36$ ). The continuous process scores themselves correlate at Pearson $r=0.62$ with a mean absolute difference of 0.21, indicating that annotators often assign directionally similar scores but differ enough near the 0.8 boundary to flip the binary label. This confirms that process evaluation is inherently more subjective than outcome evaluation: judging *whether the agent’s steps were reasonable* requires more nuanced assessment than judging *whether the final goal was met*.

After seeing the UV’s scores and reasoning (UV-informed stage), outcome agreement improves slightly ( $\kappa$ : $0.57\to 0.53$ ; disagreements: $21\to 18$ ), while process agreement remains unchanged at 28 disagreements—suggesting the UV’s detailed rubric reasoning is more effective at resolving outcome ambiguity than process ambiguity. Notably, the UV’s outcome $\kappa$ with human labels (0.58, Table [2](#S6.T2)) slightly exceeds the inter-annotator outcome $\kappa$ (0.53–0.57), and the UV’s process $\kappa$ (0.43) is comparable to the inter-annotator process $\kappa$ (0.36–0.45), indicating that the UV agrees with humans about as well as humans agree with each other on both dimensions.

|  | UV-Blind |  | UV-Informed |  |
| --- | --- | --- | --- | --- |
|  | % Agree | $\kappa$ | % Agree | $\kappa$ |
| Outcome (binary) | 79.6 | 0.57 | 82.5 | 0.53 |
| Process (binary) | 72.8 | 0.45 | 72.8 | 0.40 |
| Process (score $\geq$ 0.8) | 68.9 | 0.36 | — | — |

Table 14: Inter-annotator agreement on 103 Browserbase-OM2W tasks with two raters. Process labels show consistently lower agreement than outcome labels, reflecting the greater subjectivity of process evaluation. The continuous process scores have Pearson $r=0.62$ and MAE $=0.21$ .

### B.3 Ablation: Upgrading WebJudge and WebVoyager Backbones

To test whether the UV’s advantage stems from its multi-step rubric pipeline or simply from using a stronger backbone model, we re-run WebVoyager and WebJudge with GPT-5.2—the same model the UV uses—keeping all other settings (prompts, screenshot selection) unchanged. Results are in Table [2](#S6.T2).

Upgrading the backbone substantially reduces FPR for both verifiers (e.g., WebVoyager outcome FPR drops from 0.45 to 0.10 on Internal, and from 0.60 to 0.28 on Browserbase). However, this comes at the cost of sharply increased FNR: WebVoyager outcome FNR rises from 0.24 to 0.44 on Internal, and WebJudge outcome FNR rises from 0.33 to 0.57. The net effect on Cohen’s $\kappa$ is modest—WebVoyager improves from 0.31 to 0.43 on Internal outcome, still well below the UV’s 0.64. For the full UV results, the reader can refer to Table [2](#S6.T2). These results confirm that the UV’s advantage is architectural: its rubric-based decomposition, two-pass scoring, and structured outcome verification provide gains that cannot be replicated by simply dropping in a more capable model.

|  | Internal Dataset ( $n{=}140$ ) |  |  | Browserbase OM2W ( $n{=}106$ ) |  |  |
| --- | --- | --- | --- | --- | --- | --- |
|  | WebVoy. | WebJudge | UV | WebVoy. | WebJudge | UV |
|  | (GPT-4o) | (o4-mini) | (GPT-5.2) | (GPT-4o) | (o4-mini) | (GPT-5.2) |
| Agreement with outcome human labels |  |  |  |  |  |  |
| Accuracy ( $\uparrow$ ) | $0.67\pm 0.01$ | $0.72\pm 0.01$ | $0.81\pm 0.02$ | $0.48\pm 0.01$ | $0.64\pm 0.02$ | ${0.88\pm 0.00}$ |
| F1 ( $\uparrow$ ) | $0.73\pm 0.01$ | $0.74\pm 0.00$ | $0.81\pm 0.02$ | $0.35\pm 0.00$ | $0.44\pm 0.02$ | ${0.65\pm 0.03}$ |
| Cohen’s $\kappa$ ( $\uparrow$ ) | $0.31\pm 0.01$ | $0.44\pm 0.01$ | $0.64\pm 0.03$ | $0.13\pm 0.01$ | $0.26\pm 0.03$ | $0.58\pm 0.04$ |
| FNR ( $\downarrow$ ) | $0.24\pm 0.01$ | $0.33\pm 0.01$ | $0.32\pm 0.03$ | $0.12\pm 0.00$ | $0.12\pm 0.05$ | $0.31\pm 0.07$ |
| FPR ( $\downarrow$ ) | $0.45\pm 0.01$ | $0.22\pm 0.02$ | $0.01\pm 0.01$ | $0.60\pm 0.01$ | $0.40\pm 0.02$ | $0.08\pm 0.01$ |
| Agreement with process human labels |  |  |  |  |  |  |
| Accuracy ( $\uparrow$ ) | $0.62\pm 0.01$ | $0.66\pm 0.01$ | $0.81\pm 0.01$ | $0.55\pm 0.01$ | $0.68\pm 0.01$ | ${0.78\pm 0.01}$ |
| F1 ( $\uparrow$ ) | $0.70\pm 0.01$ | $0.70\pm 0.01$ | $0.86\pm 0.01$ | $0.47\pm 0.00$ | $0.53\pm 0.02$ | ${0.57\pm 0.02}$ |
| Cohen’s $\kappa$ ( $\uparrow$ ) | $0.17\pm 0.01$ | $0.32\pm 0.02$ | $0.59\pm 0.03$ | $0.22\pm 0.01$ | $0.34\pm 0.02$ | $0.43\pm 0.03$ |
| FNR ( $\downarrow$ ) | $0.31\pm 0.01$ | $0.40\pm 0.01$ | $0.24\pm 0.01$ | $0.05\pm 0.00$ | $0.12\pm 0.04$ | $0.29\pm 0.02$ |
| FPR ( $\downarrow$ ) | $0.52\pm 0.00$ | $0.25\pm 0.03$ | $0.04\pm 0.01$ | $0.56\pm 0.01$ | $0.38\pm 0.01$ | $0.20\pm 0.01$ |

Table 15: Agreement between three verifiers and human labels on two datasets. All values are mean $\pm$ std over 3 independent runs. *Internal Dataset* are internally annotated trajectories while *Browserbase OM2W* are Fara-7B trajectories from Online-Mind2Web with UV-informed human labels aggregated across two annotators per task by majority vote (outcome) or median rubric score binarized at $\geq 0.8$ (process); see §[5](#S5.SSx1). For the UV, outcome uses the binary outcome signal and process uses the rubric score binarized at $\geq 0.8$ . WebVoyager and WebJudge each produce a single binary prediction compared against both label types.

### B.4 AgentRewardBench Agreement

|  | Success | Fail | Total | Success Rate |
| --- | --- | --- | --- | --- |
| Over-budget (truncated) | 44 | 663 | 707 | 6.2% |
| Terminated (agent stopped) | 312 | 283 | 595 | 52.4% |

Table 16: Partitions AgentRewardBench’s 1302 human annotated trajectories based on its relation to the step budget and human-annotated success

From Table [16](#A2.T16), we see that 707 trajectories went over its step budget, and of those, we see that  94% were labeled as failure by AgentRewardBench human annotators. An expert annotator qualitatively verified the highest quality successful and terminated trajectories from Table [16](#A2.T16) with respect to the agent’s actions, thoughts, and screenshots. Similar to AgentRewardBench’s annotators, our expert annotator annotated the trajectories with respect to the outcome as opposed to the process. Based on the expert annotator’s labeling of 30 randomly sampled high quality, we observed a FPR of 8/30 $\approx$ 0.27. An example of such a FP can be seen in Figure [12](#A2.F12).

![Refer to caption](images/03_Verifiers/ARB_bad.png)


Figure 12: An example false positive from AgentRewardBench. The task is ”Navigate to the item on this page whose image is a desktop screenshot”. Although this is a screenshot, the spring mattress screenshot is a mobile screenshot, not a desktop screenshot

.

## Appendix C Auto-Research Details

![](images/03_Verifiers/kappa_progression_process.svg)


Figure 13: Process Cohen’s $\kappa$ agreement with human labels across successive verifier design iterations. Compare with the outcome $\kappa$ in Figure [1](#S0.F1). Process agreement is consistently lower than outcome agreement for all three settings, reflecting the greater subjectivity of process evaluation.

![](images/03_Verifiers/fpr_fnr_progression_outcome.svg)


Figure 14: Outcome false positive rate (FPR) and false negative rate (FNR) across successive design iterations. See Figure [1](#S0.F1) for the corresponding Cohen’s $\kappa$ .

![](images/03_Verifiers/fpr_fnr_progression_process.svg)


Figure 15: Process false positive rate (FPR) and false negative rate (FNR) across successive design iterations. See Figure [13](#A3.F13) for the corresponding Cohen’s $\kappa$ .

### C.1 Auto-Research Run Summary

Qualitative observations.
The slopes of the auto-research curves in Figures [1](#S0.F1),  [13](#A3.F13),  [14](#A3.F14), and [15](#A3.F15) are less steep than the human expert. When digging into the auto-research agent logs, the first observation was in *depth of analysis* was much shallower than what the human experts often derived from CUA trajectory logs. For example, the human expert, after observing the verifier failing many trajectories over minor issues—such as “inferring most Coursera courses can be audited for free is unsubstantiated,” or “not disambiguating apartment from rental-unit”—deduced general scoring rules like “separate nitpicks from critical failures.” These opinionated, high-level insights drove large jumps in agreement.
The auto-research agent tended to be conservative and incremental—adjusting thresholds or tightening rubric language for individual failure cases—rather than making larger structural or conceptual changes that drove the human expert’s biggest gains.

Changes the Auto-Research Agent Made
This section provides details on the auto-research agent’s iterations when continuing from the human expert’s best verifier (§[6](#S6.SS0.SSS0.Px1), green curve in Figure [1](#S0.F1)). Table [17](#A3.T17) lists each iteration, its purpose, and whether it was committed or rolled back based on the FPR constraint. Table [18](#A3.T18) highlights the most impactful prompt and code changes the agent made, illustrating the types of modifications an AI research agent discovers autonomously.

| Run | Purpose | Decision |
| --- | --- | --- |
| 0 | Baseline | BASELINE |
| 1 | Outcome verification fixes | ROLLED BACK (process FPR 8.82%) |
| 2 | Semantic precision + entity non-existence + nitpick calibration | COMMITTED |
| 3 | Variant/tier + binding examples + CP rule | ROLLED BACK (process FPR 5.88%) |
| 4 | Similar to run 3, different approach | ROLLED BACK (process FPR 5.88%) |
| 5 | Binding example matching | ROLLED BACK (outcome FPs=2) |
| 6 | Rubric score context code change | COMMITTED |
| 7 | CP output + multi-item cart + info non-existence + superlative check | ROLLED BACK (kappa worse) |
| 8 | CP output + multi-item cart + info non-existence (no superlative) | ROLLED BACK (kappa worse) |
| 9 | No changes — stochastic baseline measurement | Confirmed run 6 was lucky ( $\kappa=0.6407$ ) |
| 10 | Same as run 8 (re-applied after baseline calibration) | COMMITTED |
| 11 | Rubric consistency + expanded example_match_check + lower cart threshold + colloquial terms | COMMITTED |

Table 17: Summary of auto-research agent iterations continuing from the human expert’s best verifier. Each run represents a single prompt modification cycle. Green rows were committed (improved $\kappa$ without increasing FPR), red rows were rolled back, and yellow indicates a stochastic baseline check.


| Run | Change Type | What the Agent Did | Why It Helped |
| --- | --- | --- | --- |
| 2 | Nitpick calibration (prompt) | Added explicit test: “Would a reasonable user say this output is useful?” Enumerated always-nitpick scenarios (approximate walk times, price tier symbols, common knowledge inferences). | Fixed 10+ false negatives where minor issues were treated as critical failures. |
| 2 | Semantic precision in rubric generation (prompt) | Added rule: criteria must test the exact concept the task asks about, not a related one. E.g., “how many people work remotely” $\neq$ “how many remote job postings.” | Fixed false positives from rubrics testing the wrong quantity. |
| 6 | Rubric score context (code) | Computed normalized rubric score and appended calibration guidance to the outcome prompt. If rubric $\geq 95\%$ , verifier must identify a specific critical issue to override. | Most impactful single change: provided quantitative signal instead of adding more text to an already-long prompt. |
| 10 | Critical point output rule (prompt) | When screenshots confirm the agent reached a transaction boundary (checkout, passenger info page) with correct selections, a brief output message is a nitpick, not grounds for failure. | Fixed persistent false negatives on booking/flight tasks where the agent correctly stopped but didn’t restate details. |
| 11 | Forced rule checking (prompt) | Expanded the mandatory example_match_check JSON field to require the LLM to also check named rules (Entity Non-Existence, Multi-Item Cart, Critical Point Output, etc.) before making its verdict. | Mitigated the “rules exist but aren’t applied” problem in ${\sim}1{,}800$ -line prompts. |

Table 18: Representative prompt and code changes made by the auto-research agent across its iterations. Changes span prompt engineering (calibration rules, forced structured checking) and code modifications (injecting rubric scores as quantitative context).

##### Lessons from the auto-research agent’s behavior.

Several patterns emerged from observing the agent’s iterations:
(1) Code changes outperformed prompt additions when prompts were already long. The rubric score context injection (run 6) was the single most impactful change because it provided quantitative calibration without adding more text to parse.
(2) Forcing explicit rule checking (run 11) partially mitigated the problem of rules existing in prompts but not being applied by the scoring LLM. By naming rules in a mandatory output field, the LLM is more likely to consider them.
(3) Concrete tests beat abstract principles. “Would the user say this is useful?” (run 2) proved more actionable than “be reasonable about minor issues.”
(4) Stochastic variance is large. Across identical prompts, outcome $\kappa$ ranged from 0.64 to 0.71 due to LLM non-determinism in rubric generation, necessitating multiple runs to distinguish signal from noise.
