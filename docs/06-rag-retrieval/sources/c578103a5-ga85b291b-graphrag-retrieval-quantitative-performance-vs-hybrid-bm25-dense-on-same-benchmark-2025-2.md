[ ![logo](https://services.dev.arxiv.org/html/static/arxiv-logomark-small-white.svg) Back to arXiv ](https://arxiv.org/)
[ ](https://arxiv.org/abs/2506.22644) [ ](javascript:toggleColorScheme\(\) "Toggle dark/light mode")
[ ![logo](https://services.dev.arxiv.org/html/static/arxiv-logo-one-color-white.svg) Back to arXiv ](https://arxiv.org/)
This is **experimental HTML** to improve accessibility. We invite you to report rendering errors. Use Alt+Y to toggle on accessible reporting links and Alt+Shift+Y to toggle off. Learn more [about this project](https://info.arxiv.org/about/accessible_HTML.html) and [help improve conversions](https://info.arxiv.org/help/submit_latex_best_practices.html). 
[Why HTML?](https://info.arxiv.org/about/accessible_HTML.html) [Report Issue](/html/2506.22644v1/#myForm) [Back to Abstract](https://arxiv.org/abs/2506.22644v1) [Download PDF](https://arxiv.org/pdf/2506.22644v1) [ ](javascript:toggleColorScheme\(\) "Toggle dark/light mode")
## Table of Contents
  1. [ Abstract  ](https://arxiv.org/html/2506.22644#abstract "Abstract")
  2. [1 Introduction](https://arxiv.org/html/2506.22644v1#S1 "In Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
  3. [2 Methods](https://arxiv.org/html/2506.22644v1#S2 "In Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    1. [2.1 Data Generation](https://arxiv.org/html/2506.22644v1#S2.SS1 "In 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    2. [2.2 Retrieval Architecture](https://arxiv.org/html/2506.22644v1#S2.SS2 "In 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    3. [2.3 Answer Generation](https://arxiv.org/html/2506.22644v1#S2.SS3 "In 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
  4. [3 Experimental Results](https://arxiv.org/html/2506.22644v1#S3 "In Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    1. [3.1 Retrieval Performance Analysis](https://arxiv.org/html/2506.22644v1#S3.SS1 "In 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    2. [3.2 Generation Performance Analysis](https://arxiv.org/html/2506.22644v1#S3.SS2 "In 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    3. [3.3 Performance by Question, User Categories](https://arxiv.org/html/2506.22644v1#S3.SS3 "In 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    4. [3.4 LiveRAG Challenge Performance](https://arxiv.org/html/2506.22644v1#S3.SS4 "In 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
    5. [3.5 Limitations](https://arxiv.org/html/2506.22644v1#S3.SS5 "In 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
  5. [4 Conclusion](https://arxiv.org/html/2506.22644v1#S4 "In Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")
  6. [ References  ](https://arxiv.org/html/2506.22644#bib "References")


HTML conversions [sometimes display errors](https://info.dev.arxiv.org/about/accessibility_html_error_messages.html) due to content that did not convert correctly from the source. This paper uses the following packages that are not yet supported by the HTML conversion tool. Feedback on these issues are not necessary; they are known and are being worked on.
  * failed: fvextra


Authors: achieve the best HTML results from your LaTeX submissions by following these [best practices](https://info.arxiv.org/help/submit_latex_best_practices.html).
[License: CC BY 4.0](https://info.arxiv.org/help/license/index.html#licenses-available)
arXiv:2506.22644v1 [cs.CL] 27 Jun 2025
# Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge
Report issue for preceding element
Chase Fensore††\dagger†, Kaustubh Dhole††\dagger†, Joyce Ho∗, Eugene Agichtein∗ Emory University, USA cfensore, kdhole@emory.edu
Report issue for preceding element
(2025)
###### Abstract.
Report issue for preceding element
We present our submission to the LiveRAG Challenge 2025, which evaluates retrieval-augmented generation (RAG) systems on dynamic test sets using the FineWeb-10BT corpus. Our final hybrid approach combines sparse (BM25) and dense (E5) retrieval methods and then aims to generate relevant and faithful answers with Falcon3-10B-Instruct. Through systematic evaluation on 200 synthetic questions generated with DataMorgana across 64 unique question-user combinations, we demonstrate that neural re-ranking with RankLLaMA improves MAP from 0.523 to 0.797 (52% relative improvement) but introduces prohibitive computational costs (84s vs 1.74s per question). While DSPy-optimized prompting strategies achieved higher semantic similarity (0.771 vs 0.668), their 0% refusal rates raised concerns about over-confidence and generalizability. Our submitted hybrid system without re-ranking achieved 4th place in faithfulness and 11th place in correctness among 25 teams. Analysis across question categories reveals that vocabulary alignment between questions and documents was the strongest predictor of performance on our development set, with document-similar phrasing improving cosine similarity from 0.562 to 0.762.
Report issue for preceding element
††copyright: none††journalyear: 2025††copyright: None
##  1. Introduction
Report issue for preceding element
The LiveRAG Challenge 2025 presents a unique evaluation framework for retrieval augmented generation (RAG) systems using dynamic test sets that capture the evolving nature of real-world information needs. Unlike traditional static benchmarks, this challenge evaluates systems on their ability to handle diverse question types, user expertise levels, and rapidly changing information landscapes using the FineWeb-10BT corpus (Penedo et al., [2024](https://arxiv.org/html/2506.22644v1#bib.bib11)).
Report issue for preceding element
Our approach focuses on developing a hybrid retrieval system that combines the complementary strengths of sparse and dense retrieval methods. Sparse retrieval excels at exact term matching and handling specific factual queries, while dense retrieval captures semantic similarity and contextual understanding. By combining these approaches and exploring document reformulation, neural re-ranking, and prompt optimization, we ultimately aimed to maximize correctness and faithfulness of our RAG system’s responses on the unseen LiveRAG Challenge Day test set.
Report issue for preceding element
The key contributions of our work include: (1) a systematic evaluation of hybrid retrieval strategies on synthetic dataset we generated with the DataMorgana tool (Filice et al., [2025](https://arxiv.org/html/2506.22644v1#bib.bib3)) that mirrors real-world QA diversity, (2) analysis of performance across different question and user categories as defined by DataMorgana, (3) demonstration of the effectiveness of neural re-ranking in improving RAG system performance, which also comes at high computational cost, and (4) insights into trade-offs between development set optimization and real-world robustness through DSPy (Khattab et al., [2023](https://arxiv.org/html/2506.22644v1#bib.bib4)) prompt optimization experiments.
Report issue for preceding element
This paper is organized as follows: In Section [2](https://arxiv.org/html/2506.22644v1#S2 "2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge"), we first describe our retrieval and RAG pipeline in detail. In Section [3](https://arxiv.org/html/2506.22644v1#S3 "3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge"), we demonstrate our experiments and discuss our results.
Report issue for preceding element
##  2. Methods
Report issue for preceding element
We now describe our baseline experiments carried out to inform the development of our final RAG system.
Report issue for preceding element
###  2.1. Data Generation
Report issue for preceding element
We utilized DataMorgana to create a development QA dataset (n=200) that reflects the diversity expected in real-world RAG applications. Our synthetic dataset incorporated multiple question categories and user categorizations, to simulate up to 64 unique combinations of RAG QA settings.   
Question Categories: We used four question categorizations consistent with those introduced by DataMorgana: (Filice et al., [2025](https://arxiv.org/html/2506.22644v1#bib.bib3))
Report issue for preceding element
  1. (1)
Question Factuality: Balancing factoid questions (50%) seeking specific information with open-ended questions (50%) encouraging detailed responses
Report issue for preceding element
  2. (2)
Question Premise: Including direct questions (50%) without user context and premise-based questions (50%) where users provide relevant background
Report issue for preceding element
  3. (3)
Question Phrasing: Covering concise natural questions (25%), verbose natural questions (25%), short search queries (25%), and long search queries (25%)
Report issue for preceding element
  4. (4)
Question Linguistic Variation: Distinguishing between questions using document-similar terminology (50%) and document-distant phrasing (50%)
Report issue for preceding element


User Categories: We focused on User Expertise categories, with expert users (80%) asking complex questions and novice users (20%) asking basic questions.
Report issue for preceding element
###  2.2. Retrieval Architecture
Report issue for preceding element
Documents were first split into 512 token chunks with a sentence-aware splitter. For the initial stage of retrieval, we explored three retrieval strategies:
Report issue for preceding element
  1. (1)
Sparse Retrieval: OpenSearch BM25 based index. k=30 documents
Report issue for preceding element
  2. (2)
Dense Retrieval: Pinecone with E5 embeddings (`intfloat/`   
`e5-base-v2`, size 768) and cosine similarity for retrieval. k=30 documents
Report issue for preceding element
  3. (3)
Hybrid Retrieval: Combined sparse and dense retrieval (k=30 each), selecting top 10 documents based on normalized score fusion (Lee, [1995](https://arxiv.org/html/2506.22644v1#bib.bib5))
Report issue for preceding element


Document Reformulation   
We explored doc2query-enhanced sparse indexing (Nogueira et al., [2019](https://arxiv.org/html/2506.22644v1#bib.bib8)), where documents were augmented with generated questions to improve retrieval coverage. We created a custom doc2query-enhanced sparse BM25 index, using 512 token chunks similar to the OpenSearch BM25 index. When using this index, the top 30 documents were retrieved and included in the final prompt. However, this doc2query approach showed limited effectiveness in our experiments.
Report issue for preceding element
Generative Re-ranking   
We employed RankLLaMA-7B (`castorini/rankllama`   
`-v1-7b-lora-passage`) (Ma et al., [2024](https://arxiv.org/html/2506.22644v1#bib.bib7)) for pointwise re-ranking of the top k retrieved passages — this means that the a given retrieved passage is assigned a score by the generative re-ranker independently of all other retrieved passages. Pointwise re-rankers have shown improved retrieval effectiveness in many tasks and are more robust compared to other approaches like listwise.
Report issue for preceding element
To do this, the re-ranker uses the prompt structure from the `pyterrier_genrank` package (Dhole, [2024](https://arxiv.org/html/2506.22644v1#bib.bib2)), where each prompt contains exactly one query and one passage (Figure [1](https://arxiv.org/html/2506.22644v1#S2.F1 "Figure 1 ‣ 2.2. Retrieval Architecture ‣ 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")).
Report issue for preceding element
Report issue for preceding element Report issue for preceding element
Query: {query} Passage: {passage}
Report issue for preceding element Report issue for preceding element Report issue for preceding element
Figure 1. Pointwise Re-ranking Prompt Report issue for preceding element
###  2.3. Answer Generation
Report issue for preceding element
We used the ` Falcon3-10B-Instruct `(Team, [2024](https://arxiv.org/html/2506.22644v1#bib.bib15)) model for answer generation with temperature=0.6 and top_p=0.9. We performed manual prompt engineering and arrived at a base prompt aimed to emphasize conciseness and faithfulness (Figure [2](https://arxiv.org/html/2506.22644v1#S2.F2 "Figure 2 ‣ 2.3. Answer Generation ‣ 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")).
Report issue for preceding element
Report issue for preceding element Report issue for preceding element
"""You are an AI assistant tasked with answering questions based on the provided information.
Report issue for preceding element Report issue for preceding element
Information:
Report issue for preceding element
context as k chunks/documents
Report issue for preceding element Report issue for preceding element
Question: query
Report issue for preceding element Report issue for preceding element
Answer the question based only on the provided information. Keep the answer concise, limited to 200 tokens. If the information doesn’t contain the answer, say "I don’t have enough information to answer this question."
Report issue for preceding element Report issue for preceding element
Answer:"""
Report issue for preceding element Report issue for preceding element Report issue for preceding element
Figure 2. Answer Generation Prompt Report issue for preceding element
Few-shot and Chain-of-Thought (CoT) approaches were also explored via ` DSPy ` (Khattab et al., [2023](https://arxiv.org/html/2506.22644v1#bib.bib4)). For few-shot prompting using DSPy, we used a 160/40 train/validation split of our synthetic dataset. Answers were scored during prompt optimization with question similarity measured by MiniLM.111<https://huggingface.co/sentence-transformers/all-MiniLM-L6-v2> MIPROv2 and BootstrapFewShot optimizers were studied for CoT and few-shot respectively. For CoT prompting, we explored MIPROv2 to optimize the reasoning instructions and step-by-step decomposition structure, producing prompts that aim to explicitly guide the model through Context → Question → Reasoning → Answer sequences. BootstrapFewShot automatically curates high-quality demonstrations by bootstrapping examples from our training set, selecting demonstrations that maximize performance on our evaluation metric. This technique generates few-shot prompts containing up to four optimally chosen examples that are most representative of successful question-answering patterns in our domain. The optimization process operates on a subset of our 200-question synthetic dataset, using an 80/20 train-dev split with cross-validation. The resulting optimized prompt templates are serialized as JSON configurations and integrated into our generation pipeline, allowing dynamic selection between default prompting, DSPy-optimized CoT reasoning, and DSPy-optimized few-shot demonstration strategies.
Report issue for preceding element
##  3. Experimental Results
Report issue for preceding element
###  3.1. Retrieval Performance Analysis
Report issue for preceding element
Table [1](https://arxiv.org/html/2506.22644v1#S3.T1 "Table 1 ‣ 3.1. Retrieval Performance Analysis ‣ 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge") presents our retrieval, document reformulation, and re-ranking results on our DataMorgana synthetic dataset. The hybrid approach matches sparse retrieval performance in most metrics, suggesting that the dense component provides complementary rather than additive benefits. However, the combination creates a more robust foundation for re-ranking and shows stronger downstream answer generation performance (Table [2](https://arxiv.org/html/2506.22644v1#S3.T2 "Table 2 ‣ 3.2. Generation Performance Analysis ‣ 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")). The most significant finding is the substantial improvement achieved by neural re-ranking. RankLLaMA re-ranking improved MAP from 0.523 using Hybrid to 0.797, representing a 52% relative improvement. Interestingly, doc2query enhancement performed poorly across all retrieval metrics, possibly due to the domain mismatch between the enhancement model’s training data and the FineWeb-10BT corpus characteristics. Despite the impressive retrieval and generation performance boost from including RankLLaMA, this approach was computationally expensive (~84 seconds/question). Applying this solution to the 500-question test set on LiveRAG Challenge Day would have been infeasible as there was a 2 hour window to generate answers, and this generative re-ranking strategy would have required ~12 hours. As a result, we opted to use the hybrid retrieval approach for the LiveRAG Challenge Day, as it gave the second strongest retrieval and downstream generation performance on our development question set while maintaining low computational overhead (~1.74 seconds/question). 
Report issue for preceding element
Table 1. Baseline retrieval, re-ranking results on DataMorgana synthetic QA dataset (n=200). Bold denotes best, underline denotes second best. Time indicates the mean time required for retrieval and generation, in seconds.  
| Name  | MAP  | Recip. Rank  | nDCG@10  | Recall@1  | Recall@10  | Prec@1  | Prec@10  | Time (s)  |  
| --- | --- | --- | --- | --- | --- | --- | --- | --- |  
| Sparse (OpenSearch BM25)  | .523  | .347  | .497  | .285  | .485  | .285  | .074  | 1.57  |  
| Dense (Pinecone E5)  | .352  | .260  | .367  | .190  | .435  | .190  | .058  | 1.56  |  
| Hybrid  | .523  | .347  | .497  | .285  | .485  | .285  | .074  | 1.74  |  
| Hybrid →→\rightarrow→ RankLLaMA  | .797  | .422  | .710  | .340  | .590  | .340  | .116  | 84.37  |  
| doc2query+BM25  | .321  | .321  | .353  | .275  | .455  | .275  | .046  | 2.93  |  
Report issue for preceding element
###  3.2. Generation Performance Analysis
Report issue for preceding element
Table [2](https://arxiv.org/html/2506.22644v1#S3.T2 "Table 2 ‣ 3.2. Generation Performance Analysis ‣ 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge") shows the automatic evaluation of generated answers across different retrieval strategies. We used multiple metrics to capture different aspects of answer quality: ROUGE scores for measuring n-gram recall (Lin, [2004](https://arxiv.org/html/2506.22644v1#bib.bib6)), BLEU for precision-oriented matching (Papineni et al., [2002](https://arxiv.org/html/2506.22644v1#bib.bib10)), cosine similarity of MiniLM embeddings[1](https://arxiv.org/html/2506.22644v1#footnote1 "footnote 1 ‣ 2.3. Answer Generation ‣ 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge") to measure semantic match. We also measure the refusal rate to measure system reliability, by comparing whether the answer contains any of a set of refusal responses like “not enough information.”
Report issue for preceding element
Table 2. Generation evaluation on DataMorgana synthetic QA dataset (n=200). Semantic similarity was calculated with cosine similarity of embeddings from MiniLM-L6-v2. Bold denotes best, underline denotes second best.  
| Name  | ROUGE-1  | ROUGE-L  | BLEU  | Cos. Sim.  | % Refusal (↓↓\downarrow↓)  |  
| --- | --- | --- | --- | --- | --- |  
| Retrieval  |   |   |   |   |   |  
| Sparse  | .366  | .276  | .115  | .659  | 17.50%  |  
| Dense  | .337  | .244  | .079  | .668  | 15.00%  |  
| Hybrid  | .368  | .279  | .117  | .668  | 17.00%  |  
| Re-ranking  |   |   |   |   |   |  
| Hybrid →→\rightarrow→ RankLLaMA  | .403  | .307  | .123  | .754  |  3.50%  |  
| Document Reformulation  |   |   |   |   |   |  
| doc2query+BM25  | .337  | .247  | .088  | .641  | 19.50%  |  
| Prompting  |   |   |   |   |   |  
| Few-shot (w/ Hybrid)  | .368  | .266  | .106  | .771  |  0.00%  |  
| CoT (w/ Hybrid)  | .358  | .255  | .096  | .756  |  0.00%  |  
Report issue for preceding element
Our re-ranker-based hybrid approach consistently outperforms all other methods across all metrics. Most notably, the refusal rate drops from 17% to 3.5%, indicating that better retrieval quality leads to more confident and more accurate answer generation, at least according to automatic evaluation. The cosine similarity improvement from 0.668 to 0.754 suggests that re-ranking helps surface semantically relevant content that better supports accurate answer generation. Hybrid retrieval also showed strong generation performance with the second highest ROUGE-1, ROUGE-L, and BLEU.
Report issue for preceding element
Advanced Prompting Analysis   
The DSPy-optimized prompting strategies show interesting but concerning patterns. Few-shot prompting achieved the highest semantic similarity (0.771 cosine similarity) and CoT prompting showed strong performance (0.756), both significantly outperforming our hybrid approach with a manually crafted prompt (0.668). However, both advanced prompting methods exhibit 0% refusal rates, indicating potential over-confidence that could be problematic for generalization.
Report issue for preceding element
While the improved semantic similarity suggests these methods generate more semantically coherent responses on our development set, the complete absence of refusal responses raised concerns about calibration and robustness. In RAG systems, appropriate refusal when information is insufficient is crucial for maintaining trustworthiness, especially given the LiveRAG Challenge criteria scoring for incorrect answers vs refusals. The 0% refusal rate suggests these optimized prompts may be generating confident but potentially incorrect responses when faced with insufficient context.
Report issue for preceding element
This over-optimization phenomenon aligns with known challenges in prompt optimization, where methods can achieve high performance on development metrics while degrading real-world robustness (Opsahl-Ong et al., [2024](https://arxiv.org/html/2506.22644v1#bib.bib9); Soylu et al., [2024](https://arxiv.org/html/2506.22644v1#bib.bib13)). Given these concerns about generalizability, we opted to use our conservative baseline prompting strategy for the LiveRAG Challenge submission (Figure [2](https://arxiv.org/html/2506.22644v1#S2.F2 "Figure 2 ‣ 2.3. Answer Generation ‣ 2. Methods ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge")), which maintains appropriate refusal behavior while achieving strong faithfulness rankings.
Report issue for preceding element
###  3.3. Performance by Question, User Categories
Report issue for preceding element
Table [3](https://arxiv.org/html/2506.22644v1#S3.T3 "Table 3 ‣ 3.3. Performance by Question, User Categories ‣ 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge") analyzes generation performance stratified by DataMorgana’s question and user categories using our best-performing hybrid approach without re-ranking. Based on Table [3](https://arxiv.org/html/2506.22644v1#S3.T3 "Table 3 ‣ 3.3. Performance by Question, User Categories ‣ 3. Experimental Results ‣ Evaluating Hybrid Retrieval Augmented Generation using Dynamic Test Sets: LiveRAG Challenge"), we observe significant performance variations across question and user categories using our hybrid retrieval approach.
Report issue for preceding element
Question Characteristics: Factoid questions substantially outperform open-ended questions (ROUGE-1: 0.407 vs 0.332, BLEU: 0.162 vs 0.075), confirming that the system excels at extracting specific information but struggles with comprehensive explanatory responses. Direct questions slightly outperform premise-based questions in semantic quality (0.683 vs 0.652 cosine similarity) with lower refusal rates (14.7% vs 19.4%).
Report issue for preceding element
Phrasing Impact: Natural language formulations significantly outperform search query formats. Verbose natural questions achieve the highest semantic similarity (0.739) and lowest refusal rate (8.9%), while short search queries perform poorly across metrics (0.567 cosine similarity, 26.1% refusal rate). This demonstrates clear sensitivity to query formulation quality.
Report issue for preceding element
Vocabulary Alignment: The most pronounced performance gap occurs between questions using document-similar versus distant terminology. Similar phrasing substantially improves performance (ROUGE-1: 0.431 vs 0.296, cosine similarity: 0.762 vs 0.562), with refusal rates dropping from 25.5% to 9.4%. This highlights vocabulary matching as a critical factor in RAG effectiveness.
Report issue for preceding element
User Expertise: Our system consistently outperforms on expert-level questions relative to novice questions (cosine similarity: 0.709 vs 0.628), likely reflecting the more precise, focused formulations and vocabulary present in expert-level questions.
Report issue for preceding element
Extreme Case Analysis: Looking at combinations of question and user characteristics, the primary differentiators for performance of our hybrid RAG system were Question Premise (↑↑\uparrow↑ direct, ↓↓\downarrow↓ with-premise) and Question Phrasing (↑↑\uparrow↑ concise+natural, ↓↓\downarrow↓ short search query). These sets of the best and worst performing question clusters had identical settings for all other characteristics: Question Factuality (open-ended), Linguistic Variation (similar to document), and User Expertise (novice). Our best combination achieves 0.822 cosine similarity with zero refusal rate, while the worst combination shows 0.479 cosine similarity with 33.3% refusal rate.
Report issue for preceding element
Table 3. Breakdown of answer quality stratified by DataMorgana QA characteristics. Shows hybrid retrieval + basic prompting approach, for practicality. Bold indicates best performance, excluding best and worst combination rows.  
| Name (n)  | ROUGE-1  | ROUGE-L  | BLEU  | Cos. Sim.  | % Refusal (↓↓\downarrow↓)  |  
| --- | --- | --- | --- | --- | --- |  
| Question Category  |   |   |   |   |   |  
| Question Factuality  |   |   |   |   |   |  
| Factoid (96)  | .407  | .334  | .162  | .687  | 16.67%  |  
|  Open-ended (104)  | .332  | .229  | .075  | .651  | 17.30%  |  
| Question Premise  |   |   |   |   |   |  
|  Direct (102)  | .372  | .287  | .123  | .683  | 14.70%  |  
|  With-premise (98)  | .363  | .272  | .110  | .652  | 19.40%  |  
| Question Phrasing  |   |   |   |   |   |  
|  Concise, Natural (54)  | .370  | .304  | .127  | .674  | 18.50%  |  
|  Verbose, Natural (56)  | .414  | .298  | .135  | .739  | 8.90%  |  
|  Short Search Query (46)  | .312  | .233  | .084  | .567  | 26.10%  |  
|  Long Search Query (44)  | .365  | .274  | .114  | .677  | 15.90%  |  
| Linguistic Variation  |   |   |   |   |   |  
|  Similar to Document (106)  | .431  | .336  | .153  | .762  | 9.40%  |  
|  Distant from Document (94)  | .296  | .216  | .075  | .562  | 25.50%  |  
| User Category  |   |   |   |   |   |  
| User Expertise  |   |   |   |   |   |  
|  Novice (101)  | .336  | .252  | .099  | .628  | 20.8%  |  
|  Expert (99)  | .401  | .308  | .135  | .709  | 13.1%  |  
| Best Combination (5)  | .328  | .254  | .083  | .822  | 0.0%  |  
| Worst Combination (6)  | .259  | .174  | .037  | .479  | 33.3%  |  
Report issue for preceding element
###  3.4. LiveRAG Challenge Performance
Report issue for preceding element
In the preliminary LiveRAG Challenge evaluation on 500 unseen test questions, our hybrid RAG system achieved rankings of 11th place for correctness (11/25) and 4th place for faithfulness (4/25) among participating teams. The strong faithfulness ranking suggests that our emphasis on retrieval quality and conservative answer generation effectively grounded responses in the provided context, while the moderate correctness ranking indicates room for improvement in answer accuracy. The performance gap between faithfulness (4th) and correctness (11th) suggests our conservative prompting strategy successfully grounded responses in retrieved context but may have been overly cautious, leading to refusal responses for several questions. This aligns with our synthetic evaluation showing 17% refusal rates for the hybrid approach.
Report issue for preceding element
###  3.5. Limitations
Report issue for preceding element
Our approach has several limitations. First, the hybrid retrieval method showed minimal improvement over sparse retrieval alone, suggesting dense retrieval may not provide complementary benefits for this corpus. Second, our conservative answer generation strategy, while improving faithfulness, may have reduced correctness by refusing to answer questions with sufficient but not obvious evidence. Finally, because our experiments focused on time-consuming stages like prompt optimization with DSPy and generative re-ranking, we chose to use a relatively small development set (n=200) compared to the 10,000 DataMorgana credits allotted to teams. This small development set size may have limited our systems generalizability to the test set for the LiveRAG Challenge,
Report issue for preceding element
##  4. Conclusion
Report issue for preceding element
We presented a hybrid RAG approach combining sparse and dense retrieval for the LiveRAG Challenge 2025. Our systematic evaluation using DataMorgana’s 64 question-user combinations reveals that vocabulary alignment is the most critical factor for RAG performance, with neural re-ranking providing substantial improvements at prohibitive computational cost. While our submitted system achieved strong faithfulness rankings (4th/25), the moderate correctness performance (11th/25) highlights the tension between conservative and accurate answer generation.
Report issue for preceding element
Despite the strong performance of the generative re-ranker in our development process, we determined it was computationally infeasible for the competition timing constraints. Building computationally efficient generative re-rankers is an active area of study. Works like RankZephyr (Pradeep et al., [2023](https://arxiv.org/html/2506.22644v1#bib.bib12)) and RankGPT (Sun et al., [2024](https://arxiv.org/html/2506.22644v1#bib.bib14)) have studied listwise generative re-ranking for challenging queries requiring context from multiple passages, however listwise re-ranking is often slower than pointwise re-rankers. In addition to using batching to increasing feasibility of generative re-rankers in practice, we encourage future work to focus on strategies to increase efficiency of generative re-rankers like RankLLaMA, as they show strong performance in this general-purpose RAG QA task but are computationally costly.
Report issue for preceding element
Future work could also focus on adaptive retrieval strategies that adjust computational overhead based on question complexity, and more sophisticated answer generation that balances faithfulness with completeness. The substantial performance variations across question categories (0.479 to 0.822 cosine similarity) suggest that question-aware system design could yield significant improvements.
Report issue for preceding element
## References
Report issue for preceding element
  * (1)↑
  * Dhole (2024)↑ Kaustubh Dhole. 2024.  _PyTerrier-GenRank: The PyTerrier Plugin for Reranking with Large Language Models_.  <https://github.com/emory-irlab/pyterrier_genrank>
  * Filice et al. (2025)↑ Simone Filice, Guy Horowitz, David Carmel, Zohar Karnin, Liane Lewin-Eytan, and Yoelle Maarek. 2025.  Generating Diverse Q&A Benchmarks for RAG Evaluation with DataMorgana.  [doi:10.48550/arXiv.2501.12789](https://doi.org/10.48550/arXiv.2501.12789) arXiv:2501.12789 [cs] 
  * Khattab et al. (2023)↑ Omar Khattab, Arnav Singhvi, Paridhi Maheshwari, Zhiyuan Zhang, Keshav Santhanam, Sri Vardhamanan, Saiful Haq, Ashutosh Sharma, Thomas T. Joshi, Hanna Moazam, Heather Miller, Matei Zaharia, and Christopher Potts. 2023.  DSPy: Compiling Declarative Language Model Calls into Self-Improving Pipelines.  [doi:10.48550/arXiv.2310.03714](https://doi.org/10.48550/arXiv.2310.03714) arXiv:2310.03714 [cs] 
  * Lee (1995)↑ Joon Ho Lee. 1995.  Combining multiple evidence from different properties of weighting schemes. In _Proceedings of the 18th annual international ACM SIGIR conference on Research and development in information retrieval_ _(SIGIR ’95)_. Association for Computing Machinery, New York, NY, USA, 180–188.  [doi:10.1145/215206.215358](https://doi.org/10.1145/215206.215358)
  * Lin (2004)↑ Chin-Yew Lin. 2004.  Rouge: A package for automatic evaluation of summaries. In _Text summarization branches out_. 74–81. 
  * Ma et al. (2024)↑ Xueguang Ma, Liang Wang, Nan Yang, Furu Wei, and Jimmy Lin. 2024.  Fine-Tuning LLaMA for Multi-Stage Text Retrieval. In _Proceedings of the 47th International ACM SIGIR Conference on Research and Development in Information Retrieval_ _(SIGIR 2024)_. ACM, 2421–2425.  [doi:10.1145/3626772.3657951](https://doi.org/10.1145/3626772.3657951)
  * Nogueira et al. (2019)↑ Rodrigo Nogueira, Wei Yang, Jimmy Lin, and Kyunghyun Cho. 2019.  Document expansion by query prediction.  _arXiv preprint arXiv:1904.08375_ (2019). 
  * Opsahl-Ong et al. (2024)↑ Krista Opsahl-Ong, Michael J. Ryan, Josh Purtell, David Broman, Christopher Potts, Matei Zaharia, and Omar Khattab. 2024.  Optimizing Instructions and Demonstrations for Multi-Stage Language Model Programs.  [doi:10.48550/arXiv.2406.11695](https://doi.org/10.48550/arXiv.2406.11695) arXiv:2406.11695 [cs]. 
  * Papineni et al. (2002)↑ Kishore Papineni, Salim Roukos, Todd Ward, and Wei-Jing Zhu. 2002.  Bleu: a method for automatic evaluation of machine translation. In _Proceedings of the 40th annual meeting of the Association for Computational Linguistics_. 311–318. 
  * Penedo et al. (2024)↑ Guilherme Penedo, Hynek Kydlíček, Anton Lozhkov, Margaret Mitchell, Colin A Raffel, Leandro Von Werra, Thomas Wolf, et al. 2024.  The fineweb datasets: Decanting the web for the finest text data at scale.  _Advances in Neural Information Processing Systems_ 37 (2024), 30811–30849. 
  * Pradeep et al. (2023)↑ Ronak Pradeep, Sahel Sharifymoghaddam, and Jimmy Lin. 2023.  RankZephyr: Effective and Robust Zero-Shot Listwise Reranking is a Breeze!  [doi:10.48550/arXiv.2312.02724](https://doi.org/10.48550/arXiv.2312.02724) arXiv:2312.02724 [cs]. 
  * Soylu et al. (2024)↑ Dilara Soylu, Christopher Potts, and Omar Khattab. 2024.  Fine-Tuning and Prompt Optimization: Two Great Steps that Work Better Together.  [doi:10.48550/arXiv.2407.10930](https://doi.org/10.48550/arXiv.2407.10930) arXiv:2407.10930 [cs]. 
  * Sun et al. (2024)↑ Weiwei Sun, Lingyong Yan, Xinyu Ma, Shuaiqiang Wang, Pengjie Ren, Zhumin Chen, Dawei Yin, and Zhaochun Ren. 2024.  Is ChatGPT Good at Search? Investigating Large Language Models as Re-Ranking Agents.  [doi:10.48550/arXiv.2304.09542](https://doi.org/10.48550/arXiv.2304.09542) arXiv:2304.09542 [cs]. 
  * Team (2024)↑ Falcon-LLM Team. 2024.  The Falcon 3 Family of Open Models.  <https://huggingface.co/blog/falcon3>


Report Issue
##### Report GitHub Issue
Title:
Content selection saved. Describe the issue below:
Description:
Submit without GitHubSubmit in GitHub
Report Issue for Selection
Generated by [ L A T E xml ![\[LOGO\]](/html/2506.22644v1/) ](https://math.nist.gov/~BMiller/LaTeXML/)
## Instructions for reporting errors
We are continuing to improve HTML versions of papers, and your feedback helps enhance accessibility and mobile support. To report errors in the HTML that will help us improve conversion and rendering, choose any of the methods listed below:
  * Click the "Report Issue" button.
  * Open a report feedback form via keyboard, use "**Ctrl + ?** ".
  * Make a text selection and click the "Report Issue for Selection" button near your cursor.
  * You can use Alt+Y to toggle on and Alt+Shift+Y to toggle off accessible reporting links at each section.


Our team has already identified [the following issues](https://github.com/arXiv/html_feedback/issues). We appreciate your time reviewing and reporting rendering errors we may not have found yet. Your efforts will help us improve the HTML versions for all readers, because disability should not be a barrier to accessing research. Thank you for your continued support in championing open access for all.
Have a free development cycle? Help support accessibility at arXiv! Our collaborators at LaTeXML maintain a [list of packages that need conversion](https://github.com/brucemiller/LaTeXML/wiki/Porting-LaTeX-packages-for-LaTeXML), and welcome [developer contributions](https://github.com/brucemiller/LaTeXML/issues).

