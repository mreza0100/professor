---
name: audit:ai-output
version: "1.0.0"
description: Audits AI pipeline output for faithfulness — the LLM-generated data read from its store, checked against the source input and the pipeline code + prompts. Triggers "audit ai output", "validate output fidelity", "check what the pipeline produced". Returns a report under .professor/AUDIT/ai-output/, never inline.
---

# Audit: AI Output — Pipeline Output Validation

> Three-angle faithfulness audit. Cross-validate the AI-generated data **in its store** against the **source input** that produced it and the **pipeline code + prompts/knowledge** that govern it.

**Domain-hydrated shell.** This ships the universal faithfulness method — the three angles, the data-first/code-last walk, the per-unit fan-out, the synthesizer contract. The per-project detail (what the output "channels" are, which store tables/collections they write to, which chain and prompt file governs each, how to query the store) is filled in at install by mapping this shell onto your AI pipeline. The worked source instance validated a {DOMAIN_ADJ} analysis engine whose channels wrote to DB tables; keep the structure, swap the channel/table/prompt specifics for yours.

**Trigger:** `audit ai output`, `validate output fidelity`, `audit output against source`, `check what the pipeline produced`, or any request to verify LLM output quality against what was actually in the source input.

---

## The Protocol

The question: is the stored output faithful to the source input, given the code and prompts? Three angles, each with one authoritative source:

