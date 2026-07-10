# COORDINATION.md — the Contract Relay (cross-tool lane locks)

**What this is:** the standing handoff ledger between AI tools (Claude Code, ChatGPT/Codex, or
any future implementer) for work that spans sessions or tools. A **lane** is one bounded piece of
work with a single owner at a time. This file carries the lane's **contract** — enough committed
prose that either tool can pick the lane up cold and rewrite its acceptance teeth from scratch.
Shipped by D356 (2026-07-10) under Aaron's Contract Relay kickoff; the E50 lane below is the
retroactive worked example that motivated it.

Linked from `START-HERE.md`, `AGENTS.md`, and `CLAUDE.md`. Update the lane ledger in the same
commit as the work it describes, exactly like `DECISIONS.md`.

---

## 1 · THE HARD RULE — the lock never carries red teeth in git

Non-negotiable #3 forbids pushing red. The relay exists to hand off unfinished work. These
reconcile only one way:

> **Red probe teeth NEVER land in git.** The lane lock carries the CONTRACT — the acceptance
> criteria and probe design in full, as committed prose — and the teeth themselves land **in the
> same commit as the fix that greens them.**

If a session dies mid-lane (usage cap, crash, context boundary), the uncommitted red teeth in its
working tree are a bonus for the next session, not the record. The record is this file. A next
session that finds working-tree probe edits should treat them as a candidate rendering of the
lane's contract: read them against the lane entry, adopt or deliberately amend them (log why in
`DECISIONS.md`), and commit them with the fix.

**Why this exists (the E50 near-miss, 2026-07-10):** a Codex session diagnosed E50, authored
five acceptance teeth as uncommitted edits to `tools/probe-command.mjs` + `tools/probe-save-slots.mjs`,
and ran out of usage before writing the fix. The teeth survived only because nobody cleaned the
working tree — one `git checkout -- .` and the acceptance criteria would have died with the
session, leaving only a one-line ledger entry. The relay makes that impossible: the contract
would have been committed prose before the teeth were ever authored.

## 2 · Lane states

`LAW-DRAFT → CONTRACT → DRIVE → VERIFY → SHIPPED`

- **LAW-DRAFT** — design law being written (a `docs/design/*.md` packet, a DECISIONS entry, or a
  spec section). No acceptance criteria yet. Safe to commit at any point (docs-only).
- **CONTRACT** — the lane entry below is complete: acceptance criteria in full + the probe design
  (files, what each tooth asserts, how to run it). From here, ANY tool can drive. This is the
  minimum state before a session may start implementation it might not finish.
- **DRIVE** — an owner is implementing. The owner keeps the resume pointer current at every safe
  boundary (committed docs edit or handoff prompt), so a death mid-DRIVE loses work, not context.
- **VERIFY** — code + teeth green locally; the D160/D176 focused gate, negative tests, doc sync,
  and (at release boundaries) the full battery are running or queued.
- **SHIPPED** — committed + pushed with teeth green in the same commit; the lane records the
  final commit SHA and flips its REVIEW-QUEUE/`V1-CHECKLIST` lines.

## 3 · What every lane must record

| Field | Meaning |
|---|---|
| Lane id | `LANE-###` + a short slug |
| Owning tool | who holds the lock NOW (Claude Code / Codex / unowned) |
| State | one of the five states above |
| Design law | path(s) to the binding law/spec/decision |
| Acceptance criteria | IN FULL — the contract a cold session rebuilds teeth from |
| Probe design | files · what each tooth asserts · how to run |
| Resume pointer | the exact next action for whoever picks the lane up |
| Last-touched commit | SHA of the newest commit that advanced this lane |

