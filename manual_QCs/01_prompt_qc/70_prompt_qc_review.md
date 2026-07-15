# Prompt QC -- Judgment Rubric

> **Companion to** `prompt_qc.py` (the deterministic gate).
> **Runs on** the finished prompt artifact ONLY (`PROMPT.md` / `prompt.txt` / `prompts.txt`).
> **Covers** the ~41 checklist items that require reading comprehension and cannot be proven by a script.
> **Dual-mode.** Use it as a paste-in reviewer prompt for a capable model, OR as a manual checklist a human fills in. Either way it emits the SAME report shape as `prompt_qc.py`.

The full source checklist is `PROMPT_FACTORY/PROMPT_QC_CHECKLIST.md` (71 items, sections A to K). This rubric owns the judgment half. The deterministic half is owned by `prompt_qc.py`. Run the script FIRST as a cheap gate, then run this rubric for the deep pass.

---

## How to run this

### Mode 1 -- LLM reviewer (automated)

Paste everything between the two `=== REVIEWER PROMPT ===` fences below into a fresh model session, then paste the finished prompt artifact after it. The model returns the report in the exact format specified.

**Section H (Persona-Prompt Alignment) cannot be judged from the prompt text alone.** You MUST also supply the persona files from the same bundle so the reviewer can compare the prompt against who the persona actually is. Provide these from `<TASK_DIR>/persona/`:

- `USER.md` -- who the persona is, their situation, relationships
- `IDENTITY.md` -- role, seniority, level
- `TOOLS.md` -- which services/surfaces the persona is actually connected to (this is how you verify item 40, no work on a service they do not have)
- `MEMORY.md` and `HEARTBEAT.md` -- their current live situation and focal event (verifies items 42 and 43)

Section G (traps) may also need the trap/answer context to confirm nothing is leaked. Everything outside H and G is judged from the artifact text alone.

### Mode 2 -- Human reviewer (manual)

Read each item, score `PASS` / `FAIL` / `N-A`, and write a one-line reason. Same report format. Use the same verdict rule at the end.

### Scoring rules (both modes)

- `PASS` -- the artifact clearly satisfies the item.
- `FAIL` -- the artifact clearly violates the item. Every FAIL must be fixed before bundle creation.
- `N-A` -- the item genuinely does not apply (say why in the reason).
- One line per item. No hedging. If you are not sure it passes, it FAILS.

### Verdict rule

- Any `FAIL` in **C-context**, Sections **G, H, J, K**, item **A3**, or any `FAIL` on originality (E) => overall **FAIL** (blocking).
- Any `FAIL` in Sections **A (except A3), B, F, I** => overall **REVIEW** (fix strongly advised, author may justify).
- **A3 is blocking (client requirement).** A prompt that reads as a pile of unrelated small asks instead of one coherent owned job is a hard FAIL, mirroring J4. A3 and J4 are the two views of the same client-flagged defect and BOTH block.
- Combine with `prompt_qc.py`: if the script reports `FAIL`, the whole artifact is `FAIL` regardless of this rubric.
- All clear on both => **PASS**.

---

=== REVIEWER PROMPT ===

You are a strict prompt QC reviewer for Skoll long-horizon agent tasks. You will be given ONE finished prompt artifact made of `--- TURN N ---` blocks, and (for Section H, and where noted for G) the persona files USER.md / IDENTITY.md / TOOLS.md / MEMORY.md / HEARTBEAT.md. Judge ONLY what the text supports. Do not invent merit the text does not earn. Score every item below as PASS, FAIL, or N-A with a single one-line reason. Then print the verdict.

Remember at all times that the agent ALREADY HAS its own files, tools, and environment. The prompt must not restate context the agent could read for itself, must not tell the agent to do something it should work out on its own, and must not dictate any file path. If it does, that is a FAIL on C-context below.

