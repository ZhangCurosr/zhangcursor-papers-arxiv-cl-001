# Glance: The Generator Is Its Own Reranker

Adilet Metinov Chingiz Arziev Airun Intelligence Labs

October 2026

## Abstract

Retrieval-augmented generation commonly serves separate models for reranking and answering, duplicating model residency and passage processing. We introduce Glance, which equips the generator with a lightweight decision adapter and pointer head to score candidate passages from a shared prefill. Short relevance probes branch from the cached context, producing one score per passage without separately prefilling each query–passage pair. A single resident 9B backbone supports generation, general decisions and reranking, with approximately 0.1 GiB of additional memory per decision skill. After 39 minutes of MS MARCO fine-tuning, Glance achieves nDCG@10 of 0.741 on SciFact and 0.345 on NFCorpus, compared with 0.721 and 0.326 for bge-reranker-v2-m3. On 300 HotpotQA questions, its selected context improves answer F1 by 0.045 over cross-encoder-selected context under the same base generator (paired bootstrap 95% CI [0.014, 0.076]). In a scaling study, reranking quality keeps rising up to 200 candidates (43k tokens) scored from one shared prefill, where it exceeds the cross-encoder by 0.058 nDCG@10, and a probe-only activated adapter lets generation continue from the original passage cache. These initial results demonstrate generator-based reranking with one resident backbone; evaluation currently covers two retrieval datasets, one QA dataset and one backbone family. Adapters and code: https://huggingface.co/airun-ai/GlanceRAG-MiMo-9B-Reranker.

## 1 Introduction

RAG systems often assign evidence selection and answer generation to separate models. A crossencoder reranker encodes each query–passage pair separately, typically in batches [13, 6]; LLMbased rerankers improve quality further [19, 15, 25] at higher cost [1]. Either way, an additional model must be served and the candidate passages are processed before the generator reads the selected context. The generator is going to read the passages anyway: can it judge all of them using computation shared across passages?

Glance equips the generator with a lightweight decision adapter. It prefills the candidate passages once, then evaluates short passage-specific probes that branch from the shared cache, and a 256-dimensional pointer head turns each probe into a relevance score. The same resident backbone then generates the answer (Figure 1). In an activated-adapter variant, passage encoding uses the base weights, so generation can continue from the original cache.

Our contributions:

1. Method. Passage-specific relevance probes over one shared passage prefill, read by the generator’s own backbone through a small adapter and pointer head, including on hybrid linear/fullattention backbones (§3).

2. Evidence. Retrieval results on two BEIR datasets, zero-shot and after short MS MARCO training; downstream QA on HotpotQA under the same generator; and scaling to 200 candidates per shared prefill (§4).

3. Unified serving. Small decision adapters sharing one backbone, switched per request with outputs identical to each model loaded alone, and an activated variant whose answer continues from the reranking cache (§4.6, §4.7).

Glance removes the additional reranker backbone while delivering competitive retrieval quality and improved downstream answers in the evaluated settings; a dedicated cross-encoder remains faster per query.

## 2 Related Work

Rerankers. Cross-encoders such as monoT5 [13] and BGE rerankers [6] score each query–passage pair independently. LLM rerankers score pointwise via yes/no logits [25], or listwise via permutation generation [19, 15]; FIRST [17] reads the ranking from the logits of the first generated token. Incontext reranking [7] uses attention patterns of a frozen LLM over all passages at once. Unlike in-context reranking (attention heuristics, frozen weights) and listwise methods (one permutation or one token for all candidates), Glance attaches a separate trained probe per passage over one shared multi-passage context and reads k passage-specific relevance scores; unlike Self-RAG [2], which judges each passage in its own pass, all judgments come from one shared read.

Shared-context and cache reuse. Parallel Context Windows [16] restart positions per window to process segments independently. TurboRAG [12] and CacheBlend [24] precompute and fuse passage KV caches for generation. HyperRAG [1] caches document-side KV ofline for decoder rerankers and reports 2–3× throughput with no loss in accuracy. The Kev runtime [14] packs many typed questions over one shared state, continuing each question branch from the state’s cache, including on hybrid Qwen3.5-style backbones; we build on it and apply it to reranking inside RAG. Activated LoRA [8] applies an adapter only after an invocation sequence so that the base model’s KV cache can be reused for generation; our main pipeline re-prefills the selected passages (§3.4), and §4.7 adopts activation to reuse the cache.

Retrieval-generation coupling. REPLUG [18] trains a retriever from the LM’s own likelihood; Self-RAG [2] lets the generator critique retrieved passages through reflection tokens. Long-context models still miss evidence placed in the middle of long inputs [11], which motivates reranking even when the context window is large.

## 3 Method

## 3.1 Overview and the two answer pipelines

Glance has two variants, which difer only in where the adapter is active and how the answer is produced (Figure 1).

• Glance (main). The decision adapter is active on all tokens. Prefill the candidates → score the probes → select the top-n passages → re-prefill the selected passages with the adapter of → answer.

