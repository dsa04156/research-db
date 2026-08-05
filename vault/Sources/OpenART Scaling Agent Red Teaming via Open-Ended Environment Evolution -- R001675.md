---
type: research-source
item_id: 1675
title: "OpenART: Scaling Agent Red Teaming via Open-Ended Environment Evolution"
source: "arxiv"
published: "2026-08-01T13:51:55Z"
first_seen: "2026-08-04"
review_status: "pending"
canonical_key: "arxiv:2608.00677"
url: "https://arxiv.org/abs/2608.00677v1"
generated_by: codex-research-db
aliases:
  - "OpenART: Scaling Agent Red Teaming via Open-Ended Environment Evolution"
topics:
  - "ai-agents"
---

# OpenART: Scaling Agent Red Teaming via Open-Ended Environment Evolution

[원문 열기](https://arxiv.org/abs/2608.00677v1)

## 연결

- 주제: [[vault/Topics/AI agents]]
- 최초 수집: [[vault/Daily/2026-08-04|2026-08-04]]
- 수집 채널: `arxiv`
- 검토 상태: `pending`
- Zotero: created (`77KBDSQT`)
- 발행일: 2026-08-01T13:51:55Z
- 저자: Yunhao Chen, Xin Wang, Yixu Wang, Yi Liu, Jie Li, Yan Teng, Xingjun Ma, Xia Hu, Yu-Gang Jiang
- 식별자: `arxiv:2608.00677`

## 요약·초록

AI agents operate in persistent environments where early state changes can influence decisions far into the future. Unlike conventional language-model interactions, agent behavior is mediated through a shared state that is repeatedly modified and reused across long-horizon workflows. Current safety benchmarks often fail to capture these cumulative risks because they focus on short, static tasks. To address these limitations, we introduce OpenART, an open-ended arena for scalable agent red teaming through environment evolution. OpenART provides over 10,000 validated stateful scenarios across 50 domains, drawing from a pool of more than 500,000 tools and skills. These tasks require a median of 97 tool calls and enable unified evaluation across 75 different agent-model configurations. To systematically explore these evolving attack surfaces, we propose the Evolutionary Markov Hypergraph Attack (EMHA). EMHA is a black-box policy that performs feedback-driven environment evolution by coordinating authorized state transitions without requiring parameter updates. Throughout the evaluation, task objectives remain fixed while only the environment state changes. Across all configurations, EMHA achieves a pooled Attack Success Rate (ASR) of 85.0%. Its advantage over instruction-only evolution increases from approximately 2% on simple environments to over 17% on the most complex ones, demonstrating that environment evolution increasingly exposes safety failures as task complexity grows. Furthermore, our analysis shows that the specific runtime implementation of an agent explains a significant portion of safety variation beyond the underlying model's capabilities. These results establish OpenART as a scalable foundation for studying agent safety in complex, evolving environments.

## 내 메모


