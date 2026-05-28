---
name: ship:audit:tests
description: "Ship Audit: project-wide test coverage analysis — correlates AC/REQ from spec with existing tests using Jaccard similarity, gate PASS/WARN."
argument-hint: ""
allowed-tools: Read, Glob, Grep, Bash, Agent, mcp__linear-server__*
user-invocable: true
model: "sonnet"
context: fork
agent: general-purpose
---

<!-- IMPL-REQ-01: read Test Scope from ship/config.md to filter enabled/disabled layers -->
<!-- IMPL-REQ-02: 2-agent parallel structure — Agent A discovers AC/REQ from spec, Agent B discovers tests from codebase -->
<!-- IMPL-REQ-03: Jaccard similarity correlation (same algorithm as /ship:analyze) per enabled layer -->
<!-- IMPL-REQ-04: gate logic — HIGH findings → WARN (not FAIL); no findings → PASS -->
<!-- IMPL-REQ-05: output covers both Linear mode (linear-audit-template.md) and Local mode (ship/audits/tests-<date>.md) -->
<!-- IMPL-REQ-06: strictly read-only — must NOT create, modify, or delete any test files -->

# Ship Audit — Test Coverage

You are the Ship test coverage audit agent. Your mission is to conduct a project-wide analysis of how well the existing test suite covers the acceptance criteria (AC-XX) and requirements (REQ-XX) defined in the spec. Read `ship/config.md` for Test Scope configuration and adapt all analysis accordingly.

This audit is **strictly read-only**: do NOT create, modify, or delete any test files.

---

## Determine storage mode

See # Storage Mode

Read `ship/config.md` and check the `Linear Integration` section:
- If `Configured: yes` → **Linear mode** (artifacts live in Linear)
- If `Configured: no` → **Local mode** (artifacts live in `ship/changes/`).

---

## Process

### 1. Load context

See # Load Artifacts

Matrix of artifact loading by context and storage mode:

| Context | Linear mode | Local mode |
|---------|------------|------------|
| **Spec** (`/ship:spec`) | `get_issue` + `list_comments` + linked documents | free text (no prior artifacts to load) |
| **Pipeline phase** (develop, perf, security, review) | `get_issue` + `get_document(Design)` + optionally `get_document(Proposal)` | `proposal.md` + `design.md` + `tasks.md` |
| **Orchestration** (run, homolog) | `get_issue` + `list_documents` → `get_document(Proposal)` + `get_document(Design)` | `proposal.md` + `design.md` + `tasks.md` + `report.md` |
| **PR** (`/ship:pr`) | `get_issue` + `get_document(Proposal, Design)` (via cache if available, else `list_documents`) + `list_comments` | `proposal.md` + `design.md` + `tasks.md` + `report.md` |
| **Audit** | `ship/config.md` only | `ship/config.md` only |

All contexts also read `ship/config.md` for stack and conventions.

**Pipeline phases only** (perf, security, review): after loading artifacts, run `git diff` to get the full diff of new/modified code — this is the primary analysis input..

Read `ship/config.md` and extract:
- `Test Scope` section: enabled/disabled status for `unit`, `integration`, `e2e` layers.
- If the `Test Scope` section is absent → treat all three layers as `enabled`.
- `Linear Integration` field to determine storage mode.

---

### 2. Launch 2 agents in parallel

Use the **Agent** tool to launch **2 agents in parallel in a SINGLE call**.

---

#### Agent A — AC/REQ Discovery from Spec

**Goal:** Extract all REQ-XX requirements and AC-XX acceptance criteria from spec documents.

**Linear mode:**
1. Call `mcp__linear-server__list_documents` to find Proposal documents linked to the project.
2. Call `mcp__linear-server__get_document` for each Proposal document.
3. Parse all lines matching `REQ-\d+` and `AC-\d+`.

**Local mode:**
1. Glob `ship/changes/**/proposal.md`.
2. Read each file and parse REQ-XX and AC-XX entries.

**Extraction rules:**
- A **requirement** matches `REQ-\d+` followed by a description (e.g., `REQ-01: User can log in via OAuth`).
- An **acceptance criterion** matches `AC-\d+` followed by a description (e.g., `AC-03: Login must complete in < 2s`).
- A **scenario** is a Gherkin `Scenario`/`Scenario Outline` tagged `@SC-\d+`, `@AC-\d+`, and one layer tag (`@unit`|`@integration`|`@e2e`). In Linear mode the full Gherkin lives in the issue body (`get_issue`); the Proposal carries only a compact Scenario Index. In Local mode it lives in the `#### Scenarios` block of `tasks.md`. Apply the **Gherkin-aware keyword extractor from `/ship:analyze`** (When+Then+Examples headers only; exclude Given/Background, Gherkin keywords, `@tags`, table pipes, `<placeholders>`). Record `{ id, ac, layer, keywords[] }`.
- If no markers are found, infer from functional requirements / acceptance criteria sections and assign IDs sequentially.
- For each item, build a keyword set: split identifier tokens (camelCase → `camel`, `case`; snake_case → `snake`, `case`; PascalCase → `Pascal`, `Case`). Lowercase all tokens.
- **Backward compatibility:** if the spec has no `@SC-\d+` scenarios, the scenario list is empty and this audit behaves exactly as before this feature (AC/REQ-only).

**Output:** Structured list of `{ id, description, keywords[] }` for each REQ-XX and AC-XX found, plus `{ id, ac, layer, keywords[] }` for each SC-XX.

---

#### Agent B — Test Discovery from Codebase

**Goal:** Discover all existing test files and extract their test names.

**Discovery globs (project-wide):**
- `**/*.test.ts`
- `**/*.spec.ts`
- `**/*.test.js`
- `**/*.spec.js`
- `**/__tests__/**/*`

Exclude `node_modules/`, `.cache/`, `dist/`, `build/` directories.

**For each test file:**
1. Extract `describe(`, `it(`, and `test(` block names/strings.
2. Determine the test layer based on file path and naming conventions:
   - Files in `__tests__/unit/`, `*.unit.test.*`, or top-level `*.test.*` → `unit`
   - Files in `__tests__/integration/`, `*.integration.test.*`, `*.e2e-spec.*` (NestJS) → `integration`
   - Files in `__tests__/e2e/`, `*.e2e.test.*`, Cypress/Playwright files → `e2e`
   - If layer is ambiguous → `unit` (conservative)
3. Check for explicit coverage markers: `TEST-REQ-XX`, `TEST-AC-XX`, or `TEST-SC-XX` in comments or test names.
4. Build a keyword set per test: split test name tokens + file path tokens. Lowercase all.

**Output:** Structured list of `{ file, layer, markers[], testNames[], keywords[] }` for each test file.

---