• Glance-Activated. The adapter is active only on probe tokens. Prefill the candidates with the base weights → score the probes with the adapter → continue the original cache with the base weights → answer. The continued cache retains all k candidates; losing passages are not removed from it.

![](images/7606f3242ec46a70b90b76b99efa6fd29089261014525e23fffc83afce2eabd5.jpg)  
Figure 1: One resident backbone, shared passage encoding, passage-specific decisions. Shaded parts run with the decision adapter (LoRA + pointer head). In the main pipeline the selected passages are re-prefilled and answered with the adapter of; in the activated variant the passages are prefilled with the base weights, so generation continues the same cache, which still holds all k candidates.

All experiments use the main pipeline except §4.7. Table 1 lists the adapter configurations.

## 3.2 Decision mode

Given a state s and a question with options $o _ { 1 } , \ldots , o _ { m }$ , the decision model encodes <state> s <q> instruction <opt> $\begin{array} { c c c } { { o _ { 1 } < / \mathrm { o p t } > } } & { { . . . } } & { { < \mathrm { d e c i d e } > } } \end{array}$ . The state is the shared context prefix that all questions continue from. A pointer head compares the hidden state at <decide> with the hidden state at each </opt> and returns a softmax over options. Binary yes/no questions (Kev’s noul type) use the options {false, true}. The head and a rank-16 LoRA [9] adapter are the only trained parameters; the backbone is frozen. No text is generated, so a decision costs one prefill.

## 3.3 Multi-probe packing

For a query q and candidates $p _ { 1 } , \ldots , p _ { k }$ we compare three packings:

• packed\_all: state = “[Passage 1] $p _ { 1 } \ldots$ . [Passage $k ] \mathbf { \Lambda } _ { p _ { k } } ^ { p _ { \ l } } \mathbf { \Lambda } ^ { \prime \prime }$ ; branch i is the short question “Does Passage i contain information that answers or supports the query: $q ? \ '$

• packed\_q: ${ \mathrm { s t a t e } } = q ;$ branch i contains passage $p _ { i }$ and a relevance question.

• listwise: stat $\mathrm { { e } } = q ;$ one choice question whose options are the k passages.

Branches never attend to each other; each branch continues from the end of the state, and its positions continue from there. As shorthand, “single pass” means one shared prefill of the passages followed by one batched continuation over all k probes (∼30 tokens each), so no passage is prefilled more than once. The probes give k passage-specific relevance scores; they are not statistically independent, since in packed\_all every probe sees all passages, which lets it compare them.

## 3.4 Hybrid backbones

Our 9B backbone interleaves Gated DeltaNet [23] linear-attention layers with full-attention layers (3:1). An attention mask can isolate branches in full-attention layers, but a linear-attention layer carries a single recurrent state through the sequence. Kev’s shared-prefix path therefore runs the shared state once and starts every branch from a copy of each layer’s cache at the end of the state: keys and values for attention layers, and the convolution window plus recurrent state for DeltaNet layers (the chunked delta rule’s initial\_state). This is exact, and the same path is used in training, so the state is computed once per record rather than once per question. Unlike attention KV, a DeltaNet state summarises the whole prefix in order, so per-passage caches cannot be stitched in arbitrary order; the main pipeline therefore re-prefills the selected passages (about 1.5k tokens), also because its state cache was computed with the adapter on, while Glance-Activated continues the full candidate cache.

<table><tr><td>Name</td><td>Initialised from</td><td>Training</td><td>Adapter active on</td></tr><tr><td>zero-shot</td><td></td><td>4.4k general decision records, 20 min, no retrieval data</td><td>all tokens</td></tr><tr><td>trained</td><td>zero-shot</td><td>+ 4,000 MS MARCO records, 8–20 passages, 39 min</td><td>all tokens</td></tr><tr><td>trained-long</td><td>trained</td><td>+ 450 MS MARCO records, 20–80 passages, 14 min</td><td>all tokens</td></tr><tr><td>control</td><td>zero-shot</td><td>+ 1,200 MS MARCO records, 150 steps</td><td>all tokens</td></tr><tr><td>activated</td><td>zero-shot</td><td>+ 1,200 MS MARCO records, 150 steps</td><td>probe tokens only</td></tr></table>

Table 1: Adapter configurations (rank-16 LoRA + 256-d pointer head on the frozen 9B backbone).

## 3.5 One resident backbone

The adapter is kept unmerged. Reranking runs with the adapter and pointer head; answer generation runs the same backbone with the adapter disabled, using the top-n passages and the model’s chat template. Additional decision skills cost approximately 0.1 GiB each (LoRA plus head); inference memory also depends on the candidate count and the cache implementation (§4.4).

## 3.6 Training

