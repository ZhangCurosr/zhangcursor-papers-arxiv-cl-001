# Beyond Calibration: Temporal LLM Confidence Assessment Across Languages and Local Settings

Sahil Kale<sup>1</sup> <sup>1</sup>University of California, Los Angeles CA, USA Correspondence: sahilrkale@ucla.edu

## Abstract

Large language models are expected to estimate their own uncertainty, with confidence signals used to guide retrieval, adaptive compute allocation, routing, and selective abstention. We investigate whether confidence signals measured at different temporal stages of problem solving encode distinct forms of epistemic information and remain reliable beyond English-centric settings. Inspired by classical meta-memory theory, we distinguish anticipatory pre-solve confidence (Feeling-of-Knowing, FOK) from retrospective post-solve confidence (Judgement-of-Learning, JOL). We evaluate these signals across two frontier LLMs, multiple reasoning domains, translated Marathi benchmarks, and a newly constructed benchmark of genuinely local Marathi factual questions. Across settings, the cheaper pre-solve signal remains weakly calibrated, while postsolve confidence generally provides stronger epistemic alignment despite its additional inference cost. Confidence behaviour transfers surprisingly well under direct language translation, with calibration trends largely preserved between English and Marathi, but degrades substantially on local Marathi knowledge, suggesting that linguistic transfer alone is insufficient for region-specific information needs. Finally, hallucinated responses maintain persistently elevated confidence after answer generation, highlighting important limitations of current LLM self-assessment mechanisms.

## 1 Introduction

Large language models (LLMs) are increasingly deployed across a wide range of real-world applications, including question answering, reasoning systems, retrieval-augmented generation (RAG), autonomous agents, and decision-support pipelines (Li et al., 2024; Cheng et al., 2025). Modern models contain substantial factual and procedural knowledge encoded within their parameters, while also leveraging external context through tools, retrieval systems, and long-context prompting. In many such systems, models are further expected to make decisions about their own uncertainty and knowledge limitations, a capability often framed as self-knowledge (Kale and Nadadur, 2025) or metacognition (Ma et al., 2025). These internal confidence estimates are increasingly used to influence downstream behaviours such as deciding whether to invoke tools, request additional user clarification, defer generation, allocate additional compute, or trigger retrieval mechanisms (Li et al., 2025). However, recent work has shown that LLM confidence signals are often poorly calibrated and only weakly aligned with actual correctness. This limits the efficiency, reliability, and cost-effectiveness of such confidence-driven decision policies (Kale and Dhami, 2025).

![](images/a7b486a7edb3c66cbda21e7d716d0878907cf27c52936350bb43cec94c69c30b.jpg)  
Figure 1: Illustration of pre-solve Feeling-of-Knowing (FOK) and post-solve Judgement-of-Learning (JOL) confidence signals in large language models.

While confidence calibration has been studied primarily in English-centric benchmarks, many practical deployments increasingly involve multilingual and underrepresented language settings where both model knowledge and evaluation resources are less abundant. Confidence estimates that appear reliable in high-resource settings may fail to transfer across languages or culturally specific knowledge domains, potentially leading to inappropriate retrieval decisions, overconfident hallucinations, or unsafe downstream behaviour. A particularly important open question is whether confidence calibration is primarily tied to language or to underlying knowledge availability. A model may retain similar confidence behaviour when questions are translated into another language, yet fail when confronted with genuinely local information that is sparsely represented in pre-training corpora and evaluation benchmarks. Distinguishing between these sources of distribution shift is crucial for deploying confidence-driven systems in multilingual settings.

In this work, we investigate whether confidence signals measured at different temporal stages of reasoning encode distinct forms of epistemic information, and also whether these carry across lowresource settings. Inspired by classical constructs from cognitive psychology and meta-memory research (Nelson, 1990; Koriat, 1997), we study two complementary signals: a pre-solve Feelingof-Knowing (FOK) signal, and a post-solve confidence signal similar to Judgement-of-Learning (JOL). The FOK signal measures the model’s estimated likelihood of solving a problem correctly before attempting to start reasoning towards a solution, capturing a cheap yet possibly useful anticipatory signal. In contrast, the JOL-style signal measures confidence in a provided reasoning path and solution after answer generation, reflecting retrospective evaluation expected to be costlier but better calibrated. This framing introduces a temporal distinction that is largely absent in existing LLM calibration work, where confidence is typically treated as a static scalar attached only to the final answer. In this paper, we instead ask whether epistemic self-assessment changes between presolve and post-solve states, and whether this shift itself carries useful information about model behaviour, reliability, and failure modes.

In essence, our work is guided by the following research questions: RQ1: Is the pre-solve confidence signal (FOK) or the post-solve confidence signal (JOL) better calibrated to actual answer correctness, and can either signal support downstream decisions such as routing, retrieval triggering, or adaptive compute allocation? We also explore the combined effect of these signals in error types by answering another important question, RQ2: Do strong values of FOK and JOL or delta trends correspond to distinct categories of model failure, such as knowledge gaps, reasoning failures, or hallucinated responses? In addition, we investigate a third research question motivated by multilingual deployment settings: RQ3: Do temporal confidence signals transfer across low-resource languages, and how are they affected by genuinely local knowledge distributions that differ from standard Englishcentric benchmarks?

