---
id: paper-2371
title: Task Offloading for Collaborative Inference of LLM Agents at the Network Edge
authors:
- Yang, Yixuan
- Pan, Yutong
- Zhang, Junhe
- Ni, Wanli
venue: Proceedings - 2025 IEEE 22nd International Conference on Mobile Ad-Hoc and Smart Systems, MASS 2025
venue_type: conference
year: 2025
doi: 10.1109/MASS66014.2025.00085
url: https://www.scopus.com/pages/publications/105026336527?origin=resultslist
publisher: Institute of Electrical and Electronics Engineers Inc.
pages: 525--530
keywords:
- Collaborative computing
- edge computing
- large language model
- latency minimization
- task offloading
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
    proposed_justification: C1=1.0 (agentic/LLM signal in title); C2=1.0 (resource management signal); C3=1.0 (infra/cloud-edge signal)
    winning_category: null
    overrides_applied: []
    my_final_decision: Exclude
    my_justification: LLM as workload
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

# paper-2371 — Task Offloading for Collaborative Inference of LLM Agents at the Network Edge

## Metadata (from `/03-parse-references-metadata`)

Imported from `legacy/papers/` during v3.2.0 migration. Full machine-readable fields live in the frontmatter.

**Abstract**

> The deployment of large language models (LLMs) at the network edge has emerged as a critical paradigm for enabling low-latency, privacy-preserving AI services. However, resource-constrained user devices (e.g., smartphones, IoT endpoints) struggle to execute computationally intensive LLM inference tasks solely. Collaborative computing frameworks that offload subtasks to edge servers offer a promising solution but face challenges in balancing task completion latency, energy consumption, and dynamic network conditions. This paper addresses these challenges by proposing a two-stage optimization framework that jointly manages task offloading decisions and computational resource allocation, aiming to minimize the total task completion latency. Simulation results demonstrate that the proposed algorithm reduces total latency by 49.6% compared to random, greedy, and genetic baselines, exhibits robust adaptability across varying energy budgets, and achieves 97.8% energy utilization in resource-constrained edge environments. © 2025 IEEE.

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
- **agrees_with_regex:** False
- **divergence_reason:** None
- **model:** legacy-v2
- **timestamp:** 2026-05-09T00:00:00+00:00

### final

- **my_final_decision:** Exclude
- **my_justification:** "LLM as workload"
- **locked_at_iteration:** iter-0
- **locked_at:** 2026-05-09T00:00:00+00:00

---

## 05 — Abstract Screening

_(stage 05 not run for this paper — excluded at title screening)_

---

## 06 — Full-Text Screening

_(populated by `/screen --stage full-text`. PDF location: `raw/pdfs/paper-2371.pdf`)_

---

## 07 — Taxonomy

_(populated by `/05-code-taxonomy` after stage 06 lock.)_

---

## 08 — Analysis contributions

_(populated by `/06-analyze` after taxonomy lock.)_