### 3. Correlate AC/REQ ↔ tests (per layer)

After both agents complete, run correlation for each enabled Test Scope layer.

**Algorithm:** Use the same Jaccard similarity algorithm as `/ship:analyze` to compute confidence scores. Reference the `ship:analyze` skill (invokable via Skill tool) for the exact algorithm.

**Confidence assignment per AC/REQ item:**

| Condition | Confidence |
|-----------|-----------|
| Explicit marker `TEST-AC-XX` or `TEST-REQ-XX` found in a test in this layer | 1.0 |
| Jaccard similarity >= 0.5 between AC keywords and any test keywords in this layer | 0.5–1.0 (proportional) |
| Jaccard similarity 0.3–0.49 | 0.3–0.49 (uncertain) |
| No test match (Jaccard < 0.3) | 0.0 |

**Scenario → test correlation:** apply the SC→test tier from `/ship:analyze` Step 3 for each `SC-XX`, evaluating **only the single layer named in its `@layer` tag** (1.0 if `TEST-SC-XX` marker; 0.8 if a `TEST-AC`/`TEST-REQ` marker for its parent AC; else Jaccard within that layer). Skip the scenario tier entirely if the spec has no `@SC-XX`.

**Layer handling:**
- **Enabled layer:** run full correlation; produce findings per uncovered/uncertain AC and per uncovered/uncertain SC.
- **Disabled layer:** mark all ACs and SCs as `disabled (not evaluated)` — do NOT produce findings; does not affect gate.

**Finding classification (enabled layers only):**

| Condition | Severity |
|-----------|----------|
| Confidence = 0.0 (uncovered AC **or SC** in enabled layer) | HIGH |
| Confidence 0.3–0.49 (uncertain coverage in enabled layer) | MEDIUM |
| Confidence >= 0.5 | No finding — covered |

Produce findings per # Ship — Report Templates

Canonical source for all reporting templates used across Ship command files.
Import by reference: `See ship/report-templates.md#<anchor>`.

---

## Finding Entry {#finding-entry}

Base template. All domains share this structure.

```markdown
### [SEVERITY] <Descriptive Title>
- **Category:** <domain-specific — see extensions below>
- **File:** <path>:<line>
- **Description:** <what the problem is>
- **Impact:** <estimated impact>
- **Suggestion:** <specific fix with code example if helpful>
```

> For severity definitions per domain (critical / high / medium / low), see [`ship/patterns/severity.md`](patterns/severity.md).

### Domain extensions

Fields that **replace or add to** the base template per domain:

**Performance pipeline** (`perf.md`) — categories: `DB | ALGO | MEM | NET | BUNDLE | RENDER | ARCH`
> No extra fields. Uses base template as-is.

**Security pipeline** (`security.md`) — categories: `INJ | AUTH | AUTHZ | DATA | CFG | LOGIC`
```markdown
- **OWASP:** <e.g., A01:2021 Broken Access Control>                   # adds
- **CWE:** <e.g., CWE-639 Authorization Bypass Through User-Controlled Key>  # adds
- **Vector:** <how this could be exploited — 1-2 sentences>           # replaces Description
- **Impact:** <what an attacker would gain>                            # keeps (same field, specific guidance)
- **Proof of Concept:** <example malicious request/payload when applicable>  # adds
- **Fix:** <specific code change with example>                         # replaces Suggestion
```

**Code Review pipeline** (`review.md`) — categories: `SOLID-S | SOLID-O | SOLID-L | SOLID-I | SOLID-D | DRY | KISS | CLEAN | CONSISTENCY | TEST`
```markdown
- **Principle:** <SOLID-* | DRY | KISS | CLEAN | CONSISTENCY | TEST>  # replaces Category
- **Problem:** <what's wrong and why it matters>                      # replaces Description
```

**Frontend audit** (`audit/frontend.md`) — categories: `NET | BUNDLE | LOAD | RENDER | JS | HYDRAT | IMG | FONT | MEM | 3P | ARCH`
(Next.js: `STRATEGY | BOUNDARY | CACHE | BUNDLE | STREAMING | IMG | FONT | MIDDLEWARE | BUILD | COLD | ARCH`)
```markdown
- **Metric affected:** LCP | INP | CLS | FCP | TTFB | TBT | First Load JS | Bundle size  # adds
- **Effort:** <Hours | Days | Weeks>                                   # adds
```

**Backend audit** (`audit/backend.md`) — categories: `DB | NET | CPU | MEM | CONC | CODE | CONF | ARCH`
```markdown
- **Effort:** <Hours | Days | Weeks>                                   # adds
- **Maintenance window:** <Yes | No>                                   # adds
```

**Security audit** (`audit/security.md`) — categories: `INJ | AUTH | AUTHZ | DATA | CFG | LOGIC | DEPS | PRIV`
```markdown
- **OWASP:** <e.g., A01:2021 Broken Access Control>                   # adds
- **CWE:** <e.g., CWE-639>                                            # adds
- **Vector:** <how this could be exploited — 1-2 sentences>           # replaces Description
- **Impact:** <what an attacker or data breach would yield>            # keeps
- **Proof of Concept:** <example malicious request/payload for critical/high findings>  # adds
- **Fix:** <specific code change with example using the project's patterns>  # replaces Suggestion
- **Effort:** <Hours | Days | Weeks>                                   # adds
- **Urgent deploy:** <Yes | No>                                        # adds
```

**Database audit** (`audit/database.md`) — categories: `MDL | IDX | QRY | WRT | CFG | SCH | PERF`
```markdown
- **Collection/Table:** <name(s) affected>                             # adds (before File)
- **Effort:** <Hours | Days | Weeks>                                   # adds
- **Requires migration:** <Yes | No>                                   # adds
```

---

## Finding JSON Schema {#finding-schema}

Base schema. Applies to all domains.

```json
{
  "severity": "critical|high|medium|low",
  "category": "<domain-specific>",
  "filePath": "src/path/to/file.ts",
  "line": 42,
  "title": "...",
  "description": "...",
  "suggestion": "..."
}
```

### Schema extensions by domain

**Security pipeline / Security audit** — additional fields:
```json
{
  "owasp": "A03:2021 Injection",
  "cwe": "CWE-89"
}
```

**Frontend audit** — additional fields:
```json
{
  "metricAffected": "LCP|INP|CLS|FCP|TTFB|TBT|First Load JS|Bundle size",
  "effort": "Hours|Days|Weeks"
}
```

**Backend audit** — additional fields:
```json
{
  "effort": "Hours|Days|Weeks",
  "maintenanceWindow": true
}
```

**Database audit** — additional fields:
```json
{
  "collectionOrTable": "<name>",
  "effort": "Hours|Days|Weeks",
  "requiresMigration": true
}
```

