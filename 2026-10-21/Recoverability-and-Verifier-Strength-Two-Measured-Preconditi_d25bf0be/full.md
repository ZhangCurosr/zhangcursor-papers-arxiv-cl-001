# Recoverability and Verifier Strength: Two Measured Preconditions for Unattended Agent Self-Improvement

De Wang Uniphore de.wang@uniphore.com

Peng Qi Uniphore peng.qi@uniphore.com

## Abstract

Agent platforms are starting to improve their own agents: they read a deployed agent’s execution traces, derive a change, have an automated verifier approve it, and release it with no human author. How much of this loop can safely run without a human? We propose two quantities a platform can measure. Verifier strength σ is how well the available verifier — often an LLM judge — agrees with a trusted reference verifier; it limits how much a step can improve the agent. Recoverability is how cheaply a bad change can be undone: whether undoing it needs a new verifier approval, and how much of the old behavior a rollback restores. A step should run unattended only if both are adequate. On our platform this rule allows prompt, tool and skill edits to run unattended and keeps weight updates under human sign-off.

Our main contribution is these two definitions and how to measure them. We built a platform that applies the rule and tested it in two ways: on the platform’s own approval gate, and in controlled experiments on the τ<sup>2</sup>-bench agent benchmark. On verifier strength, the platform’s LLM judge sometimes gave the same score no matter what it was shown (9 of 37 settings) and reported no error, so a verifier can look healthy while approving anything; its strength must be measured, and two simple tests catch the failure. On recoverability, restoring a saved copy brought the agent back to its original behavior, but a regenerated undo did not, so only changes whose old version is kept can be reversed without a human; and while a change was deployed, it altered the outcome of 17% of tasks beyond normal run-to-run variation, which no undo repairs. Together these support the rule: a change can run unattended only when its old version is kept and its verifier’s strength has been measured.

## 1 Introduction

Agents built on language models now hold conversations, call tools, and write to business systems (Yao et al., 2025; Barres et al., 2026). They also fail often. On the τ<sup>2</sup>-bench tasks we study the baseline agent solves just over half of its tasks, through ordinary mistakes: a wrong tool call, a missing confirmation, steps taken out of order (Cuadron et al., 2026). Fixing such failures means reading traces, finding the cause, revising the agent, checking the revision and deploying it. Done by hand, this does not scale with the number of agents a platform hosts, so platforms have begun to automate it (Wang et al., 2026; Li & Zhu, 2026).

We call one pass of this automated repair a self-improvement step: the platform reads its own agents traces, derives a change, checks it with a verifier and deploys it, with no person writing the change. Inference-time self-correction (Shinn et al., 2023; Madaan et al., 2023) and human-written fixes do not count. Training and serving became platform services long ago (Baylor et al., 2017; Moritz et al.,

![](images/128a40f4997ef85a6f68c70579df00e6c5872733a94c8698eec06a675076c5fb.jpg)  
Figure 1: One self-improvement step. Verifier strength σ governs the admit decision; recoverability governs the cost when an admitted change is bad. If the old value was kept, rollback is a plain write $\scriptstyle ( g = 0 )$ ; otherwise the undo must be regenerated and approved by the same gate $( g { = } 1 )$ .

2018); this loop has not, yet it needs the same things: a budget, controlled access to the deployed agent, a point where changes are admitted, and an audit trail (§4).

This paper asks how much of the loop may run without a human. Our answer rests on two measurable quantities (§2). Verifier strength measures how far the verifier’s approvals can be trusted: its agreement with a reference verifier on a scale from −1 to 1, where 1 is perfect agreement and a verifier that always gives the same answer scores 0. Recoverability measures how cheaply a bad change is undone. It records whether undoing a change needs a new verifier approval and how much of the old behavior actually returns. If no copy of the old version was kept (for example, after fine-tuning a model in place), the undo must pass the same verifier that just approved the mistake. Each quantity guards against a different failure, so a loop can be only as autonomous as the weaker one allows (Figure 1). We derive this rule (§3), build a platform that enforces it (§4), and test the assumptions it rests on (§5), first in a case study of our platform’s own admission gate and then in controlled experiments on $\tau ^ { 2 } { \mathrm { - } } { \mathrm { b e n c h } }$ . We do not address adversarial or misaligned agents, only the ordinary failure of admitting a change that should have been rejected.

Contributions. Our main contribution is a method: the two definitions, how to measure them, and the rule they support. (i) Two measurable preconditions for unattended changes, and a rule that refuses whenever either is unmeasured (§2, §3). (ii) A platform that enforces the rule by typing changes by recoverability, declaring verifiers as resources, and recording refusal as its own outcome (§4). (iii) Tests of the rule’s assumptions: a case study of silent gate collapse in our platform’s own admission gate, with two tests that catch it (§5.1), and experiments that vary each quantity separately for prompt edits on two $\tau ^ { 2 } .$ -bench domains (§5.2). Our verdicts for tool, skill and weight changes follow from the definitions and are not separately tested.

## 2 Definitions

We write an agent as $A = ( \theta , p , T , K )$ : model weights, system prompt, tool schemas and skills.

Self-improvement step. A change $A \mapsto A ^ { \prime }$ that the platform derives from $A \ ' \mathrm s$ own traces, in the spirit of self-taught training (Zelikman et al., 2022), and admits through a verifier, with no human writing it. Running example: airline traces show the agent canceling bookings without asking the user; the loop adds “confirm before any cancellation” to $p ,$ an LLM judge approves the edit, and it goes live. We measure a step by $\Delta _ { k }$ , the change in the share of held-out tasks solved in all k repeated trials, because a platform cares about reliability rather than best cases.

