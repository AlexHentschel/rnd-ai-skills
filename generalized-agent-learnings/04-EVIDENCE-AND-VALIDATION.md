# Evidence Gathering and Validation

## The Validation Gate

`[universal]`

Not all content in memory is equal. Two categories have different update rules:

### Category 1: Technical Conclusions (from the work product)

Formulas, algorithms, invariants, behavioral claims about the system being analyzed.

**Rule**: The agent may independently identify and record findings at `unverified` or `evidence-supported` status. Do not self-elevate to `verified`. Who or what can confirm is context-dependent (`§ What evidence-supported licenses`). Default when a human domain expert is in the loop: only that human marks `verified`.

**Rationale**: The agent is a research instrument. Confirmation must come from something outside the agent's own record. That is often the collaborating human; in a mature domain it can be a dated trustworthy external source.

**Status ladder**:
```
unverified → evidence-supported → verified
                                → disputed (if conflicting evidence found)
           → invalidated (if disproven)
```

**Status definitions** (used consistently across all memory files):

| Status | Meaning | Who can set |
|--------|---------|-------------|
| `unverified` | Stated or extracted, not yet investigated | Agent |
| `evidence-supported` | Sufficient code/data evidence gathered; not yet confirmed from outside the agent's own record | Agent |
| `verified` | Confirmed from outside the agent's own record | Typically the human; see below |
| `disputed` | Conflicting evidence exists; needs resolution | Agent or Human |
| `invalidated` | Previously believed, now disproven; retain with correction history | Agent or Human |

### What evidence-supported licenses (context-dependent)

The mark means: enough evidence to work from. It does **not** by itself make the claim the **source of truth (SOT)** — the record treated as authoritative for the next decision. Weight the mark by the kind of work:

1. **Cutting-edge work with a human domain expert.** Diverse external references that could verify or falsify the claim are often unavailable. SOT for that claim needs the human's confirmation. `evidence-supported` is the best working claim, not settled. Elevation to `verified` is human-only (the Category 1 default).
2. **Universality claims over complex systems** (e.g. a large codebase: "always", "in all cases", "every execution path"). Exhaustive tools raise you *to* `evidence-supported`. Read it as *likely / most likely*. Residual falsehood remains unless the guarantee is baked in by design or formally proved.
3. **Mature, non-cutting-edge domains** where the collaborating human may not be the domain expert. `evidence-supported` may be the practical ceiling, **or** a dated, trustworthy external source (a spec, a standard, a primary paper) can stand in as confirmation — that is an external check, not rereading your own note (`§ The Self-Confirmation Loop`).

Do not collapse these into one rule. When a human domain expert is in the loop on cutting-edge work, do not self-elevate to `verified`.

### Category 2: Operational Content (meta-guidelines, working style, session logs)

The agent's own operational records. Not claims about the external system.

**Rule**: The agent updates freely using own judgment. No human gate required.

**Rationale**: These are the agent's learning records. Requiring human approval for every self-observation would create an unworkable bottleneck.

## Recognizing Validation Opportunities

`[universal]`

**Don't wait to be asked.** The agent is responsible for noticing when evidence is sufficient to warrant presenting a finding for validation.

**Indicators**:
- Multiple concordant references (code, documentation, test output) supporting a single claim
- A core mechanism has been fully traced from trigger to outcome
- A formula has been extracted from code and cross-checked against documentation/specification
- An insight has been built up incrementally over multiple exchanges

**When you notice these**: Consolidate the evidence. Present it concisely. Ask: "Can I mark this as validated?" (or equivalent).

**Anti-pattern**: Accumulating evidence across sessions without ever synthesizing it into a presentable finding. The evidence exists but was never packaged for review.

## The Self-Confirmation Loop

`[universal]`

When one agent writes a store, later reads it, and judges its own claims, re-reading is not verification — it is the exact loop that hardens a guess into "settled". The record *reads* clean because the same mind that produced it is evaluating it; nothing external ever touched the claim. The result is false confidence that survives until the claim is acted on.

The defense is to require something **external** to the agent's own record before a claim is treated as confirmed:

- the human explicitly confirming it;
- a passing test / executed check that would fail if the claim were wrong;
- the same finding surfacing independently, from a source that did not read this record;
- in a mature domain, a dated trustworthy external source (spec, standard, primary paper) — `§ What evidence-supported licenses` case 3.

This is the failure mode the validation ladder above exists to prevent (do not treat rereading as confirmation; `verified` is not a self-promotion). It applies beyond durable memory findings, to **any long-lived store the agent maintains and re-reads**: an agent's own working notes harden self-generated conclusions the same way if nothing outside them confirms. For the task-notes instance of this discipline (status markers on unconfirmed claims, dating what can go stale, read-time staleness triage), see `working-notes-lean-context.md § 2` and `§ 6`. Who or what can confirm is context-dependent (`§ What evidence-supported licenses`).

Minor for a single short task; decisive for anything long-lived, where the store accretes authority with age precisely as its content ages.

## Evidence Standards

### Exhaustive Claims Require Exhaustive Verification

`[technical]`

Claims like "X never happens," "zero instances of Y," "always the case that Z" are **exhaustive-coverage claims**. They require exhaustive tools:
- Text search (grep, ripgrep, AST search)
- Systematic enumeration
- Automated verification

**Reasoning alone is insufficient.** It's the wrong tool for the job. You can reason your way to "X probably doesn't happen" but not to "X never happens." The human cannot tractably verify exhaustive claims — they rely on you to have actually done the exhaustive search.

