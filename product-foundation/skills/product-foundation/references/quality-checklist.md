# Quality rubric — `/product-foundation` v0.6.0

_Referenced as `quality-checklist.md` for historical continuity. It is the **quality judge's rubric contract** — the semantic half of the per-step rubric the judge grades against._

For each pipeline step the quality judge assembles a rubric from three sources and grades the step's artifact(s) pointwise:

1. **structural** — the step's `templates/pipeline/<NN-step>/schema.md` required sections + `contains`-anchors (deterministic Layer 1, also enforced at submit);
2. **semantic** — the per-step criteria in this file (§ Per-step rubric criteria, § Visual-contract rubric criteria) — what a `grep` cannot verify but a reader can;
3. **right-sizing** — one universal scope-aware criterion the judge adds to every step's rubric; defined in `quality-judge.md`, not duplicated here.

`quality-judge.md` owns rubric assembly, the verdict JSON shape, and the verdict→gate routing. This file owns the content of source (2).

**Size is not a criterion.** Artifact size is no longer a quality/scope signal. The `schema.md § Size floor` `min_size` is a `wc -c` anti-stub pre-filter (the orchestrator skips the judge on a stub); the uniform 200 KB catastrophe cap is a token-runaway circuit-breaker. The judge grades neither — it grades whether the artifact is correctly scoped, complete, and coherent (the right-sizing criterion), never how many bytes it is.

**v0.4.0 reshaped Phase 4-5.** The v2/v3 per-route screen-writer fan-out is gone — no `app/**/page.tsx` set, no `pnpm install` / build verification, no `tsc` / `biome` ship gate. Steps 01-14 are unchanged; Step 15 is the three-part visual contract (§ Visual-contract rubric criteria); Phase 5 is the SDD handoff (§ Deterministic gates).

## Per-step rubric criteria (steps 01-14)

Each criterion has a stable `id` (the **bold label**) — the quality judge's verdict keys `criteria[].id` on it. The judge grades each `pass` / `concern` / `fail`.

### 01 — Ideation → `docs/concept-brief.md`
- **structure** — required H2 sections present, including `§ Market Sizing` and `§ Product Form`
- **citations** — ≥ 5 `[N]`-style citations
- **product-form** — `§ Product Form` declares exactly one of `screen-app | headless-service | cli | bot | embedded` via a `**Form:**` line + rationale naming where the primary user value is delivered; genuine ambiguity flagged for the concept gate rather than silently resolved
- **sizing-as-hypothesis** — `§ Market Sizing` opens by declaring its numbers pre-validation desk-research estimates; every figure cited or `Estimated`-tagged; ranges used where sources disagree. TAM/SAM/SOM presented as established fact is a `fail`

### 02 — Prototype v1, lo-fi → `docs/direction-a.html` + `docs/screens/*.html` ×3-5
- **mood-files** — `direction-a.html` plus 3-5 killer-flow lo-fi mood screens present
- **token-anchors** — `direction-a.html` carries `:root`, `--background`, `--foreground`, `--primary`, `Most Popular`, and `<svg`
- **od-citation** — cites ≥ 1 Open-Design vendor
- **craft-floor** — no unexempted anti-slop tells. The orchestrator runs `scripts/craft-floor-check.ts` on the directions before this judge-unit and passes its JSON in the brief: `fail` iff `summary.active_p0 > 0` (a deterministic P0 tell — default-indigo/trust-gradient/emoji-icon/filler/sans-display-when-serif-bound — that the bound DESIGN.md does not legitimize). The judge does NOT re-discover these. It additionally weighs the two judge-only guidance tells from `references/craft-floor.md` (`rounded-card-colored-left-border`, `invented-metrics`) semantically. Applies to this unit and `15b-hifi-mood` only.

### 03 — Spec → `docs/functional-spec.md`
- **gherkin** — `**Given**` / `**When**` / `**Then**` present; ≥ 3 Gherkin scenarios
- **assumption-register** — `§ Assumption Register` carries a 5-10 row bets table with ≥1 `value` and ≥1 `viability` row, no blank Basis, plus the three subsections (Riskiest assumption / Cheapest real-world test / Abandon signal). **Any content presented as a real user interview that did not happen is a `fail`** — fabricated evidence is the failure mode this register exists to eliminate; confidence levels must trace to the stated basis (a `high` on a `value` row requires founder-supplied real-world signal)

### 04 — Validation → `docs/validation-report.md`
- **heuristics** — references both `Nielsen` and `WCAG`
- **validation-mode** — a `validation_mode:` line is present
- **findings** — the `## Findings` table carries ≥ 3 substantive, severity-rated findings (each row a concrete issue + an actionable recommendation). **Additionally, for a measurable-mode audit** — HTML inputs, the `## Accessibility Review` table carrying real measured contrast ratios rather than projected `warn`s — the YAML `findings[]` frontmatter must mirror the table (≥ 3 entries, each with `severity` + `fix_skill_hint`); a measurable-mode report that omits it is a `concern`/`fail`. A **projected-mode** audit legitimately omits the frontmatter (per `04-validation/prompt.md` step 7) — grade it on the markdown table alone; do NOT fail it for the absent frontmatter.