We fine-tune from an existing general decision adapter on 4,000 MS MARCO [3] training queries (Tevatron BM25 hard negatives). Each record packs one positive and 7–19 hard negatives, shufled, in the packed\_all format, with one binary label per probe. One epoch (500 optimizer steps, 55,598 labelled probes, 7.7M forward tokens), LoRA rank 16, learning rate 5 · 10<sup>−5</sup> (head 10<sup>−4</sup>), batch 8, bf16, on one NVIDIA B200 in 39 minutes with 21 GiB peak GPU memory. No BEIR or HotpotQA data is used in training.

## 4 Experiments

## 4.1 Setup

Backbone. MiMo-V2.6-Distill-Qwen-9B (XiaomiMiMo), a hybrid Gated DeltaNet/full-attention model (3:1), frozen in bf16. Zero-shot adapter. “Zero-shot” denotes the general decision adapter (rank-16 LoRA + pointer head), trained for 20 minutes on 4.4k public and synthetic decision records (e.g. BoolQ, topic and sentiment classification, paraphrase, sentence-level answer containment); the mixture contains no MS MARCO, BEIR or HotpotQA data. Retrieval. BM25 (bm25s) top-k=20 over each corpus; passages truncated to 220 words. Datasets. BEIR [20] SciFact [21] (300 test queries) and NFCorpus [5] (323 test queries), nDCG@10. Baselines. BM25 order; bge-reranker-v2-m3 cross-encoder [6]; the same decision model scoring each passage in a separate, sequential call (separate, passage as state, query as question). Hardware. One RTX PRO 6000 (96 GB) for zero-shot runs; latencies are median per query, bf16, without CUDA graphs or fused kernels, on a GPU shared with other jobs, so latencies may difer under isolated execution and ratios between methods are approximate. Training, the trained-adapter evaluations and §4.4 and §4.9 use one B200, and §4.7 one H100; latencies are comparable only within a section. BEIR diferences are not significance-tested; at $n \approx 3 0 0$ , gaps below about 0.02 nDCG@10 should be read as indicative.

## 4.2 Single pass vs. k passes (zero-shot)

Without any retrieval training, every one-pass mode improves on BM25, and on SciFact the sharedpassages mode (packed\_all) keeps most of the quality of 20 separate decision calls (0.715 vs. 0.729 nDCG@10) 3.6× faster than sequential pointwise calls to the same 9B model in this shared-GPU experiment, close to the dedicated cross-encoder (0.721). On NFCorpus, packed\_all scores highest in Table 2 (0.341, within 0.02 of listwise and packed\_q), above the cross-encoder (0.326) and above the same model’s 20 isolated calls (0.323), at 3.7× lower latency than the latter; one plausible explanation is that each probe can compare a passage with its neighbours, which isolated scoring cannot do, although on SciFact the isolated calls are slightly better. The cross-encoder remains far faster per query (31–60 ms). In a 20-query pilot on SciFact with less GPU contention, packed\_all scored 0.699 nDCG@10 against 0.697 for 20 separate calls at half the latency (0.60 s vs. 1.20 s), so the speed-up ratio depends on load; on Kev’s fp32-exact evaluation path, which recomputes the state for every question, the same packed request took 16.2 s, so computing the shared state once is what makes single-pass reranking practical.

## 4.3 Training for reranking

We fine-tune the decision adapter for 39 minutes on MS MARCO in the packed\_all format (§3.6) and re-evaluate without any BEIR or HotpotQA training data (Table 3). Latencies in this section were measured on a B200.

The trained-long adapter of §4.4 (14 more minutes on records with 20–80 passages) scores 0.749 (SciFact) and 0.346 (NFCorpus) in the same setting, so training on longer contexts does not hurt the standard k=20 case. After training, packed\_all is the best method in Table 3 on both datasets (not significance-tested; separate per-passage calls were not re-run with the trained adapter), above the cross-encoder by 0.020 (SciFact) and 0.019 (NFCorpus) nDCG@10, and above the zero-shot model’s 20 separate calls on SciFact (0.729).

## 4.4 How far does one pass scale?

We vary the number of candidates read in one pass, $k \in \{ 1 0 , 2 0 , 5 0 , 1 0 0 , 2 0 0 \}$ , on the first 100 SciFact queries with passages trimmed to 100 words (Table 4). The zero-shot adapter peaks at k=20 and degrades at k=100. The MS MARCO-trained adapter, although trained only on 8–20 passages per record, instead improves with k: at k=100 (21.6k context tokens in one pass) it reaches 0.682 nDCG@10, against 0.637 for the cross-encoder scoring the same 100 candidates. A further 14 minutes of training on records with 20–80 passages (trained-long) raises every evaluated k (20–100) again, to 0.697 at k=100 (+0.060 over the cross-encoder, 1.05 s per query on a B200). At k=200 (43.4k tokens), which no longer fits in one call and runs on Kev’s chunked path (one prefill of the state, probe rows in several batches; 15.8 s per query), it reaches 0.717 against 0.659 for the cross-encoder on the same 100 queries. Training thus prevents the observed degradation through k=100 in this study, which suggests that it is not an inherent limit of shared-prefill reranking. The cross-encoder scores lower here than in Table 2, presumably because of the 100-query subset and the shorter passages.

