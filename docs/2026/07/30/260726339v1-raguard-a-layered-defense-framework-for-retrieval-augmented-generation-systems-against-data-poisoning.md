# RAGuard: A Layered Defense Framework for Retrieval-Augmented Generation Systems Against Data Poisoning

- 区域：速读区
- 排名：11
- 匹配度：3.2/10
- 来源：arxiv
- 作者：Pushkal Kumar, Tucker Nielson, Tanish Kolhe, Shubham Zala, Vincent Li
- 机构：Unknown affiliation
- 链接：[arXiv / Source](http://arxiv.org/abs/2607.26339v1) · [PDF](https://arxiv.org/pdf/2607.26339v1)

## TLDR
RAGuard is a two-layer defense for Retrieval-Augmented Generation systems that combines adversarial retriever fine-tuning with a novel zero-knowledge, black-box inference-time filter (ZKIP) to completely eliminate factual corpus-poisoning attacks by measuring the causal influence of each retrieved document on the model's own outputs.

## Abstract
Retrieval-Augmented Generation (RAG) systems ground large language models (LLMs) in external corpora, but this reliance exposes them to corpus poisoning: maliciously injected passages that manipulate retrieved evidence. We introduce RAGuard, a layered defense against \emph{factual} corpus-poisoning attacks on RAG pipelines. The first layer adversarially fine-tunes a dense retriever on synthetic poisoned documents (fabricated facts, contradictions, and reasoning traps), teaching it to downrank malicious passages before generation. The second layer, the Zero-Knowledge Inference Patch ZKIP, is a label-free, black-box filter: for each retrieved document, it performs a leave-one-out decode and scores the document by the semantic shift and output-entropy change that its removal induces. ZKIP requires no poison labels, no ground-truth answers, and no access to model internals; it compares the model's own answers under counterfactual contexts. On poisoned Natural Questions at 5--30\% poison ratios, adversarial retriever training alone reduces but does not eliminate attack success, while ZKIP drives the measured attack success rate to 0.000 in every defended configuration, keeping Recall@5 within 0.03 of the clean-corpus baseline. Supervised analyses on both Natural Questions and BEIR (NFCorpus) confirm that the counterfactual signals ZKIP relies on carry learnable poison structure. The defense costs $k{+}1$ generator passes per query ($6\times$ for $k{=}5$); we analyze batching and early-stopping approximations that reduce this overhead. We also show that keyword-preserving poisons leave lexical retrievers such as BM25 essentially unaffected, an observation that delineates the boundary of the threat model. Code, datasets, and evaluation harnesses are released for reproducibility.