We operationalise FOK and JOL confidence signals using prompting-based self-assessment before and after reasoning generation across multiple LLM families and domains. We evaluate their calibration, cost-effectiveness, and transition dynamics using correctness-conditioned analyses and confidence calibration metrics. The main contributions of our work can be highlighted as follows:

• We introduce a novel temporal framing of LLM self-confidence by separating anticipatory pre-solve confidence from retrospective post-solve confidence and show that the cheaper pre-solve signal is generally insufficiently calibrated for practical deployment, while post-solve confidence is often more informative but not uniformly more reliable

• We provide one of the first analyses of temporal confidence calibration in two frontier LLMs, demonstrating that the practical utility of confidence signals depends strongly on reasoning domain and model family

• We extend temporal confidence evaluation to low-resource settings in Marathi, showing that confidence behaviour transfers relatively well across language translation but degrades substantially for genuinely local knowledge

## 2 Related Work

## 2.1 Self-Knowledge and Confidence Estimation in LLMs

Recent work has increasingly framed large language models as systems capable of exhibiting forms of self-knowledge, self-monitoring, or metacognitive behaviour (Kale, 2025; Podolak and Verma, 2025). In this context, self-knowledge refers to a model’s ability to estimate whether its own generated answer is likely to be correct or reliable (Li et al., 2025).

Prior work has shown that LLMs can often distinguish between questions they are likely to answer correctly and those where they are uncertain, particularly under calibrated confidence or selective abstention prompting (Kale and Dhami, 2025). However, these signals remain imperfect, with models frequently exhibiting overconfidence, hallucination-prone certainty, and weak calibration under reasoning-heavy or distribution-shifted settings (Lin et al., 2022; Ren et al., 2026).

Despite these limitations, confidence-aware signals are increasingly important for applications such as retrieval triggering, adaptive compute allocation, selective generation, tool invocation, and human-in-the-loop systems (Wang et al., 2026; Zhang et al., 2026).

## 2.2 Measuring Self-Knowledge and Confidence Signals

Prior work has proposed a broad range of approaches for measuring confidence in language models. A major distinction concerns whether confidence is inferred from internal model representations (white-box methods) or elicited through prompting and behavioural outputs (black-box methods). White-box approaches typically rely on token probabilities, entropy, hidden-state representations, or calibration statistics derived directly from model distributions (Kadavath et al., 2022; Kissling et al., 2026). In contrast, black-box methods estimate self-knowledge through verbalised confidence ratings, self-evaluation prompts, selective prediction, answer consistency, critique-andrevision behaviours, and confidence-guided abstention mechanisms (Xu et al., 2024; Kale and Dhami, 2025).

Most prior approaches measure confidence only after answer generation, implicitly treating selfknowledge as a static retrospective signal attached to a completed response. In contrast, our work introduces a temporal perspective on confidence estimation by distinguishing between anticipatory pre-solve confidence and retrospective post-solve confidence.

## 2.3 Metacognition, Distribution Shifts, and Underrepresented Languages

A growing body of work has examined the robustness of LLM capabilities under distribution shifts arising from changes in task domains, reasoning requirements, languages, or cultural contexts (Moskvoretskii et al., 2025; Wiemerslage and Wense, 2025). While multilingual evaluation has received increasing attention across generation, reasoning, and factual knowledge tasks, comparatively little work has investigated whether models can accurately assess their own uncertainty in these settings (Durrani et al., 2025). This distinction is important because strong task performance does not necessarily imply well-calibrated confidence estimates. Our work contributes to analysis beyond English by evaluating temporal confidence signals in Marathi using both translated factual QA tasks and locally grounded knowledge questions designed to probe underrepresented linguistic and cultural contexts.

## 3 Methodology

Our methodology is designed to measure two temporally distinct confidence signals associated with problem solving in large language models: a presolve anticipatory confidence signal and a postsolve retrospective confidence signal. Broadly inspired by classical meta-memory constructs, we refer to these signals as Feeling-of-Knowing (FOK) and Judgement-of-Learning (JOL), respectively. Because our evaluation includes closed-source models accessible only through API interfaces, we use prompting-based verbal confidence estimates as the primary confidence signal, despite known limitations. The overall pipeline consists of three sequential stages shown in Figure 1: (1) eliciting a pre-solve confidence estimate before reasoning begins, (2) generating an unconstrained answer to the task, and (3) eliciting a post-solve confidence estimate conditioned on the generated answer.

## 3.1 Pre-Solve Confidence Signal (FOK)

To obtain the pre-solve confidence signal, the model is first shown only the input question and is asked to estimate the likelihood that it would solve the problem correctly without actually attempting the solution. The prompt explicitly instructs the model not to reason about or solve the task, and to instead provide only a simple confidence estimate. The prompt used for pre-solve confidence elicitation is shown in Figure 2.

The scalar value returned by the model is treated as the FOK estimate. This signal captures the model’s anticipatory belief regarding whether its internal knowledge and reasoning capabilities are sufficient to successfully solve the task prior to answer generation.