- **Source input** (what went IN) — the raw material the pipeline processed (a transcript, document, event stream, …), read from the seed export or the store's source table.
- **AI-generated data** (what came OUT) — read from the **store** (the pipeline's output tables/collections). Never from a seed JSON: the seed is a frozen export that does not reflect the current chains, so auditing it tests history, not the code.
- **Pipeline code + prompts/knowledge** (the contract) — the chain code (deterministic guards) plus its prompt under the knowledge/prompt registry.

The orchestrator never inline-audits: accumulated context biases the verdict, and an inline pass has missed real failures before.

---

## Step 0 — Read the codebase

Read:

- The AI project's `CLAUDE.md` — pipeline conventions, chain structure
- The chain registry/config — per chain, its tier, temperature, timeout, output-token cap, response schema, and prompt keys
- The specific chain and prompt files identified in Step 1

---

## Step 1 — Identify the pipeline's output channels

Enumerate the channels — never trust a frozen list, chains evolve. Discover them from the store-write layer (the modules that hold the `INSERT`/write statements naming the exact output table/collection to query), cross-checked against the chain registry.

A chain's prompt text resolves in two hops: the chain config gives its prompt keys, and the knowledge/prompt registry resolves each key to its file. Chains never read prompt files directly, so the registry is the only true chain→prompt map — the loader modules are stubs, not the text.

Build a channel→file map (user-facing name → chain file → prompt file) as a starting reference, and verify each against the code before auditing — the mapping is discovered per install, never hardcoded here. Group the discovered channels by the domain module they come from, and present those groups.

## Step 2 — Ask which channels to audit

Present the discovered categories and ask the user which to audit (`AskUserQuestion`, multi-select). Auditing every channel at once is expensive — never assume scope.

## Step 3 — Fan out one agent per unit, then synthesize

Run the saved `audit-ai-output-sessions` workflow (`.claude/workflows/audit-ai-output-sessions.js`), passing the chosen channel(s) and — for a re-audit — any already-audited unit ids to `exclude`. Its flow:

1. **Discover** — one agent enumerates from the store every unit of every subject that carries output for the chosen channel(s) (join the source table to the channel's output table) — the unit set is discovered, never hardcoded.
2. **Audit** — one `general-purpose` frontier-tier agent PER UNIT in parallel (`args.frontierModel`, durable default `opus` — faithfulness verdicts on real domain content never run below the frontier tier), each walking ITS unit data-first, code-last per the brief below. One unit per agent bounds each agent's context to a single source plus its output, so a long multi-subject sweep stays faithful instead of degrading as one agent walks every unit.
3. **Synthesize** — a final frontier-tier agent (same `args.frontierModel`, default `opus`) quantifies the failure rates, WRITES the full report to `.professor/AUDIT/ai-output/{date}-{channel}.md`, RECONCILES the open-issue registry (§ Registry reconcile below), and returns only a pointer + the headline numbers. The chat that invoked the audit then reads that file. This is the standing output contract for every `/audit:*` command — detailed results go to `.professor/AUDIT/{audit-type}/{date}-{component}.md`, kept out of the conversation's context, never dumped inline.

The workflow file is the declared copy of this flow — change both together. The orchestrator never inline-audits.

---

## Per-unit agent brief — walk the unit

Each agent owns ONE unit and walks it **data-first, code-last** — the order is the method. Pairing the source input with the output BEFORE opening the code is what stops you from "confirming" a violation the source never supported: a grounded, source-introduced fact is not a fabricated one, and you only learn that by reading what was there before you reach for a rule. The three sources:

### A. Source input — what went IN

The source is the only thing read from seed files. Get it from the seed export or the store's source table — both hold the same input. Preserve whatever stable locator the pipeline uses (segment index, message id, row id) and resolve any coded fields (e.g. a speaker/actor int) via the unit's mapping.

### B. AI-generated data — what came OUT (STORE ONLY)

Read the chain's stored output from the **store** — never from seed JSON.

- Query the store via the project's sanctioned DB/query command (never a raw client).
- Discover the table/collection and columns from the chain's store-write code — never assume a name.
- Confirm currency: check the created-at timestamp and row counts so you know which run produced the rows. If the output is empty or stale, regenerate it by running the analysis pipeline so the current chains write to the store — then audit the store.

### C. Pipeline code + prompts/knowledge — the contract

Read this LAST — only to localize a discrepancy the source-vs-output walk already exposed, never to pre-judge the output before you have seen what was in the input. Both halves:

- **The chain code** (from Step 1) — the deterministic guards and post-processing (drop-filters, brakes, actor enforcement) that shape output before it reaches the store, and how it prepares input (projection, unit selection, actor mapping). Faithfulness is often owned by code, not the prompt.
- **The prompt** under the knowledge/prompt registry — role and system instructions, output schema, domain rules and severity scales, compliance/forbidden-output blocks, few-shot examples.

---

### Cross-validation checks (per channel)

During the paired walk, flag any of these from the source-vs-output comparison; the scope and instruction-compliance checks are confirmed against the prompt in the root-cause pass. Each check carries its severity when violated, then the failure shapes that betray it.

- **Faithfulness** (CRITICAL): do excerpts/quotes/references map to real source content? Watch for excerpts matching no unit in the source, and reasoning that sounds authoritative but doesn't match the unit it cites.
- **Actor accuracy** (CRITICAL): are speakers/actors correctly attributed, any outer-actor rule respected? Watch for cross-attribution wherever quoted content appears, and an actor carrying a label its role rarely earns.
- **Grounding** (CRITICAL): are labels/scores justified by what was actually in the source, or is the model inventing significance?
- **Scope respect** (CRITICAL): does the output stay inside the prompt's boundaries — nothing the prompt forbids ({FORBIDDEN_DOMAIN_OUTPUTS})?
- **Completeness** (HIGH): did the model label/process ALL required units (per-unit chains: count match; selective chains: no obvious skips)? Watch for labels petering out at the end of long units — model fatigue or truncation.
- **Instruction compliance** (HIGH): does the output follow the prompt's format, field constraints, severity scales, enums?
- **Consistency** (HIGH): for multi-item outputs, are severity/label distributions plausible? Watch for all-neutral labeling on a clearly non-neutral unit, and severity inflation — everything "high" without justification.
- **Locator accuracy** (MEDIUM): do timestamps/indices/offsets correspond to the correct units, for chains that emit them?
- **Token efficiency** (MEDIUM): is the output bloated with echo-back data that could be derived post-hoc?

### How to walk the unit

**Phase 1 — paired walk (data only).** Audit your one assigned unit:

1. **Fetch the source AND this unit's channel output together** (angle A + angle B) — never one without the other.
2. **Read them side by side** — for each output row, find the source unit(s) it claims to come from and read what was actually there.
3. **Note every discrepancy** against the checks above (faithful/unfaithful + evidence: unit, index, output field). Do not open the code yet.
4. Cover every output row; sample only when the unit's output is high-volume. A unit with zero output rows is a completeness check — read the source and report whether anything codable was missed.

**Phase 2 — aggregate (within your unit).** Cluster the recurring discrepancies you found; cross-unit clustering is the synthesizer's job, not yours.

**Phase 3 — root-cause (now read the code).** For each cluster, open the chain code + prompt (angle C) to find WHERE it originates — a missing guard, a prompt rule, a brake that alarms but never drops. A rule the output "violates" is a finding only when the source-vs-output evidence already proved the output wrong; a grounded output that a rule dislikes is a rule question, not an output failure.

**Phase 4 — report** your unit's findings (structured for the synthesizer).

---

### The synthesizer's report — written to the AUDIT file, led by the numbers

Written to `.professor/AUDIT/ai-output/{date}-{channel}.md`, in this order:

- **The failure rate first** — overall wrong / total as a %, then a per-category breakdown where each failure type carries its own denominator (so a mislabel category reads as failures / total-in-that-category) and a 1-of-1 reads as 100% with its n flagged.
- Output source — the store, and the rows' created-at range — and the unit count.
- Verdict: FAITHFUL / MOSTLY FAITHFUL (N issues) / UNFAITHFUL — FIX REQUIRED.
- Findings by severity (CRITICAL / HIGH / MEDIUM·LOW), each carrying subject · unit · index · field · Got vs Expected · source evidence.
- Completeness — missed codable content, per subject.
- The one root confusion that explains the most failures and where a single example would help most; prompt fixes route to `/km`, code/guard fixes are reported for the user to route.

---

### Registry reconcile — `docs/audit/ai-output/`

`docs/audit/ai-output/` is the LIVE open-issue registry (per-area files; law + record format in its `_index.md`). Every audit run ENDS by reconciling it — the synthesizer's last duty before returning:

- **Add** each newly-confirmed finding as a record in its area file (heading = code symbol or stable kebab slug; pointer-only evidence: `unit_id · index · table.field` — never source content).
- **Delete** each record the audit verifies is no longer reproducible — remove it entirely; never mark it fixed, never annotate (no changelog, no tombstones; history = git + the `.professor/AUDIT/` records).
- **Refresh** re-confirmed records whose evidence or staged-fix pointers moved.

The `.professor/AUDIT/ai-output/` file is the immutable per-run record; the registry is current state only. An audit that skips the reconcile is incomplete.

---

## Key questions the audit must answer

The closing, human-readable form of the Cross-validation checks table above: each channel gets a short list of yes/no questions a domain expert can read without translation, roughly one per channel category. A synthesizer report that can't answer every question here is not done.

> **KNOWLEDGE BASE EMPTY** — This section needs the project's domain-specific key questions (what a faithful vs. fabricated output looks like in this domain, phrased in the language a domain expert reads). Run the Professor's Analysis Protocol or `.claude/commands/audit/ai-output.md` after the pipeline's output channels are enumerated (§ Step 1). The Professor will surface this gap: "Knowledge base is empty, waiting for user specification to fill it in."

Illustrative shape (replace with the real per-channel list): "Are the {DOMAIN_NOUN} labels applied to the output grounded in what the {USER_NOUN} actually said or did, or invented?"

---

## Constraints

- **Read-only on code** — this skill does NOT modify code. It produces findings and recommendations; its ONLY writes are the `.professor/AUDIT/` record and the `docs/audit/ai-output/` registry reconcile.
- **Evidence-based** — every finding references a specific unit index, a specific output field, and the prompt instruction it violates.
- **Domain lens first** — a technically valid output that's misleading in the domain is still a failure.
- **Sacred ground** — if the model is producing forbidden output ({FORBIDDEN_DOMAIN_OUTPUTS}), that's CRITICAL regardless of whether the prompt asked for it.
- **Delegate fixes** — if findings warrant code changes, recommend `/wave:orchestrator` (systematic migration) or report the finding for the user to route directly (single chain fix). This skill diagnoses, it doesn't treat.