Memory grows faster than linearly in k (56 GiB at k=100), because in the current implementation every probe branch continues from its own copy of the shared state’s attention cache, so memory scales with k× context length. Under a 64 GiB cap, the zero-shot single call runs out of memory at k=200 (43k tokens); Kev’s chunked serving path (state once, branch rows in chunks) still runs k=200 and k=300 (65k tokens, 23 GiB, about 22 s per query), but the zero-shot adapter’s quality collapses there (0.505 on 38 queries at k=200). Batching across queries does not help with the current implementation: packing B queries (k=20) into one call lowers throughput from 2.87 queries/s (B=1) to 1.57 (B=16) and runs out of memory at B=32, with scores within bf16 noise of unbatched ones (mean |∆p| 0.002). States of diferent lengths are left-padded, which forces an explicit mask instead of the flash kernel, and each branch row copies its state’s cache, so batching multiplies the copies. Letting all branches attend to one shared cache with a block mask would remove this copy and make memory linear in context length; with it, a reranker over a 128k-token shared prefill becomes feasible, which we leave to future work.

<table><tr><td></td><td colspan="2">SciFact</td><td colspan="2">NFCorpus</td></tr><tr><td>Method</td><td>nDCG@10</td><td>ms/query</td><td>nDCG@10</td><td>ms/query</td></tr><tr><td>BM25</td><td>0.662</td><td></td><td>0.306</td><td></td></tr><tr><td>bge-reranker-v2-m3</td><td>0.721</td><td>31</td><td>0.326</td><td>60</td></tr><tr><td>Decision 9B, separate (k calls)</td><td>0.729</td><td>2210</td><td>0.323</td><td>2485</td></tr><tr><td>Glance packed_all (1 pass)</td><td>0.715</td><td>614</td><td>0.341</td><td>670</td></tr><tr><td>Glance packed_q (1 pass)</td><td>0.721</td><td>773</td><td>0.328</td><td>847</td></tr><tr><td>Glance listwise (1 pass)</td><td>0.684</td><td>544</td><td>0.331</td><td>573</td></tr></table>

Table 2: Reranking BM25 top-20 with the zero-shot adapter (no retrieval training data). One-pass rows run one prefill of the shared state plus one batched continuation over its branches per query; latencies on a shared RTX PRO 6000.
<table><tr><td colspan="2"></td><td colspan="2">SciFact</td><td colspan="2">NFCorpus</td></tr><tr><td>Method</td><td>zero-shot</td><td>trained</td><td>zero-shot</td><td></td><td>trained</td></tr><tr><td>BM25</td><td></td><td>0.662</td><td></td><td>0.306</td><td></td></tr><tr><td>bge-reranker-v2-m3</td><td></td><td>0.721</td><td></td><td>0.326</td><td></td></tr><tr><td>Glance packed_all (1 pass)</td><td></td><td>0.715</td><td>0.741</td><td>0.341</td><td>0.345</td></tr><tr><td>Glance packed_q (1 pass)</td><td></td><td>0.721</td><td>0.738</td><td>0.328</td><td>0.338</td></tr><tr><td>Glance listwise (1 pass)</td><td></td><td>0.684</td><td>0.692</td><td>0.331</td><td>0.334</td></tr></table>

Table 3: nDCG@10 before and after 39 minutes of MS MARCO training (BM25 top-20). Trained packed\_all latency on a B200: 420 ms (SciFact), 411 ms (NFCorpus) per query.

## 4.5 End to end: the same weights rerank and answer

On HotpotQA distractor [22] (first 300 validation questions; 10 paragraphs per question, 2 gold; paragraphs trimmed to 220 words), one bf16 copy of the 9B backbone serves both roles: Glance reranks with the decision adapter on, then the same backbone answers greedily (at most 48 new tokens). We compare answer EM/F1 (oficial HotpotQA scoring) given (a) all 10 paragraphs, (b) top-3 by bge-reranker-v2-m3, (c) top-3 by Glance, answering with the adapter of, (b<sup>′</sup>)/(c<sup>′</sup>) the top-3 of (b)/(c), answering with the adapter left on, and (d) the 2 gold paragraphs.

Although the cross-encoder retrieves more gold paragraphs (R@2 0.863 vs. 0.762), the generator answers better from Glance’s top-3 (F1 0.718 vs. 0.683), consistent with the generator selecting context it can use; this adapter-of gap is not significant (below), and (c) is level with giving the generator all 10 paragraphs (0.716). Answering with the adapter left on raises F1 further to 0.757, within 0.032 of the gold-paragraph ceiling; its answers are shorter (2.5 vs. 3.1 words on average), which matches HotpotQA’s short-answer format. To separate this answer-style efect from reranking, row (b<sup>′</sup>) answers from the cross-encoder’s top-3 with the same adapter-on generator: Glance’s context still wins by +0.055 F1 (paired bootstrap 95% CI [+0.018, +0.093], 10,000 resamples) and +0.043 EM ([+0.003, +0.083]). With the adapter of the gap is +0.035 F1 ([−0.003, +0.074]), positive but not significant at n=300.