![](images/7d906f083a159d8547c3dc1f41de4562a1b935159f2fa76a88a26a4800b05406.jpg)  
Figure 2: Prompt used for eliciting pre-solve confidence from LLMs

![](images/04fe0b301d2dfdb2ad028b6f699924d5aaa9e9e242bbd57f632e6953642ef9d3.jpg)  
Figure 3: Prompt used for eliciting post-solve confidence from LLMs

## 3.2 Answer Generation

After obtaining the pre-solve confidence estimate, the model is prompted again with the original question and asked to directly solve the task with chainof-thought reasoning. No additional confidence instructions, calibration prompts, or answer formatting requirements are imposed during this stage. This design choice ensures that the generated reasoning trajectory more closely reflects the model’s natural inference behaviour under standard prompting conditions.

The generated answer is then stored and used as contextual input for retrospective confidence estimation in the next stage.

## 3.3 Post-Solve Confidence Signal (JOL)

To obtain the post-solve confidence signal, the model is shown both the original question and its previously generated answer. It is then asked to estimate the probability that its answer is correct. Unlike the pre-solve stage, this confidence estimate is conditioned on the model’s completed reasoning trajectory and final output. The post-solve confidence prompt is shown in Figure 3.

The scalar value returned by the model is then used as a JOL-style retrospective confidence estimate. This signal reflects self-evaluation conditioned on the produced answer and reasoning path rather than on the question alone.

Following these steps, for each problem instance, we therefore obtain three core variables: a presolve confidence estimate (FOK), a generated answer, and a post-solve confidence estimate (JOL). The generated answer is independently evaluated against reference solutions to determine correctness labels. We then analyse confidence calibration estimates and cost-effectiveness of these signals ahead.

For multilingual experiments, the same threestage procedure is retained without modification. Confidence elicitation, answer generation, and postsolve self-assessment prompts are translated into Marathi while preserving their original structure and intent. This design allows us to study whether temporal confidence signals remain stable under linguistic transfer without changing the underlying confidence estimation framework.

## 4 Experimental Setup

## 4.1 Models

We evaluate our framework using two frontier large language models: GPT-5.4 (gpt-5.4-2026-03-05) and Claude Sonnet 4.6. Models were accessed through the official OpenAI and Anthropic APIs. All experiments use deterministic decoding with temperature set to 0, while other generation parameters remain at default settings. Full details are provided in Section A in the Appendix.

## 4.2 Datasets

We evaluate across four domains probing mathematical reasoning, logical reasoning, factual recall, and low-resource multilingual factual recall.

## 4.2.1 Mathematical Reasoning

For mathematical reasoning, we use 500 randomly sampled questions from the Mathematics Stack Exchange split of RealMath (Zhang et al., 2025). The dataset contains non-trivial user-authored mathematical problems with verified solutions and diverse reasoning structures, making it suitable for studying confidence calibration under open-ended mathematical reasoning.

## 4.2.2 Logical Reasoning

For logical reasoning, we use 400 samples from RiddleBench (Halder et al., 2025), a benchmark of challenging natural-language puzzles involving deduction, constraint satisfaction, spatial reasoning, and multi-step inference. These tasks provide a cognitively demanding setting for evaluating confidence behaviour under complex reasoning.

## 4.2.3 Factual Recall

For factual recall, we use 750 randomly sampled questions from TriviaQA (Joshi et al., 2017), a large-scale benchmark of naturally authored trivia questions with verified answers. Unlike the reasoning datasets above, TriviaQA primarily evaluates factual retrieval and parametric knowledge recall.

## 4.2.4 Low-Resource Settings

To evaluate temporal confidence signals in an underrepresented language setting, we construct two Marathi factual-recall splits.

The first split (Marathi-Translated) is derived directly by translating TriviaQA, RealMath and RiddleBench to a low-resource language, Marathi with each split retaining the same number of examples as its English counterpart (750 TriviaQA, 500 RealMath, 400 RiddleBench). Questions and reference answers are translated from English to Marathi using the Google Translate API while preserving the original task structure and evaluation protocol. Two graduate-level native Marathi speakers reviewed translated prompts and dataset samples, performed spot-checks throughout the corpus, and verified semantic equivalence with the original English questions. This split isolates language transfer while keeping knowledge requirements unchanged. Additional details are in Section B in the Appendix.

The second split (Marathi-Local) evaluates genuinely local knowledge. Unlike translated benchmarks, these questions require region-specific information that is less frequently represented in English-language resources and often available primarily through Marathi-language sources. Three native Marathi speakers manually authored 201 factual questions based on local events and public information reported before model knowledge cut-off dates using trusted Marathi news outlets such as Zee News Marathi, Maharashtra Times, and ABP Majha. Each question was paired with supporting source URLs for verification, while reference answers and correctness assessments were independently reviewed by two separate native speakers with agreement of Cohen’s κ = 0.82. Additional details and examples are in Section C in the Appendix.

## 4.3 Evaluation Protocol

