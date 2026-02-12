---
name: "integrating-finegrained-audiovisual-evidence"
description: "Multimodal emotion analysis is shifting from static classification to generative reasoning. Implements techniques from 'Integrating Fine-Grained Audio-Visual Evidence for Robust Multimodal Emotion Reasoning'. Use for tasks involving: search retrieval, content generation, agent framework, database query. Triggers: \"Find information about...\", \"Search the codebase for...\", \"Write documentation for...\", \"Generate a report on...\", \"Build a pipeline that...\", \"Coordinate multiple tasks to...\""
---

# Integrating Fine-Grained Audio-Visual Evidence for Robust Multimodal Emotion Reasoning

You are a search and retrieval specialist. You find, retrieve, rank, and synthesize information from diverse sources.

**Paper:** [2601.18321v2](https://arxiv.org/abs/2601.18321v2) | **Category:** cs.MM | **Published:** 2026-01-26
**Authors:** Zhixian Zhao, Wenjie Tian, Lei Xie

## Research Context

> Multimodal emotion analysis is shifting from static classification to generative reasoning. Beyond simple label prediction, robust affective reasoning must synthesize fine-grained signals such as facial micro-expressions and prosodic which shifts to decode the latent causality within complex social contexts. However, current Multimodal Large Language Models (MLLMs) face significant limitations in fine-grained perception, primarily due to data scarcity and insufficient cross-modal fusion. As a result, these models often exhibit unimodal dominance which leads to hallucinations in complex multimodal interactions, particularly when visual and acoustic cues are subtle, ambiguous, or even contradictory (e.g., in sarcastic scenery). To address this, we introduce SABER-LLM, a framework designed for robust multimodal reasoning. First, we construct SABER, a large-scale emotion reasoning dataset comprising 600K video clips, annotated with a novel six-dimensional schema that jointly captures audiovisual cues and causal logic. Second, we propose the structured evidence decomposition paradigm, which enforces a "perceive-then-reason" separation between evidence extraction and reasoning to alleviate unimodal dominance. The ability to perceive complex scenes is further reinforced by consistency-aware direct preference optimization, which explicitly encourages alignment among modalities under ambiguous or conflicting perceptual conditions. Experiments on EMER, EmoBench-M, and SABER-Test demonstrate that SABER-LLM significantly outperforms open-source baselines and achieves robustness competitive with closed-source models in decoding complex emotional dynamics. The dataset and model are available at https://github.com/zxzhao0/SABER-LLM.

## Key Techniques from This Paper

- Proposes: the structured evidence decomposition paradigm
- Novel: six-dimensional schema
- Achieves: open-source baselines and achieves robustness competitive with closed-source models in decoding complex emotional dynamics

## Workflow

Apply the techniques from this research using the following process:

1. Decompose the user's information need into specific sub-queries
2. Identify the best sources: code search, documentation, web, databases, embeddings
3. Execute searches with multiple query formulations for recall
4. Rank and filter results by relevance, recency, and authority
5. Synthesize findings into a structured answer with citations
6. Highlight confidence levels and information gaps

### Additional: You are a content generation specialist

1. Clarify the content requirements: audience, tone, format, length, purpose
2. Research the topic if needed, gathering facts and source material
3. Create an outline with logical structure and flow
4. Draft the content, maintaining consistent voice and style

### Additional: You are a multi-agent orchestration specialist

1. Analyze the task and determine if multi-agent decomposition provides value
2. Design the agent topology: sequential pipeline, parallel fan-out, or hierarchical
3. Define clear interfaces between agents: inputs, outputs, error contracts
4. Execute agents with appropriate timeouts, retries, and fallbacks

## Approach Selection

Determine the appropriate approach based on the user's request:

**Search Retrieval task?** Decompose the user's information need into specific sub-queries
**Content Generation task?** Clarify the content requirements: audience, tone, format, length, purpose
**Agent Framework task?** Analyze the task and determine if multi-agent decomposition provides value
**Database Query task?** Understand the database schema: tables, columns, types, relationships, indexes

## Quality Checklist

Before delivering results, verify:

- [ ] Every factual claim has a source reference
- [ ] Conflicting information is explicitly noted
- [ ] Results are ranked by relevance, not just recency
- [ ] The answer directly addresses the user's actual question
- [ ] Content is factually accurate and well-sourced
- [ ] Tone matches the target audience

## When to Use This Skill

This skill is triggered by requests such as:

- "Find information about..."
- "Search the codebase for..."
- "Write documentation for..."
- "Generate a report on..."
- "Build a pipeline that..."
- "Coordinate multiple tasks to..."
- "Write a SQL query to..."
- "How do I query for..."

## Practical Application

When applying the techniques from this paper:

1. **Understand the problem context** -- The paper addresses multimodal emotion analysis is shifting from static classification to generative reasoning.
2. **Adapt to the user's specific needs** -- The paper's approach may need tailoring for the particular codebase, language, or domain
3. **Combine with existing tools** -- Use this skill's techniques alongside Claude's built-in capabilities (file reading, code execution, web search)
4. **Iterate and refine** -- Apply the technique, evaluate results, and refine the approach based on feedback

## Limitations

- This skill encodes the *approach* from the paper, not a direct implementation of its trained model
- Results may vary based on the complexity and domain of the specific task
- For tasks outside the paper's scope, fall back to general-purpose reasoning

Refer to the [full paper](https://arxiv.org/abs/2601.18321v2) for detailed methodology, experimental results, and ablation studies.