Recoverability. For a change ι and its undo $\iota ^ { - 1 }$ we measure three things. Re-approval $g ( \iota ) \in \{ 0 , 1 \}$ records whether the way back from $A ^ { \prime }$ to $A$ needs a new verifier approval. If the old value was kept, the undo is a plain write and $g { = } 0 ;$ ; this holds for prompt and schema edits and for a retained model checkpoint. If no old value was kept, as after fine-tuning from the current checkpoint, the undo must itself be generated and approved, so $g { = } 1$ . Both other measures use a fixed set of probe tasks $P _ { \mathrm { : } }$ scored pass or fail. Restoration $\mathrm { \it f i d e l i t y } \mathrm { \it \rho } ( \mathrm { \Delta } l )$ asks whether the undo brings the old behavior back: it is the share of tasks in $P$ with the same outcome after the change is undone as before the change was made. Blast radius $\beta ( \iota )$ is the share of tasks in $P$ whose outcome changed while ι was deployed, relative to the unchanged agent: what even a perfect rollback cannot recover, because those outcomes were already delivered. In our experiments (§5.2), P is the 20 held-out test tasks for $\rho$ (the 30 training tasks for the regenerated undos) and all 50 airline tasks for $\beta .$ The agent and the simulated user are both stochastic, so we also run a null change (no change at all), which gives noise floors $\rho _ { 0 } < 1$ and $\beta _ { 0 } > 0 ;$ only values beyond these floors count. Because $\beta$ covers only the probe tasks, it is a lower bound: real side effects such as an issued refund must be tracked at the tool boundary, where recent work locates recoverability for agents (Yang et al., 2026; Zheng et al., 2026).

old value kept (g=0)  
old value gone (g=1)
<table><tr><td> $\sigma \geq \sigma _ { \mathrm { m i n } } ,$  measured</td><td>Run unattended prompt, tool-schema and skill edits</td><td>Human sign-off irreversible, even with a strong verifier</td></tr><tr><td>σ low or unmeasured</td><td>Human sign-off weight updates; data filter (disabled)</td><td>Human sign-off fine-tune with no checkpoint kept</td></tr></table>

Figure 2: The rule as a matrix, with our platform’s intervention types placed. A change runs unattended only when both preconditions hold (shaded); every other cell needs a human.

Verifier strength. A verifier scores a trajectory as pass or fail; it may be a program or an LLM judge (Zheng et al., 2023). Given a trusted reference verifier $v ^ { \star }$ and a set of trajectories $C ,$ strength is the Matthews correlation $\sigma ( v ) = \operatorname { M C C } ( v , v ^ { \star } ) \big | _ { C } \in [ - 1 , 1 ]$ . We use MCC rather than accuracy because a verifier that always gives the same answer scores exactly $\sigma { = } 0 $ , whereas its accuracy equals the share of the more common verdict and can look respectable.

## 3 The autonomy rule

The rule. A change may go live without human sign-off only if $g ( \iota ) { = } 0$ and $\sigma ( v ) \geq \sigma _ { \operatorname* { m i n } }$ , where $\sigma _ { \mathrm { m i n } }$ reflects the cost of wrongly admitting a bad change. If either quantity is unmeasured, the platform refuses. Our data do not fix $\sigma _ { \mathrm { m i n } } \colon$ the strength below which weak verifiers start to hurt moves by ±0.15 with the number of simulations the gate averages, so a threshold from one benchmark would not transfer (App. E gives the numbers and a calibration procedure). In the running example the old prompt is kept, so $g { = } 0$ , and σ is the judge’s agreement with $\tau ^ { 2 }$ -bench’s database check; the edit goes live only if that σ was measured and clears $\sigma _ { \mathrm { m i n } }$ . A fine-tune with no checkpoint kept has $g { = } 1$ and is refused however good the judge is.

Why both conditions. A self-improvement step does two things: it decides whether to admit $A  A ^ { \prime }$ , and then it changes a live system. Each quantity bounds one of these failures. Verifier strength bounds the decision, because the verdict is the loop’s only evidence that $A ^ { \prime }$ is better than $A ;$ at σ=0 the verdict says nothing about quality (Zheng et al., 2023). Recoverability bounds the change. $\operatorname { A t } g { = } 0$ the platform writes back the old value and pays only for the traffic served while the change was deployed, which is what $\beta$ measures. $\operatorname { A t } g { = } 1$ the old value is gone, so the way back must be regenerated and approved by the same gate that made the mistake. Neither quantity can make up for the other, so autonomy is limited by the weaker one rather than traded between them. A strong verifier cannot justify an irreversible change, since its errors would then be permanent, and easy rollback cannot justify a weak verifier, since the loop would only churn the agent.

Assumptions to test. The rule rests on three assumptions, which §5 tests: (a) a verifier’s strength cannot be taken for granted and must be measured; (b) a weaker verifier admits worse changes; and (c) keeping the old value makes rollback exact and losing it does not, while an admitted change still affects tasks that rollback cannot undo.

## 4 The platform: enforcing the rule

What the platform does. Our platform improves deployed agents from their own production traces. For each agent it (1) collects execution traces and classifies failures, such as a wrong tool sequence, outdated knowledge or a degraded prompt; (2) maps each failure to a change along one of four dimensions: rewriting the system prompt, fixing a tool definition, updating a skill, or fine-tuning a small model on distilled traces; (3) builds the candidate and evaluates it; and (4) promotes it or stops. Each attempt runs as a recorded session, so every deployed change can be traced back to the evidence that admitted it, as in production ML pipelines (Baylor et al., 2017). We built this loop to enforce the rule; three design choices put the rule into it.

Changes are typed by recoverability. An agent can be changed in four ways — weights, system prompt, tool definitions and skills — and each is a separate resource type that records how it is undone and hence its g (App. C). This lets “may this proceed without a human?” have a different answer for each type (Figure 2). Prompt, tool-schema and skill edits are undone by a write and may promote automatically. Weight updates can be undone by re-pinning the previous adapter, but their verifier is a learned judge of the kind §5.1 shows can fail silently, so they need human sign-off. A training-data filter with no workable verifier ships disabled.