Anchor beliefs you enforce:
- Difficulty must be VISIBLE in the prose and come from a large, coherent underlying data load, not from many small asks.
- There are TWO valid prompt shapes and BOTH are fully acceptable. (1) Single heavy complex turn: one very complex opening turn and nothing else. (2) Multi-turn: one very complex opening turn PLUS a small number of light follow-ups (2 to 3 max) that only clarify or inject a small organic intrusion. A single-turn prompt must NEVER be marked down for lacking follow-ups, and a multi-turn prompt must never be forced into a single turn. The long horizon is always driven by the ONE very complex opening turn. If follow-ups exist, none introduces a new project and topics must not keep switching.
- The honest answer to "would a competent human need more than 8 to 10 hours to do this well?" must be YES.
- The prompt must carry WHAT (intent, goals, outcomes), never HOW (no plan, no stages, no file names, no field lists, no system names).
- Traps stay hidden. The prompt never reveals the conflicting values, never flags decoys, never names the red lines, never leaks answers.
- It must read like a specific busy human dictating to their assistant, not like generated copy.

Score these:

### C-context. Nothing the agent already has (judgment partner to the script)
- **C11a (item 11) No restated context.** The prompt does not restate anything the agent could read for itself from its own files, inbox, calendar, or records. It states the intent, not a recap of data the agent already holds.
- **C11b (item 11) No do-it-yourself instructions.** The prompt does not tell the agent to do work it should decide on its own (no dictated approach it could infer). It names WHAT is wanted, never narrates HOW to look or where to look.
- **C11c (item 15) No file paths.** No explicit file path anywhere (the script hard-fails obvious ones, you catch the subtle ones the regex missed). The persona never dictates where a file lives.
- **C11d (item 21) No explicit date or year.** No literal year, numeric date, or month-name date anywhere (the script hard-fails the common forms, you catch the subtle ones the regex missed, such as an unusual written-out year). The model must infer which year and date are meant from its own context. Relative timing (today, tomorrow, next Tuesday, this quarter) and a lone month or weekday name with no number are allowed.

### A. Domain and Framing
- **A1 (item 1) Single domain.** Sits in exactly one domain (Enterprise / Personal / Professional-Prosumer), not a blur of several.
- **A2 (item 2) Outcome-led.** Opens on the outcome the person wants, not a preamble or throat-clearing.
- **A3 (item 3) One owned job (BLOCKING).** Reads as one coherent owned job, not a pile of unrelated small asks. A FAIL here is a hard FAIL (blocking), not REVIEW: too many unrelated asks stapled together to inflate model failure is a client-flagged defect. This is the framing view of the same problem J4 checks at the difficulty-source level.

### B. Difficulty Visible in the Text
- **B1 (item 4) Many parallel surfaces.** Points at many independent surfaces / workstreams at once, forcing parallel work, not one linear task.
- **B2 (item 5) Fan-out demanded.** A single thread could not comfortably do it in sequence; it visibly demands fanning out.
- **B3 (item 6) Large object population.** References work over dozens to hundreds of objects (or thousands of rows), not a handful.
- **B4 (item 7) Two-plus deliverables.** At least two substantive deliverables are requested, woven into the prose.
- **B5 (item 8) Non-trivial analysis.** At least one non-trivial calculation or analysis is asked for.
- **B6 (item 9) Depth and open conclusion.** Expects verifying significant things against more than one source, and holding an open conclusion when evidence is thin, stated as judgment not procedure.
- **B7 (item 10) 8 to 10 hour honesty.** Read honestly, a competent human would need 8 to 10-plus hours to do it well.

### E. Voice and Originality
- **E1 (item 28) Persona voice.** Sounds like this specific persona speaking, not a generic assistant or a spec sheet.
- **E2 (item 29) Fresh specifics.** Scenario, focal event, deliverables, numbers, and names are fresh and original to this persona.
- **E3 (item 30) Nothing lifted.** Nothing (scenario, event, workstream, deliverable, conflict, number, name, phrase) is lifted from reference files or any existing task. (If you cannot verify against references, mark N-A and say so; do not assume PASS.)