Answers are evaluated using benchmark-specific matching procedures to obtain correctness labels. We report Expected Calibration Error (ECE) (Naeini et al., 2015), Brier Score (Naeini et al., 2015), and AUROC. ECE measures the gap between predicted confidence and empirical correctness, Brier Score evaluates the quality of probabilistic confidence estimates, and AUROC measures how effectively confidence scores distinguish correct from incorrect predictions. We note that AUROC evaluates discrimination independently of calibration and can remain high even when ECE or Brier Score indicate poor calibration, but we report all three because they capture complementary properties of confidence quality. Reliability curves are additionally used to visualise calibration behaviour. Uncertainty estimates are computed using 2000 bootstrap resamples and reported as 95% confidence intervals. We further report cost-benefit analyses and confidence trends across error categories.

For the Marathi-Translated split, evaluation was adapted to support valid multilingual answer variations. Each example contains both the original English reference answer and its Marathi translation. Predictions are considered correct if they match either reference set under the benchmark evaluation procedure, reducing false negatives caused by transliteration differences, bilingual generations, or alternative entity forms. Native-speaker spot checks were conducted to verify evaluation quality.

For the Marathi-Local split, no benchmark labels are available. Answer correctness is therefore assessed manually by native Marathi speakers using the associated source material. Following prior factuality evaluation work, correctness is scored on a continuous scale between 0 and 1, where 1 denotes a fully correct answer, 0 an incorrect answer, and intermediate values partially correct responses (AUROC computed with threshold of 0.5). These scores are subsequently used when computing calibration and confidence metrics.

<table><tr><td rowspan="2">Model</td><td rowspan="2">Domain</td><td colspan="3">Pre-Solve (FOK)</td><td colspan="3">Post-Solve (JOL)</td></tr><tr><td>ECE↓</td><td>Brier↓</td><td>AUROC↑</td><td>ECE↓</td><td>Brier↓</td><td>AUROC↑</td></tr><tr><td rowspan="3">GPT-5.4</td><td>TriviaQA</td><td> $0 . 1 9 5 \pm 0 . 0 2 7$ </td><td> $0 . 2 0 9 \pm 0 . 0 2 8$ </td><td> $0 . 5 6 7 \pm 0 . 0 5 3$ </td><td> $0 . 1 9 4 \pm 0 . 0 2 1$ </td><td> $0 . 2 0 3 \pm 0 . 0 2 5$ </td><td> $0 . 6 0 6 \pm 0 . 0 5 1$ </td></tr><tr><td>Math</td><td> $0 . 3 8 1 \pm 0 . 0 4 1$ </td><td> $0 . 3 6 6 \pm 0 . 0 3 7$ </td><td> $0 . 7 1 9 \pm 0 . 0 4 7$ </td><td> $0 . 3 1 5 \pm 0 . 0 4 5$ </td><td> $0 . 3 3 0 \pm 0 . 0 3 7$ </td><td> $0 . 7 5 1 \pm 0 . 0 4 8$ </td></tr><tr><td>Logic</td><td> $0 . 4 8 3 \pm 0 . 0 3 9$ </td><td> $0 . 4 6 9 \pm 0 . 0 3 5$ </td><td> $0 . 6 7 9 \pm 0 . 0 5 5$ </td><td> $0 . 2 8 6 \pm 0 . 0 4 1$ </td><td> $0 . 3 1 3 \pm 0 . 0 3 6$ </td><td> $0 . 6 9 0 \pm 0 . 0 4 9$ </td></tr><tr><td rowspan="3">Claude Sonnet 4.6</td><td>TriviaQA</td><td> $0 . 0 7 1 \pm 0 . 0 2 3$ </td><td> $0 . 1 1 9 \pm 0 . 0 1 9$ </td><td> $0 . 6 5 6 \pm 0 . 0 5 5$ </td><td> $0 . 0 7 7 \pm 0 . 0 2 4$ </td><td> $0 . 1 1 4 \pm 0 . 0 2 0$ </td><td> $0 . 7 0 3 \pm 0 . 0 4 6$ </td></tr><tr><td>Math</td><td> $0 . 1 8 8 \pm 0 . 0 6 1$ </td><td> $0 . 2 3 1 \pm 0 . 0 5 1$ </td><td> $0 . 5 0 0 \pm 0 . 0 9 2$ </td><td> $0 . 1 0 8 \pm 0 . 0 6 4$ </td><td> $0 . 1 4 0 \pm 0 . 0 4 7$ </td><td> $0 . 7 9 1 \pm 0 . 0 8 5$ </td></tr><tr><td>Logic</td><td> $0 . 3 4 1 \pm 0 . 0 5 1$ </td><td> $0 . 3 1 6 \pm 0 . 0 2 9$ </td><td> $0 . 7 6 7 \pm 0 . 0 5 7$ </td><td> $0 . 4 7 2 \pm 0 . 0 5 3$ </td><td> $0 . 4 5 6 \pm 0 . 0 4 1$ </td><td> $0 . 6 9 5 \pm 0 . 0 4 9$ </td></tr></table>

Table 1: Calibration and discrimination performance (95% confidence intervals) across domains and temporal stages

![](images/8a3b5ef6d0fd74168b8059d96168eb9ca5c078d43042d2f3cbde6a516d88fb92.jpg)  
Figure 4: Aggregate reliability curves comparing presolve (FOK) and post-solve (JOL) confidence calibration across models and domains

