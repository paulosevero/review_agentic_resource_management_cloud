---
id: paper-2626
title: Multi-agent-based time-sensitive task scheduling optimization strategy in satellite-terrestrial collaboration; [星地协同中基于多智能体的时敏任务调度优化策略]
authors:
- Juan, Chen
- Jie, Zhong
- Zongling, Wu
- Di, Tian
- Yujie, Chen
venue: Chinese Journal on Internet of Things
venue_type: journal
year: 2026
doi: 10.11959/j.issn.2096-3750.2026.00507
url: https://www.scopus.com/pages/publications/105035548410?origin=resultslist
publisher: Beijing Xintong Media Co., Ltd.
pages: 189--201
keywords:
- multi-agent deep reinforcement learning
- resource allocation
- SatEC
- self-attention temporal convolutional network
- task priority
language: Chinese
source:
  databases:
  - Scopus
  exports:
  - scopus-2026-04-26.bib
  dedup:
    merged_from: []
    merge_reason: ''
status:
  04-title-screening: include
  05-abstract-screening: exclude
  06-full-text-screening: pending
  07-taxonomy-development: pending
  08-analysis: pending
screening:
  04-title-screening:
    last_iteration: 0
    proposed_decision: Include
    proposed_justification: C1=1.0 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=0 (no infra signal)
    winning_category: null
    overrides_applied: []
    my_final_decision: Include
    my_justification: Talvez tenha algo de LLM e/ou Agentic AI (MAS).
    agrees_with_regex: true
    divergence_reason: null
    locked_at_iteration: iter-0
    locked_at: '2026-05-09T00:00:00+00:00'
  05-abstract-screening:
    last_iteration: 0
    proposed_decision: Exclude
    proposed_justification: RL
    winning_category: rl
    overrides_applied: []
    my_final_decision: Exclude
    my_justification: RL
    agrees_with_regex: true
    divergence_reason: null
    locked_at_iteration: iter-0
    locked_at: '2026-05-09T00:00:00+00:00'
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

# paper-2626 — Multi-agent-based time-sensitive task scheduling optimization strategy in satellite-terrestrial collaboration; [星地协同中基于多智能体的时敏任务调度优化策略]

## Metadata (from `/03-parse-references-metadata`)

Imported from `legacy/papers/` during v3.2.0 migration. Full machine-readable fields live in the frontmatter.

**Abstract**

> With the deep integration of intelligent Internet of things technology and 5G/6G communication technology, satellite edge computing (SatEC) offers new computational services to areas with weak terrestrial network coverage through its aerospace collaborative computing network. However, the SatEC system faces dual challenges of unbalanced dynamic resource allocation between satellite and ground and insufficient task priority control under multi-dimensional spatiotemporal constraints. Existing methods have defects in hierarchical decision-making, spatiotemporal feature extraction, and task urgency quantification mapping, which limit the efficiency of time-sensitive task processing. To address this proldem, a multi-agent deep reinforcement learning algorithm based on self-attention temporal convolutional networks was proposed in this paper. The algorithm achieved joint optimization of task prioritization and resource allocation by constructing a multi-agent architecture, employed a hybrid neural network integrating spatiotemporal features to accurately extract dynamic correlation characteristics of satellite-ground collaboration scenarios, and established a dynamic scheduling mechanism based on a probabilistic model to synergistically optimize latency constraints and task completion rates. Simulation results show that, compared with the baseline algorithm, the proposed algorithm achieves significant improvements in both task completion rate and delay control, demonstrating its effectiveness and superiority in complex satellite edge computing scenarios. © 2026, Beijing Xintong Media Co., Ltd.. All rights reserved.

**Dedup notes**

no duplicates found

---

## 04 — Title Screening

### iter-0 (migrated from legacy)

- **regex_decision:** Include
- **regex_justification:** "C1=1.0 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=0 (no infra signal)"
- **winning_category:** None
- **overrides_applied:** []
- **evidence_trail:**
  - _(not preserved from legacy)_
- **llm_decision:** Include
- **llm_justification:** "Migrated from legacy v2 — pass-1 (regex) and pass-2 (LLM) collapsed; legacy used dual sub-agents."
- **agrees_with_regex:** True
- **divergence_reason:** None
- **model:** legacy-v2
- **timestamp:** 2026-05-09T00:00:00+00:00

### final

- **my_final_decision:** Include
- **my_justification:** "Talvez tenha algo de LLM e/ou Agentic AI (MAS)."
- **locked_at_iteration:** iter-0
- **locked_at:** 2026-05-09T00:00:00+00:00

---

## 05 — Abstract Screening

### iter-0 (migrated from legacy)

- **regex_decision:** Exclude
- **regex_justification:** "RL"
- **winning_category:** 'rl'
- **overrides_applied:** []
- **evidence_trail:**
  - `{ category: rl, pattern_id: rl_ma_rl_combo, matched_substring: "With the deep integration of i" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "Multi-agent" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "multi-agent" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "multi-agent" }`
  - `{ category: classical_agents, pattern_id: cls_agent_term, matched_substring: "agent" }`
- **llm_decision:** Exclude
- **llm_justification:** "Migrated from legacy v2 — pass-1 (regex) and pass-2 (LLM) collapsed; legacy used dual sub-agents."
- **agrees_with_regex:** True
- **divergence_reason:** None
- **model:** legacy-v2
- **timestamp:** 2026-05-09T00:00:00+00:00

### final

- **my_final_decision:** Exclude
- **my_justification:** "RL"
- **locked_at_iteration:** iter-0
- **locked_at:** 2026-05-09T00:00:00+00:00

---

## 06 — Full-Text Screening

_(populated by `/screen --stage full-text`. PDF location: `raw/pdfs/paper-2626.pdf`)_

---

## 07 — Taxonomy

_(populated by `/05-code-taxonomy` after stage 06 lock.)_

---

## 08 — Analysis contributions

_(populated by `/06-analyze` after taxonomy lock.)_
