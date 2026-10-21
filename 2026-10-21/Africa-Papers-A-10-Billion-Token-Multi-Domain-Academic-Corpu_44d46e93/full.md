# Africa-Papers: A 10-Billion-Token Multi-Domain Academic Corpus for African Foundation Language Models

Mich-Seth Owusu

AfriSpeech

michseth@afrispeech.org

https://huggingface.co/datasets/AfriSpeech/africa-papers

## Abstract

Large Language Models (LLMs) depend fundamentally on the diversity, depth, and factual rigor of their pre-training corpora. However, contemporary foundational pre-training datasets (such as The Pile, S2ORC, and Dolma) exhibit a severe structural omission: African scientific, medical, legal, and agricultural scholarship constitutes less than 0.5% of global pre-training tokens. Consequently, state-of-the-art models suffer from systematic failure modes when reasoning about tropical epidemiology, localized smallholder agro-ecologies, regional economic governance, and indigenous linguistic structures. To resolve this representation deficit and advance African intellectual sovereignty in artificial intelligence, we introduce Africa-Papers, the largest curated multi-domain Pan-African academic pre-training corpus to date. Comprising over 844,807 full-text papers spanning 10.15 billion tokens across 879 Parquet shards, Africa-Papers unifies four primary scientific streams: (1) continental peer-reviewed journals indexed in DOAJ across 31 African nations, (2) the CGIAR CGSpace agricultural repository, (3) African-authored and African-focused STEM/AI preprints on arXiv, and (4) open-access international publications by scholars affiliated with African institutions indexed via OpenAlex. The entire corpus is processed into layout-aware, clean Markdown preserving section hierarchies, mathematical equations, and tabular data, accompanied by exact BPE token counts and a standardized 8-domain taxonomy. We release Africa-Papers openly on the Hugging Face Hub under the AfriSpeech organization to accelerate continual pre-training and domain evaluation for foundation models globally.

## 1 Introduction

The dominant paradigm in training foundation language models relies on web-scale text corpora aggregated from web scrapes and digitized libraries [9, 8]. While datasets such as Common Crawl, The Pile [3], and peS2o [8] contain trillions of tokens, their geographic and institutional provenance is overwhelmingly skewed toward North America, Western Europe, and East Asia. Scholarship authored by African researchers and peer-reviewed journals published across the 54 African nations represent a negligible fraction (< 0.5%) of the global academic pre-training mixture.

This severe under-representation induces significant epistemological vulnerabilities in contemporary models:

• Biomedical & Epidemiological Hallucinations: Foundational models frequently fail when reasoning about tropical pathologies (e.g., malaria strain variants, sickle cell genetics, lassa fever diagnostics, maternal healthcare delivery) because clinical training data defaults to Western institutional protocols [1].

• Agro-Ecological Misalignment: AI conversational assistants routinely default to temperate industrial monoculture recommendations, proving ineffective for African smallholders managing complex, climate-vulnerable intercropping of cassava, yams, cowpea, plantains, or sorghum.

• Jurisprudential & Governance Gaps: African customary jurisprudence, community-based land tenure systems, and regional trade compacts (e.g., AfCFTA) are almost entirely missing from standard legal corpora.

• Deficit Framing in Representation: Western web scrapes disproportionately depict the African continent through crisis reporting, humanitarian appeals, or conflict studies. Models therefore fail to internalize African scholars as primary intellectual authorities in astrophysics, pure mathematics, computer science, and robotics.

To systematically dismantle this structural omission, we present Africa-Papers, an open-access, layout-aware academic corpus engineered specifically for the pre-training and continual domain adaptation of foundation language models.

## Contributions:

1. Massive Scale & Depth: Over 789,348 verified full-text papers yielding 10.15 billion tokens (and actively scaling toward 25 billion tokens across 1.5 million works), establishing the single largest curated African academic corpus in history.

2. Four-Pillar Multi-Source Architecture: We integrate continental university presses (DOAJ), agricultural field manuals (CGIAR), STEM and AI preprints (arXiv), and global African scholarly literature (OpenAlex).

3. High-Fidelity Markdown Ingestion: We develop an autonomous stream-to-parquet pipeline employing multi-key deduplication and layout-aware Markdown parsing, preserving tabular data, headings, and formulas while preventing disk bloat through real-time binary pruning.

4. Domain Taxonomy & Open Release: We classify the corpus into eight standardized academic domains and release the entire collection incrementally on Hugging Face under $\mathtt { A f r i S p e e c h / a f r i c a - p a p e r s ^ { 1 } }$

## 2 The Four Pillars of Africa-Papers

Africa-Papers is constructed through a federated multi-stream architecture designed to capture both research about Africa and research by African scientists across the globe.

