# Application Assessment Methodology

Common basis of the skills `/checkup:performance`, `/checkup:security`, `/checkup:privacy`, `/checkup:ai-readiness` and `/checkup:full`. Each skill ships its own criteria catalog in `references/checklist.md` (derived from the *Senior checklist for application assessment — v3*). This file defines **how to assess, score and report**, so that successive runs are comparable and the score rises as problems get fixed.

---

## 0. Language

- Detect the user's language from the invocation text (`$ARGUMENTS`) and from their most recent messages. Write the chat reply **and** the saved report in that language.
- If the language cannot be determined, use **English**.
- Translate the labels, headings and prose of the report template (§8) into that language. Keep unchanged: item IDs (`SEC-3.02`), file paths, code, commands, the classification names (Dangerous, Bronze, Silver, Gold, Platinum) and the four status keys and three severity keys defined below, which may be shown with a localized label next to the English key.
- Reports from earlier runs may be in another language. Compare them by item ID, never by wording.

## 1. Principles

- **Evidence, not declarations.** An item is compliant only with verifiable evidence in the repository: code, configuration, pipeline, test, script, IaC, report or versioned record. Statements from the team, "TODO" comments or intentions do not count.
- **Fixed severity.** Severity comes from the catalog and is **never** reclassified by the assessor. This keeps the score comparable between runs.
- **Same criterion every time.** Items are judged by the catalog text. If there is a previous report, the previous verdict only changes when the evidence changed, and the change is explained.
- **Read-only.** The assessment does not change code, run migrations, call production, run destructive scripts or run load tests against shared environments. Safe local commands (lint, typecheck, unit tests, build) may be executed.
- **No sensitive data in the report.** Secrets, tokens and personal data found are cited by location (file:line) and type, with the value masked.

## 2. Status of each item

| Status | When to use | Score |
|---|---|---|
| **Compliant** | All requirements of the criterion are met and there is enough evidence (see §3). | 100% of the weight |
| **Partially compliant** | A relevant part of the criterion is met, **or** the control exists but the required evidence is missing (e.g., the code exists but there is no test for a Critical/Important item), **or** it holds for only some components/routes. | 50% of the weight |
| **Non-compliant** | The control does not exist, exists only in documentation where the criterion requires an implementation, or no evidence could be found in the repository. | 0 |
| **N/A** | The item (or section) is conditional (*If: …*) and the condition provably does not apply. Requires a justification **and** evidence (e.g., a search with no hits, a stack inventory). | Excluded from the calculation |

Additional rules:

- The condition written in the title or at the start of a section (*If: …*) applies to **all** items in the section.
- **N/A without evidence = Non-compliant.**
- **External evidence.** Items that depend on something outside the repository (production data, observability dashboard, signed contract, DR exercise) are compliant only if there is a versioned record in the repository (e.g., `docs/`, `docs/assessments/evidence/`) or if the user gives the evidence path when invoking the skill. Otherwise mark **Non-compliant** with the tag `external evidence needed` and explain in the recommendation how to record the evidence.
- When in doubt between two statuses, choose the more conservative one and note the doubt on the item.

## 3. Minimum evidence by severity

| Severity | Minimum evidence for "Compliant" |
|---|---|
| Critical, Important | Implementation (code/config/pipeline) **and** proof that it works: automated test, CI gate, measurement or reproducible execution. Documentation only ⇒ at most Partial. |
| Minor | Implementation, or versioned documentation/record consistent with the code. |

For governance/process items (policies, plans, impact assessments, DR plans), the evidence is the versioned document **plus** a sign that it is used (execution record, review date, link to the code).

## 4. Weights and score

| Severity | Compliant | Partially compliant | Non-compliant |
|---|---|---|---|
| Critical | 3 | 1.5 | 0 |
| Important | 2 | 1 | 0 |
| Minor | 1 | 0.5 | 0 |

```
score = 100 × (Σ points earned) ÷ (Σ possible points of the applicable items)
possible points = 3 × critical + 2 × important + 1 × minor   (N/A items excluded)
```

Round the score to **one decimal place**. The report always shows the calculation table, so anyone can check the number.

## 5. Classification

| Score | Classification |
|---|---|
| 0 to < 25 | **Dangerous** |
| 25 to < 50 | **Bronze** |
| 50 to < 70 | **Silver** |
| 70 to < 90 | **Gold** |
| ≥ 90 | **Platinum** |

## 6. Comparison with previous runs

Before assessing, look for previous reports of the same pillar in `docs/assessments/`. If one exists:

1. Use the previous verdict as the starting point and re-assess **every** item with the current evidence.
2. Record in the **Evolution** section: previous score → current, items that improved, items that regressed (always with the cause) and items added to or removed from the catalog.
3. An item only gets worse if the evidence stopped existing or if the previous assessment was wrong; in that case, say explicitly that it is an assessment correction.

## 7. Where to save

- Per-pillar report: `docs/assessments/YYYY-MM-DD-<pillar>.md` at the root of the assessed repository (`<pillar>` ∈ `performance`, `security`, `privacy`, `ai-readiness`).
- Consolidated report: `docs/assessments/YYYY-MM-DD-full-assessment.md`.
- If a file with the same name already exists, add a suffix `-2`, `-3`… (never overwrite history).
- Do not commit automatically: follow the commit rules of the assessed repository.
- If the project has no `docs/` folder, create `docs/assessments/`. If the user explicitly asks not to save files, only show the report in the chat.

## 8. Report format (per pillar)

The **score is the first piece of information** in the report and the **classification comes right after**. Use exactly this order (translating the labels per §0):

````markdown
# Score: 63.4 / 100
## Classification: Silver

# <Pillar> Assessment — <repository name>

| Field | Value |
|---|---|
| Date | YYYY-MM-DD |
| Assessed commit | `<short sha>` (branch `<branch>`) |
| Catalog | application-assessment v3 — <N> items (<N applicable>, <N N/A>) |
| Scope | <detected stack, assessed components, what was left out> |
| Previous run | <file and previous score, or "first run"> |

## Summary

| Severity | Compliant | Partial | Non-compliant | N/A | Points earned / possible |
|---|---:|---:|---:|---:|---:|
| Critical | | | | | x / y |
| Important | | | | | x / y |
| Minor | | | | | x / y |
| **Total** | | | | | **X / Y = score** |

Main risks (3–5 lines, in business language).

## Evolution
<only if there is a previous run: previous score → current, improvements, regressions>

## 1. Non-compliant items

### 1.1 Critical
### 1.2 Important
### 1.3 Minor

## 2. Partially compliant items

### 2.1 Critical
### 2.2 Important
### 2.3 Minor

## 3. Compliant items
| ID | Item | Severity | Evidence |

## 4. N/A items
| ID | Item | Justification | Evidence of non-applicability |

## 5. Suggested backlog
| Priority | ID | Task title | Severity | Effort | Score gain |

## 6. Methodology and limitations
<commands run, what could not be verified, external evidence needed>
````

### 8.1 Format of each finding (non-compliant and partial)

Each item that is not fully compliant is written as a pentest-style finding, with enough information to become a task without further investigation:

```markdown
#### PERF-4.07 · Timeouts per dependency — Critical · Non-compliant

- **Criterion:** <faithful summary of the catalog criterion>
- **Situation found:** <what exists and what is missing, objectively>
- **Reason for the status:** <why it is not compliant/partial, citing the rule in §2/§3>
- **Evidence:** `src/services/Email.service.ts:42` — `fetch(url)` without `signal`/timeout; search `rg "fetch\(" src/` → 7 hits, 5 without timeout (list below)
- **Affected components:** <files, routes, services>
- **Impact / risk:** <technical and business consequence; exploitation or failure scenario>
- **Recommendation:** <step-by-step fix at the right boundary, with a code example when useful>
- **Retest criterion:** <what must be true for the item to become Compliant on the next run — e.g., test X exists and passes; gate Y in CI>
- **Estimated effort:** S (≤ 1 day) | M (≤ 1 week) | L (> 1 week)
- **References:** <catalog ID + external standard: ASVS, OWASP, LGPD article, Core Web Vitals…>
```

For Partial items, make explicit **what is already met** and **what is missing**.

### 8.2 Suggested backlog

Order by: severity (Critical → Minor), then status (Non-compliant before Partial), then effort (S before L). The **Score gain** column shows how many percentage points the score rises if the item becomes Compliant (`missing weight ÷ possible points × 100`). Group items that are solved by the same change and say so in the task.

## 9. Consolidated report (`/checkup:full`)

Same order: **overall score** first, **classification** right after. The overall score uses the same formula over **all** applicable items of the four pillars (sum of points earned ÷ sum of possible points), not the average of the scores. Then: a table per pillar (score, classification, open criticals), cross-cutting risks (findings that appear in more than one pillar, e.g., logs with PII in SEC-6.08, PERF-2.14 and PRIV-12.06), a deduplicated consolidated backlog and links to the four per-pillar reports.