### 05 — PRD → `docs/prd/v1.md`
- **user-stories** — at least one literal `| US-NN |` table row
- **structure** — 9 H2 sections (6 Lenny bones + 3 our-specific)
- **nsm** — exactly ONE North Star Metric, in its dedicated slot
- **priority-tiers** — P0 / P1 / P2 tiers visible

### 06 — OST → `docs/ost.md`
- **tree-shape** — 1 outcome → 3-5 opportunities → 2-3 solutions per opportunity
- **solution-status** — every solution carries a status

### 07 — Sitemap-IA → `docs/sitemap.yaml`
- _No semantic criterion._ The sitemap is fully deterministic-gated — valid YAML + `required_categories` coverage, enforced by the orchestrator (§ Deterministic gates → Sitemap completeness). The judge still grades schema structure + right-sizing.

### 08 — System Design → `docs/system-design.md` + `docs/security.md` + `docs/data-flow.json`
- **structure** — `system-design.md` has 8 H2 sections, including RACI + Risk Register
- **security-doc** — `docs/security.md` present
- **data-flow** — `docs/data-flow.json` is valid JSON with `flows[]` ≥ 3

### 09 — Legal posture → `docs/legal-posture.md`
- **escape-clause** — an escape-clause line within lines 1-5
- **dpia-conditional** — `§ DPIA` present iff `data-flow.json` carries sensitive categories
- **subprocessor-consistency** — sub-processor count matches `system-design.md`

### 10 — Roadmap → `docs/roadmap.md`
- **phases** — 3 phase headers, user-flow-shaped
- **milestones** — 1-3 milestones per phase
- **open-decisions** — `§ Open Decisions` present
- **projection-notice** — the `**Pre-validation projection.**` blockquote opens the document; Phase-2+ content phrased as sequencing intent, not commitment

### 11 — Cost Estimate → `docs/cost-estimate.md`
- **structure** — Assumptions / Build Cost / Run Cost / Legal & Audit Budget / Recommendations headers
- **roadmap-traceability** — build-cost rows reference roadmap phases
- **projection-notice** — the `**Pre-validation projection.**` blockquote opens the document
- **ranges-not-points** — every `[Estimated]` monetary/effort figure presents as a range; point values appear only on sourced facts (vendor list prices, signed contracts); derived totals propagate range arithmetic. A single-point estimated total is a `fail`

### 12 — GTM-launch → `docs/gtm-launch.md`
- **positioning-canvas** — a 5-line Positioning Canvas
- **launch-plan** — a Launch Plan with 4 weekly milestones
- **pricing-strategy** — a Pricing Strategy section
- **projection-notice** — the `**Pre-validation projection.**` blockquote opens the document; pricing framed as working hypothesis

### 13 — Brand → `docs/brand-book.md`
- **metadata** — `**Version:**` + `**Date:**`
- **language-glossary** — `## Language` + `## Glossary` (both sub-sections)
- **voice** — `**We are**` / `**We are not**` + ≥ 3 voice samples
- **product-name** — a Product Name decision

### 14 — Design System → `docs/design-system/{tokens.css, components.md, README.md}`
- **tokens** — `tokens.css` carries a Tailwind v4 `@theme` block + a light-mode `@media` override
- **components** — `components.md` present
- **readme** — `README.md` carries an `Audit Response` section + an Open-Design vendor citation

## Visual-contract rubric criteria (Step 15 — three judge-units)

Step 15 dispatches three parallel sub-agents; each is a separate judge-unit with its own rubric and its own verdict.

### 15a — Screen atlas → `docs/screen-atlas.md`
- **structure** — all 8 required H2 headers present: Overview / Screens Index / Sitemap Coverage Cross-Check / PRD Coverage Matrix / Design Fidelity / States Coverage Matrix / User Flow Walkthrough / Open Decisions
- **screens-index** — the Screens Index table has one row per `docs/sitemap.yaml` route (full inventory, no silent drop)
- **prd-coverage** — the PRD Coverage Matrix lists every `US-NN` from `docs/prd/v1.md` (covered → route(s), or deferred → reason); a silent omission is a `fail`
- **sitemap-coverage** — the Sitemap Coverage Cross-Check confirms every `required_categories` member is represented
- **acceptance-clause** — `§ User Flow Walkthrough` carries the literal `Closed-beta partner` named-human acceptance clause
- **no-implementation** — NO `app/` / `.tsx` / `.html` file was written; a stray `app/` tree is a `fail` (the writer overstepped its brief)