<table><tr><td>k</td><td>tokens/pass</td><td>zero-shot</td><td>trained</td><td>trained-long</td><td>bge-v2-m3</td><td>ms/query</td><td>peak GiB</td></tr><tr><td>10</td><td>2.2k</td><td>0.651</td><td>0.653</td><td></td><td>0.626</td><td>252</td><td>15.4</td></tr><tr><td>20</td><td>4.3k</td><td>0.662</td><td>0.658</td><td>0.674</td><td>0.624</td><td>165</td><td>16.7</td></tr><tr><td>50</td><td>10.8k</td><td>0.637</td><td>0.674</td><td>0.691</td><td>0.642</td><td>417</td><td>25.5</td></tr><tr><td>100</td><td>21.6k</td><td>0.584</td><td>0.682</td><td>0.697</td><td>0.637</td><td>1049</td><td>56.4</td></tr><tr><td>200†</td><td>43.4k</td><td>一</td><td></td><td>0.717</td><td>0.659</td><td>15790</td><td>20.5</td></tr></table>

Table 4: Single-pass reranking with k candidates (SciFact, 100 queries, BM25 top-k, 100-word passages). Trained: MS MARCO adapter of §3.6 (8–20 passages per record). Trained-long: warmstarted from it and trained 14 more minutes on 450 records with 20–80 passages. Latency and memory: trained-long on a B200 (k=10: trained adapter, separate run). <sup>†</sup>Does not fit in one call; run on Kev’s chunked path (one prefill of the state, probe rows in several batches).  
![](images/60fa990051001bb03106f38795b47eb7bf39ef03b4a83e5abebdda8941aeaa54.jpg)  
Figure 2: Quality vs. candidate count (data of Table 4). Trained adapters keep improving as more candidates share one prefill (k=200 on the chunked path); the zero-shot adapter degrades beyond k=20. Peak memory grows from 15 GiB (k=10) to 56 GiB (k=100) because of per-branch cache copies.

Real-time mode switching. With the adapter unmerged, switching modes changes no weights. Over 20 alternations of a real 10-passage rerank (adapter on) and a real 24-token generation (adapter of), entering adapter-of took 11 ms (median) and leaving it 2.8 ms; every on-visit produced bitidentical probabilities and every of-visit the identical greedy answer, and allocated GPU memory stayed at 16.77 GiB (14.78 GiB backbone, 0.08 GiB LoRA, 1.89 GiB LM head).

Does the model still chat with the adapter on? On general prompts (an explanation, a translation, an arithmetic word problem) adapter-on and adapter-of outputs were identical or nearly so, and the per-token NLL on 1,024 tokens of Wikipedia text rose only from 1.556 to 1.564 (perplexity 4.74 to 4.78). On these prompts the decision LoRA changes general generation little, though on HotpotQA it measurably shortens answers; whether a single adapted model can replace

