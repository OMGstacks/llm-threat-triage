# openai-tia-prep

[![CI](https://github.com/OMGstacks/openai-tia-prep/actions/workflows/ci.yml/badge.svg)](https://github.com/OMGstacks/openai-tia-prep/actions/workflows/ci.yml)
[![tests](https://img.shields.io/badge/tests-83%20passing-brightgreen.svg)](projects/llm-log-triage/tests)
[![Python](https://img.shields.io/badge/python-3.10%2B-blue.svg)](https://www.python.org/)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](LICENSE)
[![OWASP LLM Top 10 (2025)](https://img.shields.io/badge/OWASP-LLM%20Top%2010%20(2025)-000000.svg)](reference/owasp-llm-top-10.md)
[![MITRE ATLAS](https://img.shields.io/badge/MITRE-ATLAS-cc0000.svg)](reference/mitre-atlas.md)

A portfolio repo built to demonstrate readiness for a **Technical Intelligence Analyst (TIA)** role focused on frontier-AI threats — investigating how large language models (not networks) break: prompt injection, jailbreaks, sensitive-data leakage, and other novel harms, using **Python + SQL**.

I'm a security / incident-management professional transitioning into frontier-AI threat intelligence. This repo is the proof of work: a real, tested pipeline that ingests **messy LLM interaction logs**, detects adversarial-ML attack patterns mapped to industry frameworks, and answers investigative questions with SQL — the exact day-to-day shape of the TIA job.

<picture>
  <source media="(prefers-color-scheme: dark)" srcset="docs/architecture-dark.png">
  <img alt="LLM Log Triage detection pipeline: messy logs → normalize → events → 9 detectors → detections → SQL/report, all mapped to OWASP LLM Top 10 + MITRE ATLAS" src="docs/architecture.png">
</picture>

> 📄 One-page case study (PDF): [`docs/llm-log-triage-case-study.pdf`](docs/llm-log-triage-case-study.pdf)

---

## Repository map

```
openai-tia-prep/
├── README.md                      ← you are here
├── projects/
│   └── llm-log-triage/            ← FLAGSHIP: messy-log → detection → SQL triage pipeline
│       ├── src/                    generate_logs, normalize, detectors, db, pipeline, cli
│       ├── sql/                   schema.sql + analysis/01..07_*.sql (7 analyst queries)
│       ├── data/                  sample_logs.jsonl (800 messy synthetic records)
│       ├── tests/                 83 passing pytest tests
│       └── Makefile               make demo | test | queries | data | clean
├── reference/
│   ├── owasp-llm-top-10.md        OWASP LLM Top 10 (2025) reference
│   ├── mitre-atlas.md             MITRE ATLAS technique reference
│   └── glossary.md                adversarial-ML / LLM-security glossary
├── red-team/
│   ├── README.md                 red-team index + offline quickstart
│   ├── pyrit/                     Microsoft PyRIT (runnable offline probe)
│   ├── garak/                     NVIDIA garak scan config + commands
│   ├── promptfoo/                 promptfoo redteam config
│   └── local_redteam_harness.py  offline: attacks graded by our own detectors
└── docs/                         career package (apply · interview · do the job)
    ├── application/              cover letter, résumé + LinkedIn copy
    ├── interview/               demo script, printable cheat-sheet (+PDF)
    ├── playbook/                day-to-day analyst runbook, 30-60-90 plan
    ├── interview-prep.md        the dossier (repo→JD, 18 Q&As, STAR, study plan)
    └── *-case-study.pdf         one-page PDF case study
```

| Area | What it is |
|------|-----------|
| [`projects/llm-log-triage/`](projects/llm-log-triage/) | **Flagship.** End-to-end, tested triage pipeline (details below). |
| [`reference/`](reference/) | Framework references — [OWASP LLM Top 10 (2025)](reference/owasp-llm-top-10.md), [MITRE ATLAS](reference/mitre-atlas.md), [glossary](reference/glossary.md). |
| [`red-team/`](red-team/) | Offensive-tooling scaffolds: [PyRIT](red-team/pyrit/), [Garak](red-team/garak/), [Promptfoo](red-team/promptfoo/), + an offline [harness](red-team/local_redteam_harness.py). |
| [`docs/`](docs/) | **Career package** — [apply · interview · do the job](docs/README.md): cover letter & résumé, demo script & cheat-sheet, and a day-to-day [analyst runbook](docs/playbook/analyst-runbook.md). |

---

## Flagship: LLM Log Triage

A pipeline that takes **realistically messy** LLM interaction logs (malformed timestamps, missing IDs, mixed roles and channels) and turns them into a queryable triage database: normalize → detect → store → analyze. It flags **OWASP LLM01 prompt injection** and eight other LLM attack classes, mapping every finding to both **OWASP LLM Top 10 (2025)** and **MITRE ATLAS** techniques.

### Quickstart

Run from `projects/llm-log-triage/`:

```bash
# 1. Generate 800 messy synthetic log records
python -m src.cli generate --rows 800 --out data/sample_logs.jsonl

# 2. Run the full pipeline (normalize → detect → load into SQLite)
python -m src.cli run --db triage.db --logs data/sample_logs.jsonl

# 3. Ask an investigative question with SQL
python -m src.cli query --db triage.db --sql sql/analysis/01_attack_overview.sql

# 4. Run the test suite
python -m pytest -q
```

Or use the Makefile:

```bash
make demo      # generate data + run pipeline + print the attack overview
make test      # run the 83-test suite
make queries   # run all sql/analysis/*.sql queries
make clean
```

### Verified demo output

Real numbers from a clean run (`make demo`):

```
800   events ingested
156   unparseable timestamps handled (normalized, not dropped)
63    missing event IDs synthesized
150   events flagged  →  39 critical · 96 high · 15 medium (by worst finding)
217   findings  →  61 critical · 126 high · 25 medium · 5 info
```

Findings by OWASP category:

| OWASP (2025) | Category | Findings |
|---|---|---|
| LLM01 | Prompt Injection | **132** |
| LLM05 | Improper Output Handling | 29 |
| LLM07 | System Prompt Leakage | 25 |
| LLM02 | Sensitive Information Disclosure | 22 |
| LLM06 | Excessive Agency | 9 |

Top flagged users: `user-5132` (78) · `user-3472` (65) · `user-2359` (56).

The pipeline does **not** drop malformed records — 156 bad timestamps and 63 missing IDs are recovered and carried through, because in real incident work the broken rows are often where the attack hides.

### Detector inventory

All nine detectors live in [`src/detectors.py`](projects/llm-log-triage/src/detectors.py) (`ALL_DETECTORS`) and are exercised by the test suite. Each finding is dual-mapped to OWASP + ATLAS.

| # | Detector | OWASP (2025) | MITRE ATLAS | Severity | What it catches |
|---|----------|--------------|-------------|----------|-----------------|
| 1 | `direct_prompt_injection` | LLM01 Prompt Injection | AML.T0051.000 LLM Prompt Injection: Direct | high | USER messages with `"ignore previous instructions"`, `"disregard system prompt"`, `"new instructions:"`, `"override safety"`. |
| 2 | `indirect_prompt_injection` | LLM01 Prompt Injection | AML.T0051.001 LLM Prompt Injection: Indirect | **critical** | Fires **only on untrusted sources** (rag/tool/document/email/web/plugin): HTML-comment instructions, `"Assistant: please ignore…"`, `"when you read this, do…"`. |
| 3 | `jailbreak_persona_override` | LLM01 Prompt Injection | AML.T0054 LLM Jailbreak | high | Persona/roleplay bypass — DAN, "developer mode", "no restrictions", "act as uncensored". |
| 4 | `system_prompt_extraction` | LLM07 System Prompt Leakage | AML.T0056 LLM Meta Prompt Extraction | medium | USER probing to reveal the hidden system prompt — "what is your system prompt", "repeat the words above". |
| 5 | `excessive_agency_probe` | LLM06 Excessive Agency | AML.T0053 AI Agent Tool Invocation | high | Coercing connected tools/plugins into destructive or unintended actions. |
| 6 | `encoded_injection_payload` | LLM01 Prompt Injection | AML.T0051.001 (Indirect) | **critical** | Decodes base64/hex blobs from USER + untrusted sources, then re-runs injection checks on the decoded text (also emits `suspicious_encoded_blob`, medium). |
| 7 | `sensitive_information_disclosure` | LLM02 Sensitive Information Disclosure | AML.T0057 LLM Data Leakage | high/critical | Scans ASSISTANT output for secrets/PII: OpenAI/AWS/Google/Slack/Stripe/GitLab/GitHub keys, bearer tokens, JWTs, private keys, SSNs, Luhn-valid credit cards, emails. |
| 8 | `sensitive_information_inbound` | LLM02 Sensitive Information Disclosure | AML.T0057 LLM Data Leakage | high | Secrets arriving via **untrusted inbound content** (RAG/tool) — leakage entering, not just leaving. |
| 9 | `improper_output_handling` | LLM05 Improper Output Handling | AML.T0024 Exfiltration via AI Inference API | high | Markdown-image/link and bare-URL exfil plus active content (`<script>`, `onerror=`, `javascript:`). |

The **untrusted-source gate** on detectors #2 and #8 is deliberate: indirect injection (and inbound leakage) is only a finding when the content arrives through a channel the model should not trust (retrieved documents, tool output, email, web). The same text in a direct USER turn is a different (lower) class of event — channel provenance is part of the verdict.

Beyond the per-detector logic, the engine adds **evasion-resistant matching** (NFKC normalization + zero-width stripping + spaced-letter and leetspeak folding), **base64/hex payload decoding** before re-checking for injection, **Luhn validation** on credit-card hits, **expanded secret formats** (Google `AIza`, Slack `xox`, Stripe `sk_live`, GitLab `glpat`, GitHub PAT, and generic `key=`-high-entropy), and a **per-event severity rollup** so each event carries a verdict equal to its worst finding.

### Example analysis query

```sql
-- sql/analysis/01_attack_overview.sql — findings by OWASP category and severity
SELECT owasp_id,
       owasp_name,
       SUM(CASE WHEN severity = 'critical' THEN 1 ELSE 0 END) AS critical,
       SUM(CASE WHEN severity = 'high'     THEN 1 ELSE 0 END) AS high,
       COUNT(*)                                                AS total_findings,
       COUNT(DISTINCT event_id)                                AS distinct_events
FROM v_triage                              -- detections joined to event context
GROUP BY owasp_id, owasp_name
ORDER BY critical DESC, high DESC, total_findings DESC;
```

Seven analyst queries ship in [`sql/analysis/`](projects/llm-log-triage/sql/analysis/) (`01` … `07`): attack overview, repeat offenders, injection timeline, indirect-injection-via-RAG, output exfil/disclosure, [`06_consumption_anomaly.sql`](projects/llm-log-triage/sql/analysis/06_consumption_anomaly.sql) (a pure-SQL **OWASP LLM10:2025 (Unbounded Consumption)** outlier check), and [`07_session_escalation.sql`](projects/llm-log-triage/sql/analysis/07_session_escalation.sql) (**multi-turn / cross-event correlation** — sessions that pair an injection with a data-exposure event).

---

## Frameworks I speak

- **OWASP LLM Top 10 (2025)** — the canonical taxonomy for LLM application risk. Every detector maps to an `LLMxx` ID. Reference: [`reference/owasp-llm-top-10.md`](reference/owasp-llm-top-10.md).
- **MITRE ATLAS** — the adversarial-ML threat-technique matrix (the ATT&CK analogue for ML systems). Every finding carries an `AML.Txxxx` technique ID. Reference: [`reference/mitre-atlas.md`](reference/mitre-atlas.md).
- **Glossary** — working definitions for direct vs. indirect injection, jailbreak vs. prompt extraction, excessive agency, and output-handling exfil: [`reference/glossary.md`](reference/glossary.md).

Dual-mapping every finding to both frameworks is intentional: OWASP frames the *application risk*, ATLAS frames the *adversary technique*. A triage analyst needs both vocabularies to communicate across security and ML teams.

**OWASP coverage (honest).** The flagship has at least partial coverage of **LLM01, LLM02, LLM05, LLM06, LLM07** (detectors) and **LLM10** (the consumption-anomaly SQL query); multi-turn / cross-event correlation is handled *analytically* by [`07_session_escalation.sql`](projects/llm-log-triage/sql/analysis/07_session_escalation.sql). Not yet covered — kept here as an explicit roadmap, not a claim: **LLM03** Supply Chain, **LLM04** Data/Model Poisoning, **LLM08** Vector/Embedding Weaknesses, **LLM09** Misinformation, and *real-time* (streaming) multi-turn detection.

---

## Skills demonstrated

- **Messy-data ingestion** — normalizing real-world-grade logs: 156 unparseable timestamps recovered, 63 missing IDs synthesized, zero records silently dropped. ([`src/normalize.py`](projects/llm-log-triage/src/normalize.py))
- **Detection engineering** — nine independent detectors with channel-aware logic, evasion-resistant matching, encoded-payload decoding, severity tiers, and false-positive-conscious gating. ([`src/detectors.py`](projects/llm-log-triage/src/detectors.py))
- **SQL analytics** — schema design plus a library of investigative queries that answer "what attacked us, how badly, and through which channel" — now including a pure-SQL unbounded-consumption anomaly check (LLM10). ([`sql/`](projects/llm-log-triage/sql/))
- **Red-team tooling fluency** — scaffolding for PyRIT, Garak, and Promptfoo, the standard LLM offensive/eval stack. ([`red-team/`](red-team/))
- **Framework fluency** — OWASP LLM Top 10 (2025) + MITRE ATLAS applied, not just cited.
- **Testing discipline** — 83 passing pytest tests covering normalization, every detector, the self-review hardening, DB load, and the end-to-end pipeline.

---

## Status / roadmap

| Area | Status |
|------|--------|
| `projects/llm-log-triage` (pipeline, detectors, SQL, tests) | ✅ Built, working, 83 tests passing |
| `reference/` (OWASP, ATLAS, glossary) | ✅ Written |
| `docs/interview-prep.md` | ✅ Written |
| `red-team/` (PyRIT / Garak / Promptfoo) | 🚧 Scaffolded — runnable offline harness + PyRIT probe; Garak/Promptfoo configs |
| CI workflow | ✅ Built — test suite + end-to-end smoke test on push (Python 3.10–3.12) |

**Next:** wire the red-team scaffolds into runnable eval suites and feed their transcripts back through the triage pipeline, closing the loop from *generate attacks* → *detect* → *analyze*.