---

## Drift Analysis Findings {#drift-findings}

Used by `/ship:analyze` phase. Extends the base Finding Entry with drift-specific fields.

### Finding Entry Format

| Field | Type | Description |
|-------|------|-------------|
| Severity | critical \| high \| medium \| low | See severity.md — Drift domain |
| Category | IMPL \| TEST \| SCENARIO \| DRIFT | IMPL = implementation gap, TEST = AC test coverage gap, SCENARIO = scenario coverage gap, DRIFT = low-confidence match |
| File | path or — | Source file where the issue was detected |
| Description | string | What is missing or mismatched |
| Suggestion | string | How to fix: implement the req, add a test, or add an override marker |
| Requirement ID | REQ-XX or — | Linked requirement, if applicable |
| Criterion ID | AC-XX or — | Linked acceptance criterion, if applicable |
| Scenario ID | SC-XX or — | Linked scenario, if applicable |
| Layer | unit \| integration \| e2e or — | Scenario's tagged test layer (SCENARIO findings only) |

### Severity Mapping

| Severity | Trigger | Gate Impact |
|----------|---------|-------------|
| critical | Requirement with 0 code matches | FAIL |
| high | Requirement confidence < 0.5 | FAIL |
| medium | Acceptance criterion with 0 test matches | WARN |
| medium | Scenario with 0 test matches in its tagged enabled layer | WARN |
| low | Criterion or scenario confidence < 0.5 | PASS |

### Example Reports

#### PASS
`✓ Análise de Drift: PASS (0 gaps) — [ver relatório completo](link)`

#### WARN (medium findings)
```
### [MEDIUM] Critério sem cobertura de teste: AC-03
- **Categoria:** TEST
- **Descrição:** O critério de aceitação "AC-03" não possui testes identificados.
- **Sugestão:** Crie um teste para o critério AC-03 ou adicione o marcador TEST-AC-03.
```

#### FAIL (critical findings)
```
### [CRITICAL] Requisito não implementado: REQ-05
- **Categoria:** IMPL
- **Descrição:** O requisito "REQ-05: Cache invalidation" não possui implementação identificada.
- **Sugestão:** Implemente o requisito REQ-05 ou adicione o marcador IMPL-REQ-05 no arquivo.
```

### JSON Schema

```json
{
  "severity": "critical | high | medium | low",
  "category": "IMPL | TEST | DRIFT",
  "title": "string",
  "description": "string",
  "suggestion": "string",
  "requirementId": "REQ-XX | null",
  "criterionId": "AC-XX | null",
  "filePath": "string | null",
  "line": "number | null"
}
```

---

## Quality Report {#quality-report}

Consolidated from `homolog.md`. Used in both Linear mode (as issue comment) and Local mode (as `report-<task-id>.md`).

Each findings section is rendered using the lazy-load algorithm — see ---
# Lazy-Load Findings Algorithm

Canonical algorithm for consolidating phase findings into acceptance and quality reports.
Referenced by `homolog.md` (both Linear and Local mode).

