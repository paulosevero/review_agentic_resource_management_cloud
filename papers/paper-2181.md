---
id: paper-2181
title: A cooperative multi-agent optimization approach for task offloading in vehicular edge computing systems
authors:
- Sun, Xiangfei
- Hu, Yafei
- Gao, Xuehang
- Wang, Hezhe
venue: Discover Computing
venue_type: journal
year: 2025
doi: 10.1007/s10791-025-09887-6
url: https://www.scopus.com/pages/publications/105026377723?origin=resultslist
publisher: Springer Science and Business Media B.V.
pages: ''
keywords:
- Internet of vehicles
- Multi-agent deep reinforcement learning
- Resource allocation
- Task offloading
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
  04-title-screening: include
  05-abstract-screening: exclude
  06-full-text-screening: pending
  07-taxonomy-development: pending
  08-analysis: pending
screening:
  04-title-screening:
    last_iteration: 0
    proposed_decision: Include
    proposed_justification: C1=1.0 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=1.0 (infra/cloud-edge signal)
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

# paper-2181 — A cooperative multi-agent optimization approach for task offloading in vehicular edge computing systems

## Metadata (from `/03-parse-references-metadata`)

Imported from `legacy/papers/` during v3.2.0 migration. Full machine-readable fields live in the frontmatter.

**Abstract**

> With the rapid development of the internet of vehicles (IoV) system and intelligent applications, vehicles are generating increasingly computation-intensive tasks, which impose stringent demands on real-time performance, energy efficiency, and resource management. Recently, multi-agent deep reinforcement learning (MADRL) has emerged as a promising solution for task offloading in such dynamic environments, owing to its adaptability and low decision-making complexity. However, most existing approaches predominantly focus on resource constraints at the vehicle level, often neglecting the limited computing and storage capacities of edge servers, such as roadside units (RSUs), which results in inefficient offloading and coordination decisions. To address these challenges, we propose the Combinatorial Multi-Agent Actor-Critic with Coordination (COMA2C) algorithm. In this algorithm, vehicle agents dynamically generate task offloading requests based on link conditions and local resource availability, while RSU agents, constrained by limited resources, perform centralized decision-making through a combinatorial action selection mechanism. This enables global resource coordination and efficient task allocation. Simulation results under typical Vehicular Edge Computing (VEC) scenarios show that the proposed approach outperforms existing benchmarks in terms of task completion rate, task delay and energy consumption, thereby validating its effectiveness and scalability in real-world vehicular environments. © The Author(s) 2026.

**Dedup notes**

no duplicates found

---

## 04 — Title Screening

### iter-0 (migrated from legacy)

- **regex_decision:** Include
- **regex_justification:** "C1=1.0 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=1.0 (infra/cloud-edge signal)"
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
  - `{ category: rl, pattern_id: rl_madrl, matched_substring: "MADRL" }`
  - `{ category: rl, pattern_id: rl_ma_rl_combo, matched_substring: "With the rapid development of" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "multi-agent" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "multi-agent" }`
  - `{ category: classical_agents, pattern_id: cls_mas_term, matched_substring: "Multi-Agent" }`
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

_(populated by `/screen --stage full-text`. PDF location: `raw/pdfs/paper-2181.pdf`)_

---

## 07 — Taxonomy

_(populated by `/05-code-taxonomy` after stage 06 lock.)_

---

## 08 — Analysis contributions

_(populated by `/06-analyze` after taxonomy lock.)_