### G. Secrecy of the Test (traps stay hidden) -- persona/trap context may be supplied
- **G1 (item 34) Conflicts hidden.** The specific conflicting values are NOT revealed in the prompt.
- **G2 (item 35) Decoys hidden.** Decoys / distractors are NOT flagged.
- **G3 (item 36) Red lines hidden.** The red lines are NOT named.
- **G4 (item 37) No answer leak.** Answer values are NOT leaked anywhere.
- **G5 (item 38) Judgment as intent.** Judgment expectations are stated as intent only (for example, newest source wins, name what you trusted and set aside), never as a numbered procedure.

### H. Persona-Prompt Alignment -- REQUIRES the persona files
- **H1 (item 39) Ownable surfaces.** Every surface, task, and stake is something this persona would plausibly own and act on; nothing outside their role or expertise.
- **H2 (item 40) Connected services only.** The job touches only surfaces the persona actually has; no work implied on a service they do not have.
- **H3 (item 41) Level match.** Stakes, scale, and seniority match the persona's actual level (no junior handed a CEO's job, or vice versa).
- **H4 (item 42) Live-situation fit.** The focal event is consistent with the persona's current live situation; no contradiction with what their world says is going on.
- **H5 (item 43) Facts consistent.** Names, places, money, dates, entities are consistent with the persona; no invented people or facts that conflict with who they are.
- **H6 (item 44) Relationships fit.** Relationships and tone toward others (boss, clients, family, team) fit the persona's actual relationships.
- **H7 (item 45) Jargon matches expertise.** Vocabulary and domain jargon match the persona's real expertise; a specialist sounds like one, a layperson does not use insider terms.
- **H8 (item 46) Right red lines.** The boundaries implied are ones this specific persona would actually care about (their confidentiality, their approval gates, their money).

### I. AI Slop (does it read human-dictated, not model-generated)
- **I1 (item 47) No filler openers.** No "I hope this finds you well", "Let's dive in", "In today's fast-paced world".
- **I2 (item 48) No connective scaffolding.** No "Furthermore", "Moreover", "Additionally", "It's worth noting that", "That said" used as glue.
- **I3 (item 49) No marketing adjectives.** No "comprehensive", "robust", "seamless", "cutting-edge", "holistic", "leverage", "delve", "navigate the landscape".
- **I4 (item 50) Uneven rhythm.** No symmetrical / listy triplets or balanced parallel clauses; real dictation is uneven.
- **I5 (item 51) No over-explaining.** Does not restate the same point two ways for clarity.
- **I6 (item 52) No wrap-up.** No motivational or summarizing closing sentence.
- **I7 (item 53) Concrete not vague.** No vague placeholder abstraction where a real person would be concrete and specific.
- **I8 (item 54) Idiosyncratic voice.** Carries the persona's real idiosyncrasies (clipped, blunt, warm, rambling) not a smooth neutral register.
- **I9 (item 55) Sounds dictated.** Read aloud, it sounds like a real busy person dictating to an assistant, not polished generated copy.

### J. Client Requirements (binding calibration)
- **J1 (item 56) Single complex opening.** The long horizon is driven by one very complex opening turn carrying most of the requirements, not many small self-contained turns. This holds for BOTH prompt shapes.
- **J2 (item 57) Follow-ups, if any, are light.** This item is conditional. If the prompt is a single heavy complex turn with NO follow-ups, score PASS (a single-turn prompt is a valid shape and is not penalized for lacking follow-ups). If follow-ups exist, they must be light (2 to 3 max), only clarify or inject a small organic intrusion, introduce no new project, and not keep switching topics; otherwise FAIL.
- **J3 (item 58) 8 to 10 hour anchor.** Honest answer to "more than 8 to 10 hours to do well?" is yes.
- **J4 (item 59) Rich coherent database as lever.** Difficulty comes from a large, coherent underlying data load, not from ten emails and ten contacts, and not from richness without coherence.
- **J5 (item 60) Scale of objects.** At least one workstream operates over a genuinely large population (dozens of core objects reviewed independently, or many thousands of records reconciled).
- **J6 (item 61) Long-horizon skew.** The work is something a company, consultancy, or busy professional would actually own (favor long-horizon over a quick personal chore), unless a Personal domain genuinely carries equivalent volume-and-coherence weight.
- **J7 (item 62) Cross-source conflicts present.** The work requires resolving disagreements where newest / most-authoritative wins and the stale source is set aside, present as a judgment expectation, never revealed.
- **J8 (item 63) Finished deliverable bar (GDPval).** Deliverables are believable, role-appropriate finished professional work products, not short answers about the work.
- **J9 (item 64) Owned job amid clutter (JobBench).** The opening turn is a whole job to own with several dependent deliverables, and the real signal must be found amid believable clutter, not one isolated pre-sorted question.
- **J10 (item 65) Writeback where applicable (ClawMark).** Where relevant, at least one outcome requires committing a result back to the right place, phrased as intent not instruction. (N-A only if the task genuinely has no place to commit.)
- **J11 (item 66) Not overly prescriptive.** Reaches client-level complexity through scale and depth WITHOUT the prescriptive form the client dislikes (no numbered stages, no dictated file names, no dictated field counts).

