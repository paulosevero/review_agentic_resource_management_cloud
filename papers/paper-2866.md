---
id: paper-2866
title: 'PF-MPPO: Task-dependent workflow scheduling method based on deep reinforcement learning in dynamic heterogeneous cloud environments'
authors:
- Xu, Donghong
- Li, Bin
venue: Future Generation Computer Systems
venue_type: journal
year: 2026
doi: 10.1016/j.future.2025.108236
url: https://www.scopus.com/pages/publications/105023820363?origin=resultslist
publisher: Elsevier B.V.
pages: ''
keywords:
- Cloud computing
- Deep reinforcement learning
- Dependent task
- Directed acyclic graph
- Task scheduling
language: English
source:
  databases:
  - Scopus
  exports:
  - scopus-2026-04-26.bib
  dedup:
    merged_from: []
    merge_reason: ''
status:
  04-title-screening: exclude
  05-abstract-screening: pending
  06-full-text-screening: pending
  07-taxonomy-development: pending
  08-analysis: pending
screening:
  04-title-screening:
    last_iteration: 0
    proposed_decision: Include
    proposed_justification: C1=0.5 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=1.0 (infra/cloud-edge signal)
    winning_category: null
    overrides_applied: []
    my_final_decision: Exclude
    my_justification: RL
    agrees_with_regex: false
    divergence_reason: null
    locked_at_iteration: iter-0
    locked_at: '2026-05-09T00:00:00+00:00'
  05-abstract-screening:
    last_iteration: 0
    proposed_decision: null
    proposed_justification: null
    winning_category: null
    overrides_applied: []
    my_final_decision: null
    my_justification: null
    agrees_with_regex: null
    divergence_reason: null
    locked_at_iteration: null
    locked_at: null
  06-full-text-screening:
    last_iteration: 0
    proposed_decision: null
    proposed_justification: null
    winning_category: null
    overrides_applied: []
    my_final_decision: null
    my_justification: null
    agrees_with_regex: null
    divergence_reason: null
    locked_at_iteration: null
    locked_at: null
taxonomy: {}
---

# paper-2866 — PF-MPPO: Task-dependent workflow scheduling method based on deep reinforcement learning in dynamic heterogeneous cloud environments

## Metadata (from `/03-parse-references-metadata`)

Imported from `legacy/papers/` during v3.2.0 migration. Full machine-readable fields live in the frontmatter.

**Abstract**

> Workflow task scheduling in heterogeneous dynamic cloud environments faces significant challenges, including balancing task precedence constraints with parallel execution and adapting to dynamic node configurations. This paper proposes PF-MPPO (Pre-training Fine-tuning Multi-agent Proximal Policy Optimization), a Deep Reinforcement Learning (DRL)-based algorithm designed for such environments. PF-MPPO integrates pre-training and fine-tuning within a multi-agent architecture, modeling workflows as Directed Acyclic Graphs (DAGs) and optimizing for latency, energy consumption, and load balancing. A dual-stage PPO framework enables rapid adaptation by comparing current task clusters with pre-trained models and selecting the most suitable one for incremental learning. Simulation results demonstrate that PF-MPPO outperforms baseline algorithms, significantly reducing latency and energy consumption while maintaining load balancing, validating its effectiveness in dynamic cloud environments. © 2025 Elsevier B.V. All rights are reserved, including those for text and data mining, AI training, and similar technologies.

**Dedup notes**

no duplicates found

---

## 04 — Title Screening

### iter-0 (migrated from legacy)

- **regex_decision:** Include
- **regex_justification:** "C1=0.5 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=1.0 (infra/cloud-edge signal)"
- **winning_category:** None
- **overrides_applied:** []
- **evidence_trail:**
  - _(not preserved from legacy)_
- **llm_decision:** Include
- **llm_justification:** "Migrated from legacy v2 — pass-1 (regex) and pass-2 (LLM) collapsed; legacy used dual sub-agents."
- **agrees_with_regex:** False
- **divergence_reason:** None
- **model:** legacy-v2
- **timestamp:** 2026-05-09T00:00:00+00:00

### final

- **my_final_decision:** Exclude
- **my_justification:** "RL"
- **locked_at_iteration:** iter-0
- **locked_at:** 2026-05-09T00:00:00+00:00

---

## 05 — Abstract Screening

_(stage 05 not run for this paper — excluded at title screening)_

---

## 06 — Full-Text Screening

_(populated by `/screen --stage full-text`. PDF location: `raw/pdfs/paper-2866.pdf`)_

---

## 07 — Taxonomy

_(populated by `/05-code-taxonomy` after stage 06 lock.)_

---

## 08 — Analysis contributions

_(populated by `/06-analyze` after taxonomy lock.)_