## 5 Results

Table 1 reports calibration and discrimination performance for pre-solve (FOK) and post-solve (JOL) confidence signals across models and domains. Reported values are means with 95% bootstrap confidence intervals. Figure 4 shows aggregate reliability curves. We evaluate calibration using Expected Calibration Error (ECE) and Brier Score, where lower values indicate stronger alignment between confidence and correctness, and discrimination using AUROC.

## 5.1 Calibration Analysis

## 5.1.1 Post-solve confidence generally provides stronger epistemic alignment

Across most domains, JOL-style confidence estimates exhibit lower calibration error and stronger discrimination than FOK estimates, although gains are not uniform and remain modest for factual recall. This trend is particularly pronounced in mathematics, where Claude Sonnet 4.6 improves from near-random discrimination (0.500 ± 0.092) to strong discrimination $( 0 . 7 9 1 \pm 0 . 0 8 5 )$ . The consistently weaker calibration of the cheaper pre-solve signal suggests that FOK alone is insufficiently reliable for downstream decisions such as retrieval triggering, model routing, or adaptive compute allocation. Instead, models appear to require answer generation before producing confidence estimates that better reflect correctness.

## 5.1.2 Reasoning domains exhibit substantially higher calibration instability than factual recall

Both models remain notably miscalibrated on mathematics and logical reasoning despite moderate discrimination performance. Logic reasoning in particular exhibits consistently high ECE values, with GPT-5.4 reaching a pre-solve ECE of $0 . 4 8 3 \pm 0 . 0 3 9$ and Claude Sonnet 4.6 a post-solve ECE of $0 . 4 7 2 { \scriptstyle \pm 0 . 0 5 3 }$ . In contrast, TriviaQA shows lower calibration error and smaller temporal shifts between FOK and JOL. This suggests that retrospective confidence adjustment is more useful for multi-step reasoning tasks than for direct factual retrieval, where confidence remains relatively stable before and after answer generation.

## 5.1.3 Temporal confidence transitions reveal domain-dependent failure behaviour

The transition from FOK to JOL is not uniformly beneficial. While post-solve confidence often improves calibration and ranking quality, certain domains exhibit confidence inflation after reasoning. Most notably, Claude Sonnet 4.6 on logic reasoning degrades from an ECE of 0.341 to 0.472, while AU-ROC falls from 0.767 to 0.695. The corresponding reliability curves are also less stable after reasoning. These results suggest that generating extended reasoning traces can sometimes induce false certainty rather than improved self-knowledge.

## 5.2 Cost-Benefit Analysis

We next examine the trade-off between the additional inference cost required to obtain JOL confidence and the calibration gains achieved. FOK cost includes only the confidence estimation prompt, whereas JOL additionally requires answer generation. We note this cost comparison assumes an application where answer generation is not otherwise required (e.g., pre-generation retrieval routing). In settings where an answer must be produced regardless (e.g., post-hoc abstention or answer verification), the marginal cost of JOL is limited to the additional confidence-elicitation query. Costs were estimated using average dataset lengths and provider pricing rates as of May 2026. Positive ∆ECE values indicate improved calibration from JOL relative to FOK, as shown in Figure 5.

![](images/3517f8ae851e8f464150fbb0b02b4f32d333da8fd735bbb02b3651f4a967bf2e.jpg)  
Figure 5: Calibration improvement versus additional inference cost for post-solve confidence (JOL) relative to pre-solve confidence (FOK) across models and domains.

## 5.2.1 JOL is primarily cost-effective in structured reasoning domains

For GPT-5.4, JOL consistently improves calibration, with the largest gains occurring in Logic $( \Delta \mathrm { E C E } = 0 . 1 9 8 )$ . Mathematics also shows meaningful improvements for both models, whereas TriviaQA exhibits only marginal gains. These results suggest that post-solve confidence becomes most useful as reasoning complexity increases and can justify additional inference cost in structured problem-solving settings.

## 5.2.2 Additional reasoning does not always improve self-assessment

TriviaQA shows minimal calibration improvement from JOL and slight degradation for Claude Sonnet 4.6, suggesting that the cheaper FOK signal may already be sufficient for factual recall. More notably, Claude on Logic becomes substantially less calibrated despite higher inference cost, indicating that additional reasoning can sometimes amplify miscalibration rather than improve confidence reliability.

## 5.3 Error Type Analysis

To investigate whether confidence patterns correspond to distinct failure mechanisms, we manually analysed 200 incorrect responses sampled across models and domains. Two graduate-level annotators independently reviewed all samples, achieving a Cohen’s κ of 0.92. Disagreements were subsequently resolved through discussion. Errors were assigned to one of three categories:

![](images/70fa7a90465d4df3a8f15f7aec60d4d0fc22c3e715d8f5180630205415092e59.jpg)  
Figure 6: Mean pre-solve (FOK) and post-solve (JOL) confidence across annotated error categories.

• Knowledge gap: The model lacked the required information or explicitly hedged between alternatives.

• Hallucinated knowledge: The model confidently generated fabricated facts, entities, or incorrect theorem usage.