**Lock discipline:** one owner per lane. Take the lock by setting `Owning tool` + `State` in a
committed edit; release it the same way. A session that finds a lane locked by the other tool
does not drive it — it either works another lane or (if the lock is plainly stale, e.g. the
owning tool's session died) takes over and says so in the lane's history line.

## 4 · Model routing — the Contract Relay binds ROLES, not model names

Subscriptions churn (D223 put the main loop on Fable 5; D286 reverted to Opus 4.8 when Fable left
the plan; Fable returned 2026-07-10). So lanes and kickoffs name **roles**; each session resolves
the role to the best model its tool offers that day and states the resolution once at the top of
its run.

- **TOP LOOP** — Claude: Fable 5 if on the plan, else Opus 4.8, at xhigh. ChatGPT: 5.6 Sol at
  Ultra. Owns design law, acceptance criteria, historical judgment, combat balance,
  UX/accessibility judgment, adversarial adjudication, final integration, the commit. NEVER
  delegated.
- **REASONING HELPERS** — Claude: Opus at high/xhigh. ChatGPT: the next tier below Sol Ultra.
  Bug-hunt finders/verifiers/critics, design + judge panels, citation-grade research-verify.
- **MECHANICAL HELPERS** — Claude: Sonnet at low/medium; Haiku for pure greps/reads/sizing.
  ChatGPT: whatever lower tier the surface exposes. Search summaries, inventories, probe-log
  summaries, schema fills, probe scaffolding, mechanical doc syncs, first-pass source gathering.

Set model AND effort explicitly whenever the surface exposes those controls. An unset call can
inherit the top tier (~97% of the 2026-06-16 cost spike), so inheritance is never accidental.
**ChatGPT/Codex exception (Aaron, 2026-07-10):** a surface with no per-helper controls may use
inheriting helpers for bounded, output-insensitive evidence work: read-only inventories,
log/artifact summaries, gate execution, or independent mechanical audits. State the exception
once and assign by task-specific strength. Helpers produce evidence; the TOP LOOP verifies every
packet and retains architecture, code ownership, combat balance, historical claims,
UX/accessibility judgment, final synthesis, integration, and the commit.

---

## 5 · LANE LEDGER

### LANE-001 · e50-save-envelope-deep-guard — **SHIPPED** *(retroactive worked example)*

- **Owning tool:** Claude Code (drove + shipped); teeth authored by ChatGPT/Codex.
- **State:** SHIPPED (D353, commit `47f6f71`).
- **Design law:** `DECISIONS.md` D244 (E13 guard pattern) + D323 (Transfer sink) + the
  REVIEW-QUEUE run-2 E50 entry; fix record D353.
- **Acceptance criteria (as the relay would have carried them):**
  1. A save whose campaign envelope carries an own `hasOwnProperty` at ANY depth is rejected at
     `loadLocal` (reads as corrupt/null; `hasSave()` false; boot reaches the menu with 0 pageerrors).
  2. The same payload is rejected at EVERY import/slot-read accept lane (`_slImportText`,
     `_slRead`, undo — all via `_slValidSave`).
  3. `applySave` is ATOMIC: a rejected payload applies NOTHING — settings must not be partially
     applied before the campaign is rejected, and the live `G.campaign` object must survive.
  4. The D323 sink `_cmdTransferClean` cannot be crashed by an own non-callable `hasOwnProperty`
     in `transfer.ids`: iteration is tamper-proof, the poison key is dropped, legitimate sibling
     records survive, and the rebuilt `ids` inherits the callable prototype method.
  5. Every legitimate save (anything `serializeSave` ever wrote) is byte-identical through all
     lanes; the E41 save-shape hashes are updated consciously with NO `_SAVE_VER` bump.
  6. Negative test: remove the guard → exactly these teeth go red → restore.
- **Probe design:** `tools/probe-save-slots.mjs` — deep-poison import tooth, slot-read tooth, a
  third E50BOOT page-load with a settings-clean/campaign-poisoned autosave (rejected-at-boot +
  atomic-applySave steps); `tools/probe-command.mjs` — the raw.ids sink sanitization tooth.
  Run: `export TMPDIR="$PWD/.tmp"`, shared `:8765` server, foreground `2>/dev/null`, read
  `tools/shots/*.json`.
- **Resume pointer:** none — closed. Residual logged in D353 (remaining callable-form
  `raw.hasOwnProperty(k)` sites are unreachable from any save lane; a future slice may sweep them).
- **Last-touched commit:** `47f6f71`.
- **History:** teeth authored (uncommitted) by Codex 2026-07-09/10 · contract reconstructed from
  the working tree + REVIEW-QUEUE by Claude Code 2026-07-10 · shipped D353.

### LANE-002 · phase-i-named-army — **CONTRACT** (opened ahead of the M5 drive)

- **Owning tool:** Claude Code (this session).
- **State:** CONTRACT → DRIVE as each slice starts.
- **Design law:** `V1-CHECKLIST.md` Phase I · `RATING-SYSTEM-DESIGN.md` (D94 OVR/ratings law) ·
  `SOLDIER-REPLACEMENT-FORMAT.md` (`cw_soldier_replacements_v1`, the citation-grade replacement
  lane) · DECISIONS D91/D93 (journey mode), D152 (lane tooling), D172-D298 (31 shipped records),
  D299 (row deferral, superseded for this lane by the D324 unlock + Aaron's 2026-07-10 kickoff) ·
  memory pillar: EA-Sports-style prosopography, play-as-anyone whole-war journey.
- **Slices + acceptance criteria:**
  - **5a · Army Register muster-roll UI:** wire the probe-vetted `fldMusterRollHtml(u)`
    (src/tactical/T14-ratings.js) to a player-reachable inspect/expand surface in the tactical
    UI. Criteria: reachable by pointer AND keyboard from a selected unit; renders the existing
    muster-roll HTML unmodified (no new historical claims); no sim/output writes (presentation
    only — D74 byte-identity on AI-vs-AI baselines); full WCAG 2.2 AA (name/role/value, focus
    order, visible focus, ≥4.5:1 text, reduceMotion-safe, aria-live only where state changes);
    wcag-auditor pass; probe teeth assert reachability, content fidelity vs `fldMusterRollHtml`,
    keyboard path, and zero pageerrors; existing probe-ratings rows stay green.
  - **5b · prosopography batch:** FIRST a mechanical-helper inventory of remaining
    generated/unresearched replacement rows (count · by side · by theater · candidate-source
    coverage in `HISTORICAL-DATA*.md`); the TOP LOOP sizes the batch from that count + remaining
    context and logs the number + reasoning in `DECISIONS.md` BEFORE the first record. Per
    record: ≥2 independent reputable sources = Verified else Inferred/Disputed; no fabricated
    people/ranks/units/citations; rank-and-sector verified AT THE BATTLE DATE; no women/support
    figures collapsed into `ss:` replacements; mechanical helpers gather, REASONING helpers
    default-refute, TOP LOOP adjudicates and owns final text; importer gate + focused
    replacement-overlay probe green per record; batch ships as its own slice with the remainder
    left HERE as an open count.
  - **5c · start-anywhere career trajectory:** richer whole-war journey per the pillar —
    save/journey/report contracts unbroken; `_SAVE_VER` bumps ONLY with an idempotent lazy
    migration (E41 gate updated consciously in the same commit); D74 byte-identity where the
    journey is inactive.
- **Probe design:** 5a — extend `tools/probe-ratings.mjs` (the `fldMusterRollHtml` teeth live at
  :451-458) or a focused `probe-muster-roll.mjs` with UI reachability/keyboard/pageerror teeth +
  wcag-auditor run; 5b — `tools/import-soldier-replacements.mjs` gate + the replacement-overlay
  probe per record; 5c — extend `tools/probe-camp.mjs`/`probe-loot-survival.mjs` journey teeth +
  save round-trip teeth. All: build GATE OK, `git diff --check`, JSON/pageerror readback.
- **5b inventory (mechanical helper, Sonnet, 2026-07-10 — size any batch FROM THIS COUNT, never
  from a prompt; decremented by D358):** universe **879** slots = 293 unique units × 3 types
  (`cmd`/`nco`/`pvt`), derived by `ssPersonRegistry()` (src/37-loot-survival.js:800,
  `_ssCollectScenarioUnits`:774, `_ssUnitSpecs`:553) over `fldScenarioRegistry()`;
  phases/reinforcements deduped by battle:side:uid. **Replaced 39 · remaining 840** (US 19 · CS 20
  shipped). Remaining by battle (total/replaced/remaining): bullrun1 54/10/44 · malvernHill
  60/0/60 · antietam 84/4/80 · fredericksburg 51/1/50 · chancellorsville 39/2/37 · gettysburg
  105/8/97 · shiloh 48/3/45 · vicksburg 81/3/78 · chickamauga 90/8/82 · chattanooga 81/0/81 ·
  kennesaw 54/0/54 · franklin 57/0/57 · nashville 75/0/75. **In-repo candidate sources:** only
  Bull Run has real banked OOB material (~560 lines, HISTORICAL-DATA.md:21-580; its 8 richest
  cmd rows are now spent — remaining Bull Run rows are nco/pvt diarists or thinner cmd slots
  like Keyes/Franklin/Willcox/Ricketts/Cocke/Stuart/Early/Elzey/Jackson); Nashville has a
  ~40-line USCT paragraph (Steedman's brigades, 13th USCT); Vicksburg a Milliken's Bend paragraph
  (related but distinct engagement); the other 10 battles have NO in-repo roster research —
  records there need fresh external NPS/CMOHS/primary-source work (~2 sources + default-refute +
  adjudication per record, the repo's most expensive work per shipped line).
- **Resume pointer:** **5a SHIPPED (D357) · 5b batch 1 SHIPPED (D358: 8 Bull Run cmd rows; probe
  pins 31→39, 912 pin HELD — replacement batches preserve registry length, only new battle units
  move 912) · 5c SHIPPED (D360: 11-rung promotion lattice + Career Trajectory read-out; nothing
  new rides the save).** The lane's PLANNED slices are complete; it stays OPEN for further 5b
  batches — size each from the 840-row count above and log the number in DECISIONS before the
  first record. NOTE for future batches: a new battle shipping (LANE-003) adds units ×3 slots to
  the universe AND moves the 912 registry pin — whoever ships a battle bumps that pin with a
  documented-history comment (the D355 idiom); replacement batches never do.
- **Last-touched commit:** D360 (5c).
- **History:** lane opened by Claude Code 2026-07-10 under Aaron's Contract Relay kickoff;
  5b inventory attached 2026-07-10; 5a shipped D357 2026-07-10; 5b batch 1 (8 records) shipped
  D358 2026-07-10; 5c shipped D360 2026-07-10.

### LANE-003 · codex-battle-ladder — **DRIVE** (ChatGPT/Codex lock taken in D361)

- **Owning tool:** ChatGPT/Codex (takes the lock by starting; state → DRIVE in its first commit).
- **State:** DRIVE.
- **Design law:** `docs/design/battle-build-research/` packets (`eastern-1862` → Gaines' Mill ·
  `usct` → New Market Heights · `western-gaps` → Stones River · stretch: `shenandoah-1864` Cedar
  Creek · `shenandoah-1862` Cross Keys/Port Republic · `appomattox-campaign` Five Forks ·
  `naval-river` Fort Donelson land+river · `trans-mississippi` Pea Ridge ELKHORN-TAVERN AXIS
  ONLY) · the D330-D335 spec→playable→guard pattern · D74 universal combat (NO per-battle fudge) ·
  D92 accurate-inputs · **D359 (AARON): all phase locks cleared for this session, with two
  dignity carve-outs a blanket unlock does NOT reach — NO Leetown Native OOB (D178/D183), NO
  playable Fort Pillow (teaching-only). No ship-vs-ship engine exists.**
- **Acceptance criteria (per battle, the full D330-D335 pattern + extras per Aaron's popup):**
  1. Durable spec (`docs/design/<battle>-battle-build-spec.md`) + plan probe green BEFORE runtime.
  2. Playable slice: `data/<battle>.json`, registry/menu rank in `src/tactical/T1-bull-run.js`,
     schema-validator enrollment, generated HTML rebuilt from source.
  3. Focused runtime guard `tools/probe-<battle>.mjs` with HISTORICAL-DIRECTION teeth from the
     packet (⚠ Stones River / Perryville invert "the winner bleeds less" — near-parity guards,
     never assume US < CS), 8/8-style direction batteries, 0 pageerrors.
  4. Source honesty: engaged strengths not campaign totals; `Verified identity; Inferred
     strength` where exact numbers are unpinned; rank-at-battle-date traps from the packet
     (Polk/Hardee are Maj. Gens. at Perryville but Lt. Gens. at Stones River; New Market Heights
     USCT Medal of Honor men; no anachronistic ranks).
  5. Roster/custom-builder baselines updated; **probe-loot-survival registry pin 912 moves**
     (+units×3, documented-history comment — see LANE-002 note); teaching cards + codex axes;
     honest A/B whenever a sim input moves.
  6. Negative bind test per new guard; D160/D176 focused gate; docs sync; commit + push per
     green slice. Full battery only at a release boundary.
- **Probe design:** per battle — plan probe (spec invariants) + runtime probe (registry/menu/
  OOB sums by sector/direction battery/pageerrors), modeled on `tools/probe-nashville*.mjs`.
- **Resume pointer:** **D361 planning/spec gate is the committed boundary; next is D362 playable Gaines' Mill implementation**
  from `docs/design/gaines-mill-battle-build-spec.md` + `tools/probe-gaines-mill-plan.mjs`.
  After Gaines' Mill ships, continue to **New Market Heights** (USCT — the game's biggest
  representation gap, unlocked by D359), then **Stones River** (multi-phase, near-parity
  direction guards). Stretch in order: Cedar Creek · Cross Keys/Port Republic · Five Forks ·
  Fort Donelson · Elkhorn Tavern. 2-3 battles at FULL depth beat 6 shallow ones (Aaron's popup).
- **Last-touched commit:** D361 (Gaines' Mill spec + plan probe + lane lock; SHA recorded at the next lane boundary).
- **History:** lane opened by Claude Code 2026-07-10 after Aaron's popup Q&A (D359) fixed scope,
  depth, and locks for the Codex session · ChatGPT/Codex took DRIVE in D361 and locked the
  Gaines' Mill source/strength/rank/direction contract before runtime.