Evaluation decides what goes live. A proposed change is not deployed until evaluation approves it, so evaluation works like an admission check in other platforms (Kubernetes, 2026): if it fails or cannot run, nothing is deployed; every decision is logged; and no caller can skip it. Each agent declares which verifiers it uses, with each verifier’s measured σ, so before promoting a change the platform can check whether an adequate verifier exists.

Refusal is a recorded decision. The rule has three outcomes, not two: admit, reject (the change is worse), and refuse (the platform cannot decide unattended because σ is unmeasured or the old value is gone). Ours records each refusal with the missing precondition, so a human sees what is waiting and why instead of a change that silently waits forever.

## 5 Experiments and results

We test the three assumptions in two settings: a case study of our platform’s own admission gate (§5.1), and controlled experiments on τ<sup>2</sup>-bench (§5.2). Table 3 summarizes what each result implies.

## 5.1 Case study: silent gate collapse in our platform

This case study tests assumption (a), that a verifier’s strength must be measured rather than assumed. Before our platform fine-tunes a model, it collects agent traces into a training set, and an LLM-judge gate scores the set’s diversity; a set that scores too low is not used for training. This gate is a verifier in the sense of §2: it decides whether a change, here a weight update, may proceed. It had been treated as working because it always returned a score. (A second gate, which filters individual training rows, ships disabled; App. A.)

A diversity gate that ignores half its instructions. The gate’s LLM judge (Zheng et al., 2023) scores the training set from 0 to 1. Its prompt asks for two things: reward breadth (many distinct seed tasks) and penalize imbalance (a few seeds dominating); the input gives the imbalance as a number. We tested 3 judge models, 4 prompt variants, 4 imbalance levels, breadths 3–12 and two agent configurations: 172 settings of 10 runs each. In the deployed setting the gate ignores imbalance completely. It returned 0.250 in all 40 runs with zero spread, exactly what it returns when every mention of imbalance is removed from the prompt. This is not an artifact of greedy decoding, since 98 of the 172 settings vary. Full collapse, the same score at all four imbalance levels, occurs in 9 of 37 configurations, all on the deployed judge, the smallest of the three. That judge also ran most configurations (33 of 37), so the count alone does not implicate it; a matched comparison does: on identical inputs the deployed judge stays flat while both larger judges track imbalance $( p < 1 0 ^ { - 1 1 }$ each; App. A).

Implication. We call this silent gate collapse: a gate sound in one configuration and empty in another, with no error to show the difference. A constant score looks like a confident answer; this is the σ=0 point of §2, and it supports assumption (a).

Two cheap tests catch this, each costing a handful of calls, and both belong in the platform. Delete the signal: remove the property the gate claims to measure and check that its score changes. Check the guarantees: verify that request-level settings the gate relies on actually took effect; three of ours did not, forced tool calls among them (App. B). What did work was stating the criterion as a checkable bound: “if the largest seed exceeds 50%, score at most 0.10” held in all 16 settings above

<table><tr><td>Verifier v</td><td>σ(v) ↑</td><td>α↓</td><td>4↓</td><td>Admits</td><td>n</td></tr><tr><td>DB × COMM (ref.)</td><td>1.00†</td><td>0.00</td><td>0.00</td><td>0.48</td><td>80</td></tr><tr><td>DB equality alone</td><td>1.00</td><td>0.00</td><td>0.00</td><td>0.48</td><td>80</td></tr><tr><td>LLM judge, NL assertions</td><td>0.70</td><td>0.10</td><td>0.21</td><td>0.43</td><td>80</td></tr><tr><td>Reference-action match</td><td>0.67</td><td>0.21</td><td>0.12</td><td>0.53</td><td>72</td></tr><tr><td>Communication substrings</td><td>N/A</td><td>一</td><td>0.00</td><td>1.00</td><td>4</td></tr><tr><td>Constant (admit all)</td><td>0.00</td><td>1.00</td><td>0.00</td><td>1.00</td><td>80</td></tr></table>

Table 1: Verifier strength on the airline test split: one set of trajectories re-scored by each verifier v; n is the number of trajectories it applies to. α and $\varphi$ are falseadmit and false-reject rates against the reference (↑/↓: higher/lower is better). Errors cluster by task (App. E). † 1.00 by definition. ‡ 1.00 because the communication checks pass on all 4 trajectories they apply to, so DB equality agrees with the reference on all 80. N/A: σ is undefined because the reference passes all 4 trajectories this check applies to, leaving nothing to correlate.

<table><tr><td>ε</td><td>σ</td><td>Regret↓</td><td>Calib. gap↓</td></tr><tr><td>0.00</td><td>1.000</td><td>+0.0000</td><td>+0.2000</td></tr><tr><td>0.10</td><td>0.802</td><td>-0.0007</td><td>+0.1604</td></tr><tr><td>0.20</td><td>0.602</td><td>+0.0026</td><td>+0.1311</td></tr><tr><td>0.30</td><td>0.399</td><td>+0.0164</td><td>+0.1255</td></tr><tr><td>0.40</td><td>0.199</td><td>+0.0328</td><td>+0.1308</td></tr><tr><td>0.50</td><td>0.001</td><td>+0.0671</td><td>+0.1573</td></tr></table>

Table 2: Experiment A2 (airline, eight candidates); σ set by flipping reference verdicts with probability ε. Regret: heldout loss from picking with the corrupted verifier. Calib. gap: the picked candidate’s reported training score minus its held-out score; 0 means the loop reports its gain accurately. ↓: lower is better.

50%, where the original wording never scored that low (30 of 30 runs vs. 0 of 30 on matched inputs, Fisher $p < 1 0 ^ { - 1 6 }$ ; Table 4).

## 5.2 Controlled experiments on τ<sup>2</sup>-bench