`phase-status.md` is the canonical gate index — it is **always** read first (in step 1.4 of homolog's "Load all artifacts"). The algorithm below assumes it is already in memory; do NOT re-read it.

---

## Algorithm

`phase-status.md` has structured columns: `Phase | Run | Timestamp | Files | Gate | Critical | High | Medium | Low | Notes`.

For each phase (perf, security, review):

1. **Look up the gate** from the `phase-status.md` table — take the **last row** for that phase (most recent run).
   - If the phase has no row in `phase-status.md`: treat as `FAIL` (safe default)
2. **Branch on gate status:**

### If gate = PASS

Emit a single summary line — do **NOT** open the findings markdown:

```
✓ <Phase>: PASS (0 critical/high findings) — [see full report](<link or path>)
```

Translate the user-facing text to `Artifact language` from `ship/config.md`.

### If gate = WARN or FAIL

Open the findings markdown file for this phase, then filter before embedding:
- Include all findings with severity `critical`, `high`, or `medium` in full
- For `low` severity findings: replace the full list with a single aggregated line:
  `+ N low-severity findings — [see full report](<link or path>)`
- Translate the aggregated line text to `Artifact language` from `ship/config.md`

## Link/reference (always required)

- **Linear mode:** URL of the Linear comment containing the full findings; if the comment has not been posted yet (it is posted in step 6 of `homolog.md`), write `(full report will be attached to this issue)`
- **Local mode:** relative path `ship/changes/<feature>/report-<task-id>.md`.

```markdown
# Quality Report — <Feature / Task Title>

## Summary
| Phase | Gate | Critical | High | Medium | Low |
|-------|------|----------|------|--------|-----|
| Performance | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |
| Security | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |
| Code Review | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |

## Performance Findings
<!-- gate = PASS: one-line summary only -->
✓ Performance: PASS (0 critical/high findings) — [see full report](<link or path>)

<!-- gate = WARN or FAIL: critical/high/medium in full; low aggregated -->
### [HIGH] <Title>
<finding in Finding Entry format>

### [MEDIUM] <Title>
<finding in Finding Entry format>

+ 3 low-severity findings — [see full report](<link or path>)

## Security Findings
<!-- same lazy-load pattern as Performance -->

## Code Review Findings
<!-- same lazy-load pattern as Performance -->

## Fixes Applied
<list of fixes applied automatically during the pipeline, or "None.">

## Homologation
- [ ] User has reviewed all changes
- [ ] User has verified acceptance criteria
- [ ] User approves for PR
```

---

## Acceptance Report {#acceptance-report}

Consolidated from `homolog.md`. Presented to the user during the acceptance phase.

```markdown
## Acceptance Report — <Feature / Task Title>

### What was implemented
<3-5 bullet points summarizing what was built>

### Technical decisions
<Key decisions from the Design document>

### Tests
- Unit tests: X created, all passing
- Integration tests: Y created, all passing
- E2E tests: Z created (or "not applicable")

### Quality Gates
| Phase | Status | Details |
|-------|--------|---------|
| Performance | PASS / WARN / FAIL | X findings |
| Security | PASS / WARN / FAIL | X findings |
| Code Review | PASS / WARN / FAIL | X findings |

### Pending warnings
<Medium-level findings accepted by the user, or "None.">

### Acceptance criteria — Manual verification
<From the issue/proposal — for the user to check off>
- [ ] Criterion 1
- [ ] Criterion 2
```

---

## PR Body Template {#pr-body}

Extracted from `pr.md`. Used by `/ship:pr` to build the pull request description via `gh pr create`.

```markdown
## Summary
<From Proposal: why this change was made — 2-3 sentences>

## Changes
<From Design: architecture overview + key technical decisions>

### Files Changed
<From Design: files created and modified>

## Test Results
| Type | Count | Status |
|------|-------|--------|
| Unit | <n> | Passing |
| Integration | <n> | Passing |
| E2E | <n> | Passing / N/A |

## Quality Report
<!-- lazy-load algorithm: see ---
# Lazy-Load Findings Algorithm

Canonical algorithm for consolidating phase findings into acceptance and quality reports.
Referenced by `homolog.md` (both Linear and Local mode).

`phase-status.md` is the canonical gate index — it is **always** read first (in step 1.4 of homolog's "Load all artifacts"). The algorithm below assumes it is already in memory; do NOT re-read it.

---

## Algorithm

`phase-status.md` has structured columns: `Phase | Run | Timestamp | Files | Gate | Critical | High | Medium | Low | Notes`.

For each phase (perf, security, review):

1. **Look up the gate** from the `phase-status.md` table — take the **last row** for that phase (most recent run).
   - If the phase has no row in `phase-status.md`: treat as `FAIL` (safe default)
2. **Branch on gate status:**

### If gate = PASS

Emit a single summary line — do **NOT** open the findings markdown:

```
✓ <Phase>: PASS (0 critical/high findings) — [see full report](<link or path>)
```

Translate the user-facing text to `Artifact language` from `ship/config.md`.

### If gate = WARN or FAIL

Open the findings markdown file for this phase, then filter before embedding:
- Include all findings with severity `critical`, `high`, or `medium` in full
- For `low` severity findings: replace the full list with a single aggregated line:
  `+ N low-severity findings — [see full report](<link or path>)`
- Translate the aggregated line text to `Artifact language` from `ship/config.md`

## Link/reference (always required)

- **Linear mode:** URL of the Linear comment containing the full findings; if the comment has not been posted yet (it is posted in step 6 of `homolog.md`), write `(full report will be attached to this issue)`
- **Local mode:** relative path `ship/changes/<feature>/report-<task-id>.md` -->

### Summary
| Phase | Gate | Critical | High | Medium | Low |
|-------|------|----------|------|--------|-----|
| Performance | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |
| Security | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |
| Code Review | PASS/WARN/FAIL | 0 | 0 | 0 | 0 |

### Performance Findings
<!-- gate = PASS: one-line summary only -->
✓ Performance: PASS (0 critical/high findings) — [see full report](<link or path>)

<!-- gate = WARN or FAIL: critical/high/medium in full; low aggregated -->

### Security Findings
<!-- same lazy-load pattern as Performance -->

### Code Review Findings
<!-- same lazy-load pattern as Performance -->

## Test Plan
<From acceptance criteria — for PR reviewer to verify>
- [ ] Criterion 1
- [ ] Criterion 2

---
Generated by **Ship** | Co-Authored-By: Claude Opus 4.6 (1M context) <noreply@anthropic.com>
```

---

## Lazy Mode {#lazy-mode}

Canonical rendering format for per-phase findings in quality reports and PR descriptions.
For the decision algorithm (how to determine PASS / WARN / FAIL), see ---
# Lazy-Load Findings Algorithm

Canonical algorithm for consolidating phase findings into acceptance and quality reports.
Referenced by `homolog.md` (both Linear and Local mode).

`phase-status.md` is the canonical gate index — it is **always** read first (in step 1.4 of homolog's "Load all artifacts"). The algorithm below assumes it is already in memory; do NOT re-read it.

---

## Algorithm

`phase-status.md` has structured columns: `Phase | Run | Timestamp | Files | Gate | Critical | High | Medium | Low | Notes`.

For each phase (perf, security, review):

1. **Look up the gate** from the `phase-status.md` table — take the **last row** for that phase (most recent run).
   - If the phase has no row in `phase-status.md`: treat as `FAIL` (safe default)
2. **Branch on gate status:**

### If gate = PASS

Emit a single summary line — do **NOT** open the findings markdown:

```
✓ <Phase>: PASS (0 critical/high findings) — [see full report](<link or path>)
```

Translate the user-facing text to `Artifact language` from `ship/config.md`.

### If gate = WARN or FAIL

Open the findings markdown file for this phase, then filter before embedding:
- Include all findings with severity `critical`, `high`, or `medium` in full
- For `low` severity findings: replace the full list with a single aggregated line:
  `+ N low-severity findings — [see full report](<link or path>)`
- Translate the aggregated line text to `Artifact language` from `ship/config.md`

## Link/reference (always required)

- **Linear mode:** URL of the Linear comment containing the full findings; if the comment has not been posted yet (it is posted in step 6 of `homolog.md`), write `(full report will be attached to this issue)`
- **Local mode:** relative path `ship/changes/<feature>/report-<task-id>.md`.

### Gate = PASS — tabela-resumo

When a phase gate = PASS, emit only the compact summary table row. **No findings content is embedded.**

Format:

| Fase | Status | Findings críticos/altos |
|------|--------|------------------------|
| Performance | ✅ PASS | 0 |
| Security | ✅ PASS | 0 |
| Code Review | ✅ PASS | 0 |

Single-phase inline variant (used inside phase subsections):

```
✓ <Phase>: PASS (0 critical/high findings) — [see full report](<link or path>)
```

**Example — all phases PASS:**

| Fase | Status | Findings críticos/altos |
|------|--------|------------------------|
| Performance | ✅ PASS | 0 |
| Security | ✅ PASS | 0 |
| Code Review | ✅ PASS | 0 |

### Gate = WARN or FAIL — bloco expandido

When a phase gate = WARN or FAIL, embed findings inline. Apply the filter:
- **Include in full**: all findings with severity `critical`, `high`, or `medium`
- **Aggregate**: replace all `low` findings with a single count line

Format:

```
### [HIGH] <Title>
<finding in Finding Entry format — see #finding-entry>

### [MEDIUM] <Title>
<finding in Finding Entry format>

+ N low-severity findings — [see full report](<link or path>)
```

**Example — Security gate = FAIL:**

### [HIGH] SQL Injection in search endpoint
- **Category:** INJ
- **File:** src/routes/search.ts:34
- **Description:** User input is interpolated directly into a raw SQL query without parameterization.
- **Impact:** Full database read/write access for an attacker.
- **Suggestion:** Use parameterized queries via the ORM or prepared statements.

### [MEDIUM] Missing rate limiting on login route
- **Category:** CFG
- **File:** src/routes/auth.ts:12
- **Description:** The POST /login endpoint has no rate limit, enabling brute-force attacks.
- **Impact:** Credential enumeration and account takeover.
- **Suggestion:** Apply a rate-limiting middleware (e.g., express-rate-limit) with a 5-attempts/minute threshold.

+ 3 low-severity findings — [see full report](https://linear.app/mobitech/issue/MOB-XXXX)

---

## Report Summary Table {#report-summary}

Compact summary block used at the end of `/ship:perf`, `/ship:security`, `/ship:review`, and all `/ship:audit:*` reports.

```markdown
## Summary
- Critical: X
- High: X
- Medium: X
- Low: X
- **Gate: PASS | WARN | FAIL**
```#finding-entry with the Test Coverage domain extensions (Layer, Current confidence, Effort).

---

### 4. Write report

**Local mode:** Write to `ship/audits/tests-<YYYY-MM-DD>.md`

**Linear mode:** See # Ship — Linear Audit Template

Canonical pattern for creating Linear artifacts after an audit run.
Import by reference: `See ship/linear-audit-template.md`.

Used by: `audit/backend.md`, `audit/frontend.md`, `audit/security.md`, `audit/database.md`.

---

## When to use

Apply this template in **Linear mode** (i.e., `ship/config.md → Linear Integration: yes`) after completing an audit analysis and generating a report.

In **Local mode**, write the report to `ship/audits/<type>-<YYYY-MM-DD>.md` instead.

---

## Step 1 — Create Linear project

Call `mcp__linear-server__save_project` with:

- **Name**: `<Audit Type> — <YYYY-MM-DD>` (e.g., "Backend Performance Audit — 2026-04-29")
- **Team**: from `ship/config.md → Linear Integration → Team ID`
- **Description** (varies by audit type — see [Category variations](#category-variations)):
  - Project/app name (from `ship/config.md → Project → Name`)
  - Stack context (runtime, framework, database or framework methodology)
  - Gate result and findings count (e.g., "2 critical, 3 high, 1 medium")
  - One-sentence summary of the most critical/impactful issue found

> **Never search for or reuse an existing project** — not even one that looks related. Each audit run gets its own dedicated project.

---

## Step 2 — Create report document

Call `mcp__linear-server__save_document` with:

- **Title**: `<Audit Type> — <YYYY-MM-DD>`
- **Project**: the project created in Step 1
- **Content**: the full audit report in markdown

---

## Step 3 — Create milestones per severity

Call `mcp__linear-server__save_milestone` for each severity level that has at least one finding. Skip milestones with zero findings.

| Condition | Milestone name |
|-----------|---------------|
| Any `critical` findings | "Critical Fixes" |
| Any `high` findings | "High Fixes" |
| Any `medium` findings | "Medium Fixes" |
| Any `low` findings | "Low Fixes" |

For each milestone:
- **Team**: from `ship/config.md → Linear Integration → Team ID`
- **Project**: the project created in Step 1

---

## Step 4 — Create issues per finding

For each finding at any severity (critical, high, medium, low), call `mcp__linear-server__save_issue` with:

- **Title**: `[PREFIX] <finding title>` — see [Category variations](#category-variations) for the prefix
- **Team**: from `ship/config.md → Linear Integration → Team ID`
- **Project**: the project created in Step 1
- **Priority**: Urgent (critical) / High (high) / Medium (medium) / Low (low)
- **Labels**: primary label (or closest available in the team) + `severity` label — see [Category variations](#category-variations)
- **Milestone**: link to the corresponding milestone from Step 3
- **Description**: use the base template below, extended with category-specific fields

### Base issue description template

```markdown
## Problem
<What the problem is, with concrete evidence from the code. Cite file and line.>

## Impact
<Estimated impact — latency, memory, security risk, data integrity. Include projection at 10x data if relevant.>

## Evidence
- **File:** <path>:<line>
- **Code:** <relevant snippet showing the issue>

## Fix
<Specific fix with a code example in the project's language and framework.>

## Acceptance Criteria
- [ ] <Specific, verifiable criterion>
- [ ] <Another verifiable criterion>
- [ ] No regressions in related tests

## Notes
- **Effort:** <Hours | Days | Weeks>
```

---

## Category variations {#category-variations}

Each audit type customizes the project description, issue prefix, labels, and adds extra fields to the issue description template.

### Backend Performance (`audit/backend.md`)

- **Project description**: includes runtime, framework, database
- **Issue prefix**: `[PERF]`
- **Labels**: `performance`
- **Extra fields** (append to `## Notes`):
  ```markdown
  - **Maintenance window required:** <Yes | No>
  ```

### Frontend Performance (`audit/frontend.md`)

- **Project description**: includes framework and methodology (e.g., "Next.js App Router — 5-layer methodology")
- **Issue prefix**: `[PERF]`
- **Labels**: `performance`
- **Replaces `## Impact` guidance with**:
  ```markdown
  ## Impact
  <Estimated impact on user-perceived performance — which Web Vital is affected, estimated degradation.>
  ```
- **Extra fields** (append to `## Notes`):
  ```markdown
  - **Affected Web Vital:** <LCP | CLS | INP | TTFB | FCP | TBT>
  ```

### Security (`audit/security.md`)

- **Project description**: includes runtime, framework, database and overall A–F score
- **Issue prefix**: `[SEC]`
- **Labels**: `security`
- **Replaces base template** with:
  ```markdown
  ## Vulnerability
  <What the vulnerability is, with concrete evidence. Cite file and line. Include OWASP category and CWE.>

  ## Attack Vector
  <How this could be exploited — step-by-step. Who can trigger it (unauthenticated / authenticated).>

  ## Impact
  <What an attacker or a data breach would yield. Data exposed, accounts compromised, system access gained.>

  ## Proof of Concept
  <For critical/high: example malicious request, payload, or exploit flow demonstrating the vulnerability.>

  ## Fix
  <Specific code change with example using the project's patterns.>

  ## Acceptance Criteria
  - [ ] <Specific, verifiable criterion — e.g., "input is validated server-side before being used in query">
  - [ ] <Another verifiable criterion>
  - [ ] Security-related tests pass
  - [ ] No regressions in related tests

  ## Notes
  - **Effort:** <Hours | Days | Weeks>
  - **Urgent deploy required:** <Yes | No>
  ```

### Database (`audit/database.md`)

- **Project description**: includes database engine and version (MongoDB / PostgreSQL / MySQL)
- **Issue prefix**: `[DB]`
- **Labels**: `performance`
- **Extra fields** (replace `## Evidence` guidance and append to `## Notes`):
  ```markdown
  ## Evidence
  - **File:** <path>:<line>
  - **Query/Schema:** <relevant snippet — query, schema definition, or index declaration>

  ## Notes
  - **Effort:** <Hours | Days | Weeks>
  - **Maintenance window required:** <Yes | No>
  ```

### Tests Coverage (`audit/tests.md`)

- **Project description**: includes Test Scope layers enabled/disabled (unit, integration, e2e), total AC count, gate result (PASS / WARN), and one-sentence summary of the most critical coverage gap
- **Issue prefix**: `[TEST]`
- **Labels**: `test-coverage`
- **Replaces `## Evidence` and appends extra fields to `## Notes`**:
  ```markdown
  ## Evidence
  - **AC / REQ:** <AC-XX or REQ-XX>
  - **Layer:** unit | integration | e2e
  - **Current confidence:** <0.0 to 1.0>
  - **Closest test match:** <file>:<test name> (Jaccard: <score>) | none

  ## Fix
  <Example test snippet that would cover this AC>

  ## Notes
  - **Layer:** unit | integration | e2e
  - **Current confidence:** <0.0 to 1.0>
  - **Effort:** <Hours | Days>
  ```. Use prefix `[TEST]`, label `test-coverage`, and apply the Tests Coverage category variation (includes AC/REQ Evidence fields and Fix snippet).

**Report format:**

```markdown
# Test Coverage Audit — <YYYY-MM-DD>

## Summary
- Total ACs: X
- Covered (≥0.5): X (XX%)
- Uncertain (0.3–0.49): X
- Uncovered (0.0): X
- Total Scenarios: X  <!-- omit these 4 SC lines if the spec has no @SC-XX -->
- Scenarios covered (≥0.5): X (XX%)
- Scenarios uncertain (0.3–0.49): X
- Scenarios uncovered (0.0): X
- Layers evaluated: unit | integration | e2e
- Layers skipped (disabled): <layer> | none
- **Gate: PASS | WARN**

## Test Scope Configuration
| Layer | Status |
|-------|--------|
| unit | enabled / disabled |
| integration | enabled / disabled |
| e2e | enabled / disabled |

## Coverage by Layer

### Unit
| AC / REQ | Description | Confidence | Test File | Status |
|----------|-------------|-----------|-----------|--------|
| AC-01 | <desc> | 1.0 | path/to/file.test.ts | covered |
| AC-02 | <desc> | 0.0 | — | UNCOVERED |

#### Scenarios (unit)
<Omit this sub-table when the spec has no @SC-XX scenarios for this layer.>
| SC | AC | Description | Confidence | Test File | Status |
|----|----|-------------|-----------|-----------|--------|
| SC-01 | AC-01 | <scenario name> | 1.0 | path/to/file.test.ts | covered |
| SC-02 | AC-01 | <scenario name> | 0.0 | — | UNCOVERED |

### Integration
[same table format, including the per-layer Scenarios sub-table]

### E2E
[same table format, including the per-layer Scenarios sub-table]

## Findings

[findings ordered by severity — HIGH first, then MEDIUM]

## Prioritized Recommendations

| Priority | AC / REQ | Layer | Confidence | Recommended Action |
|----------|----------|-------|-----------|-------------------|
| 1 | AC-02 | unit | 0.0 | Add unit test verifying <description> |

## Blind Spots

| Hypothesis | Why unconfirmed | What to collect |
|------------|----------------|-----------------|
```

See # Gate Rules

Gate decision rules applied after every quality phase:

- Any `critical` or `high` finding → **FAIL**
- Any `medium` finding → **WARN**
- Only `low` or no findings → **PASS**

Gate behavior on FAIL/WARN is configured in `ship/config.md → Gate Behavior` (`on_fail`, `on_warn`).

## Snapshot pré-fix

Before launching the parallel quality phases (perf / security / review), the orchestrator captures a snapshot of the current HEAD commit. This snapshot is used by the PR agent to build the diff and, when auto-fix is applied, to decide which phases to re-run.

**When it is captured:** step 0.5 of `run.md` — during scratch-dir initialization, before any quality agent starts.

**File:** `.context/ship-run/<task-id>/pre-quality-snapshot.sha`

**Format:** single line containing the SHA from `git rev-parse HEAD` (no trailing newline required).

**When it is read:**
- By the PR agent (`pr.md`) to build the diff between the snapshot and the final HEAD.
- By the orchestrator after auto-fix to determine which phases to re-run (controlled by `on_fail_rerun`).

**Flag `on_fail_rerun`** (configured in `ship/config.md → Gate Behavior`):

| Value | Behavior |
|-------|----------|
| `surgical` *(default)* | After auto-fix is applied, re-run **only the phases that failed or warned**. Phases that already passed are skipped. |
| `all` | After auto-fix is applied, re-run **all quality phases** (perf, security, review) regardless of their previous result. |

> **Scope note:** M5.1 establishes the schema and snapshot capture step only. The actual re-run logic that reads `on_fail_rerun` and selects which phases to re-launch is implemented in M5.2.

## Re-run cirúrgico

After auto-fix is applied (on_fail: fix or on_warn: fix), the orchestrator selects which quality phases to re-run based on the `on_fail_rerun` config flag.

### Phase → scope mapping

| Phase | Scope | Rationale |
|-------|-------|-----------|
| `perf` | Files matching `src/**` or `lib/**`, excluding `*.test.*`, `*.spec.*`, `**/__tests__/**` | Performance issues are in hot paths, not test code |
| `security` | All files in the diff | Security scope is intentionally broad — any file could introduce a vulnerability |
| `review` | All files in the original diff | Review covers everything that changed |

### Algorithm (surgical mode)

1. Read `pre-quality-snapshot.sha` from scratch dir
2. Run `git diff --name-only <sha> HEAD` to get modified files from the fix
3. For each phase that previously ran:
   - Compute intersection of (modified files) and (phase scope)
   - If intersection is non-empty → re-run phase
   - If intersection is empty → skip phase
4. Log decision (see format below)
5. Launch selected phases in parallel

### Log format

```
Fix tocou: <file1>, <file2> (<N> arquivo(s))
Re-run cirúrgico: <phase1> (<reason>), <phase2> (<reason>)
Re-run pulado: <phase3> (não analisava arquivos modificados), <phase4> (não analisava arquivos modificados)
```

### Behavior with `on_fail_rerun: all`

When `on_fail_rerun: all`, skip the scope mapping entirely and re-run all quality phases that were originally enabled. This is the "safe" fallback — guaranteed to catch any regression introduced by the fix.

## Example: analyze phase in phase-status.md

```markdown
| analyze | #1 | 2026-05-01T10:07:00Z | 5 | warn | 0 | 0 | 2 | 1 | 2 criterios sem testes |
| analyze | #2 | 2026-05-01T10:12:00Z | 5 | pass | 0 | 0 | 0 | 0 | re-run cirúrgico |
```

### analyze phase scope mapping (Surgical Re-run)

| Phase | Scope |
|-------|-------|
| `analyze` | All files in the original diff (broad scope — re-run if any file changed by fix) |

The analyze phase is always re-run after a fix because spec↔code correlation depends on the entire diff, not individual files.

## Re-run: edge cases

The following edge cases apply to both `on_fail: fix` and `on_warn: fix` paths. They are enforced inside the **Surgical Re-run Procedure** in `run.md`.

### Edge case 1 — Fix vazio (sem mudanças)

**Trigger:** `git diff --name-only <sha> HEAD` returns empty after the fix agent runs.

**Behavior:**
- Skip all re-run phases (nothing changed, nothing to validate).
- Log: `⚠ Fix não produziu mudanças. Re-run ignorado.`
- For each phase that failed/warned: write a new row in `phase-status.md` with gate=`warn` and notes=`fix sem mudanças — revisão manual necessária`.
- Continue to acceptance with the warning visible.

### Edge case 2 — Loop de re-runs (máximo 3 iterações)

**Trigger:** `$FIX_ITERATION` counter exceeds 3 (i.e., the pipeline has already cycled through fix→re-run three times without resolving the gate).

**Behavior:**
- Abort the pipeline immediately.
- Inform the user: "Limite de 3 iterações fix→re-run atingido. Intervenção manual necessária."
- Do NOT proceed to acceptance — wait for user action.

### Edge case 3 — `on_warn: fix` usa lógica cirúrgica

**Trigger:** Gate returns exit code 1 (WARN) and `on_warn` is set to `fix`.

**Behavior:** Identical to `on_fail: fix` — apply the full Surgical Re-run Procedure including all edge cases (empty fix, iteration limit, out-of-scope files). No special handling for warnings vs failures.

### Edge case 4 — Fix tocou arquivo fora do scope original

**Trigger:** After the fix, `git diff --name-only` returns a file that does not match any phase scope rule (not under `src/**`, `lib/**`, or any recognized path from the scope mapping table).

**Behavior:**
- Re-run ALL originally enabled quality phases (conservative mode — the fix touched unknown territory).
- Log: `Fix tocou arquivo(s) fora do scope original (<file>). Re-run conservador: todas as fases ativadas.`
- Do NOT apply surgical scoping — launch all phases in parallel as in Phase 4. for gate reference.

**Gate rules for this audit (override standard gate):**
- HIGH findings (uncovered ACs in enabled layers) → **WARN** (not FAIL — test gaps are a quality issue, not a blocking defect)
- MEDIUM findings only → **WARN**
- No findings → **PASS**

> Note: This audit intentionally uses WARN (not FAIL) for HIGH findings. Uncovered acceptance criteria represent a quality gap to be addressed, not a pipeline-blocking vulnerability.

### Return JSON summary

After writing the report, output the following JSON block as the **very last content** of your tool result. `ship:audit:run` reads this directly from the agent result — no file re-read needed.

See # Audit Summary Schema

Each `ship:audit:*` agent must output this JSON block as the **very last content** of its tool result. `ship:audit:run` reads it directly from the agent result (already in context) — no file I/O needed.

## Schema

```json
{
  "audit": "<backend|frontend|database|security|tests>",
  "gate": "<PASS|WARN|FAIL>",
  "score": "<A|B|C|D|F>",
  "counts": {
    "critical": 0,
    "high": 0,
    "medium": 0,
    "low": 0
  },
  "top_findings": [
    {
      "id": "<FINDING-ID>",
      "severity": "<critical|high|medium|low>",
      "title": "<short title>",
      "file": "<path/to/file.ts:line>"
    }
  ],
  "report_path": "ship/audits/<type>-<YYYY-MM-DD>.md"
}
```

## Field definitions

| Field | Type | Description |
|-------|------|-------------|
| `audit` | string | Audit type identifier |
| `gate` | `PASS\|WARN\|FAIL` | Gate result per `# Gate Rules

Gate decision rules applied after every quality phase:

- Any `critical` or `high` finding → **FAIL**
- Any `medium` finding → **WARN**
- Only `low` or no findings → **PASS**

Gate behavior on FAIL/WARN is configured in `ship/config.md → Gate Behavior` (`on_fail`, `on_warn`).

## Snapshot pré-fix

Before launching the parallel quality phases (perf / security / review), the orchestrator captures a snapshot of the current HEAD commit. This snapshot is used by the PR agent to build the diff and, when auto-fix is applied, to decide which phases to re-run.

**When it is captured:** step 0.5 of `run.md` — during scratch-dir initialization, before any quality agent starts.

**File:** `.context/ship-run/<task-id>/pre-quality-snapshot.sha`

**Format:** single line containing the SHA from `git rev-parse HEAD` (no trailing newline required).

**When it is read:**
- By the PR agent (`pr.md`) to build the diff between the snapshot and the final HEAD.
- By the orchestrator after auto-fix to determine which phases to re-run (controlled by `on_fail_rerun`).

**Flag `on_fail_rerun`** (configured in `ship/config.md → Gate Behavior`):

| Value | Behavior |
|-------|----------|
| `surgical` *(default)* | After auto-fix is applied, re-run **only the phases that failed or warned**. Phases that already passed are skipped. |
| `all` | After auto-fix is applied, re-run **all quality phases** (perf, security, review) regardless of their previous result. |

> **Scope note:** M5.1 establishes the schema and snapshot capture step only. The actual re-run logic that reads `on_fail_rerun` and selects which phases to re-launch is implemented in M5.2.

## Re-run cirúrgico

After auto-fix is applied (on_fail: fix or on_warn: fix), the orchestrator selects which quality phases to re-run based on the `on_fail_rerun` config flag.

### Phase → scope mapping

| Phase | Scope | Rationale |
|-------|-------|-----------|
| `perf` | Files matching `src/**` or `lib/**`, excluding `*.test.*`, `*.spec.*`, `**/__tests__/**` | Performance issues are in hot paths, not test code |
| `security` | All files in the diff | Security scope is intentionally broad — any file could introduce a vulnerability |
| `review` | All files in the original diff | Review covers everything that changed |

### Algorithm (surgical mode)

1. Read `pre-quality-snapshot.sha` from scratch dir
2. Run `git diff --name-only <sha> HEAD` to get modified files from the fix
3. For each phase that previously ran:
   - Compute intersection of (modified files) and (phase scope)
   - If intersection is non-empty → re-run phase
   - If intersection is empty → skip phase
4. Log decision (see format below)
5. Launch selected phases in parallel

### Log format

```
Fix tocou: <file1>, <file2> (<N> arquivo(s))
Re-run cirúrgico: <phase1> (<reason>), <phase2> (<reason>)
Re-run pulado: <phase3> (não analisava arquivos modificados), <phase4> (não analisava arquivos modificados)
```

### Behavior with `on_fail_rerun: all`

When `on_fail_rerun: all`, skip the scope mapping entirely and re-run all quality phases that were originally enabled. This is the "safe" fallback — guaranteed to catch any regression introduced by the fix.

## Example: analyze phase in phase-status.md

```markdown
| analyze | #1 | 2026-05-01T10:07:00Z | 5 | warn | 0 | 0 | 2 | 1 | 2 criterios sem testes |
| analyze | #2 | 2026-05-01T10:12:00Z | 5 | pass | 0 | 0 | 0 | 0 | re-run cirúrgico |
```

### analyze phase scope mapping (Surgical Re-run)

| Phase | Scope |
|-------|-------|
| `analyze` | All files in the original diff (broad scope — re-run if any file changed by fix) |

The analyze phase is always re-run after a fix because spec↔code correlation depends on the entire diff, not individual files.

## Re-run: edge cases

The following edge cases apply to both `on_fail: fix` and `on_warn: fix` paths. They are enforced inside the **Surgical Re-run Procedure** in `run.md`.

### Edge case 1 — Fix vazio (sem mudanças)

**Trigger:** `git diff --name-only <sha> HEAD` returns empty after the fix agent runs.

**Behavior:**
- Skip all re-run phases (nothing changed, nothing to validate).
- Log: `⚠ Fix não produziu mudanças. Re-run ignorado.`
- For each phase that failed/warned: write a new row in `phase-status.md` with gate=`warn` and notes=`fix sem mudanças — revisão manual necessária`.
- Continue to acceptance with the warning visible.

### Edge case 2 — Loop de re-runs (máximo 3 iterações)

**Trigger:** `$FIX_ITERATION` counter exceeds 3 (i.e., the pipeline has already cycled through fix→re-run three times without resolving the gate).

**Behavior:**
- Abort the pipeline immediately.
- Inform the user: "Limite de 3 iterações fix→re-run atingido. Intervenção manual necessária."
- Do NOT proceed to acceptance — wait for user action.

### Edge case 3 — `on_warn: fix` usa lógica cirúrgica

**Trigger:** Gate returns exit code 1 (WARN) and `on_warn` is set to `fix`.

**Behavior:** Identical to `on_fail: fix` — apply the full Surgical Re-run Procedure including all edge cases (empty fix, iteration limit, out-of-scope files). No special handling for warnings vs failures.

### Edge case 4 — Fix tocou arquivo fora do scope original

**Trigger:** After the fix, `git diff --name-only` returns a file that does not match any phase scope rule (not under `src/**`, `lib/**`, or any recognized path from the scope mapping table).

**Behavior:**
- Re-run ALL originally enabled quality phases (conservative mode — the fix touched unknown territory).
- Log: `Fix tocou arquivo(s) fora do scope original (<file>). Re-run conservador: todas as fases ativadas.`
- Do NOT apply surgical scoping — launch all phases in parallel as in Phase 4.` |
| `score` | `A–F` | Quality score (see scoring table below) |
| `counts` | object | Finding counts by severity |
| `top_findings` | array | Up to 5 most severe findings; empty array if none |
| `report_path` | string | Relative path to the full markdown report |

## Scoring table

| Score | Criteria |
|-------|----------|
| A | No findings, or only `low` findings |
| B | No `critical`/`high`; at least one `medium` |
| C | No `critical`; 1–2 `high` findings |
| D | No `critical`; 3+ `high` findings |
| F | At least one `critical` finding |

## Audit-specific notes

| Audit | Gate cap | Notes |
|-------|----------|-------|
| `backend` | PASS\|WARN\|FAIL | Standard gate |
| `frontend` | PASS\|WARN\|FAIL | Standard gate |
| `database` | PASS\|WARN\|FAIL | Standard gate |
| `security` | PASS\|WARN\|FAIL | Standard gate |
| `tests` | **PASS\|WARN** | HIGH findings map to WARN, not FAIL — test gaps are a quality issue, not blocking |

## Usage in `ship:audit:run`

After all parallel audit agents complete, their tool results are already in the orchestrator context. Extract the JSON block from each result — no need to re-open the markdown files. Pass the extracted JSON objects inline to any consolidation step. for field definitions and scoring table.

> **Note:** Gate for this audit is capped at `PASS|WARN` — never `FAIL`. The `score` field follows the standard scoring table but `F` is not applicable here.

```json
{
  "audit": "tests",
  "gate": "<PASS|WARN>",
  "score": "<A|B|C|D>",
  "counts": {"critical": 0, "high": 0, "medium": 0, "low": 0},
  "top_findings": [
    {"id": "<ID>", "severity": "<high|medium>", "title": "<title>", "file": "<file:line>"}
  ],
  "report_path": "ship/audits/tests-<YYYY-MM-DD>.md"
}
```

---

## Rules

- **Entire codebase scope**: project-wide audit — scans all test files, not just a diff. For diff-scoped analysis, use `/ship:analyze`.
- **Read-only**: do NOT create, modify, or delete any test files or source files.
- **Test Scope respected**: disabled layers are informational only and do not affect gate.
- **Evidence required**: cite file and test name for every covered AC; cite absence of match for every uncovered AC.
- **Jaccard reference**: use the algorithm from the `ship:analyze` skill (invokable via Skill tool). Do not reimplement independently.
- **HIGH → WARN (not FAIL)**: this audit uses a softer gate than security/backend audits. Uncovered scenarios (SC-XX) follow the same HIGH→WARN cap.
- **Scenario backward compatibility**: detection is presence-based. No `@SC-XX` in the spec → omit all scenario rows/sub-tables and behave exactly as before this feature. Never fabricate scenarios.
- **ALWAYS launch 2 agents in parallel** — never sequentially. Single Agent tool call.
- **Language**: See # Artifact Language

- All user-facing text during execution (reports, summaries, gate results, status updates, questions) follows the `Artifact language` field from `ship/config.md → Conventions`
- Code, variable names, file paths, commit messages, branch names, and technical identifiers are always in English
- LLM system prompts (command files) are always in English — not configurable
- **Gherkin scenarios**: the natural-language step prose (`Given`/`When`/`Then` bodies, `Scenario`/`Feature` titles) is user-facing and follows the `Artifact language`. The Gherkin **keywords** (`Feature`, `Background`, `Scenario`, `Scenario Outline`, `Examples`, `Given`, `When`, `Then`, `And`, `But`), the `@SC-XX`/`@AC-XX`/`@layer` tags, and the `TEST-*`/`IMPL-*` markers are technical identifiers — always English, never translated

## Resolving artifact language

If `Artifact language` is already injected inline in the current prompt (e.g., by the `ship:run` orchestrator or a skill wrapper), use that value directly — do not re-read `ship/config.md`.

Otherwise, read `Artifact language` from `ship/config.md → Conventions`..
- For diff-scoped coverage analysis during the pipeline, use `/ship:analyze`.