<table><tr><td>Context given to the generator</td><td>EM</td><td>F1</td><td>R@2</td><td>R@3 rerank ms</td></tr><tr><td>(a) all 10 paragraphs</td><td>0.533</td><td>0.716</td><td></td><td></td></tr><tr><td>(b) bge-reranker-v2-m3 top-3</td><td>0.500</td><td>0.683</td><td>0.863 0.918</td><td>29</td></tr><tr><td>(c) Glance top-3, adapter off</td><td>0.543</td><td>0.718 0.762</td><td>0.865</td><td>378</td></tr><tr><td>(b&#x27;) bge-reranker-v2-m3 top-3, adapter on</td><td>0.547</td><td>0.702</td><td>0.863 0.918</td><td>29</td></tr><tr><td>(c&#x27;) Glance top-3, adapter on</td><td>0.590</td><td>0.757</td><td>0.762 0.865</td><td>378</td></tr><tr><td>(d) oracle: 2 gold paragraphs</td><td>0.607</td><td>0.789</td><td></td><td></td></tr><tr><td>trained adapter (separate B200 run)</td><td></td><td></td><td></td><td></td></tr><tr><td>(bt) bge-reranker-v2-m3 top-3, adapter off</td><td>0.503</td><td>0.684 0.863</td><td>0.918</td><td>24</td></tr><tr><td>(ct) Glance trained top-3, adapter off</td><td>0.553</td><td>0.729</td><td>0.897 0.962</td><td>274</td></tr><tr><td>(bt) bge-reranker-v2-m3 top-3, trained adapter on</td><td>0.510</td><td>0.682</td><td>0.863 0.918</td><td>24</td></tr><tr><td>(ct) Glance trained top-3, trained adapter on</td><td>0.577</td><td>0.747</td><td>0.897 0.962</td><td>274</td></tr></table>

Table 5: End-to-end RAG on HotpotQA distractor (n=300; packed\_all, k=10). Upper block: zeroshot adapter; lower block: trained adapter. Every row uses the same 9B generator; rows (b<sup>′</sup>) and (c<sup>′</sup>) answer with the adapter left on. R@n: recall of the gold paragraphs in the top n. Latencies: upper block on a shared RTX PRO 6000, lower block on a B200.

toggling needs broader evaluation.

Trained reranker, end to end. With the trained adapter (lower block of Table 5), Glance also retrieves more gold paragraphs than the cross-encoder (R@2 0.897 vs. 0.863), and under the same base generator (adapter of) its top-3 improves answer F1 from 0.684 to 0.729 (+0.045, paired bootstrap 95% CI [+0.014, +0.076]). This comparison isolates the efect of selecting diferent evidence from any efect of the adapter on answer style. With the trained adapter left on for both contexts the gap is +0.065 ([+0.038, +0.094]), but the trained adapter-on F1 (0.747) is below the zero-shot one (0.757), suggesting that the two adapters afect answer style diferently. The lower-recall-but-better-answers pattern of the zero-shot adapter is consistent with useful evidence selection, but it does not show that the model has learned answer utility; our training labels are passage relevance, not answer quality. The adapter-of cross-encoder and all-paragraph rows of this run difer from the upper block by at most 0.003 F1 presumably because of bf16 kernel diferences between GPUs.

## 4.6 Three modes on one backbone

Because both the general decision adapter and the reranking adapter are LoRA modules over the same frozen backbone, a single resident copy can serve three modes, chosen per request: base chat (all adapters of), general decisions (the general adapter and its pointer head), and rerank (the MS MARCO adapter and its own head). We load the backbone once, attach the second adapter as a named PEFT adapter with its own head, and cycle base → general → rerank for 10 rounds (Table 6).

Each extra decision skill costs about 0.1 GiB. On the same inputs the two adapters’ probabilities difer by up to 0.81, so the modes are genuinely distinct. Skill retention. On the 231 public items of JevBench [4], a benchmark of typed decision requests in easy, original and hard tiers (the hard tier holds adversarial and multi-step items), the general adapter scores 184/231 (79.7%) and the reranking adapter, warm-started from it, 175/231 (75.8%), a net loss of 9 items, 7 of them in the hard tier. Specialising one adapter for reranking therefore causes moderate forgetting of general decisions, which the multi-adapter setup sidesteps: each request uses the adapter trained for it.

<table><tr><td>Mode</td><td>Check against the model loaded alone</td><td>Switch into mode (median)</td></tr><tr><td>Base</td><td>greedy chat text identical on all visits (3 prompts × 10)</td><td>4.2–6.4 ms</td></tr><tr><td>General</td><td>probabilities bit-identical (max  $| \Delta p | = 0 )$ </td><td>9.4 ms</td></tr><tr><td>Rerank</td><td>probabilities bit-identical (max  $| \Delta p | = 0 )$ </td><td>8.8 ms</td></tr></table>

Table 6: One 9B backbone, three modes, switched per request. Memory: 16.85 GiB resident (backbone 14.78, each LoRA 0.08, both heads 0.016, LM head 1.89 GiB), unchanged after the loop (16.86 GiB).

## 4.7 Activated adapter: one read for reranking and answering

In the runs above the LoRA is active on every token, so the state is read by an adapted model and its cache is not the base model’s. For Glance-Activated, following Activated LoRA [8], we switch the adapter of for the state pass and on only for the probe branches (the invocation point is the first probe token), in both training and inference, by patching Kev’s shared-prefix step. On a 0.8B Qwen3.5 check, the patched adapter-on state cache equals the base model’s bitwise (48 tensors: attention KV, DeltaNet convolution and recurrent states; max $| \Delta | = 0$ , vs. 8.18 unpatched), while branch outputs still difer from the base.

Quality. We train the activated adapter for 150 steps (1,200 MS MARCO records, H100, 17 minutes) and a matched control with the LoRA on all tokens (same data, steps and seed). The activated adapter reaches 0.740 / 0.351 nDCG@10 on SciFact / NFCorpus (packed\_all, k=20), against 0.744 / 0.351 for the control: reranking scores are similar in this matched experiment.

Chat. Without probe tokens the activated model runs the exact base weights, so its greedy chat output is identical to the base by construction; the control adapter already changes the wording on one of two test prompts.

Cache reuse. Because the state cache is now the base model’s own, generation can continue from it. On 100 HotpotQA distractor questions (10 paragraphs, median state 1.4k tokens, H100 not shared): the state pass takes 64 ms, the 10 probes fork from its cache in 85 ms (R@3 0.97), and the base model then answers by continuing the same cache with the question in the chat format. Continuing the cache gives EM/F1 0.61 / 0.750 against 0.59 / 0.754 for re-prefilling the top-3 passages, with a lower answer latency (138 ms vs. 181 ms median). On 5 checked questions the continued answer equals that of a fresh base-model prefill of the same text. Telling the model which passages scored highest added nothing at this scale, and a continuation without the chat turn markers is much worse (F1 0.577). In this mode the generator sees all passages; the reranking scores do not select its context. The passages are thus prefilled once for both reranking and answering; the continued cache still contains all 10 candidates. This is a 100-question, single-seed result.

## 4.8 Order sensitivity

In packed\_all every probe sees all passages, so scores can depend on passage order. On 100 SciFact queries (220-word passages, as in Table 3) with the MS MARCO-trained adapter, we score each query’s 20 candidates in BM25 order and in 4 random orders. nDCG@10 ranges from 0.678 (BM25 order) to 0.693 across orders (per-query standard deviation 0.020); averaging scores over the 5 orders gives 0.689. The median per-passage probability changes by 10<sup>−4</sup> across orders (90th percentile

0.033, maximum 0.36), and the top-ranked passage is the same as under BM25 order in 91% of cases. Order efects are therefore small on average but not negligible for individual passages, and the slightly lower score in BM25 order may indicate a mild position efect.

## 4.9 Serving chat and decisions in one vLLM engine

vLLM [10] has no pointer head, but it can expose hidden states. We serve the base model with the reranking LoRA registered as a vLLM adapter: chat requests use no adapter, decision rows are one-token requests with the adapter, and the residual stream at the readout positions is passed through the final norm and the 256-dimensional pointer head outside the engine. Rows of one request share the state through vLLM’s prefix cache on the hybrid model. In a single generate call, 4 chat answers (48 tokens each) and the 19 decision rows of one packed request completed in 0.76 s, against 0.43 s for the 4 chats alone. On 20 SciFact packed requests (400 probes), probabilities difer from Kev by 0.006 on average (maximum 0.10, about 2.6× the 0.039 spread between Kev’s two bf16 inference paths, the default and the shared-prefix fast path), per-query Spearman rank correlation 0.995, with 4 of 400 decisions flipped; serving throughput on a shared B200 was 1.54 requests/s vs. 0.86 for Kev’s sequential fast path. Production use needs a connector that exports only the readout positions and the head inside the engine.

## 5 Limitations

This is a proof of concept. Evaluation sets are small (hundreds of queries) and cover two BEIR datasets and one QA dataset. We test one backbone family (hybrid 9B). Latencies are from an unoptimised eager path; a dedicated cross-encoder remains faster per query. The shared-state construction itself is provided by the Kev runtime; our contribution is its use and training fo reranking inside RAG with the generator’s own weights. In packed\_all every probe sees all passages, so a passage’s score depends somewhat on its neighbours and on order (§4.8); averaging over orders is a simple remedy. BEIR diferences are not significance-tested, and the per-passage baseline was not re-run with the trained adapter. Latencies come from diferent, partly shared GPUs (RTX PRO 6000, B200, H100), and speed-up ratios depend on load. The zero-shot adapter degrades beyond k=20 and collapses at k=200; batching across queries currently lowers throughput. The activated-adapter and cache-reuse results are single-seed, on 100 questions, the bitwise cache check used a 0.8B model, and with cache reuse the answer sees all passages rather than the reranked subset. Chat quality with the adapter on was checked on a handful of prompts, and specialising the adapter for reranking loses 9 JevBench items. Memory currently grows with k× context length (§4.4), and the vLLM path is a prototype whose probabilities difer from Kev’s by 0.006 on average (maximum 0.10; 4 of 400 decisions flipped; §4.9).

## 6 Conclusion

Glance shows that the generator can also serve as its reranker. Passage-specific probes share one candidate prefill, while lightweight adapters support ranking and general decisions on a single resident backbone. In the evaluated settings, the resulting rankings are competitive with a dedicated cross-encoder, and they improve downstream QA under the same generator. Probe-only adaptation further allows generation to reuse the original passage cache. The next questions are how these benefits extend across larger benchmarks and backbone families, how far a shared-cache implementation can push the candidate count toward 128k-token contexts, and how optimized serving systems change the latency trade-of against small cross-encoders.

## Availability

All adapters and code are released under Apache-2.0 by Airun Intelligence Labs (the repositories keep the working name GlanceRAG): the reranker (trained-long in the repository root, the 39-minute checkpoint under checkpoints/msmarco-short) at https://huggingface.co/ airun-ai/GlanceRAG-MiMo-9B-Reranker, the activated variant at https://huggingface.co/ airun-ai/GlanceRAG-MiMo-9B-Reranker-Activated, and the general decision adapter at https: //huggingface.co/airun-ai/MiMo-V2.6-Distill-Qwen-9B-Decision. Code is in the code/ folders of the two reranker repositories.

## References

[1] Y. An, Y. Cheng, S. J. Park, J. Jiang. HyperRAG: Enhancing quality-eficiency tradeofs in retrievalaugmented generation with reranker KV-cache reuse. arXiv:2504.02921, 2025.

[2] A. Asai, Z. Wu, Y. Wang, A. Sil, H. Hajishirzi. Self-RAG: Learning to retrieve, generate, and critique through self-reflection. ICLR, 2024.

[3] P. Bajaj et al. MS MARCO: A human generated machine reading comprehension dataset. arXiv:1611.09268, 2016.

[4] Benchmark Heaven. JevBench: a benchmark for decision models. Software, https://github.com/ fstandhartinger/jevbench, commit 7625ecb1, 2026.

[5] V. Boteva, D. Gholipour, A. Sokolov, S. Riezler. A full-text learning to rank dataset for medical information retrieval. ECIR, 2016.

[6] J. Chen, S. Xiao, P. Zhang, K. Luo, D. Lian, Z. Liu. BGE M3-Embedding: Multi-lingual, multifunctionality, multi-granularity text embeddings through self-knowledge distillation. Findings of ACL, 2024.

[7] S. Chen, B. J. Gutiérrez, Y. Su. Attention in large language models yields eficient zero-shot re-rankers. ICLR, 2025.

[8] K. Greenewald et al. Activated LoRA: Fine-tuned LLMs for intrinsics. arXiv:2504.12397, 2025.

[9] E. J. Hu, Y. Shen, P. Wallis, Z. Allen-Zhu, Y. Li, S. Wang, L. Wang, W. Chen. LoRA: Low-rank adaptation of large language models. ICLR, 2022.

[10] W. Kwon, Z. Li, S. Zhuang, Y. Sheng, L. Zheng, C. H. Yu, J. E. Gonzalez, H. Zhang, I. Stoica. Eficient memory management for large language model serving with PagedAttention. SOSP, 2023.

[11] N. F. Liu, K. Lin, J. Hewitt, A. Paranjape, M. Bevilacqua, F. Petroni, P. Liang. Lost in the middle: How language models use long contexts. TACL, 2024.

[12] S. Lu, H. Wang, Y. Rong, Z. Chen, Y. Tang. TurboRAG: Accelerating retrieval-augmented generation with precomputed KV caches for chunked text. arXiv:2410.07590, 2024.

[13] R. Nogueira, Z. Jiang, R. Pradeep, J. Lin. Document ranking with a pretrained sequence-to-sequence model. Findings of EMNLP, 2020.

[14] J. Palmer. Kev: typed decision models. Software, https://github.com/jaredpalmer/kev, commit 0a6d3faf, 2026.

[15] R. Pradeep, S. Sharifymoghaddam, J. Lin. RankZephyr: Efective and robust zero-shot listwise reranking is a breeze! arXiv:2312.02724, 2023.

[16] N. Ratner, Y. Levine, Y. Belinkov, O. Ram, I. Magar, O. Abend, E. Karpas, A. Shashua, K. Leyton-Brown, Y. Shoham. Parallel context windows for large language models. ACL, 2023.

[17] R. G. Reddy, J. Doo, Y. Xu, M. A. Sultan, D. Swain, A. Sil, H. Ji. FIRST: Faster improved listwise reranking with single token decoding. EMNLP, 2024.

[18] W. Shi, S. Min, M. Yasunaga, M. Seo, R. James, M. Lewis, L. Zettlemoyer, W. Yih. REPLUG: Retrieval-augmented black-box language models. NAACL, 2024.

[19] W. Sun, L. Yan, X. Ma, S. Wang, P. Ren, Z. Chen, D. Yin, Z. Ren. Is ChatGPT good at search? Investigating large language models as re-ranking agents. EMNLP, 2023.

[20] N. Thakur, N. Reimers, A. Rücklé, A. Srivastava, I. Gurevych. BEIR: A heterogeneous benchmark for zero-shot evaluation of information retrieval models. NeurIPS Datasets and Benchmarks, 2021.

[21] D. Wadden, S. Lin, K. Lo, L. L. Wang, M. van Zuylen, A. Cohan, H. Hajishirzi. Fact or fiction: Verifying scientific claims. EMNLP, 2020.

[22] Z. Yang, P. Qi, S. Zhang, Y. Bengio, W. W. Cohen, R. Salakhutdinov, C. D. Manning. HotpotQA: A dataset for diverse, explainable multi-hop question answering. EMNLP, 2018.

[23] S. Yang, J. Kautz, A. Hatamizadeh. Gated delta networks: Improving Mamba2 with delta rule. ICLR, 2025.

[24] J. Yao, H. Li, Y. Liu, S. Ray, Y. Cheng, Q. Zhang, K. Du, S. Lu, J. Jiang. CacheBlend: Fast large language model serving for RAG with cached knowledge fusion. EuroSys, 2025.

[25] Y. Zhang et al. Qwen3 Embedding: Advancing text embedding and reranking through foundation models. arXiv:2506.05176, 2025.