• Reasoning failure: The answer was incorrect due to flawed reasoning despite the absence of fabricated knowledge.

Absolute confidence levels proved more informative than confidence transitions for distinguishing failure categories. Confidence deltas exhibited high variance and did not significantly separate error types $( p = 0 . 3 6 6$ , Kruskal-Wallis test). Nevertheless, clear differences emerge in Figure 6, where confidence generally decreases from FOK to JOL, consistent with the calibration improvements observed earlier.

## 5.3.1 Hallucinations exhibit persistently elevated confidence

Hallucinated responses showed the highest confidence both before and after reasoning (FOK: 0.837, JOL: 0.758) despite being incorrect. This suggests that hallucinations are associated less with confidence increases during reasoning and more with overconfident internal representations that remain stable throughout answer generation, consistent with prior hallucination research (Simhi et al., 2025; Kalai and Vempala, 2024).

## 5.3.2 Reasoning failures show lower and more unstable confidence patterns

Reasoning failures exhibited the lowest confidence levels alongside substantial variance in confidence transitions, indicating that models partially recognise reasoning difficulty even when failing. Knowledge gaps occupied an intermediate regime, where models often began uncertain but also decreased confidence after producing an answer.

## 5.4 Multilingual Transfer and Local Knowledge

## 5.4.1 Temporal confidence signals largely transfer across language translation

Direct translation of benchmark questions into Marathi (Marathi-Translated split) produces only modest changes in calibration and discrimination performance relative to the original English benchmarks, as seen in Table 2. Across models and domains, most ECE differences remain small and within bootstrap uncertainty intervals. GPT-5.4 exhibits only minor calibration changes after translation, and temporal confidence dynamics remain largely unchanged across mathematical, logical, and factual tasks. Claude Sonnet 4.6 shows somewhat larger degradation for factual recall, but the overall pattern of stronger post-solve confidence discrimination persists.

These findings suggest that the temporal confidence mechanisms captured by FOK and JOL are relatively robust to language transfer. Translating tasks into an underrepresented language does not substantially alter how these frontier models assess their own uncertainty.

## 5.4.2 Locally grounded knowledge produces substantially larger calibration failures

A markedly different picture emerges on the Marathi-Local split. Both models exhibit substantially higher calibration error and weaker discrimination than on either English or translated Marathi benchmarks (Table 3).

For GPT-5.4, pre-solve ECE increases from 0.195 on English TriviaQA and 0.205 on translated Marathi TriviaQA to 0.421 on Marathi-Local questions. Claude Sonnet 4.6 exhibits a similar increase from 0.071 and 0.122 to 0.378. AUROC values simultaneously approach near-random ranking behaviour, falling to 0.521 and 0.558 respectively.

These results indicate that calibration degrades far more strongly under local knowledge shifts than under language shifts alone. While models largely preserve self-assessment behaviour across languages, they remain substantially less reliable when confronted with region-specific information that is sparsely represented in training data and retrieval resources.

<table><tr><td>Model</td><td>Domain</td><td>FOK ΔECE</td><td>JOL ΔECE</td></tr><tr><td rowspan="3">GPT-5.4</td><td>TriviaQA</td><td>+0.010</td><td>-0.005</td></tr><tr><td>Math</td><td>+0.030</td><td>-0.016</td></tr><tr><td>Logic</td><td>+0.028</td><td>+0.019</td></tr><tr><td rowspan="3">Claude</td><td>TriviaQA</td><td>+0.051</td><td>+0.045</td></tr><tr><td>Math</td><td>+0.004</td><td>+0.016</td></tr><tr><td>Logic</td><td>-0.009</td><td>+0.040</td></tr></table>

Table 2: Change in calibration error (∆ECE) after translation from English to Marathi. Positive values indicate worse calibration in Marathi.

<table><tr><td>Model</td><td>Signal</td><td>ECE</td><td>AUROC</td></tr><tr><td>GPT-5.4</td><td>FOK</td><td>0.421</td><td>0.521</td></tr><tr><td>GPT-5.4</td><td>JOL</td><td>0.287</td><td>0.579</td></tr><tr><td>Claude</td><td>FOK</td><td>0.378</td><td>0.558</td></tr><tr><td>Claude</td><td>JOL</td><td>0.255</td><td>0.616</td></tr></table>

Table 3: Confidence calibration on the Marathi-Local benchmark.

## 6 Conclusion and Future Work

In this work, we introduced a temporal framing of confidence estimation in large language models by separating pre-solve (FOK) and post-solve (JOL) confidence signals. Across models and reasoning domains, post-solve confidence generally provides stronger calibration and discrimination than the cheaper pre-solve signal, although gains depend strongly on the model and task. In Marathi, confidence behaviour transfers well under direct language translation, but calibration degrades substantially on genuinely local knowledge questions. Hallucinated responses also maintain persistently elevated confidence, highlighting limitations of current self-assessment mechanisms. Overall, confidence-aware systems should account for both temporal stage and knowledge domain when using confidence for retrieval, routing, or adaptive compute decisions.