Assumptions (b) and (c) need controlled conditions, since on a live platform the two quantities change together. We fix one and vary the other: experiment A tests (b), experiment B tests (c). Both use $\tau ^ { 2 } .$ bench, whose agents match ours (multi-turn, tool-using, database-backed, with a simulated user) and whose task score is the product of a configurable subset of five checks (Barres et al., 2026). Changing the subset changes the verifier v while leaving tasks, agent and environment fixed, and scoring is separate from running, so one set of trajectories can be re-scored under every verifier.

Setup. We use the airline domain: 50 tasks split 30 for training and 20 for testing, with naturallanguage assertions on every task, so a program verifier and an LLM judge score the same trajectories, the comparison §5.1 could not make in production. The reference verifier combines database-state equality with communication checks; the latter apply to only 4 of 80 test trajectories, so on the other 76 the reference is database equality alone. The loop is ours, reduced to one recipe: read failed training trajectories, propose a system-prompt revision, admit it if the verifier under test prefers it, and measure the result on the test split with the reference verifier. We report mean pass rate rather than pass<sup>k</sup>, which at four trials discards partial credit. A1 measures σ for real verifiers; A2 tests whether lower σ picks worse changes; B fixes the verifier at the reference and compares restoring a stored copy (g=0) with regenerating the undo (g=1). Weight updates are not tested. Each agent is run twice per training task and four times per test task. Intervals are 95% task-resampling bootstrap intervals (App. D), paired for differences (Miller, 2024). Where the hypothesis fixes a direction we report one-sided p-values, and we correct across candidates with Holm’s method.

Real verifiers (A1). Table 1 gives σ for each verifier on one set of 80 test trajectories (20 tasks, 4 trials each). The LLM judge reaches σ=0.70 against the program check on the same trajectories, far above zero (Fisher $\overset { \cdot } { p } < \overset { \cdot } { 1 } 0 ^ { - 9 } )$ but far from perfect. Its errors are clustered: all 4 false admits come from one task and the 8 false rejects from two, repeated across trials, so resampling whole tasks widens its interval to [0.36, 1.00]. A verifier that approves everything scores exactly 0 while passing all 42 failing trajectories.

Weaker verifiers pick worse changes, but not significantly (A2). To get a fine-grained σ scale cheaply, we flip each reference verdict with probability ε, which gives a verifier of known strength; re-scoring one set of trajectories yields every point, each averaged over 400 random draws. Regret, how much worse the picked change is than the one a perfect verifier would pick, rises from 0.000 at σ=1 to 0.067 at σ≈0 (Table 2), as predicted, but the fitted slope (−0.065, CI [−0.234, 0.120]) includes zero (one-sided p=0.23); resolving it would take about 220 held-out tasks, eleven times our 20. The bottleneck is the candidates, not σ: the candidate a perfect verifier would pick is only 0.069 above the average one, so even a random pick loses little, and the observed 0.067 is already 98% of that maximum (App. D). Retail shows no trend (slope +0.008, CI [−0.115, 0.109]), but its candidates are so similar that replication is untested rather than failed.

<table><tr><td>Precondition</td><td>Finding</td><td>Implication for unattended changes</td></tr><tr><td></td><td>Verifier strength Platform&#x27;s LLM gate gave a constant in 9/37 set- A gate can look healthy while approving anything: tings, no error (§5.1)</td><td>measure σ</td></tr><tr><td></td><td>Verifier strength Weaker verifiers picked worse changes; not signifi- cant at 20 tasks (A2)</td><td> $\sigma _ { \mathrm { m i n } }$  must be calibrated per platform (App. E)</td></tr><tr><td>Recoverability</td><td>Saved copy restores exactly; regenerated undo does Only changes with not (B)</td><td> $g { = } 0$  can be undone without a human</td></tr><tr><td>Recoverability</td><td>noise (B)</td><td>A deployed change altered 17% of tasks beyond Undoing a change does not repair what it already did</td></tr></table>

Table 3: Each result, the precondition it tests, and what it implies for unattended self-improvement.

Two secondary observations (A). With a perfect verifier the loop still overstated its own gain (0.20; one-sided p=0.08, not in retail), and two verifiers with nearly equal σ erred in opposite directions (Table 1; App. D, E).

Only a stored copy restores behavior (B). With the verifier fixed at the reference, a null change sets the noise floors $( \rho _ { 0 } \mathrm { = } 0 . 9 5 $ , CI [0.89, 1.00]; β<sub>0</sub>=0.08, CI [0.02, 0.16]). Restoring a prompt edit from a stored copy $\scriptstyle ( g = 0 )$ ) returns behavior to the floor: $\rho - \rho _ { 0 } { = } 0 . 0 0 0 \left( \mathbf { C I } \left[ - 0 . 0 3 8 , 0 . 0 3 8 \right] \right)$ , equivalent to zero within ±0.05 (TOST p=0.007). Without a stored copy (g=1) the undo must be regenerated, and three regenerated undos left behavior measurably different from the baseline: $\rho - \rho _ { 0 } { = } - 0 . 1 6$ (CI $[ - 0 . 2 7 , - 0 . 0 7 ]$ , one-sided $p { = } 0 . 0 0 0 1 ;$ each undo significant after Holm correction), measured on the training split against a floor of 0.98. The gate refused all three, as the rule requires (App. C).

Admitted changes reach tasks that rollback cannot undo (B). Deployed on all 50 probe tasks, the three admitted changes with complete data altered the outcome of 17% of tasks beyond the noise floor $( \beta - \beta _ { 0 } \mathrm { { = } } 0 . \bar { 1 7 }$ , CI [0.08, 0.27], one-sided $\scriptstyle p = 0 . 0 0 0 2 )$ , and each change does so on its own after Holm correction. Tasks flipped in both directions in nearly equal numbers (18 up, 20 down), so the average effect is near zero while the reach is not, and reach is what rollback cannot undo (Garcia-Molina & Salem, 1987).

## 6 Related work and discussion