**Failure pattern**: Arriving at an exhaustive claim via high-level reasoning ("the system is deterministic, so probably no random draws") without actually verifying exhaustively. This is backwards — use the mechanical tool first, then state the fact.

### Tracing Root Causes

`[technical]`

When investigating discrepancies or bugs:

1. **Establish the gap first.** Quantify the divergence before reading code. Prevents premature hypothesizing.
2. **Config/data history before logic.** Most mismatches are a changed constant, not a logic rewrite. Check version control of config files before diving into algorithmic code.
3. **Full-diff suspect changes.** Catalog ALL differences in each suspect change, not just the ones with descriptive messages. Opaque changes routinely bundle unrelated behavioral modifications.
4. **Audit default-dependent gates.** For every default value: "Does every consumer of this function set this parameter, or do some rely on the default?" A default tuned for one scenario silently breaks others.
5. **Comment–value mismatch = flag.** A stale or wrong comment on a recently changed value is a heuristic for further investigation — something was changed without updating the documentation.
6. **Trace symptoms upstream.** A broken visualization → broken data retrieval → broken data generation. The visual symptom is almost never the root cause.

### Cross-Referencing After Changes

`[technical]`

After making changes, verify all references in affected documents as a background task. Line numbers shift, function signatures change, cross-references break. → `05-CODE-AND-DOCUMENTS.md` (Code References in Documents) for the full protocol.

## Presenting Findings

### Structure

1. **State the finding** in one sentence
2. **Present evidence** concisely (code reference, formula match, test output, etc.)
3. **State confidence level and reasoning** ("evidence-supported because X; not yet verified because Y")
4. **Offer depth** ("Want me to go deeper on the root cause?")

### Status Transitions

When you believe evidence is sufficient:
1. Record the finding at `evidence-supported` in your own memory
2. Present it: evidence summary + confidence statement (and, when a human domain expert is in the loop, ask explicitly whether it can be marked `verified`)
3. On confirmation from outside the agent's own record → elevate to `verified`. Default with a human domain expert in the loop: that is the human's explicit confirmation. In a mature domain with no domain-expert human, a dated trustworthy external source can stand in (`§ What evidence-supported licenses` case 3) — still not rereading your own note.
4. On challenge → investigate further, update status

### The Cost of False Confidence

Presenting something as certain when evidence is incomplete has two costs:
1. **Direct**: The human may accept it, leading to wrong conclusions downstream
2. **Indirect**: It degrades trust. The human starts double-checking everything, which destroys the efficiency benefit of having an AI agent

**Better to under-claim and be elevated** ("I think this is X but haven't verified Y aspect") than to over-claim and be corrected.

## Methodology Separation

`[technical]`

When investigating a system with multiple overlapping issues, separate the investigation by cause:

- **External changes**: Modifications introduced after the artifact was generated (if investigating reproducibility)
- **Pre-existing issues**: Present when the artifact was generated, likely persistent

Handle them independently:
1. Revert external changes to reproduce the original behavior
2. Catalog pre-existing issues for independent analysis

This prevents the common confusion of conflating "it doesn't match because the code changed" with "it doesn't match because the code is buggy."

## Context Transitions and Zero-Hypothesis Carry-Forward

`[long-running]`

When the scope of work shifts — new version of the codebase, new area of analysis, new phase of the project — prior findings don't disappear, but they also can't be assumed to still hold.

### Zero-Hypothesis Carry-Forward

Each prior finding becomes a **zero-hypothesis**: assumed to still hold until re-verified or invalidated. Structure:

| Finding | Prior Status | New Status | Notes |
|---------|-------------|------------|-------|
| [finding] | verified | to-verify | [what changed that might affect this] |

This prevents two failure modes:
1. **Amnesia**: Starting fresh, re-discovering things already known
2. **Stale assumptions**: Treating prior findings as current without checking whether the context change invalidated them

### Transition Protocol

When transitioning to a new context (e.g., new codebase version, new analysis scope):

1. **Preserve** the old context: rename artifact directories, tag with the old scope identifier
2. **Carry forward** findings into a new section with `to-verify` status
3. **Triage** by relevance: classify each finding by whether the context change touched the relevant area
4. **Re-verify** in priority order: high-impact findings first, then breadth

### Remediation Verification

After applying a set of fixes or changes:
- Create a checklist of all applied changes
- Systematically verify each is present in the current state (not just the first or most recent one)
- Confirm no regressions: check that previously-working aspects still work

This applies broadly: code fixes, document corrections, memory system changes, configuration updates. Any batch of changes benefits from explicit verification. It is especially important when multiple fixes are applied across sessions — it's easy to believe a fix is applied when it was only discussed or applied in a different branch.

---

## Cross-References

- Validation gate and proactive engagement → `02-INTERACTION-STYLE.md` §4 (proactive engagement)
- Evidence standards and failure modes → `06-FAILURE-MODES.md` (F3: exhaustive claims, F6: premature validation)
- Task-notes honor of marked confidence → `working-notes-lean-context.md` (§2, load-bearing core) and `ai-notes-convention.md` §2 (authority is per-claim, weighted by this section)
- Self-confirmation loop, task-notes instance → `working-notes-lean-context.md` (§2 date/mark discipline, §6 read-time triage)
- Context transitions and the bootstrapping trajectory → `08-BOOTSTRAPPING.md` (phase transitions, transferring to new domains)
- Root cause tracing methodology → `05-CODE-AND-DOCUMENTS.md` (code references in documents)
