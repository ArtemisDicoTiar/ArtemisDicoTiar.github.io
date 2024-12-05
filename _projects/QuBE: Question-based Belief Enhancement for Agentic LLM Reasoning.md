---
title: "QuBE: Question-based Belief Enhancement for Agentic LLM Reasoning"
image: 
  path: /assets/images/qube-emnlp2024.png
  thumbnail: /assets/images/qube-emnlp2024.png
  caption: "EMNLP 2024"
categories: 
  - Publication
tags:
  - EMNLP
last_modified_at: 2024-07-31 12:00:00 +0900
date: 2024-07-31 12:00:00 +0900
---

# Summary
This research tackles LLM reasoning errors in game environment and search environment.


# Abstraction
Despite advancements in Large Language Models (LLMs), many complex tasks are not easily solved in a single inference step, requiring the use of agentic LLMs in interactive environments. However, agentic LLMs suffer from a phenomenon known as reasoning derailment, due to the indiscriminate incorporation of observations from partially observable environments. We introduce QuBE, a method that enhances agents’ focus on task-relevant contexts, by constructing a belief state via question answering. We validate QuBE through experiments in two agentic LLM scenarios with partial observability: 1) a canonical interactive decision-making scenario using text-based game engines, and 2) an interactive retrieval-augmented generation (RAG) scenario using search engines. In the AlfWorld text-based game, QuBE outperforms established baselines by substantial margins, and in the search engine scenario, it achieves marked improvements on the BeIR zero-shot retrieval benchmark. The results demonstrate that QuBE significantly mitigates reasoning derailment, refining the decision-making process of LLM agents in partially observed environments.

## Paper
* ACL-Anthology: [🔗 Official Link](https://aclanthology.org/2024.emnlp-main.1193/)

## Code
[**Source Code**](https://github.com/ldilab/QuBE)
