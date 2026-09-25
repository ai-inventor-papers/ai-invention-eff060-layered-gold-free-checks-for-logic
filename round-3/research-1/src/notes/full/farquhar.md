URL: https://www.nature.com/articles/s41586-024-07421-0 | FULL FETCH | 2026-09-24T01:47:32Z
warning: The `fitz` API is deprecated and will be removed in future. Use `import pymupdf` instead.
URL: https://www.nature.com/articles/s41586-024-07421-0
Type: HTML
Length: 113759 chars (truncated)

--- Content ---

Skip to main content

Thank you for visiting nature.com. You are using a browser version with limited support for CSS. To obtain the best experience, we recommend you use a more up to date browser (or turn off compatibility mode in Internet Explorer). In the meantime, to ensure continued support, we are displaying the site without styles and JavaScript.

Advertisement

[ ](//pubads.g.doubleclick.net/gampad/jump?iu=/285/nature.com/article&sz=728x90&c=-22791442&t=pos%3Dtop%26type%3Darticle%26artid%3Ds41586-024-07421-0%26doi%3D10.1038/s41586-024-07421-0%26subjmeta%3D117,258,639,705%26kwrd%3DComputer+science,Information+technology)

[ ](/)

  * [ View all journals ](https://www.nature.com/siteindex)
  * [ Saved research ](/saved-research)
  * Search
  * [Log in](https://idp.nature.com/auth/personal/springernature?redirect_uri=https://www.nature.com/articles/s41586-024-07421-0)



  * Content Explore content
  * About the journal
  * Publish with us


  * [ Sign up for alerts ](https://journal-alerts.springernature.com/subscribe?journal_id=41586)
  * [ RSS feed ](https://www.nature.com/nature.rss)



  1. [nature](/)
  2. [articles](/nature/articles?type=article)
  3. article



Detecting hallucinations in large language models using semantic entropy 

[ Download PDF ](/articles/s41586-024-07421-0.pdf)

[ Download PDF ](/articles/s41586-024-07421-0.pdf)

  * Article
  * [Open access](https://www.springernature.com/gp/open-science/about/the-fundamentals-of-open-access-and-open-research)
  * Published: 19 June 2024



# Detecting hallucinations in large language models using semantic entropy

  * Sebastian Farquhar [ORCID: orcid.org/0000-0002-9185-6415](https://orcid.org/0000-0002-9185-6415)1 na1, 
  * Jannik Kossen1 na1, 
  * Lorenz Kuhn1 na1 &
  * …
  * Yarin Gal [ORCID: orcid.org/0000-0002-2733-2078](https://orcid.org/0000-0002-2733-2078)1

Show authors

[_Nature_](/) **volume 630**, pages 625–630 (2024) Cite this article

[ Save article ](/articles/s41586-024-07421-0/save-research?_csrf=h8URF1EQiljoUwce5-50vTDK_VDPWOZQ)

[ View saved research ](/saved-research)

  * 416k Accesses

  * 1160 Citations

  * 1661 Altmetric

  * [Metrics details](/articles/s41586-024-07421-0/metrics)




## Abstract

Large language model (LLM) systems, such as ChatGPT[1](/articles/s41586-024-07421-0#ref-CR1 "GPT-4 technical report. Preprint at 
                  https://arxiv.org/abs/2303.08774
                  
                 \(2023\).") or Gemini[2](/articles/s41586-024-07421-0#ref-CR2 "Gemini: a family of highly capable multimodal models. Preprint at 
                  https://arxiv.org/abs/2312.11805
                  
                 \(2023\)."), can show impressive reasoning and question-answering capabilities but often ‘hallucinate’ false outputs and unsubstantiated answers[3](/articles/s41586-024-07421-0#ref-CR3 "Xiao, Y. & Wang, W. Y. On hallucination and predictive uncertainty in conditional language generation. In Proc. 16th Conference of the European Chapter of the Association for Computational Linguistics 2734–2744 \(Association for Computational Linguistics, 2021\)."),[4](/articles/s41586-024-07421-0#ref-CR4 "Rohrbach, A., Hendricks, L. A., Burns, K., Darrell, T. & Saenko, K. Object hallucination in image captioning. In Proc. 2018 Conference on Empirical Methods in Natural Language Processing \(eds Riloff, E., Chiang, D., Hockenmaier, J. & Tsujii, J.\) 4035–4045 \(Association for Computational Linguistics, 2018\)."). Answering unreliably or without the necessary information prevents adoption in diverse fields, with problems including fabrication of legal precedents[5](/articles/s41586-024-07421-0#ref-CR5 "Weiser, B. Lawyer who used ChatGPT faces penalty for made up citations. The New York Times \(8 Jun 2023\).") or untrue facts in news articles[6](/articles/s41586-024-07421-0#ref-CR6 "Opdahl, A. L. et al. Trustworthy journalism through AI. Data Knowl. Eng. 146, 102182 \(2023\).") and even posing a risk to human life in medical domains such as radiology[7](/articles/s41586-024-07421-0#ref-CR7 "Shen, Y. et al. ChatGPT and other large language models are double-edged swords. Radiology 307, e230163 \(2023\)."). Encouraging truthfulness through supervision or reinforcement has been only partially successful[8](/articles/s41586-024-07421-0#ref-CR8 "Schulman, J. Reinforcement learning from human feedback: progress and challenges. Presented at the Berkeley EECS Colloquium. YouTube 
                  www.youtube.com/watch?v=hhiLw5Q_UFg
                  
                 \(2023\)."). Researchers need a general method for detecting hallucinations in LLMs that works even with new and unseen questions to which humans might not know the answer. Here we develop new methods grounded in statistics, proposing entropy-based uncertainty estimators for LLMs to detect a subset of hallucinations—confabulations—which are arbitrary and incorrect generations. Our method addresses the fact that one idea can be expressed in many ways by computing uncertainty at the level of meaning rather than specific sequences of words. Our method works across datasets and tasks without a priori knowledge of the task, requires no task-specific data and robustly generalizes to new tasks not seen before. By detecting when a prompt is likely to produce a confabulation, our method helps users understand when they must take extra care with LLMs and opens up new possibilities for using LLMs that are otherwise prevented by their unreliability.

### Similar content being viewed by others

###  [Factuality challenges in the era of large language models and opportunities for fact-checking ](https://www.nature.com/articles/s42256-024-00881-z?fromPaywallRec=false)

Article 22 August 2024

###  [Hallucination in Time-series Large Language Models: An empirical lnvestigation and analysis of mitigation strategies ](https://www.nature.com/articles/s41598-026-62952-y?fromPaywallRec=false)

Article Open access 21 July 2026

###  [Does ChatGPT need a psychiatrist? Similarities between human psychopathology and errors in large language models ](https://www.nature.com/articles/s44277-026-00064-1?fromPaywallRec=false)

Article Open access 10 June 2026

### Explore related subjects

Discover the latest articles and news in related subjects.

  * [Computer science](/subjects/computer-science)
  * [Information technology](/subjects/information-technology)



## Main

‘Hallucinations’ are a critical problem[9](/articles/s41586-024-07421-0#ref-CR9 "Ji, Z. et al. Survey of hallucination in natural language generation. ACM Comput. Surv.55, 248 \(2023\).") for natural language generation systems using large language models (LLMs), such as ChatGPT[1](/articles/s41586-024-07421-0#ref-CR1 "GPT-4 technical report. Preprint at 
                  https://arxiv.org/abs/2303.08774
                  
                 \(2023\).") or Gemini[2](/articles/s41586-024-07421-0#ref-CR2 "Gemini: a family of highly capable multimodal models. Preprint at 
                  https://arxiv.org/abs/2312.11805
                  
                 \(2023\)."), because users cannot trust that any given output is correct.

Hallucinations are often defined as LLMs generating “content that is nonsensical or unfaithful to the provided source content”9,10,[11](/articles/s41586-024-07421-0#ref-CR11 "Filippova, K. Controlled hallucinations: learning to generate faithfully from noisy data. In Findings of the Association for Computational Linguistics: EMNLP 2020 \(eds Webber, B., Cohn, T., He, Y. & Liu, Y.\) 864–870 \(Association for Computational Linguistics, 2020\).") but they have come to include a vast array of failures of faithfulness and factuality. We focus on a subset of hallucinations which we call ‘confabulations’[12](/articles/s41586-024-07421-0#ref-CR12 "Berrios, G. Confabulations: a conceptual history. J. Hist. Neurosci. 7, 225–241 \(1998\).") for which LLMs fluently make claims that are both wrong and arbitrary—by which we mean that the answer is sensitive to irrelevant details such as random seed. For example, when asked a medical question “What is the target of Sotorasib?” an LLM confabulates by sometimes answering KRASG12 ‘C’ (correct) and other times KRASG12 ‘D’ (incorrect) despite identical instructions. We distinguish this from cases in which a similar ‘symptom’ is caused by the following different mechanisms: when LLMs are consistently wrong as a result of being trained on erroneous data such as common misconceptions[13](/articles/s41586-024-07421-0#ref-CR13 "Lin, S., Hilton, J. & Evans, O. Teaching models to express their uncertainty in words. Transact. Mach. Learn. Res. \(2022\)."); when the LLM ‘lies’ in pursuit of a reward[14](/articles/s41586-024-07421-0#ref-CR14 "Evans, O. et al. Truthful AI: developing and governing AI that does not lie. Preprint at 
                  https://arxiv.org/abs/2110.06674
                  
                 \(2021\)."); or systematic failures of reasoning or generalization. We believe that combining these distinct mechanisms in the broad category hallucination is unhelpful. Our method makes progress on a portion of the problem of providing scalable oversight[15](/articles/s41586-024-07421-0#ref-CR15 "Amodei, D. et al. Concrete problems in AI safety. Preprint at 
                  https://arxiv.org/abs/1606.06565
                  
                 \(2016\).") by detecting confabulations that people might otherwise find plausible. However, it does not guarantee factuality because it does not help when LLM outputs are systematically bad. Nevertheless, we significantly improve question-answering accuracy for state-of-the-art LLMs, revealing that confabulations are a great source of error at present.

We show how to detect confabulations by developing a quantitative measure of when an input is likely to cause an LLM to generate arbitrary and ungrounded answers. Detecting confabulations allows systems built on LLMs to avoid answering questions likely to cause confabulations, to make users aware of the unreliability of answers to a question or to supplement the LLM with more grounded search or retrieval. This is essential for the critical emerging field of free-form generation in which naive approaches, suited to closed vocabulary and multiple choice, fail. Past work on uncertainty for LLMs has focused on simpler settings, such as classifiers[16](/articles/s41586-024-07421-0#ref-CR16 "Jiang, Z., Araki, J., Ding, H. & Neubig, G. How can we know when language models know? On the calibration of language models for question answering. Transact. Assoc. Comput. Linguist. 9, 962–977 \(2021\)."),[17](/articles/s41586-024-07421-0#ref-CR17 "Desai, S. & Durrett, G. Calibration of pre-trained transformers. In Proc. 2020 Conference on Empirical Methods in Natural Language Processing \(EMNLP\) \(eds Webber, B., Cohn, T., He, Y. & Liu, Y.\) 295–302 \(Association for Computational Linguistics, 2020\).") and regressors[18](/articles/s41586-024-07421-0#ref-CR18 "Glushkova, T., Zerva, C., Rei, R. & Martins, A. F. Uncertainty-aware machine translation evaluation. In Findings of the Association for Computational Linguistics: EMNLP 2021 \(eds Moens, M-F., Huang, X., Specia, L. & Yih, S.\) 3920–3938 \(Association for Computational Linguistics, 2021\)."),[19](/articles/s41586-024-07421-0#ref-CR19 "Wang, Y., Beck, D., Baldwin, T. & Verspoor, K. Uncertainty estimation and reduction of pre-trained models for text regression. Transact. Assoc. Comput. Linguist. 10, 680–696 \(2022\)."), whereas the most exciting applications of LLMs relate to free-form generations.

The term hallucination in the context of machine learning originally comes from filling in ungrounded details, either as a deliberate strategy[20](/articles/s41586-024-07421-0#ref-CR20 "Baker, S. & Kanade, T. Hallucinating faces. In Proc. Fourth IEEE International Conference on Automatic Face and Gesture Recognition. 83–88 \(IEEE, Catalogue no PR00580, 2002\).") or as a reliability problem[4](/articles/s41586-024-07421-0#ref-CR4 "Rohrbach, A., Hendricks, L. A., Burns, K., Darrell, T. & Saenko, K. Object hallucination in image captioning. In Proc. 2018 Conference on Empirical Methods in Natural Language Processing \(eds Riloff, E., Chiang, D., Hockenmaier, J. & Tsujii, J.\) 4035–4045 \(Association for Computational Linguistics, 2018\)."). The appropriateness of the metaphor has been questioned as promoting undue anthropomorphism[21](/articles/s41586-024-07421-0#ref-CR21 "Eliot, L. AI ethics lucidly questioning this whole hallucinating AI popularized trend that has got to stop. Forbes Magazine \(24 August 2022\)."). Although we agree that metaphor must be used carefully with LLMs[22](/articles/s41586-024-07421-0#ref-CR22 "Shanahan, M. Talking about large language models. Commun. Assoc. Comp. Machinery 67, 68–79 \(2024\)."), the widespread adoption of the term hallucination reflects the fact that it points to an important phenomenon. This work represents a step towards making that phenomenon more precise.

To detect confabulations, we use probabilistic tools to define and then measure the ‘semantic’ entropy of the generations of an LLM—an entropy that is computed over meanings of sentences. High entropy corresponds to high uncertainty23,24,[25](/articles/s41586-024-07421-0#ref-CR25 "Lindley, D. V. On a measure of the information provided by an experiment. Ann. Math. Stat. 27, 986–1005 \(1956\).")—so semantic entropy is one way to estimate semantic uncertainties. Semantic uncertainty, the broader category of measures we introduce, could be operationalized with other measures of uncertainty, such as mutual information, instead. Entropy in free-form generation is normally hard to measure because answers might mean the same thing (be semantically equivalent) despite being expressed differently (being syntactically or lexically distinct). This causes naive estimates of entropy or other lexical variation scores[26](/articles/s41586-024-07421-0#ref-CR26 "Xiao, T. Z., Gomez, A. N. & Gal, Y. Wat zei je? Detecting out-of-distribution translations with variational transformers. In Workshop on Bayesian Deep Learning at the Conference on Neural Information Processing Systems \(NeurIPS, Vancouver, 2019\).") to be misleadingly high when the same correct answer might be written in many ways without changing its meaning.

By contrast, our semantic entropy moves towards estimating the entropy of the distribution of meanings of free-form answers to questions, insofar as that is possible, rather than the distribution over the ‘tokens’ (words or word-pieces) which LLMs natively represent. This can be seen as a kind of semantic consistency check[27](/articles/s41586-024-07421-0#ref-CR27 "Christiano, P., Cotra, A. & Xu, M. Eliciting Latent Knowledge \(Alignment Research Center, 2021\); 
                  https://docs.google.com/document/d/1WwsnJQstPq91_Yh-Ch2XRL8H_EpsnjrC1dwZXR37PC8/edit
                  
                .") for random seed variation. An overview of our approach is provided in Fig. [1](/articles/s41586-024-07421-0#Fig1) and a worked example in Supplementary Table [1](/articles/s41586-024-07421-0#MOESM1).

**Fig. 1: Overview of semantic entropy and confabulation detection.**

[ Full size image](/articles/s41586-024-07421-0/figures/1)

**a** , Naive entropy-based uncertainty measures variation in the exact answers, treating ‘Paris’, ‘It’s Paris’ and ‘France’s capital Paris’ as different. But this is unsuitable for language tasks for which sometimes different answers mean the same things. Our semantic entropy clusters answers which share meanings before computing the entropy. A low semantic entropy shows that the LLM is confident about the meaning. **b** , Semantic entropy can also detect confabulations in longer passages. We automatically decompose a long generated answer into factoids. For each factoid, an LLM generates questions to which that factoid might have been the answer. The original LLM then samples  _M_ possible answers to these questions. Finally, we compute the semantic entropy over the answers to each specific question, including the original factoid. Confabulations are indicated by high average semantic entropy for questions associated with that factoid. Here, semantic entropy classifies Fact 1 as probably not a confabulation because generations often mean the same thing, despite very different wordings, which a naive entropy would have missed.

Intuitively, our method works by sampling several possible answers to each question and clustering them algorithmically into answers that have similar meanings, which we determine on the basis of whether answers in the same cluster entail each other bidirectionally[28](/articles/s41586-024-07421-0#ref-CR28 "Negri, M., Bentivogli, L., Mehdad, Y., Giampiccolo, D. & Marchetti, A. Divide and conquer: crowdsourcing the creation of cross-lingual textual entailment corpora. In Proc. 2011 Conference on Empirical Methods in Natural Language Processing 670–679 \(Association for Computational Linguistics, 2011\)."). That is, if sentence A entails that sentence B is true and vice versa, then we consider them to be in the same semantic cluster. We measure entailment using both general-purpose LLMs and natural language inference (NLI) tools developed specifically for detecting entailment for which we show direct evaluations in Supplementary Tables [2](/articles/s41586-024-07421-0#MOESM1) and [3](/articles/s41586-024-07421-0#MOESM1) and Supplementary Fig. [1](/articles/s41586-024-07421-0#MOESM1). Textual entailment has previously been shown to correlate with faithfulness[10](/articles/s41586-024-07421-0#ref-CR10 "Maynez, J., Narayan, S., Bohnet, B. & McDonald, R. On faithfulness and factuality in abstractive summarization. In Proc. 58th Annual Meeting of the Association for Computational Linguistics \(eds Jurafsky, D., Chai, J., Schluter, N. & Tetreault, J.\) 1906–1919 \(Association for Computational Linguistics, 2020\).") in the context of factual consistency[29](/articles/s41586-024-07421-0#ref-CR29 "Honovich, O. et al. TRUE: Re-evaluating factual consistency evaluation. In Proc. Second DialDoc Workshop on Document-grounded Dialogue and Conversational Question Answering 161–175 \(Association for Computational Linguistics, 2022\).") as well as being used to measure factuality in abstractive summarization[30](/articles/s41586-024-07421-0#ref-CR30 "Falke, T., Ribeiro, L. F. R., Utama, P. A., Dagan, I. & Gurevych, I. Ranking generated summaries by correctness: an interesting but challenging application for natural language inference. In Proc. 57th Annual Meeting of the Association for Computational Linguistics 2214–2220 \(Association for Computational Linguistics, 2019\)."), especially when applied at the right granularity[31](/articles/s41586-024-07421-0#ref-CR31 "Laban, P., Schnabel, T., Bennett, P. N. & Hearst, M. A. SummaC: re-visiting NLI-based models for inconsistency detection in summarization. Trans. Assoc. Comput. Linguist. 10, 163–177 \(2022\).").

Semantic entropy detects confabulations in free-form text generation across a range of language models and domains, without previous domain knowledge. Our evaluations cover question answering in trivia knowledge (TriviaQA[32](/articles/s41586-024-07421-0#ref-CR32 "Joshi, M., Choi, E., Weld, D. S. & Zettlemoyer, L. TriviaQA: a large scale distantly supervised challenge dataset for reading comprehension. In Proc. 55th Annual Meeting of the Association for Computational Linguistics 1601–1611 \(Association for Computational Linguistics. 2017\).")), general knowledge (SQuAD 1.1; ref. [33](/articles/s41586-024-07421-0#ref-CR33 "Rajpurkar, P., Zhang, J., Lopyrev, K. & Liang, P. SQuAD: 100,000+ questions for machine compression of text. In Proc. 2016 Conference on Empirical Methods in Natural Language Processing \(eds Su, J., Duh, K. & Carreras, X.\) 2383–2392 \(Association for Computational Linguistics, 2016\).")), life sciences (BioASQ[34](/articles/s41586-024-07421-0#ref-CR34 "Tsatsaronis, G. et al. An overview of the BIOASQ large-scale biomedical semantic indexing and question answering competition. BMC Bioinformatics 16, 138 \(2015\).")) and open-domain natural questions (NQ-Open[35](/articles/s41586-024-07421-0#ref-CR35 "Lee, K., Chang, M.-W. & Toutanova, K. Latent retrieval for weakly supervised open domain question answering. In Proc. 57th Annual Meeting of the Association for Computational Linguistics 6086–6096 \(Association for Computational Linguistics, 2019\).")) derived from actual queries to Google Search[36](/articles/s41586-024-07421-0#ref-CR36 "Kwiatkowski, T. et al. Natural questions: a benchmark for question answering research. Transact. Assoc. Comput. Linguist. 7, 452–466 \(2019\)."). In addition, semantic entropy detects confabulations in mathematical word problems (SVAMP[37](/articles/s41586-024-07421-0#ref-CR37 "Patel, A., Bhattamishra, S. & Goyal, N. Are NLP models really able to solve simple math word problems? In Proc. 2021 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies \(eds Toutanova, K. et al.\) 2080–2094 \(Assoc. Comp. Linguistics, 2021\).")) and in a biography-generation dataset, FactualBio, accompanying this paper.

Our results for TriviaQA, SQuAD, BioASQ, NQ-Open and SVAMP are all evaluated context-free and involve sentence-length answers (96 ± 70 characters, mean ± s.d.) and use LLaMA 2 Chat (7B, 13B and 70B parameters)[38](/articles/s41586-024-07421-0#ref-CR38 "Touvron, H. et al. Llama 2: open foundation and fine-tuned chat models. Preprint at 
                  https://arxiv.org/abs/2307.09288
                  
                 \(2023\)."), Falcon Instruct (7B and 40B)[39](/articles/s41586-024-07421-0#ref-CR39 "Penedo, G. et al. The RefinedWeb dataset for Falcon LLM: outperforming curated corpora with web data, and web data only. In Proc. 36th Conference on Neural Information Processing Systems \(eds Oh, A. et al.\) 79155–79172 \(Curran Associates, 2023\)") and Mistral Instruct (7B)[40](/articles/s41586-024-07421-0#ref-CR40 "Jiang, A. Q. et al. Mistral 7B. Preprint at 
                  https://arxiv.org/abs/2310.06825
                  
                 \(2023\)."). In the [Supplementary Information](/articles/s41586-024-07421-0#MOESM1), we further consider short-phrase-length answers. Results for FactualBio (442 ± 122 characters) use GPT-4 (ref. [1](/articles/s41586-024-07421-0#ref-CR1 "GPT-4 technical report. Preprint at 
                  https://arxiv.org/abs/2303.08774
                  
                 \(2023\).")). At the time of writing, GPT-4 (ref. [1](/articles/s41586-024-07421-0#ref-CR1 "GPT-4 technical report. Preprint at 
                  https://arxiv.org/abs/2303.08774
                  
                 \(2023\).")) did not expose output probabilities[41](/articles/s41586-024-07421-0#ref-CR41 "Manakul, P., Liusie, A. & Gales, M. J. F. SelfCheckGPT: Zero-Resource Black-Box hallucination detection for generative large language models. In Findings of the Association for Computational Linguistics: EMNLP 2023 \(eds Bouamor, H., Pino, J. & Bali, K.\) 9004–9017 \(Assoc. Comp. Linguistics, 2023\).") or hidden states, although it does now. As a result, we propose a discrete approximation of our estimator for semantic entropy which allows us to run experiments without access to output probabilities, which we use for all GPT-4 results in this paper and which performs similarly well.

Our confabulation detection with semantic entropy is more robust to user inputs from previously unseen domains than methods which aim to ‘learn’ how to detect confabulations from a set of example demonstrations. Our method is unsupervised, meaning that we do not need labelled examples of confabulations. By contrast, supervised methods detect confabulations by learning patterns behind examples of confabulations, assuming that future questions preserve these patterns. But this assumption is often untrue in new situations or with confabulations that human overseers are unable to identify (compare Fig. 17 of ref. [24](/articles/s41586-024-07421-0#ref-CR24 "Kadavath, S. et al. Language models \(mostly\) know what they know. Preprint at 
                  https://arxiv.org/abs/2207.05221
                  
                 \(2022\).")). As a strong supervised baseline, we compare to an embedding regression method inspired by ref. [24](/articles/s41586-024-07421-0#ref-CR24 "Kadavath, S. et al. Language models \(mostly\) know what they know. Preprint at 
                  https://arxiv.org/abs/2207.05221
                  
                 \(2022\).") which trains a logistic regression classifier to predict whether the model correctly answered a question on the basis of the final ‘embedding’ (hidden state) of the LLM. We also use the _P_(True) method[24](/articles/s41586-024-07421-0#ref-CR24 "Kadavath, S. et al. Language models \(mostly\) know what they know. Preprint at 
                  https://arxiv.org/abs/2207.05221
                  
                 \(2022\).") which looks at the probability with which an LLM predicts that the next token is ‘True’ when few-shot prompted to compare a main answer with ‘brainstormed’ alternatives.

Confabulations contribute substantially to incorrect answers given by language models. We show that semantic entropy can be used to predict many incorrect model answers and to improve question-answering accuracy by refusing to answer those questions the model is uncertain about. Corresponding to these two uses, we evaluate two main metrics. First, the widely used area under the receiver operating characteristic (AUROC) curve for the binary event that a given answer is incorrect. This measure captures both precision and recall and ranges from 0 to 1, with 1 representing a perfect classifier and 0.5 representing an un-informative classifier. We also show a new measure, the area under the ‘rejection accuracy’ curve (AURAC). This studies the case in which the confabulation detection score is used to refuse to answer the questions judged most likely to cause confabulations. Rejection accuracy is the accuracy of the answers of the model on the remaining questions and the area under this curve is a summary statistic over many thresholds (representative threshold accuracies are provided in [Supplementary Material](/articles/s41586-024-07421-0#MOESM1)). The AURAC captures the accuracy improvement which users would experience if semantic entropy was used to filter out questions causing the highest entropy.

## Detecting confabulations in QA and math

In Fig. [2](/articles/s41586-024-07421-0#Fig2), we show that both semantic entropy and its discrete approximation outperform our best baselines for sentence-length generations. These results are averaged across datasets and provide the actual scores on the held-out evaluation dataset. We report the raw average score across held-out evaluation datasets without standard error because the distributional characteristics are more a property of the models and datasets selected than the method. Consistency of relative results across different datasets is a stronger indicator of variation in this case.

**Fig. 2: Detecting confabulations in sentence-length generations.**

[ Full size image](/articles/s41586-024-07421-0/figures/2)

Semantic entropy outperforms leading baselines and naive entropy. AUROC (scored on the _y_ -axes) measures how well methods predict LLM mistakes, which correlate with confabulations. AURAC (likewise scored on the _y_ -axes) measures the performance improvement of a system that refuses to answer questions which are judged likely to cause confabulations. Results are an average over five datasets, with individual metrics provided in the [Supplementary Information](/articles/s41586-024-07421-0#MOESM1).

Semantic entropy greatly outperforms the naive estimation of uncertainty using entropy: computing the entropy of the length-normalized joint probability of the token sequences. Naive entropy estimation ignores the fact that token probabilities also express the uncertainty of the model over phrasings that do not change the meaning of an output.

Our methods also outperform the supervised embedding regression method both in- and out-of-distribution. In pale-yellow bars we show that embedding regression performance deteriorates when its training data do not match the deployment distribution—which mirrors the common real-world case in which there is a distribution shift between training and deployment[42](/articles/s41586-024-07421-0#ref-CR42 "Mukhoti, J., Kirsch, A., van Amersfoort, J., Torr, P. H. & Gal, Y. Deep deterministic uncertainty: a new simple baseline. In IEEE/CVF Conference on Computer Vision and Pattern Recognition 24384–24394 \(Computer Vision Foundation, 2023\).")—the plotted value is the average metric for embedding regression trained on one of the four ‘off-distribution’ datasets for that evaluation. This is critical because reliable uncertainty is most important when the data distribution shifts. Semantic entropy also outperforms _P_(True) which is supervised ‘in-context’; that is, it is adapted to the deployment task with a few training examples provided in the LLM prompt itself. The discrete variant of semantic entropy performs similarly to our standard estimator, despite not requiring exact output probabilities.

Averaged across the 30 combinations of tasks and models we study, semantic entropy achieves the best AUROC value of 0.790 whereas naive entropy (0.691), _P_(True) (0.698) and the embedding regression baseline (0.687) lag behind it. Semantic entropy performs well consistently, with stable performance (between 0.78 and 0.81 AUROC) across the different model families (LLaMA, Falcon and Mistral) and scales (from 7B to 70B parameters) which we study (we report summary statistics for each dataset and model as before). Although semantic entropy outperforms the baselines across all model sizes, _P_(True) seems to improve with model size, suggesting that it might become more competitive for very capable honest models in settings that the model understands well (which are, however, not the most important cases to have good uncertainty). We use ten generations to compute entropy, selected using analysis in Supplementary Fig. [2](/articles/s41586-024-07421-0#MOESM1). Further results for short-phrase generations are described in Supplementary Figs. [7](/articles/s41586-024-07421-0#MOESM1)–[10](/articles/s41586-024-07421-0#MOESM1).

The results in Fig. [2](/articles/s41586-024-07421-0#Fig2) offer a lower bound on the effectiveness of semantic entropy at detecting confabulations. These evaluations determine whether semantic entropy and baseline methods can detect when the answers of the model are incorrect (which we validate against human correctness evaluations in Supplementary Table [4](/articles/s41586-024-07421-0#MOESM1)). In addition to errors from confabulations (arbitrary incorrectness), this also includes other types of mistakes for which semantic entropy is not suited, such as consistent errors learned from the training data. The fact that methods such as embedding regression are able to spot other kinds of errors, not just confabulations, but still are outperformed by semantic entropy, suggests that confabulations are a principal category of errors for actual generations.

Examples of questions and answers from TriviaQA, SQuAD and BioASQ, for LLaMA 2 Chat 70B, are shown in Table [1](/articles/s41586-024-07421-0#Tab1). These illustrate how only semantic entropy detects when the meaning is constant but the form varies (the first row of the table) whereas semantic entropy and naive entropy both correctly predict the presence of confabulations when the form and meaning vary together (second row) and predict the absence of confabulations when the form and meaning are both constant across several resampled generations (third row). In the final row, we give an example in which semantic entropy is erroneously high as a result of overly sensitive semantic clustering relative to the reference answer. Our clustering method distinguishes the answers which provide a precise date from those which only provide a year. For some contexts that would have been correct but in this context the distinction between the specific day and the year is probably irrelevant. This highlights the importance of context and judgement in clustering, especially in subtle cases, as well as the shortcomings of evaluating against fixed reference answers which do not capture the open-ended flexibility of conversational deployments of LLMs.

**Table 1 Semantic entropy applied to examples**

[ Full size table](/articles/s41586-024-07421-0/tables/1)

## Detecting confabulations in biographies

Semantic entropy is most natural for sentences that express a single proposition but the idea of semantic equivalence is trickier to apply to longer passages which express many propositions which might only agree partially[43](/articles/s41586-024-07421-0#ref-CR43 "Schuster, T., Chen, S., Buthpitiya, S., Fabrikant, A. & Metzler, D. Stretching sentence-pair NLI models to reason over long documents and clusters. In Findings of the Association for Computational Linguistics: EMNLP 2022 \(eds Goldberg, Y. et al.\) 394–412 \(Association for Computational Linguistics, 2022\)."). Nevertheless, we can use semantic entropy to detect confabulations in longer generations, such as entire paragraphs of text. To show this, we develop a dataset of biographical generations from GPT-4 (v.0613) for 21 individuals notable enough to have their own Wikipedia page but without extensive online biographies. From each biography generated by GPT-4, we automatically extract propositional factual claims about the individual (150 factual claims in total), which we manually label as true or false.

Applying semantic entropy to this problem is challenging. Naively, one might simply regenerate each sentence (conditioned on the text so far) and then compute semantic entropy over these regenerations. However, the resampled sentences often target different aspects of the biography: for example, one time describing family and the next time profession. This is analogous to the original problem semantic entropy was designed to resolve: the model is uncertain about the right ordering of facts, not about the facts themselves. To address this, we break down the entire paragraph into factual claims and reconstruct questions which might have been answered by those claims. Only then do we apply semantic entropy (Fig. [1](/articles/s41586-024-07421-0#Fig1)) by generating three new answers to each question (selected with analysis in Supplementary Figs. [3](/articles/s41586-024-07421-0#MOESM1) and [4](/articles/s41586-024-07421-0#MOESM1)) and computing the semantic entropy over those generations plus the original factual claim. We aggregate these by averaging the semantic entropy over all the questions to get an uncertainty score for each proposition, which we use to detect confabulations. Unaggregated results are shown in Supplementary Figs. [5](/articles/s41586-024-07421-0#MOESM1) and [6](/articles/s41586-024-07421-0#MOESM1).

As GPT-4 did not allow access to the probability of the generation at the time of writing, we use a discrete variant of semantic entropy which makes the further approximation that we can infer a discrete empirical distribution over semantic meaning clusters from only the generations ([Methods](/articles/s41586-024-07421-0#Sec5)). This allows us to compute semantic entropy using only the black-box outputs of an LLM. However, we were unable to compute the naive entropy baseline, the standard semantic entropy estimator or the embedding regression baseline for GPT-4 without output probabilities and embeddings.

In Fig. [3](/articles/s41586-024-07421-0#Fig3) we show that the discrete variant of semantic entropy effectively detects confabulations on this dataset. Its AUROC and AURAC are higher than either a simple ‘self-check’ baseline—which just asks the LLM whether the factoid is likely to be true—or a variant of _P_(True) which has been adapted to work for the paragraph-length setting. Discrete semantic entropy has better rejection accuracy performance until 20% of the questions have been rejected at which point _P_(True) has a narrow edge. This indicates that the questions predicted to cause confabulations are indeed more likely to be wrong.

**Fig. 3: Detecting GPT-4 confabulations in paragraph-length biographies.**

[ Full size image](/articles/s41586-024-07421-0/figures/3)

The discrete variant of our semantic entropy estimator outperforms baselines both when measured by AUROC and AURAC metrics (scored on the _y_ -axis). The AUROC and AURAC are substantially higher than for both baselines. At above 80% of questions being answered, semantic entropy has the highest accuracy. Only when the top 20% of answers judged most likely to be confabulations are rejected does the answer accuracy on the remainder for the _P_(True) baseline exceed semantic entropy.

## Discussion

Our probabilistic approach, accounting for semantic equivalence, detects an important class of hallucinations: those that are caused by a lack of LLM knowledge. These are a substantial portion of the failures at present and will continue even as models grow in capabilities because situations and cases that humans cannot reliably supervise will persist. Confabulations are a particularly noteworthy failure mode for question answering but appear in other domains too. Semantic entropy needs no previous domain knowledge and we expect that algorithmic adaptations to other problems will allow similar advances in, for example, abstractive summarization. In addition, extensions to alternative input variations such as rephrasing or counterfactual scenarios would allow a similar method to act as a form of cross-examination[44](/articles/s41586-024-07421-0#ref-CR44 "Barnes, B. & Christiano, P. Progress on AI Safety via Debate. AI Alignment Forum 
                  www.alignmentforum.org/posts/Br4xDbYu4Frwrb64a/writeup-progress-on-ai-safety-via-debate-1
                  
                 \(2020\).") for scalable oversight through debate[45](/articles/s41586-024-07421-0#ref-CR45 "Irving, G., Christiano, P. & Amodei, D. AI safety via debate. Preprint at 
                  https://arxiv.org/abs/1805.00899
                  
                 \(2018\).").

The success of semantic entropy at detecting errors suggests that LLMs are even better at “knowing what they don’t know” than was argued by ref. [24](/articles/s41586-024-07421-0#ref-CR24 "Kadavath, S. et al. Language models \(mostly\) know what they know. Preprint at 
                  https://arxiv.org/abs/2207.05221
                  
                 \(2022\).")—they just don’t know they know what they don’t know. Our method explicitly does not directly address situations in which LLMs are confidently wrong because they have been trained with objectives that systematically produce dangerous behaviour, cause systematic reasoning errors or are systematically misleading the user. We believe that these represent different underlying mechanisms—despite similar ‘symptoms’—and need to be handled separately.

One exciting aspect of our approach is the way it makes use of classical probabilistic machine learning methods and adapts them to the unique properties of modern LLMs and free-form language generation. We hope to inspire a fruitful exchange of well-studied methods and emerging new problems by highlighting the importance of meaning when addressing language-based machine learning problems.

## Methods

Semantic entropy as a strategy for overcoming confabulation builds on probabilistic tools for uncertainty estimation. It can be applied directly to any LLM or similar foundation model without requiring any modifications to the architecture. Our ‘discrete’ variant of semantic uncertainty can be applied even when the predicted probabilities for the generations are not available, for example, because access to the internals of the model is limited.

In this section we introduce background on probabilistic methods and uncertainty in machine learning, discuss how it applies to language models and then discuss our contribution, semantic entropy, in detail.

### Background

#### Uncertainty and machine learning

We aim to detect confabulations in LLMs, using the principle that the model will be uncertain about generations for which its output is going to be arbitrary.

One measure of uncertainty is the predictive entropy of the output distribution, which measures the information one has about the output given the input[25](/articles/s41586-024-07421-0#ref-CR25 "Lindley, D. V. On a measure of the information provided by an experiment. Ann. Math. Stat. 27, 986–1005 \(1956\)."). The predictive entropy (PE) for an input sentence **x** is the conditional entropy (_H_) of the output random variable _Y_ with realization _y_ given **x** ,

$${\rm{PE}}({\bf{x}})=H(Y| {\bf{x}})=-\sum _{y}P(\,y| {\bf{x}})\mathrm{ln}P(\,y| {\bf{x}}).$$

(1) 

A low predictive entropy indicates an output distribution which is heavily concentrated whereas a high predictive entropy indicates that many possible outputs are similarly likely.

#### Aleatoric and epistemic uncertainty

We do not distinguish between aleatoric and epistemic uncertainty in our analysis. Researchers sometimes separate aleatoric uncertainty (uncertainty in the underlying data distribution) from epistemic uncertainty (caused by having only limited information)[46](/articles/s41586-024-07421-0#ref-CR46 "Der Kiureghian, A. & Ditlevsen, O. Aleatory or epistemic? Does it matter? Struct. Saf. 31, 105–112 \(2009\)."). Further advances in uncertainty estimation which separate these kinds of uncertainty would enhance the potential for our semantic uncertainty approach by allowing extensions beyond entropy.

#### Joint probabilities of sequences of tokens

Generative LLMs produce strings of text by selecting tokens in sequence. Each token is a wordpiece that often represents three or four characters (though especially common sequences and important words such as numbers typically get their own token). To compute entropies, we need access to the probabilities the LLM assigns to the generated sequence of tokens. The probability of the entire sequence, **s** , conditioned on the context, **x** , is the product of the conditional probabilities of new tokens given past tokens, whose resulting log-probability is \\(\log P({\bf{s}}| {\boldsymbol{x}})={\sum }_{i}\log P({s}_{i}| {{\bf{s}}}_{ < i},{\boldsymbol{x}})\\), where _s_ _i_ is the _i_ th output token and **s** <_i_ denotes the set of previous tokens.

#### Length normalization

When comparing the log-probabilities of generated sequences, we use ‘length normalization’, that is, we use an arithmetic mean log-probability, \\(\frac{1}{N}{\sum }_{i}^{N}\log P({s}_{i}| {{\bf{s}}}_{ < i},{\boldsymbol{x}})\\), instead of the sum. In expectation, longer sequences have lower joint likelihoods because of the conditional independence of the token probabilities[47](/articles/s41586-024-07421-0#ref-CR47 "Malinin, A. & Gales, M. Uncertainty estimation in autoregressive structured prediction. In Proceedings of the International Conference on Learning Representations 
                  https://openreview.net/forum?id=jN5y-zb5Q7m
                  
                 \(2021\)."). The joint likelihood of a sequence of length _N_ shrinks exponentially in _N_. Its negative log-probability therefore grows linearly in _N_ , so longer sentences tend to contribute more to entropy. We therefore interpret length-normalizing the log-probabilities when estimating the entropy as asserting that the expected uncertainty of generations is independent of sentence length. Length normalization has some empirical success[48](/articles/s41586-024-07421-0#ref-CR48 "Murray, K. & Chiang, D. Correcting length bias in neural machine translation. In Proc. Third Conference on Machine Translation \(eds Bojar, O. et al.\) 212–223 \(Assoc. Comp. Linguistics, 2018\)."), including in our own preliminary experiments, but little theoretical justification in the literature.

### Principles of semantic uncertainty

If we naively calculate the predictive entropy directly from the probabilities of the generated sequence of tokens, we conflate the uncertainty of the model over the meaning of its answer with the uncertainty over the exact tokens used to express that meaning. For example, even if the model is confident in the meaning of a generation, there are still usually many different ways for phrasing that generation without changing its meaning. For the purposes of detecting confabulations, the uncertainty of the LLM over meanings is more important than the uncertainty over the exact tokens used to express those meanings.

Our semantic uncertainty method therefore seeks to estimate only the uncertainty the LLM has over the meaning of its generation, not the choice of words. To do this, we introduce an algorithm that clusters model generations by meaning and subsequently calculates semantic uncertainty. At a high level this involves three steps:

  1. 1.

Generation: sample output sequences of tokens from the predictive distribution of a LLM given a context **x**.

  2. 2.

Clustering: cluster sequences by their meaning using our clustering algorithm based on bidirectional entailment.

  3. 3.

Entropy estimation: estimate semantic entropy by summing probabilities of sequences that share a meaning following equation ([2](/articles/s41586-024-07421-0#Equ2)) and compute their entropy.




#### Generating a set of answers from the model

Given some context **x** as input to the LLM, we sample _M_ sequences, {**s**(1), …, **s**(_M_)} and record their token probabilities, {_P_(**s**(1)∣**x**), …,  _P_(**s**(_M_)∣**x**)}. We sample all our generations from a single model, varying only the random seed used for sampling from the token probabilities. We do not observe the method to be particularly sensitive to details of the sampling scheme. In our implementation, we sample at temperature 1 using nucleus sampling (_P_ = 0.9) (ref. [49](/articles/s41586-024-07421-0#ref-CR49 "Holtzman, A., Buys, J., Du, L., Forbes, M. & Choi, Y. The curious case of neural text degeneration. In Proceedings of the International Conference on Learning Representations 
                  https://openreview.net/forum?id=rygGQyrFvH
                  
                 \(2020\).")) and top-_K_ sampling (_K_ = 50) (ref. [50](/articles/s41586-024-07421-0#ref-CR50 "Fan, A., Lewis, M. & Dauphin, Y. Hierarchical neural story generation. In Proc. 56th Annual Meeting of the Association for Computational Linguistics \(eds Gurevych, I. & Miyao, Y.\) 889–898 \(Association for Computational Linguistics, 2018\).")). We also sample a single generation at low temperature (0.1) as an estimate of the ‘best generation’ of the model to the context, which we use to assess the accuracy of the model. (A lower sampling temperature increases the probability of sampling the most likely tokens).

#### Clustering by semantic equivalence

To estimate semantic entropy we need to cluster generated outputs from the model into groups of outputs that mean the same thing as each other.

This can be described using ‘semantic equivalence’ which is the relation that holds between two sentences when they mean the same thing. We can formalize semantic equivalence mathematically. Let the space of tokens in a language be \\({\mathcal{T}}\\). The space of all possible sequences of tokens of length _N_ is then \\({{\mathcal{S}}}_{N}\equiv {{\mathcal{T}}}^{N}\\). Note that _N_ can be made arbitrarily large to accommodate whatever size of sentence one can imagine and one of the tokens can be a ‘padding’ token which occurs with certainty for each token after the end-of-sequence token. For some sentence \\({\bf{s}}\in {{\mathcal{S}}}_{N}\\), composed of a sequence of tokens, \\({s}_{i}\in {\mathcal{T}}\\), there is an associated meaning. Theories of meaning are contested[51](/articles/s41586-024-07421-0#ref-CR51 "Speaks, J. in The Stanford Encyclopedia of Philosophy \(ed. Zalta, E. N.\) \(Metaphysics Research Lab, Stanford Univ., 2021\)."). However, for specific models and deployment contexts many considerations can be set aside. Care should be taken comparing very different models and contexts.

Let us introduce a semantic equivalence relation, _E_( ⋅ , ⋅ ), which holds for any two sentences that mean the same thing—we will operationalize this presently. Recall that an equivalence relation is any reflexive, symmetric and transitive relation and that any equivalence relation on a set corresponds to a set of equivalence classes. Each semantic equivalence class captures outputs that can be considered to express the same meaning. That is, for the space of semantic equivalence classes \\({\mathcal{C}}\\) the sentences in the set \\(c\in {\mathcal{C}}\\) can be regarded in many settings as expressing a similar meaning such that \\(\forall {\bf{s}},{{\bf{s}}}^{{\prime} }\in c:E({\bf{s}},{{\bf{s}}}^{{\prime} })\\). So we can build up these classes of semantically equivalent sentences by checking if new sentences share a meaning with any sentences we have already clustered and, if so, adding them into that class.

We operationalize _E_( ⋅ , ⋅ ) using the idea of bidirectional entailment, which has a long history in linguistics[52](/articles/s41586-024-07421-0#ref-CR52 "Culicover, P. W. Paraphrase generation and information retrieval from stored text. Mech. Transl. Comput. Linguist. 11, 78–88 \(1968\).") and natural language processing[28](/articles/s41586-024-07421-0#ref-CR28 "Negri, M., Bentivogli, L., Mehdad, Y., Giampiccolo, D. & Marchetti, A. Divide and conquer: crowdsourcing the creation of cross-lingual textual entailment corpora. In P