### K. Multi-Agent Forcing (does the prompt genuinely require subagents)
- **K1 (item 67) Single-thread inadequacy.** A single linear thread is visibly insufficient; breadth of independent work forces fan-out.
- **K2 (item 68) Taxonomy patterns present.** The job maps onto one or more recognized multi-agent patterns (not just "a lot of steps"). List which apply:
  - a. Parallel search -- fans out queries across multiple independent sources at once.
  - b. Parallel analysis -- data load too large for one context window, forcing split analysis.
  - c. Parallel generation -- multiple independent deliverables produced concurrently.
  - d. Specialist delegation -- sub-tasks need genuinely different expertise / surfaces.
  - e. Productivity flow -- output of one stream feeds the next (parse, transform, validate, commit).
  - f. Verify and cross-check -- a result validated against a second source (ties to depth and conflict resolution).
  - g. Divide and conquer -- a large homogeneous population decomposed into per-object work (ties to scale of objects).
  - h. Aggregate and reconcile -- conflicting sub-results merged into one coherent answer (ties to hidden cross-source conflicts).
  - i. Iterative refinement -- a draft, review, revise loop is implied.
- **K3 (item 69) Multiple patterns.** Several of the above trigger, not just one. If only one weak pattern applies, FAIL (likely too thin).
- **K4 (item 70) Structural not cosmetic parallelism.** Fan-out comes from genuinely independent streams on different surfaces, not from chopping one linear task into fake parallel pieces.
- **K5 (item 71) Reconciliation back to one result.** Where work fans out, the prompt still expects strands pulled back into coherent deliverables; breadth does not leave loose, unmerged outputs.

### Output format (print exactly this)

```
PROMPT QC -- JUDGMENT PASS
artifact: <path>

C-context. Nothing the agent already has
  C11a  PASS/FAIL/N-A  -- <one line>
  C11b  ...
  C11c  ...
A. Domain and Framing
  A1  PASS/FAIL/N-A  -- <one line>
  A2  ...
B. Difficulty Visible
  ...
E. Voice and Originality
  ...
G. Secrecy of the Test
  ...
H. Persona Alignment
  ...
I. AI Slop
  ...
J. Client Requirements
  ...
K. Multi-Agent Forcing
  K2 patterns present: <letters, e.g. b, f, g, h>
  ...

FAILS: <count>   (blocking: C-context/G/H/J/K/E-originality: <count>)
VERDICT: PASS | REVIEW | FAIL
TOP FIXES:
  1. <most important fix>
  2. ...
```

=== END REVIEWER PROMPT ===

---

## Combined verdict with the deterministic gate

| `prompt_qc.py` | This rubric | Overall |
|----------------|-------------|---------|
| FAIL | any | **FAIL** (fix forbidden content first, then re-review) |
| PASS | FAIL in C-context, G/H/J/K, A3, or E-originality | **FAIL** |
| PASS | FAIL in A (except A3) / B / F / I only | **REVIEW** (author may justify) |
| PASS | PASS | **PASS -- clears to bundle creation** |

Nothing moves to bundle creation while any blocking FAIL stands.