Production ML platforms made training and serving platform services (Baylor et al., 2017; Breck et al., 2019; Moritz et al., 2018; Sculley et al., 2015), but not deciding what to change in a deployed agent. Self-improvement and prompt-optimization methods (Shinn et al., 2023; Madaan et al., 2023; Zelikman et al., 2022; Khattab et al., 2024) supply the changes we schedule but assume a trustworthy verifier; work on reward gaming and LLM judges questions that assumption (Skalse et al., 2022; Gao et al., 2023; Zheng et al., 2023), and verifiable-reward methods avoid it (Lambert et al., 2025; Pezeshkpour & Hruschka, 2026). Deployment engineering gates changes on measured evidence (Humble & Farley, 2010; Beyer et al., 2016; Kubernetes, 2026) but assumes a human author. Closest is off-policy evaluation, which promotes only when a lower confidence bound beats the incumbent (Thomas et al., 2015; Thomas & Brunskill, 2016; Sakhi et al., 2024); σ plays that role where no unbiased value estimate exists.

Limitations. The rule comes from one platform and was applied after the fact; only prompt edits were tested end to end, on τ<sup>2</sup>-bench airline and retail rather than in production; and experiment A was too small to confirm the σ effect (App. D).

Conclusion. A self-improvement loop may run without a human only where the old version is kept and the verifier’s strength is measured; where either is missing, the platform should refuse.

## Acknowledgments

We thank Will Lu and Frank Petterson for their executive sponsorship of this work.

## References

H. Garcia-Molina and K. Salem. Sagas. SIGMOD, pages 249–259, 1987.

S. Zöllner and J. K. Pritchard. Overcoming the Winner’s Curse: Estimating Penetrance Parameters from Case-Control Data. The American Journal ofHuman Genetics, 80(4):605–615, 2007.

J. Humble and D. Farley. Continuous Delivery: Reliable Software Releases through Build, Test, and Deployment Automation. Addison-Wesley, 2010.

B. Efron. Tweedie’s Formula and Selection Bias. Journal ofthe American Statistical Association, 106(496):1602– 1614, 2011.

D. Sculley, G. Holt, D. Golovin, E. Davydov, T. Phillips, D. Ebner, V. Chaudhary, M. Young, J.-F. Crespo, and D. Dennison. Hidden Technical Debt in Machine Learning Systems. NIPS, pages 2503–2511, 2015.

P. S. Thomas, G. Theocharous, and M. Ghavamzadeh. High Confidence Policy Improvement. ICML, pages 2380–2388, 2015.

B. Beyer, C. Jones, J. Petoff, and N. R. Murphy, editors. Site Reliability Engineering: How Google Runs Production Systems. O’Reilly, 2016.

P. S. Thomas and E. Brunskill. Data-Efficient Off-Policy Policy Evaluation for Reinforcement Learning. ICML, pages 2139–2148, 2016.

D. Baylor, E. Breck, H.-T. Cheng, N. Fiedel, C. Y. Foo, Z. Haque, S. Haykal, M. Ispir, V. Jain, L. Koc, C. Y. Koo, L. Lew, C. Mewald, A. N. Modi, N. Polyzotis, S. Ramesh, S. Roy, S. E. Whang, M. Wicke, J. Wilkiewicz, X. Zhang, and M. Zinkevich. TFX: A TensorFlow-Based Production-Scale Machine Learning Platform. KDD, pages 1387–1395, 2017.

P. Moritz, R. Nishihara, S. Wang, A. Tumanov, R. Liaw, E. Liang, M. Elibol, Z. Yang, W. Paul, M. I. Jordan, and I. Stoica. Ray: A Distributed Framework for Emerging AI Applications. OSDI, pages 561–577, 2018.

E. Breck, N. Polyzotis, S. Roy, S. E. Whang, and M. Zinkevich. Data Validation for Machine Learning. MLSys, 2019.

J. Skalse, N. H. R. Howe, D. Krasheninnikov, and D. Krueger. Defining and Characterizing Reward Gaming. NeurIPS, 2022.

E. Zelikman, Y. Wu, J. Mu, and N. Goodman. STaR: Bootstrapping Reasoning With Reasoning. NeurIPS, 2022.

L. Gao, J. Schulman, and J. Hilton. Scaling Laws for Reward Model Overoptimization. ICML, pages 10835– 10866, 2023.

A. Madaan, N. Tandon, P. Gupta, S. Hallinan, L. Gao, S. Wiegreffe, U. Alon, N. Dziri, S. Prabhumoye, Y. Yang, S. Gupta, B. P. Majumder, K. Hermann, S. Welleck, A. Yazdanbakhsh, and P. Clark. Self-Refine: Iterative Refinement with Self-Feedback. NeurIPS, 2023.

N. Shinn, F. Cassano, A. Gopinath, K. Narasimhan, and S. Yao. Reflexion: Language Agents with Verbal Reinforcement Learning. NeurIPS, 2023.

L. Zheng, W.-L. Chiang, Y. Sheng, S. Zhuang, Z. Wu, Y. Zhuang, Z. Lin, Z. Li, D. Li, E. P. Xing, H. Zhang, J. E. Gonzalez, and I. Stoica. Judging LLM-as-a-Judge with MT-Bench and Chatbot Arena. NeurIPS Datasets and Benchmarks Track, 2023.

I. Andrews, T. Kitagawa, and A. McCloskey. Inference on Winners. Quarterly Journal of Economics, 139(1):305– 358, 2024.

O. Khattab, A. Singhvi, P. Maheshwari, Z. Zhang, K. Santhanam, S. Vardhamanan, S. Haq, A. Sharma, T. T. Joshi, H. Moazam, H. Miller, M. Zaharia, and C. Potts. DSPy: Compiling Declarative Language Model Calls into State-of-the-Art Pipelines. ICLR, 2024.

E. Miller. Adding Error Bars to Evals: A Statistical Approach to Language Model Evaluations. CoRR, 2024. arXiv:2411.00640.

O. Sakhi, I. Aouali, P. Alquier, and N. Chopin. Logarithmic Smoothing for Pessimistic Off-Policy Evaluation, Selection and Learning. NeurIPS, 2024.

