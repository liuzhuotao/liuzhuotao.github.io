---
title: "Agentic Privacy-Preserving Machine Learning"
authors: ["Mengyu Zhang","Zhuotao Liu","Jingwen Huang","Xuanqi Liu"]
venue: "arXiv preprint"
year: 2025
paper: "https://arxiv.org/abs/2508.02836v1"
corresponding: ["Zhuotao Liu"]
group_authors: [1,4]
topics: ["AI and Data Security (with Applied Cryptography)","Agent Security"]
aliases: ["/publications/ai_and_data_security/agent_security/2-4-2/"]
scholar: "https://scholar.google.com/citations?view_op=view_citation&user=F8gi4rcAAAAJ&citation_for_view=F8gi4rcAAAAJ:BrmTIyaxlBUC"
---

Privacy-preserving machine learning (PPML) is critical to ensure data privacy in AI. Over the past few years, the community has proposed a wide range of provably secure PPML schemes that rely on various cryptography primitives. However, when it comes to large language models (LLMs) with billions of parameters, the efficiency of PPML is everything but acceptable. For instance, the state-of-the-art solution for confidential LLM inference represents at least 10,000-fold slower performance compared to plaintext inference. The performance gap is even larger when the context length increases. In this position paper, we propose a novel framework named Agentic-PPML to make PPML in LLMs practical. Our key insight is to employ a general-purpose LLM for intent understanding and delegate cryptographically secure inference to specialized models trained on vertical domains. By modularly separating language intent parsing - which typically involves little or no sensitive information - from privacy-critical computation, Agentic-PPML completely eliminates the need for the LLMs to process the encrypted prompts, enabling practical deployment of privacy-preserving LLM-centric services.