Future work can extend this framework to additional low-resource languages, multimodal settings, agentic systems, and model families beyond the two evaluated here. Because Marathi-Local and Marathi-Translated differ along several axes besides locality, the calibration gap cannot be attributed to locality alone; a matched benchmark controlling for these factors would help isolate its effect. It would also be valuable to examine whether white-box uncertainty signals, such as token probabilities and representation-based confidence, exhibit similar temporal dynamics. More broadly, our findings motivate studying calibration not only across languages but also across local knowledge distributions, where linguistic transfer alone may be insufficient for reliable selfassessment.

## References

Jingwen Cheng, Kshitish Ghate, Wenyue Hua, William Yang Wang, Hong Shen, and Fei Fang. 2025. REALM: A dataset of real-world LLM use cases. In Findings of the Association for Computational Linguistics: ACL 2025, pages 8331–8341, Vienna, Austria. Association for Computational Linguistics.

Nadir Durrani, Basel Mousi, and Fahim Dalvi. 2025. Editing across languages: A survey of multilingual knowledge editing. In Proceedings ofthe 2025 Conference on Empirical Methods in Natural Language Processing, pages 15906–15918, Suzhou, China. Association for Computational Linguistics.

Deepon Halder, Alan Saji, Thanmay Jayakumar, Ratish Puduppully, Anoop Kunchukuttan, and Raj Dabre. 2025. Riddlebench: A new generative reasoning benchmark for llms. Preprint, arXiv:2510.24932.

Mandar Joshi, Eunsol Choi, Daniel S. Weld, and Luke Zettlemoyer. 2017. Triviaqa: A large scale distantly supervised challenge dataset for reading comprehension. In Proceedings of the 55th Annual Meeting of the Association for Computational Linguistics, Vancouver, Canada. Association for Computational Linguistics.

Saurav Kadavath, Tom Conerly, Amanda Askell, Tom Henighan, Dawn Drain, Ethan Perez, Nicholas Schiefer, Zac Hatfield-Dodds, Nova DasSarma, Eli Tran-Johnson, Scott Johnston, Sheer El-Showk, Andy Jones, Nelson Elhage, Tristan Hume, Anna Chen, Yuntao Bai, Sam Bowman, Stanislav Fort, and 17 others. 2022. Language models (mostly) know what they know. Preprint, arXiv:2207.05221.

Adam Tauman Kalai and Santosh S. Vempala. 2024. Calibrated language models must hallucinate. In Proceedings of the 56th Annual ACM Symposium on Theory of Computing, STOC 2024, page 160–171, New York, NY, USA. Association for Computing Machinery.

Sahil Kale. 2025. Mirage of mastery: Memorization tricks llms into artificially inflated self-knowledge. arXiv preprint arXiv:2506.18998.

Sahil Kale and Devendra Singh Dhami. 2025. Knowrl: Teaching language models to know what they know. Preprint, arXiv:2510.11407.

Sahil Kale and Vijaykant Nadadur. 2025. Line of duty: Evaluating LLM self-knowledge via consistency in

feasibility boundaries. In Proceedings of the 5th Workshop on Trustworthy NLP (TrustNLP 2025), pages 127–140, Albuquerque, New Mexico. Association for Computational Linguistics.

Christopher Kissling, Elena Merdjanovska, and Alan Akbik. 2026. Self-aware knowledge probing: Evaluating language models’ relational knowledge through confidence calibration. Preprint, arXiv:2601.18901.

Asher Koriat. 1997. Monitoring one’s own knowledge during study: A cue-utilization approach to judgments of learning. Journal ofExperimental Psychology: General, 126(4):349–370.

Jiawei Li, Yizhe Yang, Yu Bai, Xiaofeng Zhou, Yinghao Li, Huashan Sun, Yuhang Liu, Xingpeng Si, Yuhao Ye, Yixiao Wu, Yiguan Lin, Bin Xu, Bowen Ren, Chong Feng, Yang Gao, and Heyan Huang. 2024. Fundamental capabilities of large language models and their applications in domain scenarios: A survey. In Proceedings ofthe 62nd Annual Meeting of the Associationfor Computational Linguistics (Volume 1: Long Papers), pages 11116–11141, Bangkok, Thailand. Association for Computational Linguistics.

Wenjun Li, Dexun Li, Kuicai Dong, Cong Zhang, Hao Zhang, Weiwen Liu, Yasheng Wang, Ruiming Tang, and Yong Liu. 2025. Adaptive tool use in large language models with meta-cognition trigger. In Proceedings ofthe 63rd Annual Meeting ofthe Associationfor Computational Linguistics (Volume 1: Long Papers), pages 13346–13370, Vienna, Austria. Association for Computational Linguistics.

Stephanie Lin, Jacob Hilton, and Owain Evans. 2022. Teaching models to express their uncertainty in words. Preprint, arXiv:2205.14334.

Ziyang Ma, Qingyue Yuan, Zhenglin Wang, and Deyu Zhou. 2025. Large language models have intrinsic meta-cognition, but need a good lens. In Proceedings ofthe 2025 Conference on Empirical Methods in Natural Language Processing, pages 3460–3477, Suzhou, China. Association for Computational Linguistics.