N. Lambert, J. Morrison, V. Pyatkin, S. Huang, H. Ivison, F. Brahman, L. J. V. Miranda, A. Liu, N. Dziri, S. Lyu, Y. Gu, S. Malik, V. Graf, J. D. Hwang, J. Yang, R. Le Bras, O. Tafjord, C. Wilhelm, L. Soldaini, N. A. Smith, Y. Wang, P. Dasigi, and H. Hajishirzi. Tülu 3: Pushing Frontiers in Open Language Model Post-Training. COLM, 2025.

S. Yao, N. Shinn, P. Razavi, and K. Narasimhan. τ -bench: A Benchmark for Tool-Agent-User Interaction in Real-World Domains. ICLR, 2025.

V. Barres, H. Dong, S. Ray, X. Si, and K. Narasimhan. τ<sup>2</sup>-Bench: Evaluating Conversational Agents in a Dual-Control Environment. ICML, pages 6736–6782, 2026.

A. Cuadron, P. Yu, Y. Liu, and A. Gupta. SABER: Small Actions, Big Errors — Safeguarding Mutating Steps in LLM Agents. ICLR Workshop on Memory for LLM-Based Agentic Systems, 2026. https://openreview. net/forum?id=En2z9dckgP.

Kubernetes documentation. Dynamic Admission Control: validating and mutating admission webhooks and the failurePolicy field. https://kubernetes.io/docs/reference/access-authn-authz extensible-admission-controllers/, accessed 2026-08-17.

J. Li and J. Zhu. Auditing Self-Evolution in Financial Agents: Capability Gains, Security Drift, and Execution-Interface Mismatch. CoRR, 2026. arXiv:2608.17684.

P. Pezeshkpour and E. Hruschka. AutoPyVerifier: Learning Compact Executable Verifiers for Large Language Model Outputs. CoRR, 2026. arXiv:2604.22937.

C. H. Wang, M. Tu, Q. Zhang, W. Wu, L. Zhou, M. Shen, and C. Wei. Self-evolving Agentic Customer Support System at LinkedIn. CoRR, 2026. arXiv:2608.10224.

K. Yang, P. Li, Z. Wu, K. Xu, H. Huang, and X. Huang. DART: Semantic Recoverability for Structured Tool Agents. CoRR, 2026. arXiv:2605.23311.

Y. Zheng, Y. Yang, W. Zhang, and A. Quinn. ACRFence: Preventing Semantic Rollback Attacks in Agent Checkpoint-Restore. CoDAIM Workshop, 2026. arXiv:2603.20625.

## A The gate case study in detail

Setup. A training set is built from a few seed tasks; the number of distinct seed tasks is its breadth, and the share of examples coming from the most common seed task is its imbalance. We sent the production diversity gate, with its production prompt, training sets whose imbalance we set by hand, holding everything else fixed (number and quality of examples, agent, task list). Each setting was run 10 times. The runs came in five batches (Table 5): 172 settings and 1,720 calls, of which 1,718 returned a score (the two others answered in plain text when the scoring tool was offered but not required). The script and data are available from the authors on request.

Table 4: Scores from the diversity gate on the four-tool agent. Each column is an imbalance level: the share of training examples that come from the most common seed task (the lowest possible share is .33 with 3 seed tasks and .17 with 6). Each cell averages 10 runs. NO-SIGNAL removes all imbalance information from the prompt, so it cannot respond to imbalance; THRESHOLD states the rule as a number. $r _ { s }$ is the rank correlation between score and imbalance (— when the score never changes).
<table><tr><td rowspan="2" colspan="2"></td><td colspan="4">largest-seed share</td><td></td></tr><tr><td>.33/.17</td><td>.50</td><td>.67</td><td>.83/.79</td><td> $r _ { s }$ </td></tr><tr><td rowspan="3">breadth 3</td><td>deployed</td><td>0.250</td><td>0.250</td><td>0.250</td><td>0.250</td><td></td></tr><tr><td>NO-SIGNAL</td><td>0.250</td><td>0.250</td><td>0.250</td><td>0.250</td><td></td></tr><tr><td>THRESHOLD</td><td>0.250</td><td>0.100</td><td>0.100</td><td>0.090</td><td>-0.845</td></tr><tr><td rowspan="3">breadth 6</td><td>deployed</td><td>0.938</td><td>0.506</td><td>0.445</td><td>0.371</td><td>-0.836</td></tr><tr><td>NO-SIGNAL</td><td>0.842</td><td>0.803</td><td>0.891</td><td>0.832</td><td>+0.063</td></tr><tr><td>THRESHOLD</td><td>0.919</td><td>0.100</td><td>0.098</td><td>0.094</td><td>-0.786</td></tr></table>

Table 5: The five batches of runs. The judge models are claude-haiku-4-5 (used in production), claude-sonnet-5 and claude-opus-5. The prompt variants are SHIPPED (production), STAT-ONLY (the imbalance instruction deleted, the number kept), THRESHOLD and NO-SIGNAL.
<table><tr><td>batch</td><td>what varies</td><td>settings</td><td>calls</td></tr><tr><td>A</td><td>imbalance × judge model, breadth 3 and 6</td><td>24</td><td>240</td></tr><tr><td>B</td><td>imbalance × prompt variant, breadth 3 and 6</td><td>32</td><td>320</td></tr><tr><td>C</td><td>imbalance × how the score is requested</td><td>24</td><td>238</td></tr><tr><td>R</td><td>repeat of one dataset pair</td><td>24</td><td>240</td></tr><tr><td>S</td><td>imbalance × breadth  $\mathbf { \bar { \Pi } } \in \{ 3 , 4 , 5 , 6 , 8 , 1 2 \}$  , two agents</td><td>68</td><td>680</td></tr><tr><td colspan="2">total</td><td>172</td><td>1,718</td></tr></table>