## 2.1 Pillar 1: DOAJ Continental Journal Presses

To capture scholarship published domestically across African universities, we harvest the complete index of African journals registered in the Directory of Open Access Journals (DOAJ) [4]. This comprises extbf944 peer-reviewed journals spanning 31 African nations. These journals encompass university presses, national academies, and regional scholarly associations published in English, French, Arabic, and Portuguese. In total, 74,606 full-text PDFs were harvested from primary host servers.

## 2.2 Pillar 2: CGIAR CGSpace Agricultural Repository

Agricultural self-sufficiency and pest resilience represent existential priorities across Sub-Saharan Africa. We interface with extbfCGSpace [2], the digital repository of the CGIAR consortium, hosting the research outputs of leading African agricultural centers:

• IITA (International Institute of Tropical Agriculture, Ibadan, Nigeria)

• ILRI (International Livestock Research Institute, Nairobi, Kenya & Addis Ababa, Ethiopia)

• AfricaRice (Bouaké, Côte d’Ivoire)

• ICRAF (World Agroforestry, Nairobi, Kenya)

We filter for documents possessing verified bitstreams, extracting extbf50,534 full-text agricultural manuals, pest diagnostic guides (e.g., Fall Armyworm, Cassava Mosaic), soil maps, and extension treatises.

## 2.3 Pillar 3: African STEM & AI Preprints (arXiv)

To capture high-velocity computational and physical science outputs, we analyze the entire 3.19-million-paper historical snapshot of arXiv. We isolate preprints meeting two criteria: (1) topical and keyword focus on African systems, languages, or geographic contexts, and (2) institutional affiliations situated within African universities. This yields extbf42,530 full-text preprints. Crucially, natural language processing (cs.CL) represents the single largest computational category (1,066 papers), capturing seminal foundational works on low-resource African speech, translation, and language modeling [5, 6].

## 2.4 Pillar 4: Global African Scholar Open Access

The majority of high-impact research produced by African scholars is published in international peer-reviewed journals (e.g., Nature, PLOS ONE, Lancet, Springer, IEEE) rather than local presses. We utilize the OpenAlex open academic graph [7] to query the global scholarly record for open-access works whose author affiliations originate from African institutions (institutions.continent:africa, has\_pdf\_url:true). We indexed a master catalog of extbf1,517,281 unique African papers with direct, validated PDF URLs, which are ingested through our streaming pipeline.

## 3 Data Engineering Pipeline

Harvesting, validating, and converting hundreds of thousands of academic PDFs over the open internet presents formidable distributed systems and data engineering challenges. We implemented an autonomous, storage-conscious pipeline on remote NVIDIA H200 GPU infrastructure.

## 3.1 Cross-Source Multi-Key Deduplication

Because researchers routinely deposit preprints on arXiv, publish the final version in an academic journal, and upload institutional post-prints to CGSpace, naive aggregation leads to severe data contamination. We built an in-memory deduplication engine performing four sequential verifications:

1. Canonical DOI Normalization: Stripping protocol prefixes and trailing characters, matching against 235,461 known DOIs.

2. Title Slug Normalization: Stripping punctuation, whitespace, and diacritics, matching against 310,760 unique title hashes.

3. Repository Handle Matching: Cross-referencing persistent DSpace and arXiv handles.

4. Binary Hash Verification: Generating SHA-256 signatures for downloaded byte streams.

In our live benchmark, this engine executes over extbf2,013,298 lookups per second in sub-microseconds, discarding 145,421 duplicates before any file write occurs.

## 3.2 Layout-Aware Markdown Extraction

Traditional PDF text extractors collapse multi-column text horizontally, interleaving alternating columns into incoherent strings. We employ PyMuPDF layout analysis configured with

<table><tr><td>Academic Domain</td><td>Papers</td><td>Share</td><td>Representative Subject Areas</td></tr><tr><td>Social Sciences &amp; Economics</td><td>205,772</td><td>24.4%</td><td>African macroeconomics, monetary policy, education, public administration, governance</td></tr><tr><td>Medicine &amp; Public Health</td><td>198,240</td><td>23.5%</td><td>Tropical epidemiology, clinical surgery, malaria, maternal care, infectious diseases</td></tr><tr><td>Agriculture &amp; Food Security</td><td>152,027</td><td>18.0%</td><td>Crop protection, soil fertility, agronomy, CGIAR field manuals, smallholder farming</td></tr><tr><td>Engineering &amp; Earth Sciences</td><td>125,140</td><td>14.8%</td><td>Mineral extraction, hydrology, renewable energy, materials science, environmental geology</td></tr><tr><td>Computer Science &amp; AI</td><td>80,020</td><td>9.5%</td><td>African NLP, speech translation models, machine learning, computer vision, robotics</td></tr><tr><td>Humanities &amp; Literature</td><td>48,471</td><td>5.7%</td><td>African linguistics, indigenous languages (Swahili, Yoruba, Hausa, Twi, Zulu), history</td></tr><tr><td>Physical Sciences &amp; Mathematics</td><td>27,305</td><td>3.2%</td><td>Astronomy (MeerKAT/SKA), pure and applied mathematics, theoretical physics, chemistry</td></tr><tr><td>Multidisciplinary / General Science</td><td>5,237</td><td>0.6%</td><td>General science, university research bulletins, multidisciplinary studies</td></tr><tr><td>Law &amp; Governance</td><td>2,595</td><td>0.3%</td><td>African customary law, human rights jurisprudence, constitu- tional governance</td></tr><tr><td>TOTAL (Audited Corpus)</td><td>844,807</td><td>100.0%</td><td>10.15 Billion Tokens across 879 Parquet Shards</td></tr></table>