Viktor Moskvoretskii, Maria Marina, Mikhail Salnikov, Nikolay Ivanov, Sergey Pletenev, Daria Galimzianova, Nikita Krayko, Vasily Konovalov, Irina Nikishina, and Alexander Panchenko. 2025. Adaptive retrieval without self-knowledge? bringing uncertainty back home. In Proceedings ofthe 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 6355–6384, Vienna, Austria. Association for Computational Linguistics.

Mahdi Pakdaman Naeini, Gregory F. Cooper, and Milos Hauskrecht. 2015. Obtaining well calibrated probabilities using bayesian binning. In Proceedings of the Twenty-Ninth AAAI Conference on Artificial Intelligence, AAAI’15, page 2901–2907. AAAI Press.

Thomas O. Nelson. 1990. Metamemory: A theoretical framework and new findings. volume 26 of Psychology ofLearning and Motivation, pages 125–173. Academic Press.

Jakub Podolak and Rajeev Verma. 2025. Read your own mind: Reasoning helps surface self-confidence signals in LLMs. In Proceedings ofthe 2nd Workshop on Uncertainty-Aware NLP (UncertaiNLP 2025), pages 247–258, Suzhou, China. Association for Computational Linguistics.

Jingyi Ren, Ante Wang, Yunghwei Lai, Xiaolong Wang, Linlu Gong, Weitao Li, Weizhi Ma, and Yang Liu. 2026. Beyond "i don’t know": Evaluating llm selfawareness in discriminating data and model uncertainty. Preprint, arXiv:2604.17293.

Adi Simhi, Itay Itzhak, Fazl Barez, Gabriel Stanovsky, and Yonatan Belinkov. 2025. Trust me, I’m wrong: LLMs hallucinate with certainty despite knowing the answer. In Findings of the Association for Computational Linguistics: EMNLP 2025, pages 14665– 14688, Suzhou, China. Association for Computational Linguistics.

Mengyu Wang, Xiaoying Zhi, Zhiyi Li, Robin Schmucker, Shay B. Cohen, Tiejun Ma, and Fran Silavong. 2026. Self-knowledge re-expression: A fully local method for adapting llms to tasks using intrinsic knowledge. Preprint, arXiv:2604.22939.

Adam Wiemerslage and Katharina Von Der Wense. 2025. Improving low-resource morphological inflection via self-supervised objectives. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 24494–24510, Vienna, Austria. Association for Computational Linguistics.

Tianyang Xu, Shujin Wu, Shizhe Diao, Xiaoze Liu, Xingyao Wang, Yangyi Chen, and Jing Gao. 2024. SaySelf: Teaching LLMs to express confidence with self-reflective rationales. In Proceedings ofthe 2024 Conference on Empirical Methods in Natural Language Processing, pages 5985–5998, Miami, Florida, USA. Association for Computational Linguistics.

Jie Zhang, Cezara Petrui, Kristina Nikolic, and Flo-´ rian Tramèr. 2025. Realmath: A continuous benchmark for evaluating language models on researchlevel mathematics. Preprint, arXiv:2505.12575.

Qingjie Zhang, Yujia Fu, Yang Wang, Liu Yan, Tao Wei, Ke Xu, Minlie Huang, and Han Qiu. 2026. Stop before you fail: Operational capability boundaries for mitigating unproductive reasoning in large reasoning models. Preprint, arXiv:2509.24711.

## A Model and Inference Details

Models were accessed through the official OpenAI and Anthropic Python SDKs using their public APIs. All experiments used deterministic decoding with temperature set to 0. Maximum output length was capped at 450 tokens. Remaining providerspecific generation parameters were left at default values. Table 4 summarises the inference settings used throughout all experiments.

<table><tr><td>Setting</td><td>GPT-5.4</td><td>Claude Sonnet 4.6</td></tr><tr><td>Provider</td><td>OpenAI</td><td>Anthropic</td></tr><tr><td>Access Method</td><td>Python SDK/API</td><td>Python SDK/API</td></tr><tr><td>Temperature</td><td>0.0</td><td>0.0</td></tr><tr><td>Decoding</td><td>Deterministic</td><td>Deterministic</td></tr><tr><td>Other Parameters</td><td>Default</td><td>Default</td></tr></table>

Table 4: Model access and inference settings.

## B Marathi Dataset Translation

TriviaQA, RiddleBench and RealMath datasets with questions and reference answers were translated from English to Marathi using the Google Translate API. Two independent native Marathi speakers reviewed translated samples and verified semantic equivalence through spot-checking. Prompt templates were independently translated and reviewed by the same annotators. Proper nouns were transliterated into Marathi where appropriate.

## C Marathi Local Benchmark

Figure 7 presents representative examples from the Marathi-Local benchmark. Questions were manually authored by native Marathi speakers based on region-specific events reported in Marathilanguage news sources prior to model knowledge cut-off dates.

<table><tr><td>Question</td><td>Reference Answer</td><td>Source</td></tr><tr><td>  2022   3</td><td> R </td><td>ABP Majha</td></tr><tr><td>202 ?</td><td></td><td>Maharashtra Times</td></tr></table>

Figure 7: Examples from the Marathi-Local benchmark