The collapse is real. The judge models do not let us set the sampling temperature, so every call used the provider’s default. Scores vary from run to run in 98 of the 172 settings, so a score that never changes is not explained by deterministic decoding. We call a configuration collapsed when it gives the same score at all four imbalance levels. Nine of 37 configurations collapsed, all with the production judge. That judge was also used in 33 of the 37 configurations, so this count on its own is not significant (Fisher exact test, $\scriptstyle { p = 0 . 5 5 } )$ . The stronger evidence is batch A, which gives all three judges identical inputs: at breadth 3 the production judge returns the same score at every imbalance level, while both larger judges change their score with imbalance $( p < 1 0 ^ { - 1 1 }$ each). Collapse also depends on the agent: the six-tool agent tracks imbalance perfectly at breadth 3 but collapses at breadths 4, 5 and 8.

The fix works. With the THRESHOLD wording, the gate scored at most 0.10 in all 16 settings where the most common seed task supplies more than half of the examples. On identical inputs this happened in 30 of 30 runs, against 0 of 30 with the original wording (Fisher exact test, $p < \dot { 1 } 0 ^ { - 1 6 } )$

The second gate. A second gate removes low-scoring rows from training data. It ships switched off, because a safe threshold turned out to differ from agent to agent, and keeping unscored rows stops an unreliable judge from quietly shrinking the training set.

## B The two acceptance tests

Test 1: delete the signal. Copy the gate’s real input and remove the property it is supposed to judge, entirely rather than setting it to a neutral value, so the prompt reads the same whatever the property’s value (the NO-SIGNAL variant above). Run both versions the same number of times. If the scores are the same, the gate is ignoring the property. Ours took 40 calls. Repeat the test whenever the model, the prompt or the request format changes, because §5.1 shows a gate can work in one setup and fail in another.

Test 2: check the guarantees. List the request settings the gate depends on, such as requiring a tool call, requiring a fixed output format, or setting the temperature. For each one, send an input that would be answered differently if the setting were ignored, and check that the answer changes. Three of ours failed. Requiring a tool call cannot be combined with extended reasoning: the API rejects the request. Our company’s gateway forwarded requests for a fixed output format without the format, and said nothing. And the judge models reject temperature settings. We measured these on 2026-08-13 with one provider through one gateway; both change over time, so each setting must be tested, not taken from documentation.

## C Recoverability in detail

Noise floors. The agent and the simulated user are both stochastic, so running the same agent twice already changes some outcomes. We measure this by running the unchanged agent twice (the null change). Its restoration fidelity is ρ<sub>0</sub>=0.95 (CI [0.89, 1.00]) on the 20 test tasks, and its blast radius is $\beta _ { 0 } \mathrm { { = } } 0 . 0 8 \left( \mathbf { C I } \left[ 0 . 0 2 , 0 . 1 6 \right] \right)$ on all 50 airline tasks with four runs per task. We first used 20 tasks for blast radius, but the floor was too noisy, so we moved to 50; more tasks helped, more runs per task did not.

Table 6: How each type of change is undone on our platform. All four keep the old version, so undoing is a write and $g { = } 0$ (for weights, switching back to the previous adapter). None of them can take back what the change already did to users.
<table><tr><td>dimension</td><td>how it is undone</td><td>g</td><td>are its side effects undone?</td></tr><tr><td>system prompt</td><td>write back previous value</td><td>0</td><td>no: answers already served</td></tr><tr><td>tool definitions</td><td>write back previous value</td><td>0</td><td>no: calls already made</td></tr><tr><td>skills</td><td>write back previous value</td><td>0</td><td>no: answers already served</td></tr><tr><td>model weights</td><td>re-pin previous adapter</td><td>0</td><td>no: answers already served</td></tr></table>

Restoring a saved copy $\scriptstyle ( g = 0 )$ . Writing back the saved prompt gives $\rho { = } 0 . 9 5 ,$ , so $\rho - \rho _ { 0 } { = } 0 . 0 0 0$ $\left( \mathbf { C I } \left[ - 0 . 0 \dot { 3 } 8 , 0 . 0 3 8 \right] \right)$ . An equivalence test (TOST) with a margin of ±0.05, one task in 20, confirms that the restored agent behaves like the original (p=0.007). Three separate runs of the original agent agree with each other no more closely (ρ of 0.950, 0.950 and 0.975). This is the expected result, since the restored prompt is identical, but it is the control the other comparisons rely on.

Regenerating the undo (g=1). Here we hid the old prompt, as when a fine-tuned model’s previous version is gone, and asked the optimizer to write an undo. It wrote three. We compared each with the original agent on the 30 training tasks, against a floor measured with the same two runs per task $( \rho _ { 0 } { = } 0 . 9 8 )$ . The three undos reach ρ of 0.75, 0.83 and 0.90, that is, 0.23, 0.15 and 0.08 below the floor (one-sided $\scriptstyle { p = 0 . 0 0 0 5 , 0 . 0 0 4 }$ and 0.04, all still significant after Holm’s correction for testing three); together, 0.16 below (CI [0.07, 0.27], p=0.0001). So a regenerated undo does not bring the original behavior back, while a saved copy does; the two differ by about 0.16. Three caveats: these runs use the training tasks, not the test tasks used for the saved copy; the gate refused all three undos, so this shows what would have happened had one been installed; and the three are close rewrites of one another, so they test one kind of undo rather than many. The gate refused them because their training pass rates (0.567, 0.517, 0.517) were below the original’s (0.617), though that gap is too small to be significant (−0.05, CI [−0.23, 0.13]).

Blast radius. We deployed four admitted changes, one at a time, in place of the original agent and ran each on the 50 tasks. One change’s test runs were lost, so we report the other three: blast radius 0.24, 0.28 and 0.24, against the 0.08 floor. Together they exceed the floor by 0.17 (CI [0.08, 0.27], one-sided $p { = } 0 . 0 0 0 2 ;$ a permutation test and a Wilcoxon test agree), and each change does on its own (exact McNemar tests, $p { = } 0 . 0 2 9 , 0 . 0 0 3$ and 0.019; at most 0.04 after Holm’s correction). Tasks flipped from pass to fail about as often as from fail to pass (20 and 18), so the average pass rate barely moved even though about one task in six changed outcome.