### 15b — Hi-fi killer-flow mood → `docs/screens/hifi/<NN>-<name>.html` ×3-5
- **files** — 3-5 hi-fi HTML files present
- **self-contained** — each file is self-contained HTML: one `<style>` block + a `:root` token block (values copied from `docs/design-system/tokens.css`)
- **mobile-first** — the `<style>` block carries ≥ 1 `@media (min-width: …)` breakpoint, the base CSS targets 375 px, and there are NO `style=` layout attributes (lone exception: a single dynamic value like a progress-bar width)
- **on-brand-copy** — copy matches `brand-book.md` voice, respects `## Glossary § We don't say`, and is fixture-grounded (data from `docs/fixture-spec.md`, no lorem ipsum)
- **contrast** — body text, large text, and interactive UI components meet WCAG 2.1 AA contrast against the screen's own `:root` token values (≥ 4.5:1 body text, ≥ 3:1 large text + UI components); the judge samples real rendered text/background token pairs. A screen shipping text or UI below its AA floor is a `fail`. This is the **shift-right verification** of step 04 (Validation)'s projected-mode accessibility `warn`s — step 04 audits the pre-token lo-fi prototype and can only *project* contrast; step 15b is the first surface where real brand tokens render, so it is where each projection is confirmed or refuted.
- **craft-floor** — no unexempted anti-slop tells. Same instrument as step 02 (see `### 02 — … § craft-floor`): the orchestrator runs `scripts/craft-floor-check.ts` on the hi-fi screens, the judge grades `fail` iff `summary.active_p0 > 0` (brand-token-exempt) + weighs the two judge-only guidance tells from `references/craft-floor.md`. The deterministic `default-indigo-accent` here is the hi-fi counterpart of step 02's lo-fi check — it catches the un-bound Tailwind default surviving into real-token screens.

### 15c — Fixture spec → `docs/fixture-spec.md`
- **structure** — `## Persona` + `## Entities` + `## Cross-Screen Consistency Notes` present
- **entities** — one persona only; every `system-design.md § Data Model` entity has an example-records table
- **internal-consistency** — dates form a plausible timeline; foreign keys resolve; cross-screen totals agree

## Deterministic gates (orchestrator-checked — NOT judge-graded)

Mechanical checks the orchestrator runs directly — pass/fail by `grep`, parse, or exit code, so the judge does not grade them. Listed here so this file stays the single inventory of everything `/product-foundation` checks.

### Sitemap completeness (Step 07)
- `docs/sitemap.yaml` is valid YAML.
- All 5 `required_categories` (the declared product form's set per `product-forms.md § Step 07` — for `screen-app`: marketing / auth / primary / admin / error) each have ≥ 1 route, OR appear in `deferred_categories` with a reason. Otherwise the orchestrator BLOCKs Step 07 and re-dispatches with an augmented brief naming the uncovered category(ies) — up to 2 auto-retries before falling through to the user `iterate` choice at the Phase 2 gate (see `state-machine.md § Failure handling`).
- Per-route fields complete per `sitemap-schema.md` Rules 4-6.

### SDD handoff (Phase 5)
- `<out>/docs/specs/001-<slug>/` exists with `spec.md` filled — `**Type:** umbrella`, a `## Child-spec matrix` table, a `## Standing constraints` section.
- `<out>/docs/specs/002-foundation/` exists with `spec.md` filled (skeleton + tooling + route-group dirs + thin `layout.tsx` shells).
- The umbrella's child-spec matrix slices children #3..N by `docs/roadmap.md` phases (or falls back to a single `app-build` child when the roadmap lacks phase structure).
- The Phase 5 handoff message printed to chat names the umbrella spec path — NOT a `pnpm dev` instruction.
- See `references/sdd-handoff.md` for the full Phase 5 contract.

### Best-effort visual check (Step 15b)
If the **agent-browser plugin** is installed (its launcher shim resolves), the hi-fi screens are swept over `file://`: each `docs/screens/hifi/*.html` is screenshotted at 375 px + 1280 px and checked for obvious horizontal overflow. Results land in `REPORT.md § Visual check`. If the agent-browser plugin (or host Chrome) is unavailable, a `visual-gate-skipped: agent-browser plugin unavailable` advisory is recorded (no MCP fallback). **Best-effort — never blocks the run.**

## REPORT.md section mapping

| Source | REPORT.md section |
|---|---|
| Judge verdicts — per-step + visual-contract (`concern` / `fail` rows) | `## Quality concerns` |
| Per-step rubric (01-14) — pass / blocked status | `## Pipeline coverage` |
| Visual-contract rubric (15a / 15b / 15c) | `## Visual contract` |
| SDD handoff | `## SDD handoff` |
| Sitemap completeness | `## Coverage scorecard` |
| Best-effort visual check | `## Visual check` |

## Cross-references

- `quality-judge.md` — rubric assembly, the verdict JSON shape, the verdict→gate routing
- `templates/pipeline/<NN-step>/schema.md § Size floor` — the structural Layer 1 anchors + the `min_size` anti-stub floor
- `delegation-briefs.md § quality-judge` — the judge sub-agent's 5-field brief
- `state-machine.md` — `.state.json` `quality_verdicts`, the phase gates the routing feeds
- why size is no longer a criterion (the 200 KB catastrophe cap)