Table 1: Domain taxonomy and volume distribution in Africa-Papers. Audited across all 879 Parquet shards currently live on the Hugging Face Hub.

non-blocking vector parameters (ignore\_images=True, ignore\_graphics=True, graphics\_limit=200) and native block ordering:

• Column boundaries are respected, extracting Column 1 topto-bottom prior to Column 2.

• Heading hierarchies (#, ##) are derived from font weight and scale.

• Tables are parsed into standardized Markdown tabular syntax (|--|--|).

• Running headers, footers, and page numbers are dynamically identified and stripped via regular expression filters.

## 3.3 Stream-to-Parquet & Zero-Disk-Bloat Architecture

Storing 1.75 million raw PDF binaries on disk would require over 2.6 Terabytes of NVMe volume space. To operate sustainably, we architected a extbfStream-to-Parquet pipeline:

1. The PDF is streamed directly into an isolated temporary buffer on high-capacity scratch storage (/mnt/volume\_d2wey28/tmp).

2. The text is parsed, cleaned, and verified for digital content fidelity (> 150 characters).

3. The bulky raw PDF is instantly deleted.

4. The clean Markdown text, metadata frontmatter, and BPE token counts are buffered into memory.

5. At exactly 2,000 papers, the batch is flushed to a compressed Parquet shard using zstd compression.

Because clean Markdown in compressed Parquet is extbf35x smaller than raw PDF binaries, the entire 1.75-million-paper corpus requires only ∼55 Gigabytes of disk storage.

![](images/b18a8254b7dd20b344773698309834a5a514cb9f363b64e74bea908ad797cfa3.jpg)  
Figure 1: Representative Markdown sample in Africa-Papers. Each sample contains structured metadata frontmatter, followed by clean, linear section bodies ready for autoregressive modeling.

## 4 Corpus Characteristics & Analysis

## 4.1 Domain Distribution

As detailed in Table 1, Africa-Papers covers eight standardized academic domains:

• Medicine & Public Health (23.9%): Represents the largest single domain (188k papers), providing dense coverage of tropical medicine, clinical epidemiology, maternal health, and infectious disease management across sub-Saharan district health centers.

• Social Sciences & Economics (23.1%): Encompasses 182k papers addressing African macroeconomic modeling, regional currency dynamics, trade integration, customary institutions, and educational policy.

• Agriculture & Food Security (18.4%): Contains 145k papers and manuals detailing cassava brown streak disease, fall armyworm mitigation, soil nutrient mapping, and agropastoral systems.

• Engineering & Earth Sciences (15.0%): Captures 118k papers on hydrological modeling, artisanal and industrial mining geology, and renewable grid integration.

• Computer Science & AI (9.7%): Features 76k papers, including state-of-the-art African NLP, speech synthesis for tonal languages, and computer vision for crop diagnostics.

## 4.2 Tokenization & Quantitative Scale

We compute exact token statistics using OpenAI’s cl100k\_base byte-pair encoding (BPE) tokenizer. Across our empirical validation sample of 100 random papers on H200 compute:

• Average Paper Length: 20.2 pages (7,745 words).

• Mean Token Count per Paper: 17,214 tokens.

• Median Token Count per Paper: 11,536 tokens.

• Live Corpus Volume: extbf10.15 Billion tokens across 879 Parquet shards (averaging 35–45 MB per shard).

## 4.3 Linguistic Diversity

While scholarly reporting in STEM domains defaults predominantly to English, Africa-Papers exhibits substantial multilingual diversity. The DOAJ and OpenAlex streams capture significant corpora in extbfFrench (predominant across Senegal, Côte d’Ivoire, Cameroon, and Mali), extbfArabic (extensively represented across Egypt, Algeria, Morocco, and Tunisia), and extbfPortuguese (Angola and Mozambique). Furthermore, thousands of CGSpace farmer leaflets and arXiv speech papers feature parallel text in indigenous African languages, including extbfSwahili, Yoruba, Hausa, Amharic, Twi, and Zulu.

## 5 Continual Pre-Training & Evaluation

To validate the utility of Africa-Papers, we outline experimental protocols for Continual Pre-Training (CPT) of open-weights foundation models (e.g., Llama-3-8B and Qwen-2.5-7B).

## 5.1 Pre-Training Configuration

During domain-adaptive continual pre-training, models are trained on sequence lengths of 8,192 tokens using token packing. Because the median paper length in Africa-Papers is 11,536 tokens, individual papers fit naturally within 1 to 2 packed context windows, preserving long-range cross-section reasoning and bibliography citations without artificial chunk fragmentation.

## 5.2 Target Evaluation Benchmarks

We evaluate domain competence across three specialized benchmarks:

1. African Medical Diagnostic Reasoning: Testing zero-shot and few-shot diagnostic accuracy on tropical clinical case studies where Western-trained baselines frequently recommend inapplicable interventions.

2. Tropical Agro-Ecological QA: Evaluating recommendations for smallholder crop disease management and soil amendment against verified CGIAR protocols.

3. African NLP & Linguistic Benchmarks: Measuring downstream performance on AfriSenti, AfriQA [6], and lowresource African machine translation [5].

## 6 Ethical Considerations & Open Access

All publications included in Africa-Papers are harvested strictly from verified open-access channels under permissive licensing (predominantly Creative Commons Attribution, CC BY 4.0). Every sample retains full bibliographic attribution, including author names, institutional affiliations, original publisher, and canonical DOI links. By providing structured domain partitions, we ensure researchers can filter or subset data according to institutional review standards.

## 7 Conclusion

Africa-Papers addresses one of the most critical representation divides in modern artificial intelligence. By assembling extbf844,807 full-text papers and extbf10.15 billion tokens into a clean, layout-aware Markdown corpus, we provide the global AI community with the foundational data necessary to train models that understand and respect African scientific, medical, and agricultural knowledge. The complete corpus is available for research on Hugging Face at https://huggingface. co/datasets/AfriSpeech/africa-papers.

## References

[1] T. Adeyemi, K. Boateng, and M.-S. Owusu. Evaluating Language Models on African Biomedical Realities: Bench mark and Diagnostic Evaluation. Transactions on Machine Learningfor Health, 2024.

[2] CGIAR Consortium. CGSpace: A Repository of Agricultural Research Outputs. https://cgspace.cgiar. org/, 2024.

[3] Leo Gao, Stella Biderman, Sid Black, Laurence Golding, Travis Hoppe, Charles Foster, Jason Phang, Horace He, Anish Thite, Noa Nabeshima, et al. The Pile: An 800GB Dataset of Diverse Text for Language Modeling. arXiv preprint arXiv:2101.00027, 2020.

[4] Infrastructure Services for Open Access. Directory of Open Access Journals (DOAJ). https://doaj.org/, 2024.

[5] Wilhelmina Nekoto, Vukosi Marivate, Tshinndiwa Matsila, Timi Fasubaa, Taiwo Fagbohungbe, Solomon Oluwole Akinola, Shamsuddeen Muhammad, Salomon Kabongo, Salomey Osei, Freshia Sackey, et al. Participatory Research for Low-resourced Machine Translation: A Case Study in African Languages. Findings of the Association for Computational Linguistics: EMNLP 2020, pages 2144–2160, 2020.

[6] Odunayo Ogundepo, Mofetoluwa Adeyemi, Sebastian Gehrmann, Anuoluwapo Aremu, Iroro Olatunji, et al. AfriQA: Cross-lingual Open-Retrieval Question Answering for African Languages. Transactions of the Association for Computational Linguistics, 11:1299–1317, 2023.

[7] Jason Priem, Heather Piwowar, and Richard Orr. OpenAlex: A fully-open index of scholarly works, authors, venues, institutions, and concepts. arXiv preprint arXiv:2205.01833, 2022.

[8] Luca Soldaini, Rodney Kinney, Akshita Bhagia, Dustin Schwenk, David Atkinson, Russell Authur, Ben Bogin, Khyathi Chandu, Caio Dumas, Yanai Elazar, et al. Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research. arXiv preprint arXiv:2402.00159, 2024.

[9] Hugo Touvron, Louis Martin, Kevin Stone, Peter Albert, Amjad Almahairi, Yasmine Babaei, Nikolay Bashlykov, Soumya Batra, Prajjwal Bhargava, Shruti Bhosale, et al. Llama 2: Open Foundation and Fine-Tuned Chat Models. arXiv preprint arXiv:2307.09288, 2023.