## D Experiment A in detail

Why 20 test tasks are too few. A task’s outcome is close to all-or-nothing: its four runs usually agree, and the same task often flips completely between one candidate and another. So differences between candidates are mostly whole tasks, and with 20 test tasks the uncertainty on a candidate’s test score is about ±0.24. Confirming the regret trend would take about 220 test tasks, and confirming the overstated gain about 60.

Intervals. All intervals come from resampling tasks with replacement: 2,000 resamples in experiment A and 20,000 elsewhere.

How the regret slope is fit. For each corruption level ε from 0 to 0.5 in steps of 0.05 (Table 2 shows every other level), we measure σ and the regret, each averaged over 400 random corruptions. The slope is a straight-line (least-squares) fit of regret against σ through these 11 points; a negative slope means regret grows as the verifier gets weaker. For its interval we resample the training and test tasks 2,000 times and refit the whole curve each time; the one-sided p-value is the share of refitted slopes that are zero or positive.

When can a candidate pool show the effect at all? A verifier with $\sigma { = } 0$ picks a candidate at random, so the most it can lose is the gap between the average candidate and the one a perfect verifier would pick. If that gap is smaller than the measurement noise, no experiment on this pool can show the effect; we call such a poolfield-limited, and we fixed the threshold $( \mathrm { g a p }$ divided by noise below 1) in advance. Airline’s gap is 0.069, a ratio of 0.62, and retail’s is negative $( - 0 . 0 0 9 )$ , so both pools are field-limited. Our first version of this check used a rougher estimate that put airline at 1.39; we corrected it after the runs. We do not combine domains, because the pools with the least spread also have the smallest error bars and would dominate a combined estimate.

Widening the pool. The loop’s own four revisions gave a ratio of at most 0.42, so we added candidates made by deleting one section of the agent’s instructions (no-cancel, no-book, no-modify, and two pairs of these), each keeping at least 60% of the instructions so that it is weakened rather than broken. One candidate’s test runs were lost, leaving eight, with test pass rates from 0.26 to 0.60.

The overstated gain. The 0.20 gap at $\varepsilon { = } 0$ has two parts: a difference between the training and test tasks that affects every candidate $( \bar { 0 } . 0 9 , \mathrm { { C I } } \left[ - 0 . 0 9 , \bar { 0 . 2 6 } \right]$ , one-sided $p { = } 0 . 1 7 )$ , and the extra gain of the candidate that was picked because it scored best on training, known as the winner’s curse (0.11, $\operatorname { C I } { [ - 0 . 0 8 , 0 . 3 3 ] } , { p { = } 0 . { \overset { \cdot } { 1 } } 3 ) }$ . Neither part is significant, and neither is the total $\scriptstyle ( p = 0 . 0 8 )$ . In retail the gap $\mathrm { i s - 0 . 0 2 \ ( C I \ [ - 0 . 1 8 , 0 . 1 8 ] ) }$ ), so it does not replicate.

Data checks. A simulation that fails because of an infrastructure error still takes its place in the results, with an empty transcript and no score, and the benchmark runner reports no error. We therefore checked every set of runs before scoring and only compared runs with the same number of runs per task.

## E Choosing $\sigma _ { \mathrm { m i n } }$ and limiting false admits

How to set $\sigma _ { \mathrm { m i n } } .$ . (i) Decide how much regret r the domain can tolerate, from the cost of admitting a bad change. (ii) Build a candidate pool that is not field-limited (App. D); if that is not possible, no threshold can be estimated. (iii) Measure regret against σ as in Table 2, and set $\sigma _ { \mathrm { m i n } }$ to the smallest σ at which the upper end of the confidence interval on regret is at most r. (iv) Repeat whenever the number of runs the gate averages over changes: the strength at which regret starts to rise was 0.41 with 60 runs per candidate, 0.56 with 30 and 0.49 with 15.

Limit false admits, not only σ. Let α be the false-admit rate (how often the verifier passes a trajectory the reference fails) and φ the false-reject rate. Our LLM judge has $( \alpha , \varphi ) { = } ( 0 . 1 0 , 0 . 2 1 )$ and reference-action match (0.21, 0.12): almost the same σ but opposite mistakes, although with 20 tasks the difference is not significant. Only false admits let a worse change through, so where those are costly the rule should also require the upper confidence bound on α to stay below a limit $\alpha _ { \mathrm { m a x } } .$ with $\sigma > 0$ to rule out collapse. Because mistakes repeat across a task’s runs, the bound must count tasks rather than runs: the judge’s 4 false admits are one task seen four times, which puts the upper bound near 0.37, not the 0.20 that counting runs suggests. Showing $\alpha \leq 0 . 0 5$ with no false admits at all takes about 59 separate tasks that the reference fails.

Keeping σ up to date. σ belongs to a verifier together with its model and settings, since the same gate collapsed in some setups and not others. A σ measured before such a change counts as unmeasured, so the rule refuses. The reference does not have to be a program, only fixed: label a balanced set of trajectories once and re-score that same set each time. Where no program check exists, one can be learned from labeled examples (Pezeshkpour & Hruschka, 2026), but it must then be measured on examples it was not learned from.

Correcting the overstated gain. The winner’s-curse part can be removed by promoting a candidate on the lower end of its confidence interval rather than on its best training score (Thomas et al., 2015; Thomas & Brunskill, 2016; Sakhi et al., 2024), or reduced with statistical corrections for selecting the best of several (Andrews et al., 2024; Efron, 2011; Zöllner & Pritchard, 2007). The part that affects every candidate needs a set of test tasks the gate never uses for selection. We recommend both; we have not yet compared them on our data.