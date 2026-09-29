# Procedure Manual — Building the Next JLPT Level App

**Source project:** JLPT N5 Tutor (this repo)  
**Target audience:** any future JLPT level app (N4, N3, N2, N1) using the same architecture  
**Prepared:** 2026-05-01 from accumulated N5 build experience (Phases 1-5 + Passes 1-19)  
**Restructured:** 2026-05-13 into 5 chapters (Foundation / Safety Nets / Content / Interface / Review) for readability  
**Status:** Living document — update as each next-level build adds new lessons

This manual is written prescriptively. Where N5 hit a problem, the manual tells the next level how to avoid it. Generic best-practice advice has been omitted; only N5-specific learnings are included.

---

## Table of Contents

- **Chapter 1: Foundation**
  - 0.A One-instruction autonomous-build contract
  - ⚠ Operating modes — read this first
  - 0. Scope of "next level"
  - 1. Day 0 — Repo bootstrap (1-2 hours)
  - 11. Migration considerations from level <P> to level <L>
  - 13. Estimated total effort
- **Chapter 2: Safety Nets**
  - 2. Phase 1 — Foundation (week 1)
  - 6. Phase 5 — Quality gates (continuous)
  - 7. Tooling that paid off — port these scripts
- **Chapter 3: Content**
  - 3. Phase 2 — Content authoring strategy (weeks 2-8)
  - 10. N5-specific wins to keep
  - §20 Vocab.json structural rules + dedup tooling pattern (added 2026-05-09)
- **Chapter 4: Interface**
  - 4. Phase 3 — UI / Front-end (weeks 4-9, parallel with content)
- **Chapter 5: Review**
  - 5. Phase 4 — Audit cadence (continuous, weeks 6+)
  - 8. Process discipline
  - 9. External-blocked items — anticipate up front
  - 12. What we learned about working with Claude Code
  - 14. Anti-patterns from N5 — the bumper-sticker list
  - 15. Open questions / decisions to make for N<L>
  - 16. References
  - 17. Appendix A — One-Shot Mode supplements
  - 18. Pass-20 review findings — disposition
  - §19 Native-teacher audit playbook (added 2026-05-09)
- **Appendices**
  - §B Appendix B — Schemas & rules extracted from N5 (merged 2026-05-04)
  - Procedure Manual Appendix B — Extracted from N5 Codebase
  - B.1 Vocab-ID slug derivation rule (closes F-20.20, P0)
  - B.2 Audio manifest schema (closes F-20.18, P0)
  - B.3 JSON schemas for data/*.json (closes F-20.16)
  - B.4 i18n locale-file format (closes F-20.19)
  - B.5 Front-end test framework + Playwright config (closes F-20.23)
  - B.6 UI module list with descriptions (closes F-20.22)
  - B.7 KB markdown grammar / BNF (closes F-20.15)
  - B.8 Invariant rule specifications (closes F-20.17)
  - B.9 Diagnostic Summary algorithm (closes F-20.24)
  - B.10 Kanji-tier vs grammar-tier interaction (closes F-20.21, F-20.25)
  - B.11 External-corpus URL list per level (closes F-20.26)
  - B.12 Content-inventory extraction recipes (acknowledges F-20.12, F-20.13, F-20.14)
  - B.13 What this appendix does NOT cover
  - §C Appendix C — Pass-22 polish specifications (merged 2026-05-04)
  - Procedure Manual Appendix C — Pass-22 Polish Specifications
  - C.1 Distractor explanation rubric (closes F-22.1)
  - C.2 Ko-so-a-do scene-context formatting standard (closes F-22.2)
  - C.3 JA-2 / JA-23 invariant interaction (closes F-22.3)
  - C.4 Augmented-set escape-valve guard (closes F-22.4)
  - C.5 Auto-generation stop-condition formalization (closes F-22.6)
  - C.6 PWA spec extraction (closes F-22.8)
  - C.7 Same-pattern-string conflict resolution rule (closes F-22.9)
  - C.8 Cross-references
  - §D TASKS.md canonical template (merged 2026-05-04)
  - TASKS.md — Canonical Template
  - Appendix C — Session learnings 2026-05-10/11 (UI-audit + content-enrichment cycle)
  - C.1 The orphan-data defect class — the single biggest lesson
  - C.2 The minified-vs-unminified file pair gotcha
  - C.3 Cache busting on `index.html`
  - C.4 New schema patterns established in this session
  - C.5 CI invariant `JA-13` (out-of-scope kanji) and `SKIP_SUBTREE_FIELDS`
  - C.6 Localization parity — the chrome gap
  - C.7 Audio pipeline — manifest is the source of truth
  - C.8 The "dialogue" free-tag bug
  - C.9 Empty `form` field on kanji examples — a content-authoring trap
  - C.10 Pattern title quality — no placeholder labels
  - C.11 Commit workflow for Claude Code Desktop
  - C.12 Backup-file protection policy
  - C.13 Quality bars for Nx — minimum coverage targets
  - C.14 The order-of-operations for Nx (revised based on this cycle)
  - C.15 Anti-patterns from this session (bumper-sticker list)
  - C.16 What this appendix does NOT cover
  - Appendix D — 2026-05-12 / 2026-05-13 Audit Cycle Learnings
  - D.1 Audio engine canonicalization — VOICEVOX over gtts
  - D.2 Synthetic ambient context audio — ffmpeg-only, no third-party assets
  - D.3 Section-10 anti-items — CI enforcement pattern
  - D.4 Anti-item escalation — Defer → Avoid for legal-risk items
  - D.5 Provenance honesty discipline — phases 1 → 2 → 3 → 4 → 5
  - D.6 Backup discipline — versioned + gitignored for large rendered assets
  - D.7 Audit-prompt drift handling
  - D.8 Quality-gate progression by phase
  - D.9 Anti-patterns from this session (bumper-sticker list)
  - D.10 What this appendix does NOT cover
  - §E Appendix E — Pass-20 Review Findings (full issue text, merged 2026-05-14)
  - E.1 Issues 1-40 (full text)
  - E.2 Final Summary (from review document, 2026-05-01)

---


**Source project:** JLPT N5 Tutor (this repo)
**Target audience:** any future JLPT level app (N4, N3, N2, N1) using the same architecture
**Prepared:** 2026-05-01 from accumulated N5 build experience (Phases 1-5 + Passes 1-19)
**Status:** Living document — update as each next-level build adds new lessons

This manual is written prescriptively. Where N5 hit a problem, the manual tells the next level how to avoid it. Generic best-practice advice has been omitted; only N5-specific learnings are included.

## How to read this manual: level placeholders

This manual is **level-agnostic**. It documents the procedure for building ANY next JLPT level app (N4, N3, N2, N1) starting from the N5 source. To keep the prose readable while remaining precise, the following conventions are used:

- **`<L>`** = the target level number you are building (4 for N4, 3 for N3, 2 for N2, 1 for N1).
- **`<P>`** = the prior level number you are building from (typically `<L>+1`; usually 5 if you start from this N5 repo, but can be any lower-numbered level once intermediate apps exist).
- **`<L-1>`** = one level above the target (e.g., when `<L>=4`, `<L-1>=3`; this is the level whose grammar starts to "leak in" as borderline content). JLPT levels are numbered with N1 as the highest, so smaller `<L>` is harder.
- **`N<L>`** in narrative = "the target level" (read as N4 / N3 / N2 / N1 depending on which build you are doing).
- **`n<L>-` / `n<L>.` / `n<L>_`** in code, paths, and IDs = the lowercase level prefix (read as `n4-`, `n3-`, etc.).
- **"N5"** appearances refer specifically to the source project (this repo) and remain literal regardless of which target level you are building. If you ever build a NEW source level lower than N5 (unlikely — N5 is the lowest JLPT level), substitute `N<P>` for "N5" throughout.

The §0 scope table below shows the actual size deltas at each level transition; everything else uses placeholders so the manual works whether you are building N4, N3, N2, or N1.

When the manual references "the source level" or "the source repo", it always means N5 (this repo) unless an explicit `<P>` token is used.

---



---

# Chapter 1: Foundation

> **Foundation** — start by copying what already works from the previous level. Decide ground rules (scope, schema, permissions, level-to-level migration) before any content is authored. Time-budget the build.

## 0.A One-instruction autonomous-build contract

The user has authorised the agent to execute the entire next-level build on a single instruction. This section defines exactly what that means, so the agent can act without asking for clarification.

### 0.A.1 Trigger phrases

If the user says any of the following (case-insensitive, paraphrasing OK), execute the full procedure in §A.12 autonomously:

- "build the next level" / "make the next level" / "go build the next level"
- "build N<L>" / "make N<L>" / "scaffold N<L>" / "start N<L>" — where `<L>` ∈ {4, 3, 2, 1}
- "go" — when the immediately-prior conversation context was about building the next level
- "ya" / "yes" / "proceed" — when responding to an offer of "shall I build N<L>?"

Don't pause for confirmation after any of these. **Don't ask "are you sure?" / "which level?" / "where to put it?" — apply the defaults below.**

### 0.A.2 Implicit-input defaults (no questions asked)

When the trigger fires, derive every required input from context with these defaults:

| Input | Default rule | Worked example |
|---|---|---|
| **Target level `<L>`** | (a) If a level number is stated in the trigger, use it. (b) If "next" is used, use the lowest-numbered missing level (e.g., if N5 exists and N4 doesn't, target = N4). (c) If two are missing, pick the higher of the two (= the next-after-source: closer to the source repo). | "build the next level" with N5 present → `<L>=4` |
| **Source level `<P>`** | The highest-numbered fully-built level at a sibling directory of the working tree's parent. Typically `<P> = <L> + 1` because builds are sequential. | Source = N5 |
| **Source repo path** | `<JLPT-root>/N<P>/` where `<JLPT-root>` is the parent directory of the current source repo. | `C:\Users\...\Documents\VS Code\JLPT\N5\` |
| **Target repo path** | `<JLPT-root>/N<L>/`. Create if missing. **Refuse to overwrite a non-empty directory** — halt with a "target dir non-empty" message + instructions for the human to clear it. | `C:\Users\...\Documents\VS Code\JLPT\N4\` |
| **Inventory sources** | Use any `feedback/n<L>-*-inventory*.md` files already in the source repo as the authoritative content list. Else fall back to web fetch per §A.7 source-authorities table. | `feedback/n4-grammar-inventory.md` etc. |
| **Native voice budget** | Default = synthetic TTS (gtts). Mark every audio entry `voice: "synthetic"`. Per §A.2 / §A.3. | – |
| **Native teacher review** | Default = LLM-only audit (`tools/llm_audit.py`). Mark every authored entry `auto: false, review_status: "llm_only"`. Per §A.3. | – |
| **Translation of brief** | Default = English-only ship; queue translation in TASKS.md as EB-3. | – |
| **Subscription / monetisation** | Default = free, no monetisation, match source repo. | – |
| **Handwriting kanji practice** | Default = defer to v2. | – |
| **IME-typing input** | Default = defer to v2. Use kana-strict text_input flow. | – |
| **Reading-comprehension speed test** | Default = defer to v2. | – |
| **Mock test mode timing** | Default = use the JLPT.jp official time table per §A.9. | – |

If ANY of the above defaults will produce something the user would reject, the agent's job is to log the assumption in TASKS.md `Pass-1` so a human pass can revisit. Do not pause execution to ask.

### 0.A.3 Halt conditions (the only times the agent stops to ask)

The agent halts and asks ONLY if a default cannot be safely applied:

1. **Target directory non-empty.** Refuse to overwrite. Halt: "Target `<path>` is non-empty. Clear it manually or specify a different path."
2. **No source repo found.** Halt: "Cannot identify source level — no built JLPT repo found at sibling paths. Specify `--source <path>` or build N5 first."
3. **Unrecognised target level.** If the user says e.g. "build N0" or "build N6" (outside JLPT spec). Halt: "Target level out of range — JLPT levels are N1 (highest) to N5 (lowest)."
4. **Network unavailable AND inventory file missing.** If `feedback/n<L>-*-inventory*.md` doesn't exist in the source repo AND `WebFetch` fails on all the §A.7 source URLs. Halt: "Cannot resolve N<L> content inventories — neither local nor web sources reachable."
5. **Destructive operation requested by trigger.** If the trigger phrase includes "delete", "wipe", "reset", "force-overwrite", etc. Always halt and confirm.

Outside of these five cases, **do not halt**. The agent must complete §A.12 end-to-end, committing partial state at each checkpoint so a future invocation can resume.

### 0.A.4 What the agent delivers on completion

A successful one-instruction build delivers, at minimum:

1. **A new git repo** at `<JLPT-root>/N<L>/` initialized with the directory structure of §1.1, all files present (skeleton content allowed per §A.4 layer 0-3).
2. **All §A.5 definition-of-done items GREEN** for layers 0-2 (build pipeline, schemas, UI shell). Layers 3-7 (content) green AT LEAST to the §A.4 minimum-viable subset.
3. **A populated `TASKS.md`** with: status snapshot, current-pass section, deferred items, EB backlog, and explicit "what was authored vs deferred" record.
4. **A populated `MEMORY.md`** ≤200 lines summarising what the next session inherits.
5. **All initial commits pushed** to a remote of the agent's choosing (default: a sibling org/user-page on the same git host as the source repo's `origin`).
6. **A summary report** in chat (or stdout if non-interactive) following the §A.13 handoff format.

### 0.A.5 Skip-permissions posture

A one-instruction build assumes the agent runs in `--dangerously-skip-permissions` mode (or equivalent). The deny-list in `.claude/settings.local.json` (which the bootstrap copies from source) still gates destructive ops. The agent does NOT need to ask permission for normal git / file / fetch operations during the build.

If skip-permissions is not active and the agent's runtime keeps prompting, the build will stall. The agent should detect this on the second prompt and halt with: "Cannot run autonomously without `--dangerously-skip-permissions`. Restart with the flag and re-run the trigger."

---


## ⚠ Operating modes — read this first

This document supports **two execution modes**. The bulk of the manual (§§0–16) was written for **Mode A**. **Appendix A (§17+)** carries the supplements required for **Mode B**.

### Mode A — human team + N5 repo as co-resident reference (default)
- Reader: a human + AI assistant (Claude Code) working together over weeks-to-months.
- Required inputs: this manual **and** the N5 source repo at a known path (so "copy from N5" instructions resolve to actual files).
- The manual reads as a prescriptive playbook; "see N5", "copy from N5", "port verbatim" are concrete actions with files to read.
- Estimated effort: 17-25 weeks (per §13).

### Mode B — zero-interaction one-shot agent (limited)
- Reader: a single coding-agent run with no human in the loop.
- Required inputs: this manual **plus the entire N5 repo as a tarball or directory** that the agent can read.
- **Without the N5 repo**, this manual is approximately a table of contents — most "copy from N5" / "port" instructions are unresolvable, schemas and content inventories are not embedded, and one-shot completion is **not feasible**.
- Even WITH the N5 repo: a one-shot agent should use **Appendix A** — it provides default decisions for the §15 open questions, fallback procedures for external-blocked items, a definition-of-done, and a minimum-viable subset to ship if the full scope can't fit in one run.
- Honest expectation: a zero-interaction agent producing a *complete* N<L> app in one run is unrealistic. Realistic one-shot deliverable = scaffolded skeleton (build pipeline, schemas, CI, UI shell, ~20% of content) that a human team finishes in subsequent passes.

This split is a direct response to the Pass-20 manual review (`Appendix E (this manual)`, 40 issues across 6 risk categories). The review's core finding stands: this manual is a *playbook*, not a *self-contained build spec*. Pass-20 closure ships in two parts:
- **Appendix A (§17 of this file)** — closes 15 issues by adding operating-modes preamble, default decisions, fallback procedures, MVS, definition of done, schemas recipe, source authorities, exam structure, SM-2 params, furigana procedure.
- **Appendix B (separate file `procedure-manual-appendix-b-extracted-from-n5.md`)** — closes the remaining "extract from N5" cluster (12 items) by directly extracting schemas, rules, and conventions from the N5 codebase. Sections B.1 through B.12 cover: vocab-ID slug rule (P0), audio manifest schema (P0), JSON schemas for all data files, i18n locale format, Playwright test framework, UI module list, KB markdown grammar (BNF), all 28 invariant rule specifications, Diagnostic Summary algorithm, kanji-tier interaction, external-corpus URL list per level, and content-inventory extraction recipes (N4 kanji/vocab/grammar via authoritative-source scripts, since the agent must FETCH not INVENT content).
- **Appendix C (separate file `procedure-manual-appendix-c-pass22-polish.md`)** — closes 7 of the 10 Pass-22 polish items (F-22.1 distractor rubric, F-22.2 ko-so-a-do scene-context formatting standard, F-22.3 JA-2/JA-23 invariant interaction clarification, F-22.4 augmented-set escape-valve guard via WHY-comment regex spec, F-22.6 auto-generation stop-condition formalization, F-22.8 full PWA spec, F-22.9 same-pattern-string conflict-resolution rule). The other two Pass-22 items live in their own files: F-22.5 LLM-audit prompt at `tools/prompts/llm_audit.prompt.md`, F-22.7 TASKS.md canonical template at `specifications/tasks-md-template.md`.

Together, Appendices A + B + C close 36 of 40 Pass-20 issues plus all 10 Pass-22 polish items. [UPDATE 2026-06-04: F-22.4 (JA-25 invariant in `tools/check_content_integrity.py`) and F-22.5 (`SYSTEM_PROMPT` extraction in `tools/llm_audit.py`) are BOTH shipped, so Pass-22 is 10/10; the remaining Pass-20 open items are the content-inventory fetches F-20.12/13/14, now addressed procedurally by F.51.1 and executed at the Nx build. See F.51.6 and the Appendix B post-amble (38/40).]

---


## 0. Scope of "next level"

The same playbook scales **N5 → N4 → N3 → N2 → N1**. Each level transition adds the deltas shown below. To use this manual, locate the row matching your target `<L>` and source `<P>` (typically `<P>=<L>+1`):

| | N5 → N4 | N4 → N3 | N3 → N2 | N2 → N1 |
|---|---|---|---|---|
| Kanji whitelist | 106 → ~280 (+~170) | ~280 → ~650 | ~650 → ~1000 | ~1000 → ~2000 |
| Vocab corpus | ~1000 → ~1500 | ~1500 → ~3700 | ~3700 → ~6000 | ~6000 → ~10000 |
| Grammar patterns | ~187 → ~210 | ~210 → ~250 | ~250 → ~280 | ~280 → ~300 |
| Reading passage length | 80-150 / 250-300 chars | +long-form essays | +newspaper articles | +academic texts |
| Listening pace | slow / clear | natural-but-paced | natural | rapid + dialect |
| Borderline tier | `late_n5` | `late_n<L>` + `n<L-1>_borderline` | etc. | etc. |

The **N5 → N4** transition is the smallest content jump but introduces the most architectural decisions (tier taxonomy, kanji-policy contention, borderline-grammar handling). For N3 and lower (`<L> ≤ 3`) it is mostly content scaling once those one-time architectural choices are committed.

---


## 1. Day 0 — Repo bootstrap (1-2 hours)

### 1.1 Directory structure (copy from N5)

```
.
├── .claude/
│   ├── CLAUDE.md           # binding rule for Claude Code automation
│   └── settings.local.json # personal permission overrides (gitignored)
├── .github/
│   └── workflows/
│       └── content-integrity.yml
├── KnowledgeBank/          # source-of-truth Markdown
│   ├── grammar_n<L>.md
│   ├── kanji_n<L>.md
│   ├── vocabulary_n<L>.md
│   ├── sources.md
│   ├── moji_questions_n<L>.md
│   ├── goi_questions_n<L>.md
│   ├── bunpou_questions_n<L>.md
│   ├── dokkai_questions_n<L>.md
│   ├── chokai_questions_n<L>.md   # NEW: listening was inline at N5; promote to its own file at N<L> (any next level)
│   └── authentic_extracted_n<L>.md
├── data/                   # JSON derived from KB by build_data.py
│   ├── grammar.json
│   ├── kanji.json
│   ├── vocab.json
│   ├── reading.json
│   ├── listening.json
│   ├── questions.json
│   ├── n<L>_kanji_whitelist.json
│   ├── n<L>_vocab_whitelist.json
│   ├── n<L>_kanji_readings.json
│   └── audio_manifest.json
├── tools/
│   ├── build_data.py
│   ├── check_content_integrity.py
│   ├── test_build_data.py
│   ├── link_grammar_examples_to_vocab.py
│   ├── scan_multi_correct.py     # PORT FROM N5 — paid off for Pass-15
│   ├── heuristic_audit.py        # PORT FROM N5
│   ├── llm_audit.py              # PORT FROM N5 — Anthropic API integration
│   ├── build_audio.py
│   └── tag_vocab_pos.py
├── feedback/                # audit reports, native-teacher reviews
├── specifications/          # spec docs, design system, this manual
├── js/, css/, locales/      # vanilla static front-end
├── index.html
├── sw.js
├── manifest.webmanifest
├── package.json             # only for Playwright + tooling
├── README.md
├── TASKS.md                 # SINGLE SOURCE OF TRUTH for project state
└── MEMORY.md                # session-to-session continuity (Claude Code)
```

### 1.2 Files to create on Day 0 (no content yet, just structure)

- **`.claude/CLAUDE.md`** with the binding-rule statement: blanket autonomous-operation authorization for routine git/file operations in this repo, with explicit deny list (force-push, --hard, rm -rf, etc.). Copy from N5's version verbatim and update level references.
- **`TASKS.md`** with these top-level sections: `Live site`, `Status snapshot`, `External-blocked backlog`, plus a `Pass-1` placeholder. Status snapshot starts empty; populate as content lands.
- **`MEMORY.md`** ≤200 lines, listing project location, key files, current state, branch, HEAD. Update on every session.
- **`tools/check_content_integrity.py`** with the day-1 invariants pre-wired (see §3).
- **`.github/workflows/content-integrity.yml`** running the integrity check on every push/PR. **Make it a hard gate from day 1**, not "warn-only" — once warnings are tolerated they accumulate forever.

### 1.3 Schema decisions to lock in NOW

These are expensive to change later. N5 paid for several of these via mid-project migrations.

- **Question IDs:** `q-NNNN` (4-digit zero-pad, opaque string, never re-numbered). N5 has gaps from deletions; that's fine — document the gap policy in `_meta.id_gap_policy` and treat IDs as opaque keys.
- **Pattern IDs:** `n<L>-NNN` (3-digit zero-pad). Reserve a numeric range up front for each thematic cluster (e.g., n<L>-001..n<L>-050 for Sentence Basics) so insertions don't force renumbering.
- **Vocab IDs:** `n<L>.vocab.<section-slug>.<form>[.<disambiguator>]`. The section-slug encoding allows the same word to be cross-listed in multiple thematic sections, which the runtime UI uses (do NOT collapse cross-listings — N5 has 10 such pairs, all intentional).
- **Reading IDs:** `n<L>.read.NNN`. Listening: `n<L>.listen.NNN`.
- **Universal `_meta` block** in every data/*.json: `schema_version`, `entity_count`, `id_range`, `id_gap_policy`, `history` (append-only log of cumulative changes).
- **Sidecar `.meta.json` for flat-array files.** Some catalog files (e.g., `n<L>_kanji_whitelist.json` is a top-level JSON array `[...]` consumed via `set(json.loads(...))` by 3+ different scripts) cannot host a `_meta` key without breaking consumers. For these, ship a sibling sidecar `n<L>_kanji_whitelist.meta.json` containing the full schema documentation: `_meta.doc`, `_meta.schema_version`, `_meta.lastUpdated`, `_meta.expected_count`, `_meta.source`, `_meta.consumers` (list of files that read it), `_meta.ordering_convention`, `_meta.exceptions` (pointer to exception lists), `_meta.see_also`.
- **Provenance discipline.** Every authored field that has multiple source paths (`gloss_en` from native, `gloss_en_machine_translated`, `cultural_context_native_reviewed`, `cultural_context_llm_curated`) must carry a sibling `_provenance` field declaring which path produced it: `native_reviewed` / `llm_curated` / `machine_translated` / `claude_reviewer_persona` / `template_default`. **Honesty rule:** if `native_reviewed` is in fact "Claude playing native-reviewer role," use `claude_reviewer_persona` (or document the convention explicitly in `_meta.native_review_pass_<date>` of the parent file). Institutional adopters who need strict-human review need the disclosure.
- **`_meta` policy notes for non-obvious schema decisions.** When a catalog file embeds a non-obvious convention (sparse IDs after dedup, sokuon allophone removal, intentional cross-listings), document it inline as a `_meta.<topic>_note` paragraph. N5 carries five such: `id_gap_policy: "documented"`, `sokuon_allophony_note`, `native_review_pass_<date>`, `sparse_id_policy_<topic>`, `previous_schema` (for migration-tracked files like `dokkai_kanji_exception.json` v1 → v2). Each note explains *why* the schema looks the way it does so a future maintainer doesn't try to "clean it up" and break things.
- **Tier taxonomy on grammar entries:** `core_n<L>`, `late_n<L>`, `n<L-1>_borderline`. **Add this from day 1.** N5 paid for tier-taxonomy retrofit in Pass-13/14.
- **`auto: bool`** flag on every authored entry. `false` = human-reviewed; `true` = template-generated. Used for prioritized native review.

### 1.4 Permissions / automation setup (10 min)

If using Claude Code:

- Copy `.claude/CLAUDE.md` from N5; replace "N5" → "N<L>" throughout.
- `defaultMode: bypassPermissions` in `.claude/settings.local.json`. Add gitignore for `*.local.json`.
- Allow lists for `Bash(git *)`, `Bash(cd *)`, `Edit(**)`, `Write(**)`, plus the `gh pr/release/issue` flavors.
- Deny list for destructive ops: `git push --force`, `git reset --hard`, `rm -rf`, `git branch -D`, etc.

The N5 build wasted ~2 hours iterating on permission patterns because the binding rule wasn't established up front. Skip that pain.

---


## 11. Migration considerations from level <P> to level <L>

Beyond the obvious content scaling, three architectural decisions:

### 11.1 Tier taxonomy

At N5 we had `core_n5` and `late_n5` (borderline). At N<L>, plan for THREE tiers from day 1:
- `core_n<L>` — solidly N<L> scope
- `late_n<L>` — N<L> scope but only typically taught at end of N<L>
- `n<L-1>_borderline` — appears in N<L> materials but is N<L-1> nuance

JA-21 invariant enforces tier=late_n5 for late-N5 grammar in the N5 source content. At N<L>, the equivalent invariant should enforce tier=n<L-1>_borderline for level-`<L-1>` grammar that leaks into N<L> materials.

### 11.2 Kanji policy escalation

N5 has ~106 kanji in the whitelist, with strict scope enforcement. The next level adds more kanji per the §0 size table (e.g., N4 adds ~170 to take the whitelist to ~280; N3 adds ~370 more for ~650 total; etc.).

**Decision to make on day 1:** does the N<L> app re-use N<P> kanji (yes — they're prerequisites) or only test the N<L>-additional set? Recommended: include all N5 ∪ ... ∪ N<L> in the whitelist and use the `tier` field on each kanji entry to distinguish prerequisite vs new (see §11.2 / Appendix B.10).

### 11.3 Borderline grammar promotion

Patterns like `んです` / `のです` (N5 borderline per F-15.23) become **core at the next level** (e.g., core_n4). The grammar.json migration:
- Each former-borderline pattern at level N<P> becomes a core_n<L> pattern at the new level.
- Existing examples from level N<P> get re-tagged as `prerequisite_n<P>`.
- New questions can be authored at full N<L> scope.

Plan ~30-40 such promotions. The N5 pattern catalog `late_n5` tier is your migration manifest — copy it, retag, expand.

### 11.4 Level picker on a sibling deploy — clone-and-flip, do not clone-verbatim

When the new level ships as a **sibling deploy** (separate origin or separate sub-path on the same origin — e.g., the N5 site at `<host>/jlpt-n5-tutor/` and the N4 site at `<host>/jlpt-n4-tutor/`), `js/levels.js` and `js/app.js` **must be rewritten, not copied**, in a specific way. Otherwise the level picker on the new deploy silently mis-routes clicks to the originating level's content.

**The bug pattern to avoid (real example, 2026-05-04 N4 launch):** the N4 deploy shipped with `js/levels.js` left as a verbatim copy of the pre-launch N5 file. On the N4 origin, clicking the **N5 card** routed to `#/home` — but `#/home` resolves on whichever origin is currently loaded, so the user landed on the N4 dashboard instead of the N5 site. Simultaneously, the N4 card itself was rendered disabled (it had been `available: false` in the source state, before N4 was built). Visible symptom: *"click N5 → N4 syllabus opens, and N4 itself is disabled"* — confusing exactly because the user expects clicking the source-level card to leave the new site.

**The fix is mechanical but easy to forget. For each next-level deploy, edit `js/levels.js` so:**

| Card represents | `available` | `href` | `external` |
|---|---|---|---|
| The level THIS deploy serves (`<L>`) | `true` | `'#/home'` | (omit) |
| Any other already-built level (`<P>` and any earlier levels with their own deploys) | `true` | `'<absolute sibling URL>'` | `true` |
| Levels not yet built | `false` | `'#/n<X>'` (placeholder route) | (omit) |

The render branch adds `rel="noopener" data-external="true"` only when `external: true`. Same-origin hash routes (`#/home`) deliberately stay free of those attrs so the SPA router handles them.

**Three companion edits that go with the levels.js rewrite:**

1. **`js/app.js` ROUTES dict** — remove `n<L>: renderLevelPlaceholder`. The local level is the home, not a placeholder. Leaving it registered means a stray `#/n<L>` link (e.g., a stale bookmark or test) renders the "Content not yet available" placeholder on the very site that ships that level.
2. **`renderLevelPlaceholder` regex inside `levels.js`** — the source repo regex `^#\/(n[1-(<P>-1)])(?:$|\/)/i` must drop `<L>` from its character class (e.g., on the N4 deploy: `n[1-3]`, not `n[1-4]`). Same reason as #1.
3. **Footer copy + header comment block + placeholder English text** all reference "this site currently ships N<P> only" — update to "ships N<L>" so a user who lands on a placeholder gets the right back-link target.

**Cache invalidation is non-optional for this fix.** Bump `sw.js CACHE_VERSION` and `index.html ?v=` on the entry script (per §14 anti-pattern #18). A learner's browser may already have the broken levels.js cached from launch day.

**Smoke test to add to §6.4 release gates** (catches the bug before deploy):

```js
// tests/level-picker-cross-deploy.spec.js (Playwright)
// Run on EVERY built level deploy.
test('level picker — local level uses #/home, others use external URLs', async ({ page }) => {
  await page.goto('/#/levels');
  const cards = await page.$$('.level-card.is-available');
  let localCount = 0;
  for (const card of cards) {
    const href = await card.getAttribute('href');
    const dataLevel = await card.getAttribute('data-level');
    const isExternal = await card.getAttribute('data-external');
    if (href === '#/home') {
      localCount++;
      expect(isExternal).toBeNull();  // local is NOT external
    } else {
      expect(href).toMatch(/^https?:\/\//);  // remote sibling
      expect(isExternal).toBe('true');
    }
  }
  expect(localCount).toBe(1);  // exactly one local-home card
});
```

Run this test as a per-deploy smoke check. Failure means the levels.js was not rewritten when the deploy was forked from the source.

**At the source repo** (this manual's repo, the level you're building FROM): the source's own levels.js needs a one-line update too — flip the new level's entry from `available: false` (placeholder) to `available: true` with the new sibling's absolute URL, `external: true`. Bump that repo's cache version. Without this, the source-repo learners can't navigate forward to the new deploy.

In short: deploying level N<L> is **two** levels.js edits — one in the new repo (local-home for `<L>`, externals for everything else built), one in the source repo (flip `<L>` from disabled to external).

---


## 13. Estimated total effort

Based on N5 actuals:

| Phase | Solo + AI | With native reviewer (parallel) |
|-------|-----------|--------------------------------|
| Bootstrap + foundation (1) | 1-2 weeks | same |
| Content authoring (2-8) | 8-10 weeks | 6-8 weeks |
| UI (parallel, 4-9) | 4-6 weeks | same |
| Audit cycles (continuous, 6+) | 2-3 weeks | 2-3 weeks |
| Polish + native review | 2-4 weeks | 1-2 weeks |
| **Total** | **17-25 weeks** | **13-19 weeks** |

The native reviewer parallelism only saves time if review windows are scheduled BEFORE 100% authoring (per §5.3). Otherwise the native reviewer is a sequential bottleneck.

For N3+, multiply by ~1.5x per level due to vocab/kanji growth and reading-passage complexity.

---



---

# Chapter 2: Safety Nets

> **Safety nets** — set up automatic quality checks before writing any content. Build pipeline, CI invariants, integrity gates, and the tooling that catches regressions before they ship.

## 2. Phase 1 — Foundation (week 1)

### 2.1 Build pipeline first, content second

**Build `tools/build_data.py` BEFORE authoring KB content.** The pipeline is what catches structural errors early; without it you'll hand-edit JSON for weeks before discovering schema drift.

Required parsing:
- Grammar: `^- \*\*([一-鿿]+)\*\*` for kanji headers (allow `[Ext]` suffix tags — N5 had a regex bug here that lost 9 entries).
- Vocab: section headers + entry lines.
- Question files: `### Q\d+` headers, choices as numbered lists, `**Answer: N**` markers.

Required output:
- Each entity gets an `auto: false` flag if hand-authored, `auto: true` if template-generated.
- `_meta` block populated with counts and history.
- Idempotent — re-running on unchanged input = no diff. (N5's build was idempotent; that paid off across 13 Pass cycles.)

Test the pipeline IMMEDIATELY with `tools/test_build_data.py` covering the regression cases that bit N5:
- `[Ext]`-tagged kanji headers parse correctly.
- Parenthetical glosses don't get split on commas (N5 had a bug where `(see, n5-XXX)` fragments split on the comma).
- Plain headers still parse after both fixes.
- E2E: real KB produces N entries with no warnings.

### 2.2 Content integrity invariants (Day 1)

These were added piecewise in N5 (across X-6.1..X-6.9 and JA-1..JA-21). Pre-wire ALL of them on N<L> day 1.

| Invariant | What it checks | Lesson |
|---|---|---|
| `X-6.1` Catalog completeness | Every grammar pattern has examples + form_rules | N5 had stubs that shipped before this check |
| `X-6.2` Year-form consistency | 今年 / こんねん / ことし usage matches policy | Had a Pass-14 incident |
| `X-6.3` No mixed kanji+kana words | Don't write 大さか for おおさか | Pass-13 |
| `X-6.4` Lint script present | The lint pipeline exists and runs | Bootstrap |
| `X-6.5` No em-dashes | U+2014 banned project-wide | We stripped 881 in Pass-7 |
| `X-6.6` Ru-verb exception flags | Group-1 ru-verb exceptions flagged BOTH at section header AND per-entry | Pass-9 |
| `X-6.7` No false synonymy | "Direct synonym" rationales flagged for review | Pass-11 |
| `X-6.8` No ASCII digits in TTS source | Numbers must be in kanji or kana for TTS | Pass-8 |
| `X-6.9` Primary-reading sanity | Each kanji's primary on/kun reading is most-frequent | Pass-12 |
| `JA-1` Stem-kanji scope | Question stems use only N<L>-whitelisted kanji | Pass-12 |
| `JA-2` Particle-set sanity | Particle MCQs have valid particle distractors | Pass-13 |
| `JA-3` Furigana / catalog match | Furigana annotations match catalog entries | Pass-9 |
| `JA-4` Vocab reading uniqueness | Watch for accidental duplicate readings | Pass-13 |
| `JA-5` Answer-key sanity | `correctAnswer` is in `choices` for MCQ | Pass-9 |
| `JA-6` No two-correct-answers | Auto-detect duplicate stems with same answer | Pass-15 |
| `JA-7` No duplicate stems in file | Even with different answers, dedupe stems | Pass-19 |
| `JA-8` Q-count integrity | `_meta.question_count` matches `len(questions)` | Pass-14 |
| `JA-9` Engine display contract | UI hides `**Answer:**` until commit (test passes) | Pass-2 |
| `JA-10` No "(see n<L>-)" redirect text | Auto-gen stub redirects forbidden in user-facing fields | Pass-12 |
| `JA-11` No duplicate MCQ choices | All 4 choices distinct per question | Pass-9 |
| `JA-12` Kanji KB / JSON consistency | KB markdown and JSON have same kanji set | Pass-13 |
| `JA-13` No out-of-scope kanji | Anything user-facing limited to N<L> whitelist | Pass-13 |
| `JA-14` No auto-ruby in renderer | UI never auto-applies furigana to whitelisted kanji | Pass-13 (regression of Pass-7) |
| `JA-15` Audio refs resolve | Every audio path in JSON has a file on disk | Pass-7 |
| `JA-16` Kanji example whitelist | Example sentences use only target+whitelist kanji | Pass-13 |
| `JA-17` Grammar examples have vocab_ids | Homograph guard linkage populated | Pass-13 |
| `JA-18` Reading explanation kanji ⊂ passage | Question explanation can't introduce new kanji | Pass-15 |
| `JA-19` Reading info-search has format_type | Mondai-6 format tagged for UI rendering | Pass-15 |
| `JA-20` Reading choices kanji ⊂ passage | MCQ correctAnswer matches passage's kanji form | Pass-15 |
| `JA-21` Late-tier markers require tier=late_n<L> | Mid-tier patterns properly tagged | Pass-15 |

**Add 3 more on the next level from Pass-15/Pass-19 lessons:**
- `JA-22` No "direct synonym / directly equivalent / same as" in goi rationales (catches synonym-overclaim regression).
- `JA-23` Multi-correct scanner: every MCQ where choices include known-interchangeable particle pairs (`に`/`へ` for direction, `から`/`ので` for reason, `は`/`が` for topic-or-subject) is flagged for native review.
- `JA-24` No duplicate `pattern` strings in grammar.json across entries with overlapping `meaning_en` (catches the Pass-19 redundancy class).

**And from N5 Pass-22..Pass-24 (later additions worth pre-wiring at N<L>):**
- `JA-25` Whitelist exceptions documented — every kanji used in a user-facing field that's NOT in the N<L> whitelist must have a corresponding entry in an explicit augmented-set with a WHY-comment in `tools/check_content_integrity.py`.
- `JA-26` No duplicate question IDs (across the entire bank).
- `JA-27` No English-translation/title fields in reading/listening (Japanese-first surface policy).
- `JA-28` Dokkai-paper kanji bounded by N<L> + exception list.
- `JA-29` Question subtype taxonomy is closed — `subtype` field can only take values in an explicit allow-list (e.g., `paraphrase`, `kanji_writing` at N5). New subtypes require an explicit code change, not a data sneak-in.
- `JA-30` No past-paper provenance signatures in question text — original-content policy enforced by regex against known JEES/past-paper phrasings (see `CONTENT-LICENSE.md` template).
- `JA-31` Vocab PoS parity — `pos` field on every `data/vocab.json` entry agrees with the matching entry in `KnowledgeBank/vocabulary_n<L>.md`. **Treat homographs as a SET-VALUED match** (e.g., section-default pos for `いる` exist=verb-2 vs `いる` need=verb-1 should both be valid for the key); use `setdefault().add()` storage, not last-write-wins dict. Otherwise the parity check loses one tag and falsely flags one of the two MD lines.
- `JA-32` (suggested) Broken cross-references — every `contrasts.with_pattern_id` and every "See n<L>-NNN" reference in `form_rules.conjugations.label` resolves to an active `n<L>-` ID in `data/grammar.json#patterns[].id`. See §3.2.7.
- `JA-33` (suggested) No mid-line clipping in tile-grid card descriptions — Playwright/visual-regression assertion: at every supported viewport (320 / 480 / 768 / 1280), every `.<card>-desc` element has `boundingClientRect.height` that's an integer multiple of computed `line-height` (within 2 px tolerance). See §3.2.9.

**And from N5 native-teacher audit 2026-05-08 (close the homophone / dedup / drift class):**

- `JA-42` Vocab-section dedup — no two `data/vocab.json` entries share `(form, reading)` AND have normalized-identical glosses unless one explicitly marks itself as a cross-listing with `(also in §X)` parenthetical in the gloss. Catches the §3.2.16 cross-listing bug class. Implementation: group entries by `(form, reading)`; for each multi-entry group, normalize glosses by stripping `(also in §X...)` markers; if any pair has identical normalized gloss without a cross-listing marker, fail. Polysemes (different glosses, e.g., `は` tooth/leaf/particle) pass cleanly.
- `JA-43` No sokuon allophones in kun arrays — `data/kanji.json#entries[].kun` and `data/n<L>_kanji_readings.json#<kanji>.kun` reject any value ending in small `っ` unless the kanji is on a documented allowlist. Catches the §3.2.15 みっ/よっ/むっ/やっ bug.
- `JA-44` Vocab-tag homophone-context match — for every `vocab_ids` entry in a grammar example, if the entry's gloss is in a known-homophone-pair set (`food.あめ` ↔ `weather.雨`, etc.), the example's `translation_en` must contain a context word matching the tagged gloss (e.g., "rain" if tagged 雨). Catches the §3.2.13 substring-tag bug class. Implementation as a regex table: each homophone pair has a list of disambiguating English keywords.
- `JA-45` `vocab_used` content-word filter — `data/reading.json#passages[].vocab_used` and `vocab_preview` arrays must be content words: no entries from particle / filler / function-word sections, no single-kana surfaces. Catches the §3.2.14 substring-extraction noise.
- `JA-46` `script_ja` / `explanation_*` drift detector — for every listening item, every NOUN that appears in `script_ja` (extracted via mecab or via a kanji-substring heuristic) must appear (or have a translation appearing) in `explanation_hi` AND `explanation_en`. Catches the §3.2.17 stale-derived-metadata bug. Strictness slider: at minimum, fail when explanation_hi mentions a noun that's NOT in script_ja (the cross-contamination case from N5 items 002–005).

### 2.3 Test directly with cp932-aware Python

If contributors are on Japanese Windows: set `PYTHONIOENCODING=utf-8` before any script that prints Japanese, OR pipe through `Out-File -Encoding utf8` and read the file. N5 wasted hours on cp932 mojibake before this was standard. Document it in `MEMORY.md`.

---


## 6. Phase 5 — Quality gates (continuous)

### 6.1 Run the integrity check on every commit

GitHub Actions workflow `.github/workflows/content-integrity.yml`:
- Triggers: `push: [main]` + `pull_request: [main]` + `workflow_dispatch`
- Runs `python tools/check_content_integrity.py -v`
- Runs `python tools/test_build_data.py`
- Hard fail on any violation. **Never `continue-on-error: true`.**

If a fix introduces a violation, fix the data OR add the kanji/particle/construct to the appropriate augmented set in the integrity check tool with a comment explaining why it's legitimately in N<L> scope. Never silence by removing the check.

### 6.2 Add new invariants when bugs recur

The N5 invariants (X-6.x + JA-x) accumulated organically — each one was added after a real bug class was caught. When a bug repeats, write the invariant. Examples:
- 38 stub questions across 9 passes → finally added stub-redirect-text invariant (`JA-10`)
- Multi-correct ko-so-a-do bug → added context-presence regex
- Synonym overclaim → grep regex for `irect synonym|directly equivalent`

### 6.3 Status snapshot must reflect current state

The first ~25 lines of TASKS.md are the canonical state-of-the-project. Update them on every significant change (corpus size, SW version, vocab/kanji counts, route list). N5 drifted multiple times and required catch-up commits to refresh.

If your workflow runs scripts that change corpus size, add a post-script step that regenerates the snapshot's numeric fields (extract them from `_meta` blocks).

### 6.4 Safe-script practices for JSON-mutating tooling

When a script-driven pass mutates `data/*.json` (e.g., the dedup tool in §20, the romaji-patch tool, the homophone-retag tool), apply these guardrails. They were learned the hard way during the N5 audit pass.

- **`json.dump(..., ensure_ascii=False)` can shift Unicode normalization.** A round-trip read → modify → write may serialize the same logical string with different byte sequences (NFC vs NFD; particularly noticeable in Devanagari, where consonant-cluster forms have multiple equivalent encodings). Re-run `tools/check_content_integrity.py` after every script-driven JSON modification — don't trust visual diff inspection alone. The N5 audit caught a JA-41 (Hindi prose) violation that disappeared after a `json.dump` round-trip purely because of normalization shift.
- **Diff CI failure counts before/after via `git stash` to attribute violations.** Before touching a file, run integrity → record violation count C0. Make changes. Re-run integrity → record C1. If C1 > C0, your changes introduced violations. If C1 < C0, your changes happened to fix pre-existing violations (note this in the commit message). If C1 == C0, no net change — but verify the failing INVARIANTS are the same set (same C, different invariants = silent bug).
- **Stash dance for clean baseline.** When integrity fails after your edits AND you suspect pre-existing failures: `git stash push -- <files>`, run integrity (records true baseline), `git stash pop`, run integrity (records your delta). The difference is what your changes did.
- **`--verbose` mode finds non-obvious violations.** Plain `python tools/check_content_integrity.py` summarizes pass/fail counts. `python tools/check_content_integrity.py --verbose` (or `-v`) emits the specific failing IDs and contexts. Use verbose mode in CI; use plain mode only for quick local-loop confirmation.
- **Bump `CACHE_VERSION` after every data-content commit.** `sw.js` carries `const CACHE_VERSION = 'jlpt-n<L>-tutor-vMM.mm.pp'` — bump the patch number after any commit that touches `data/`. Without it, deployed clients keep serving stale cached JSON until the next stale-while-revalidate cycle (could be days). Pair: refresh `data/version.json` via `tools/build_version_json.py` so the runtime footer reflects the new state.
- **Backup commits before mass-mutation passes.** Before running a script that touches >50 entries (dedup, romaji-patch, audio re-render), commit the current state as `chore(backup): pre-<pass-name> checkpoint`. Recovery is trivial; `git reset` is destructive; backup commits are cheap.
- **One pass per commit.** Don't bundle three independent passes (dedup + romaji + provenance flip) into one commit. CI failure attribution becomes a archaeology project. Atomic per-pass commits make `git bisect` work and make reverting one pass without losing the others trivial.

---


## 7. Tooling that paid off — port these scripts

In rough priority order:

1. **`tools/build_data.py`** — KB markdown → JSON. The single most important script. Port + adapt.
2. **`tools/check_content_integrity.py`** — all invariants. Port the framework + the X-6.x ones; add JA-x as you author content.
3. **`tools/test_build_data.py`** — regression tests for the build pipeline. Port the structure; write new tests as N<L>-specific bugs surface.
4. **`tools/link_grammar_examples_to_vocab.py`** — homograph-aware vocab linking. Has a sophisticated boundary-check + HOMOGRAPH_RULES system. Port verbatim and extend the rules as new homograph clusters appear at the next level (at N4: 込 readings; at N3: 形 / 化 readings; etc.).
5. **`tools/scan_multi_correct.py`** — 5-category multi-correct candidate scanner. Wire as advisory CI gate.
6. **`tools/heuristic_audit.py`** — cheap mass-scan with deterministic findings (precision ~75% per N5 Pass-15a). Use for first-pass triage.
7. **`tools/llm_audit.py`** — Claude API for deep semantic review. Production-ready in N5; just update prompt template for N<L> scope.
8. **`tools/build_audio.py`** — TTS pipeline. Idempotent. Port + add native-recording skip-flag for N<L>.
9. **`tools/tag_vocab_pos.py`** — POS tagging for vocab. Adapt rules.
10. **`tools/coverage_compare.py`** — external-corpus gap analysis. Port + update for N<L> corpus.

Skip these (one-shot diagnostics from N5):
- `_inspect_*.py`, `_check_*.py`, `_dup_*.py` — N5-specific debugging.
- `fix_kosoado_basic.py`, `fix_particle_basic.py`, `fix_pass15_tier2.py` — one-shot Pass-15 fix appliers; useful as audit-trail in N5 but not as code to port.

---



---

# Chapter 3: Content

> **Content** — write the lessons: grammar, vocabulary, kanji, reading, listening. KB-first markdown → derive JSON. Apply the anti-patterns at §3.2.x to avoid repeating N5 mistakes.

## 3. Phase 2 — Content authoring strategy (weeks 2-8)

### 3.1 KB-first, JSON-derived

**Always edit `KnowledgeBank/*.md`, never `data/*.json` directly.** The MD file is the source of truth; JSON is regenerated by `build_data.py`. N5 had Pass-13 disasters when contributors edited JSON directly and the build pipeline overwrote their changes.

Exception: post-build refinements to JSON metadata (vocab_ids, audio paths) that the MD doesn't carry. Those are added by separate enrichment scripts (e.g., `link_grammar_examples_to_vocab.py`).

### 3.2 Anti-patterns from N5 — DO NOT REPEAT

#### 3.2.1 Don't auto-generate filler questions (CRITICAL — N5 Pass-14)

N5 had **38 "pattern-meta" stub MCQs** that asked "What does pattern X mean?" with the answer literally quoted in the stem. They were generated by `generate_stub_questions.py` to inflate the bank to 250. They taught nothing. Pass-14 deleted all 38.

If you find yourself wanting to generate filler MCQs because the bank looks small: **the bank is small for a reason — author real questions, or accept fewer.**

The shape of the failed pattern was: stem `つぎの いみに あう パターン：「X」`, choices = 4 random pattern strings including the correct one. This format CANNOT be saved by any audit; the answer is literally in the stem.

#### 3.2.2 Don't put both interchangeable-pair particles in MCQ choices without scene context (HIGH — N5 Pass-15)

The class of bug: any MCQ stem with a destination-of-motion verb that has BOTH `に` AND `へ` in the choice set is multi-correct. Same for `から`/`ので` (because), `は`/`が` (topic vs subject in many sentences), `に`/`と` (recipient vs companion with でんわをする), `まで`/`から` (until vs from).

Pass-15 fixed 6 such cases in N5 questions. Avoid the class by:
- Keeping only ONE of each interchangeable pair in distractors, OR
- Adding scene-setting context that disambiguates.

The multi-correct scanner (`tools/scan_multi_correct.py`) catches the class automatically; wire it as `JA-23`.

#### 3.2.3 Don't ship "see pattern detail" as a distractor explanation (MEDIUM — N5 Pass-15)

Auto-generated distractor explanations like `Wrong choice - see pattern detail.` are useless. Real distractor explanations contrast the WRONG option's role with the correct one. Example for `に` vs `を` for the recipient of giving:

> 'を already marks プレゼント (the thing being given). あげる takes one を for the object, not two. The recipient slot uses に.'

Author all distractor explanations by hand (or LLM-author then native-review). N5 has ~600 questions; budget ~2-3 minutes per question for proper distractor authoring = ~25-30 hours total.

#### 3.2.4 Don't use ko-so-a-do questions without spatial context (CRITICAL — N5 Pass-15)

The stem `（  ）は ほんです。` with choices これ/それ/あれ/どれ has THREE valid answers (これ, それ, あれ all complete to a grammatical "X is a book"). Only どれ is wrong because it's interrogative.

Always prefix ko-so-a-do questions with scene-setting in parentheses: `(じぶんの 手の中の 本を 友だちに みせて)　（  ）は ほんです。` → only これ fits.

#### 3.2.5 Don't run two parallel Claude Code sessions on the same data file (HIGH — N5 Pass-19 cascade)

If you must, **partition by ID range up front**. N5 had two sessions independently author at q-0454..q-0463, causing a 10-question collision that needed a dedup commit. Lock per-pass ID ranges in TASKS.md before any session starts.

#### 3.2.6 Don't introduce new grammar pattern entries with the same `pattern` string as an existing one (MEDIUM — N5 Pass-19)

The N5 catalog has 9 redundant pattern entries (n5-128 ⊂ n5-009, n5-141 ⊂ n5-094, etc.) created by Pass-15-era splits that didn't retire the merged entries. **Before adding a pattern entry, grep grammar.json for the same pattern string.** If found, decide: split intentionally (different IDs, narrowed meanings, both kept) OR retire-and-replace (one canonical ID).

JA-24 invariant catches this going forward.

#### 3.2.7 Don't ship cross-references to retired patterns (HIGH — N5 post-dedup)

After any dedup / pattern-retirement pass, `contrasts.with_pattern_id` and `form_rules.conjugations.label "See n<L>-XXX"` references to retired IDs are still in the JSON. The runtime renders them as broken links. The pattern is invisible until a learner clicks through.

**Before any retirement pass closes:**
1. Build a list of retiring IDs (R1, R2, ...).
2. `grep -nE '\bn<L>-(<R-list>)\b' data/grammar.json` — find every literal reference.
3. For each match: repoint to the canonical replacement OR remove the reference. Don't leave dead pointers.
4. Add an invariant (`JA-NN broken cross-references`) that fails CI if any `with_pattern_id` or "See n<L>-NNN" label points to an ID not in `data/grammar.json#patterns[].id`.

The N5 cleanup pattern: 6 stale `contrasts.with_pattern_id` + 4 stale `form_rules` see-also labels were sitting in the data 3 weeks after dedup before the bug was reported.

#### 3.2.8 Don't mass-stamp PoS by thematic section (CRITICAL — N5 Pass-24)

A vocab corpus organized into thematic sections (e.g., "Nature and Weather", "Colors", "Time / Frequency", "Verbs - Existence and Possession") is tempting to PoS-tag at the section level: every entry in section X gets `pos: "noun"`. This produces 24+ mistags per level when:

- An i-adjective (`あつい`, `さむい`, `白い`, `くろい`) is cross-listed in a "noun" section (Nature, Colors).
- An adverb (`いつも`, `よく`, `時々`) is cross-listed in a "noun" section (Time / Frequency).
- A Group-2 verb (`いる` exist, `あげる`, `くれる`) is cross-listed in a section whose default is `verb-1`.

**The Group-2 case is pedagogically dangerous** — the wrong PoS drives wrong conjugation rules. A learner using `あげる` from the existence-section copy gets told it's verb-1 → conjugates `*あげります` instead of `あげます`.

Fix policy:
- PoS is a per-WORD attribute, not a per-section default. Tag every entry by the word's actual linguistic PoS, regardless of which thematic section it appears in.
- Add an invariant (`JA-31 vocab PoS parity`) that compares each entry's PoS against the source markdown PoS tags AND fails when cross-section copies of the same form have inconsistent non-noun PoS values (homographs are an explicit exception — see §3.2.9).
- Beware homograph false-positives: 人 (person/counter), 本 (book/counter), おく (hundred-million/place), はい (yes/cup-counter), は (tooth/topic-marker), はる (spring/attach), あの (demonstrative/interjection) are GENUINE homographs and should NOT be unified across sections.

#### 3.2.9 Don't mid-line-clip card descriptions on fixed-height tile grids (HIGH — N5 layout regression)

Pattern: a card with `display: flex; flex-direction: column; height: <fixed>` containing a description child with `flex: 1` plus `display: -webkit-box; -webkit-line-clamp: N; overflow: hidden`. When the fixed height isn't enough for the line-clamped child, the flex layout *squeezes* the child to the leftover pixel height (which doesn't align to a multiple of line-height), and `overflow: hidden` clips THROUGH a line — bottom-half of characters cut off, looks like a rendering bug.

Two compounding issues:
1. Chrome normalises `display: -webkit-box` to `flow-root` on flex children, **disabling line-clamp** entirely. Computed style reports `webkitLineClamp: 4` but it has no effect.
2. The flex-allocated height is rarely an integer multiple of line-height.

Fix policy (apply on every multi-line card description in fixed-height tile grids):

```css
.card-desc {
  display: -webkit-box;
  -webkit-box-orient: vertical;
  -webkit-line-clamp: N;
  overflow: hidden;
  /* Belt-and-suspenders: clamp the BOX too, so even if Chrome
   * normalises -webkit-box → flow-root on flex children,
   * overflow: hidden clips at a clean line boundary. */
  max-height: Nlh;
  /* DO NOT use `flex: 1` here — the flex layout will squeeze
   * the child to the leftover space, breaking the clamp. */
}
.card-action {
  margin-top: auto;  /* push to card bottom inside flex column */
}
```

Audit checklist before declaring a tile-grid component done:
- For every `flex: 1` on a child that contains line-clamped text: verify it doesn't cause mid-line clipping at the smallest target viewport.
- For every fixed `height: Npx` on a card: verify the card's intrinsic content height (sum of all children at their natural sizes) ≤ N. If not, raise N or shorten the longest content.
- Test at 320 / 360 / 768 / 1280 / 1920 viewport widths; mid-line clipping shows up differently at each because text wraps to different line counts.

#### 3.2.11 Don't fragment a spec across files whose audience is one role (MEDIUM — N5 spec-corpus consolidation 2026-05-04)

A growing project tends to spawn separate spec docs per concern: functional spec, design system, UI testing plan, procedure manual, build appendices, TASKS template, design-system supplement, etc. Each one has a clear individual rationale at creation time. After ~6 months you have 8-12 markdown files where one editor has to read 5 of them to understand a single change. The N5 spec corpus reached that state by 2026-05-04 with 7 markdown files plus 1 `.docx` in `specifications/`.

**The principle:** every spec markdown source should map to **exactly one consumer role**. If two files are read by the same role for the same task, they're one file with internal headings — not two files.

The N5 audit landed at this allocation:

| Source file | Consumer role |
|---|---|
| `specifications/<level>-functional-spec.md` (or `<level>-spec-supplement.md`) | Sponsor / product / engineers — what the app does + how it looks (functional + visual). Folds in design system. |
| `<JLPT-root>/procedure-manual-build-next-jlpt-level.md` | Build agent (human or AI) — how to construct the next level. Folds in extracted-from-source schemas, polish items, TASKS.md template. Self-contained for one-shot Mode-B execution. |
| `feedback/ui-testing-plan.md` | QA / release engineer — how to verify each release. |

**Fragmentation tells:** ask "who reads file X?" — if the answer matches another file's reader, merge. Indicators of fragmentation pain:
- Cross-references like "see appendix B" / "see design-system spec §4.2" outnumber the unique content in either file.
- An editor opens 3+ tabs to cross-reference one decision.
- Stale references accumulate because reviewers don't have the bandwidth to track every file.

**The merge cost is small.** A markdown concat with a `## §X — merged YYYY-MM-DD` header and a short rationale line preserves history (git shows the move as deletes + insertions; the data is intact). A defensive markdown renderer (see §3.2.12) handles inconsistent table widths between merged sources. Build artefacts (.docx) regenerate from the merged source. Net effect: fewer files, same content, lower cognitive load.

When NOT to merge: roles differ. The UI testing plan (QA) is a separate role from the functional spec (product/engineers); merging would mean one file with two competing structures. Keep separate.

#### 3.2.12 Don't ship a markdown→docx build pipeline that crashes on inconsistent tables (MEDIUM — N5 build-script regression 2026-05-04)

When concatenating multiple markdown sources for build-time docx rendering, expect inconsistent table column counts. Markdown authors drop trailing pipes, slip a literal `|` into a cell, or carry over a different table convention from another file. A naive python-docx renderer that does `table.rows[r].cells[c]` without bounds-checking crashes with `IndexError: tuple index out of range` the moment any row's column count diverges from the header.

**Rule:** every table renderer in a multi-source build pipeline MUST normalise row width before allocating cells:

```python
def _emit_table(rows):
    if not rows: return
    n_cols = len(rows[0])  # header determines width
    if n_cols == 0: return
    normalised = []
    for row in rows:
        if len(row) < n_cols:
            row = row + [''] * (n_cols - len(row))    # pad short rows
        elif len(row) > n_cols:
            head = row[:n_cols - 1]
            tail = ' | '.join(row[n_cols - 1:])
            row = head + [tail]                        # stuff overflow into last cell
        normalised.append(row)
    table = doc.add_table(rows=len(normalised), cols=n_cols)
    # … fill cells …
```

This pattern lives in `tools/build_spec.py` `_emit_table()` after a 2026-05-04 fix. Without it, the procedure manual's tables (one row had a stray pipe in cell content) blew up the consolidated-spec build with no graceful degradation.

**Same defensive rule** applies to any other markdown feature where row/column structure is implicit: bullet lists with inconsistent indentation, code fences without closing markers, link references with missing parentheses. The renderer must handle malformed input by best-effort rendering, not by crashing.

#### 3.2.10 Don't keep stale module-level state on URL navigation (HIGH — N5 router regression)

Modules that hold session state in module-level variables (`view`, `session`, `lastResults`) and short-circuit on entry like:

```js
export async function renderX(container, params) {
  if (view === 'finished' && session) return renderFinished(container);
  // ...
}
```

…break user navigation. Scenario: user finishes a session → `view = 'finished'`. User clicks a "Back to <list>" link inside the finished view. URL hash changes. Router fires `renderX` again. The early-return short-circuits, re-rendering the SAME finished view. The user is "stuck" — clicking the back link does nothing visible.

Fix policy:

```js
export async function renderX(container, params) {
  const parts = (params || '').split('/').filter(Boolean);

  // State reset on navigation AWAY from active view. The 'attempting'
  // / 'results' state is meaningful only when the URL points to a
  // SPECIFIC entity (e.g., #/papers/<cat>/<n>, parts.length === 2).
  // If the URL is now the index or a list (parts.length < 2), the
  // user has navigated out of the flow — clear the stale state.
  if (parts.length < 2 && (view === 'attempting' || view === 'results')) {
    view = 'setup'; session = null; lastResults = null;
  }

  // Mid-flow state preserved for refresh / deep-link
  if (view === 'attempting' && session) return renderAttempting(container);
  if (view === 'results' && lastResults) return renderResults(container);
  // ...
}
```

The rule of thumb: **`'attempting' / 'in-progress'` state should resume on refresh; `'finished' / 'results'` state should reset when the user navigates away.** A user who finished and left the page once doesn't want to re-enter the same finished page on their next visit.

Same anti-pattern repeats across any module with view/session state — port the fix to all four modules at once (papers / test / review / drill or equivalent at `<L>`).

#### 3.2.13 Don't auto-tag `vocab_ids` in grammar examples by substring matching (CRITICAL — N5 native-teacher audit 2026-05-08)

A naive auto-tagger that scans each example's `ja` text and inserts every `vocab.json` ID whose `form` or `reading` appears as a substring will produce dense systematic mis-tagging on **homographs and homophones**. N5 had three classes of failure caught in the native-teacher audit:

| Bug class | Example | Wrong tag | Reason |
|---|---|---|---|
| Homophone with one-sided dictionary coverage | "きのうは あめでした" (yesterday was rainy) | `n<L>.vocab.<food-section>.あめ` (candy) — the only あめ entry happens to be the food sense | Tagger has no signal to prefer 雨 over candy |
| Homograph stem matched against wrong verb | "7時に おきます" (wake up at 7) | `n<L>.vocab.<group-1>.おく` (place) added alongside the correct `おきる` (wake) | The substring `おき` appears in both `おきます` (wake-stem) and `おきます` (place-stem); both get tagged |
| Adjective vs verb-stem homograph | "あした 雨が ふると おもいます" (I think it'll rain) | `n<L>.vocab.<i-adj>.おもい` (heavy) added alongside `おもう` (think) | Substring `おもい` appears in both `おもいます` (think-pol-stem) and the adjective `おもい` |

N5 had **18 such mis-tags** out of ~600 examples — every one would mislead a learner who clicked through to the vocab card.

**Fix policy (port verbatim to N`<L>`):**

1. **Kanji-form lookup only for kanji entries.** When indexing `vocab.json` for substring lookup, register the `form` (which contains the kanji surface) but DO NOT register the `reading` (kana surface) for any entry whose `form` contains kanji. The kana reading would substring-match unrelated kana strings; the kanji form is unambiguous.
2. **Translation-context disambiguator.** When two same-reading entries exist (e.g., `food.あめ` candy and `weather.雨` rain), use the example's `translation_en` to pick: contains "rain"/"rainy"/"raining" → tag the rain entry; contains "candy"/"sweet" → tag the candy entry. If neither, leave untagged and flag for human review.
3. **Reject co-tags of paired homographs in the same example.** Build a closed list of known verb-stem-collision pairs (`おく` / `おきる`, `おもう` / `おもい-adj`, `はる` / `はる-spring`, `かえる` / `かえる-frog`, etc.) and reject pair co-occurrence — keep only the one whose `pos` matches the surrounding verb-form. Drop the homograph.
4. **CI invariant `JA-44`** (see §2.2 update): cross-check vocab_id tags against translation context; fail if a "candy" tag is on a "rain" sentence.

The full N5 fix pattern lives in `not-required/tools-archive/dedup_vocab_2026_05_08.py` (in the N5 repo) — copy and adapt.

#### 3.2.14 Don't auto-extract `vocab_used` / `vocab_preview` from passages by raw substring scan (CRITICAL — N5 audit 2026-05-08)

Japanese has no orthographic word boundaries. A substring-scan extractor that walks each passage character-by-character and records every match against the vocab dictionary produces output dominated by:

- Single-kana matches that aren't real words: particles `は が を の に で`, sentence-final particles `ね よ ぞ`, fillers `え あ`.
- Phantom matches from across word boundaries: `うし` (cow) extracted from `とう**きょう**の` (no — actually unrelated; example: `おねが**いし**ます` substring-matches the entry いし "stone" even though there's no stone in the passage).
- Missing the actual content words because they don't appear with exact-form match (e.g., 食べる listed as `食べる` in vocab but appears as `食べてから` in passage; substring won't catch the plain-form lookup).

N5 had **997 entries across 45 reading passages** before audit; mostly noise. After the audit fix, **539 entries** of clean content vocabulary.

**Fix policy:**

1. **Same kanji-form-only rule** as §3.2.13 — register kanji `form` for any entry that has kanji; register `reading` only for purely-kana entries.
2. **Skip particle / filler sections.** When building the lookup table from `vocab.json`, exclude sections that are by definition function words: particles, fillers, conjunctions, sentence-final markers. These should never appear in a "vocab to learn" preview.
3. **Skip single-kana surfaces.** Even for kana-only entries, require ≥2 characters in the surface form. Single hiragana characters are almost always particle / aux fragments substring-matching from inside larger words.
4. **Apply the same homophone disambiguator** as §3.2.13: when `いま` (kana, "living room") and `今` (kanji, "now") both exist and both could match in the passage, prefer the kanji-form match if `今` (kanji) is present in the passage; only tag `いま` (living room) if the kana form actually stands alone.
5. **Long-term**: integrate `mecab` / `kuromoji` at build time for proper morphological tokenization. Until then, the kanji-form-only rule + section-skip + length filter gets you ~80% of the value with bounded false-positive risk.

#### 3.2.15 Don't list sokuon allophones as separate kun-readings (HIGH — N5 audit 2026-05-08)

Sokuon (small `っ`) assimilation before counter morphemes (`三つ` → `みっつ`, `四日` → `よっか`, `六つ` → `むっつ`, `八つ` → `やっつ`) is **a phonological rule, not a separate reading.** N5 mistakenly listed `みっ` / `よっ` / `むっ` / `やっ` as standalone kun entries on 三 / 四 / 六 / 八 in `data/n<L>_kanji_readings.json` and `data/kanji.json`. The audit removed them; the base reading (`み` / `よ` / `む` / `や`) is the correct kun, and the sokuon variant is allophonic.

**Fix policy:**

- For kanji that appear in counter compounds, list ONLY the base reading in `kun`.
- Document the allophony in `_meta.sokuon_allophony_note` of `data/n<L>_kanji_readings.json` (one paragraph; include an example).
- The full counter forms (`みっつ` / `よっつ` / etc.) live in the runtime UI's `js/counters.js`, not in the kanji-readings catalog.
- CI invariant `JA-43` (see §2.2 update): reject any kun array that contains a value ending in `っ` unless the kanji is on a documented allowlist.

#### 3.2.16 Don't ship duplicate vocab entries across thematic sections (CRITICAL — N5 audit 2026-05-08)

A vocab catalog organized into thematic sections (Locations, House and Furniture, Colors, Adjectives, Time, etc.) is tempting to populate by cross-listing the same word in every section it relates to. N5 did this for **41 (form, reading) pairs** — `へや` in both §13-Locations AND §26-House-and-Furniture, `白い` in both §20-Colors AND §31-i-Adjectives, `きっぷ` in both §22-Money AND §37-Common-Nouns, etc. Every cross-listing existed as a SEPARATE entry with its own ID.

The downstream cost was **164 same-reading double-tags in `grammar.json`** examples, because the auto-tagger from §3.2.13 then tagged BOTH IDs whenever the word appeared. Each double-tag is invisible until a learner clicks through and sees the same vocab card twice (or differently between two entry points).

**Fix policy (CRITICAL — apply on day 1 of N`<L>` vocab authoring):**

1. **One canonical entry per (form, reading) tuple.** Period. Cross-listing is metadata, not duplication.
2. **Polysemes are the only legitimate same-(form, reading) duplicates.** Polyseme = different glosses (e.g., は = tooth/leaf/topic-particle; おく = hundred-million/place; 本 = counter/book). Distinguish polysemes via the `.2` / `.3` suffix on the ID, and the gloss MUST explicitly disambiguate (e.g., `あつい` → §31.あつい "hot weather (暑い)", §31.あつい.2 "hot to touch (熱い)", §31.あつい.3 "thick (厚い)").
3. **Cross-listings are deliberate redundancies in the SOURCE markdown** (`KnowledgeBank/vocabulary_n<L>.md`) and must be marked with `(also in §X)` parenthetical in the gloss. The build script collapses them to a single canonical entry in `vocab.json`.
4. **CI invariant `JA-42`** (see §2.2 update): no two entries share `(form, reading)` AND have normalized-identical glosses without `(also in §X)` marker; flag for dedup.
5. **Dedup recipe** (when retrofitting an existing corpus): see new §20 for the full step-by-step.

#### 3.2.17 Refresh ALL derived metadata when re-authoring source content (HIGH — N5 audit 2026-05-08)

When N5 rewrote listening scripts (audio re-render pass), the `script_ja` / `lines` / audio file all updated correctly. But sibling derived fields — `explanation_hi`, `cultural_context`, `explanation_en` — were **not refreshed** because they were authored in an earlier draft. The audit found 4 listening items (002, 003, 004, 005) where the Hindi explanation described entirely different content from the audio:

- Item 002: audio said "buy bread, eggs, milk" → Hindi explained "salad/soup ordering at a restaurant"
- Item 003: audio said "leave home at 8:30" → Hindi explained "9:30 train"
- Item 004: audio said "iced coffee" → Hindi explained "books at ¥1,500 × 3"
- Item 005: audio said "train delayed" → Hindi explained "weather small-talk"

A learner with Hindi UI sees an explanation that contradicts the audio they just heard.

**Fix policy:**

- **Treat sibling fields as a wired group.** Any pass that modifies `script_ja` / `lines` MUST also refresh `explanation_*`, `cultural_context`, `prompt_ja` derivatives, and `correctAnswer`. Make this a checklist line in the pass's plan.
- **CI invariant `JA-46`** (see §2.2 update): drift detector — if `script_ja` mentions noun X and `explanation_hi` does not mention X (or its translation), flag for review.
- When the build script re-renders audio from updated scripts, it should write a sidecar log that lists every item touched, and `tools/check_content_integrity.py` should compare that log against `git diff --name-only` on the explanation fields. Mismatch = unrefreshed sibling.

#### 3.2.18 Don't ship pedagogically-blunt mnemonics (MEDIUM — N5 audit 2026-05-08)

The 母 mnemonic in N5 was originally:

> "Two breasts inside a body = MOTHER."

Anatomically frank for a learning context. Native teachers reviewing the corpus immediately flagged it. Same risk applies to any kanji whose etymology involves body parts, sexuality, violence, or culturally-sensitive metaphors (古 / 凶 / 悪 / 死 / 男 etc.).

**Fix policy:**

- Re-frame etymology in pedagogically-neutral language: "A figure of a nursing mother — the two emphasized dots originally depicted breasts, signaling 'mother' by the act of nursing." Same etymological fact, diplomatic phrasing.
- Add a mnemonic-tone review pass before declaring the kanji catalog done. Read every mnemonic aloud and ask: "would a 12-year-old in a classroom hear this and feel embarrassed?" If yes, soften.

#### 3.2.19 Maintain orthographic consistency in surface conventions (MEDIUM — N5 audit 2026-05-08)

Within a single corpus, don't mix kanji and hiragana renderings of the same morpheme across items. N5 had:

- `8時半` (kanji) in some listening items; `8時はん` (hiragana 半) in others; `三時はん` (kanji number + hiragana 半) in a third.
- Arabic numerals `8時` mixed with kanji numerals `八時` for clock times.

Either is acceptable; **mixing is not.** The mixing makes the corpus look unmaintained and fails the JLPT-textbook-consistency expectation.

**Fix policy:**

- Pick a convention per surface and document it in `MEMORY.md` / `specifications/`. Recommended for clock-time:
  - **Scripts** (`script_ja`, `lines.text_ja`): all-kanji numerals (`八時半`) — matches actual JLPT exam format.
  - **Choices in MCQ**: arabic numerals (`8時`, `8時半`) — clearer in a multiple-choice list.
  - **Half-hour marker**: kanji `半` everywhere (it's whitelist-N5 and matches exam convention).
- Add a CI regex check: forbid `[時]はん` outside an explicit allow-list in any user-facing field.

#### 3.2.20 Don't carry legacy schema fields past their migration (MEDIUM — N5 audit 2026-05-08)

When a schema migrates (e.g., listening item's `voice` string field → `voice_planned` block with `speaker_role_map`), **delete the legacy field** from existing entries in the same commit. N5 had 18 listening items carrying both:

```json
"voice": "synthetic-voicevox-shikoku-metan",      ← legacy, no JS consumer
"voice_planned": { "primary": "...", "speaker_role_map": {...} }  ← new
```

Tooling has to handle both shapes, every consumer pays the migration cost, and the legacy field rots until someone notices.

**Fix policy:**

- A schema migration commit MUST: (a) introduce the new field on all entries, (b) delete the legacy field from all entries, (c) update CI / runtime / build tools to expect only the new field. All three in one commit.
- If you can't do (b) in the same commit (e.g., partial migration spanning sessions), add a `_meta.legacy_field_deprecation_date` so the cleanup is scheduled.
- Provenance honesty: if a `review_status: "native_reviewed"` field is used to mark "Claude acting as native-reviewer persona" rather than a recruited human, document this explicitly in the file's `_meta.native_review_pass_<date>` block. Institutional adopters who need strict-human-review need to know the difference.

#### 3.2.21 Don't use stale-while-revalidate for shipping CHANGING content (CRITICAL — N5 deployment regression 2026-05-10)

The N5 service worker shipped with `stale-while-revalidate` for shell assets (HTML/CSS/JS). Every reload served the OLD cached version *instantly*, then fetched the new one in the background. Net effect after every deploy: the user's first reload showed the previous deploy; only the second reload (or a manual SW unregister) showed the new code. During a single fast iteration cycle this looks like "I pushed but nothing happened" — and it repeated 3+ times in one session before the root cause was traced.

**The trap:** stale-while-revalidate reads as a "best of both worlds" pattern in caching tutorials (instant load + eventual consistency). It is — for content that NEVER changes per release. The N5 shell DOES change per release. The pattern is therefore wrong for that surface.

**Fix policy (port to N`<L>` day 1):**

```js
// HTML / navigation requests: NETWORK-FIRST. Cache is offline fallback only.
if (isHTMLRequest(url, request)) {
  event.respondWith((async () => {
    try {
      const fresh = await fetch(request);
      if (fresh.ok) (await caches.open(CACHE_VERSION)).put(request, fresh.clone());
      return fresh;
    } catch {
      const cached = await (await caches.open(CACHE_VERSION)).match(request);
      return cached || new Response('Offline', { status: 503 });
    }
  })());
  return;
}
// CSS / JS / JSON / SVG / audio / fonts: cache-first (URL-keyed via ?v=N).
```

Detection: `request.mode === 'navigate'` or `url.pathname` ends in `/` or `.html` or has no extension.

**The corollary anti-pattern in the same area** — bumping `CACHE_VERSION` in `sw.js` but forgetting `?v=` cache busters on `<link>` and `<script>` in `index.html`. Already documented in bumper-sticker #18, but worth restating: the SW update mechanism is layered (SW cache + browser HTTP cache + ES-module cache); all layers need invalidation in a single commit, or the user sees nothing change.

#### 3.2.22 Don't use `<img src="…svg">` for brand-color SVG that should inherit `currentColor` (HIGH — N5 logo bug 2026-05-09)

The horizontal-lockup SVG was authored with `<g fill="currentColor">` and `<text fill="currentColor">` — designed to inherit theme color from the parent CSS. The HTML used `<img class="brand-logo" src="assets/logo/horizontal.svg">` and the CSS set `.brand-logo { color: white }`. Result: the logo rendered in **black** on the dark-green band — the design intent was silently broken.

**Why:** `<img>` loads SVG as an external resource. `currentColor` resolves against the SVG's *own* computed style (which has no `color` set; defaults to black). The HTML `<img>` element does not propagate parent CSS `color` into the loaded SVG.

**Fix policy:**

- For ANY SVG that needs to inherit the parent's `color` (logos, mark icons, theme-aware glyphs): inline the SVG directly into the HTML / template. The inlined `<svg>` becomes part of the document and `currentColor` resolves against the surrounding CSS.
- If you can't inline (e.g., the SVG is large, or you're using a static-asset pipeline that requires file references): ship a hardcoded-color variant per theme (e.g., `horizontal-white.svg`, `horizontal-brand.svg`) and swap the `src` via JS or media-query CSS.
- DO NOT rely on `<img src="…svg">` + parent CSS `color` for theme-tintable marks. The combination silently fails.

#### 3.2.23 Don't ship two slightly-different brand-color hex values across files (MEDIUM — N5 family-alignment audit 2026-05-09)

The JLPTSuccess landing page used `#14452a` for `--brand`. The N5 sub-app used `#1F4D2E` for `--color-accent`. Visually almost identical (~3% delta in luminance), but every place a learner navigated *between* the surfaces — landing page → click N5 → see N5 chrome — there was a subtle hue shift. Not catastrophic; not professional either.

**Fix policy:**
- Pick ONE canonical brand-green hex value. Use it in every CSS file across the project tree. Same for any other identity color.
- Audit on every commit that touches CSS color variables: `git diff -- '*.css' | grep -E '#[0-9a-fA-F]{6}'` and check for new color values.
- Consider a CI invariant that loads every `--brand`/`--color-accent`/`--header-bg` declaration across CSS files and asserts a closed set.

#### 3.2.24 Don't re-render the input element on every keystroke when Japanese-IME-typing is supported (CRITICAL — N5 IME composition bug 2026-05-10)

The grammar / vocab / kanji search inputs (`#grammar-filter-q`, `#vocab-filter-q`, `#kanji-filter-q`) all bound `input` event handlers that re-rendered the entire category list (`container.innerHTML = …`). Each re-render destroyed the input element. Result: a user typing いたい via a Japanese IME got いｔあい — partial-state Latin characters leaking into the value.

**Why:** A Japanese IME goes through compositionstart → multiple `input` events with intermediate state (typing "ita" emits い → ｔ → あ → い across events) → compositionend. If the input element is destroyed mid-composition, the IME's state machine loses its target and commits the partial Latin character. Same bug shape affects Korean / Chinese IMEs and dead-key sequences on European keyboard layouts.

**Fix policy:**

```js
let isComposing = false;
input.addEventListener('compositionstart', () => { isComposing = true; });
input.addEventListener('compositionend',   () => {
  isComposing = false;
  reapplyFilter();   // re-render once with the committed value
});
input.addEventListener('input', () => {
  if (isComposing) return;   // wait for compositionend
  reapplyFilter();
});
```

**Horizontal-deployment scope:** EVERY search-style input on a Japanese-content app needs this guard. Audit list — for the N5 codebase, the affected files were `js/learn-grammar.js`, `js/learn-vocab.js`, `js/kanji.js`. The header global search (`js/search.js`) was *not* affected because its handler updated a separate panel without destroying the input — but that's a per-implementation property, not a category exclusion. Test by trying to type Japanese text in every text input and see if the IME drops characters.

#### 3.2.25 Don't conflate "easy Japanese (やさしいにほんご)" with "plain Japanese with kana substitutions" (HIGH — N5 native-teacher audit follow-up 2026-05-10)

When a content field is labeled `meaning_ja` with a UI heading like `意味（やさしいにほんご）`, learners and accessibility reviewers expect the actual register of "Easy Japanese" — the formally-defined accessibility tier (弘前大学 やさしい日本語 guidelines, used by NHK NEWS WEB EASY). That register has SPECIFIC rules:

1. One idea per sentence; ≤30 characters.
2. Common vocab only (typically JLPT N5–N4 floor).
3. No abstract grammar markers like `について`, `に関して`, `に対して`, `〜ばかり`.
4. No double negative, passive voice, or causative.
5. Concrete examples instead of abstract definitions.
6. If kanji used, give furigana.

**Trap:** writing "Japanese with most kanji replaced by kana, in normal sentence-structure, using whatever vocabulary fits" produces text that LOOKS like it could be easy Japanese to a non-native author — but uses words like `しつもん` (質問, N4), grammar like `〜について` (N3), and multi-clause sentences. A real Japanese reader looking at it sees "plain Japanese with weird kanji-avoidance," not easy Japanese.

**Fix policy:**

- If a field is labeled "easy Japanese" in the UI, the content MUST follow the accessibility-register rules above. Author with the rules visible during authoring; do NOT author by intuition.
- If you can't commit to the register, RENAME the field's UI label to something honest (e.g., `意味` alone, or `Japanese definition`). Don't claim a register you don't deliver.
- Don't bulk-author "easy Japanese" fields without a reviewer — even an LLM-as-reviewer pass with the rules in the prompt catches most non-compliance. Pattern: write each entry → check against rules → commit. Not: write 100 entries by intuition → commit.

#### 3.2.26 Don't try to promote kana-to-kanji across a Japanese corpus with regex alone (HIGH — N5 Job-C false-positive cascade 2026-05-10)

The N5 audit asked: "if 何 is in the N5 whitelist, the corpus should USE 何 instead of なに / なん everywhere." Sounds simple. Two iterations of a regex-based promoter produced systematic false positives because Japanese has no orthographic word boundaries:

- `きます` (verb stem) matched inside `できます` / `いただきます` / `〜しています`, producing `でき来ます` / `いただ来ます` (wrong — できる is one verb, not で + 来る).
- `いま` (now) matched inside `もらいます` / `おもいます`, producing `もら今す` / `お今す`.
- `きょう` (today) matched inside `とうきょう` (Tokyo), producing `とう今日`.
- `とお` (ten) matched inside `とおもいます` ("I think"), producing `十もいます`.

Boundary regex options all break:
- Allow kana neighbours → compound-word false positives.
- Disallow kana neighbours → blocks all particle-suffix cases (`わたしは` no match because は is kana).
- Whitelist specific particles in lookahead → mostly works but still has compound-word risk for any ambiguous prefix.

**Fix policy:**

- DO NOT run a regex-based promoter on a Japanese corpus without a morphological tokenizer (mecab / kuromoji / sudachi). The boundary problem is fundamental to the script.
- For surgical fixes (e.g., a known small list of pattern titles): hand-edit each one. Don't generalize from "I fixed 5 manually" to "let me sweep with a regex" — the regex will hit cases the manual edit didn't anticipate.
- If you must do a sweep: integrate mecab as a build-time dependency. Pre-tokenize the text, then promote at token boundaries (mecab knows `できます` is one verb; the promoter can skip the `きます` substring).
- Before declaring "we need a sweep": SAMPLE the existing corpus. Most "promotion needed" sweeps reveal the work was already done case-by-case in earlier authoring rounds. The N5 pass discovered ~90% of grammar examples were already promoted; the remaining ~10% was 5 pattern titles fixable by hand.

**Anti-corollary:** the same lesson applies to any Japanese-text mass-edit — kana→katakana, hiragana→kanji, full-width→half-width, etc. Without a tokenizer, regex is too blunt.

#### 3.2.28 Don't trust project-level `.claude/settings.local.json` to silence permission prompts if the global `~/.claude/settings.json` doesn't already permit the pattern (HIGH — N5 permission-prompt iteration 2026-05-11)

After two CLAUDE.md files at `JLPTSuccess/.claude/` and `JLPTSuccess/N5/.claude/` both pointed at `settings.local.json` files that DID NOT EXIST, three rounds of editing project-level `settings.local.json` failed to stop a routine compound `cd "..." && git add ... && git commit -F .commit_msg.tmp && rm -f .commit_msg.tmp && git push origin master 2>&1 | tail -3` prompt. The settings files were correct on paper; the prompts kept firing.

**Why:** Claude Code resolves permission settings in this order:

1. `~/.claude/settings.json` (user-global) — **authoritative; always loaded.**
2. `<repo>/.claude/settings.json` (project, committed) — loaded if Claude Code's working directory walks up to it.
3. `<repo>/.claude/settings.local.json` (project, gitignored) — loaded if present alongside (2).

The compound command was decomposed segment-by-segment, and the `rm -f .commit_msg.tmp` segment had NO matching allow pattern in the global file even though `Bash(*)` was present. Compound commands trigger Claude Code's per-verb safety screen for destructive shell verbs (`rm`, `mv`, `cp -f`); the wildcard `Bash(*)` is treated as "I'll allow anything I don't recognize" but does NOT satisfy the per-verb requirement.

The project-level `settings.local.json` files I'd carefully crafted with `Bash(rm -f .commit_msg.tmp*)` weren't even being loaded — or were being merged with lower priority than expected, since the working directory + Claude Code resolution path didn't include them.

**Fix policy:**

- Put ALL permission patterns in `~/.claude/settings.json` (global). Project-level files are defensive duplicates, not the source of truth.
- For every `Bash(verb *)` you expect to use, add an explicit allow pattern at the global level. Don't rely on `Bash(*)` — it's not a kill switch.
- For compound chains, add the literal command shape as a fallback (e.g. `Bash(cd * && git add * && git commit -F * && rm -f .commit_msg.tmp && git push*)`).
- If a prompt fires unexpectedly, the first diagnostic is `Read ~/.claude/settings.json` — NOT iterating on project settings.
- The `update-config` skill (Claude Code built-in) has the resolution rules baked in. Use it instead of hand-iterating patterns. See §12 #15.

The N5 fix added 7 allow patterns + 17 defense-in-depth deny rules (backup-file protection at the global level) and ended the prompt churn entirely. Zero prompts across 9 subsequent commits.

#### 3.2.29 Don't trust Python integrity-check FAIL output on Windows console without forcing UTF-8 I/O (MEDIUM — N5 F-12 false-positive scare 2026-05-11)

During F-12 KB-file deletion, `python tools/check_content_integrity.py` reported "FAIL: 4 integrity violation(s)" with mojibake-corrupted (`�`-symbol) detail strings. A panicked rollback would have been triggered if the user had pushed for it. Re-running with `PYTHONIOENCODING=utf-8 python -X utf8 tools/check_content_integrity.py` → "PASS: all 52 invariants green."

**Why:** Windows default console codepage (cp1252 / cp932 depending on locale) can't encode kanji in failure-message string formatting. The Python integrity-check script collects failure descriptions including the offending kanji (e.g., `'弁'`) and tries to print them. The print fails inside the failure-collection logic itself, the exception is partially swallowed, and the script reports false-positive failure counts. The actual JA-13 check (which uses `re.compile` + Unicode whitelist comparison) is correct; only the OUTPUT path is broken.

**Fix policy:**

- ALWAYS run integrity checks on Windows with `PYTHONIOENCODING=utf-8 python -X utf8 tools/check_content_integrity.py` — never bare `python tools/check_content_integrity.py`.
- Document this in the project's `tools/` README and the binding `.claude/CLAUDE.md` test-running line.
- If a CI gate spuriously fails with kanji in the error message, the FIRST debugging step is "did the runner force UTF-8?" — not "is the content actually bad?"
- Fix the script itself when feasible: wrap `print()` in a UTF-8 reconfigured stdout (`sys.stdout = io.TextIOWrapper(sys.stdout.buffer, encoding='utf-8', errors='replace')` at script entry). This makes the script self-defending instead of relying on the runner.

**Anti-corollary:** ANY Python script that prints Japanese to stdout on Windows is suspect. Audit `tools/*.py` for missing UTF-8 stdout reconfiguration; add it as a standard pre-amble.

#### 3.2.30 Don't trust an audit's named-file scope as exhaustive (HIGH — N5 F-1 → F-12 audit gap 2026-05-11)

The 2026-05-10 legal-vetting audit's F-1 finding named two files for `git rm` (`feedback/closed/external-questions-learnjapaneseaz.md` + `external-corpus/learnjapaneseaz-extract.json`). Pre-deletion grep across the codebase surfaced a THIRD file in the same risk class — `KnowledgeBank/externally_sourced_n5.md` (1778 lines, 42 mentions of `learnjapaneseaz.com`, line 20 declared verbatim "All questions in this file are extracted from public practice tests on learnjapaneseaz.com/jlpt-n5"). The audit had missed it. Closing F-1 without acting on the third file would have left ~90% of the DMCA exposure on disk.

**Why:** audits enumerate specific examples but rarely exhaustively grep. The auditor's mental model is "I saw THESE files, they exemplify the risk" — not "I traversed the file tree and confirmed these are the ONLY files." For DMCA / IP / licensing audits especially, the risk-class membership is keyword-driven (search for the rights-holder's URL, name, or distinctive content signatures), not file-by-file curated.

**Fix policy:**

- Before closing ANY audit finding that names specific files, run `grep -rln "<risk-keyword>" .` to find adjacent files in the same risk class. Examples of keywords to grep: source URL, author name, distinctive content phrases, license-string fragments.
- If the grep surfaces additional files, register them as a NEW finding (different ID) and surface to the user for scope decision — don't unilaterally expand the original finding's scope.
- The N5 pattern: F-1 closed for the 2 audit-named files; F-12 newly registered for the discovered third file; both ultimately fixed in separate commits with separate trails.
- Same posture applies to bug audits, security audits, accessibility audits, performance audits — anywhere "find all instances" is the latent need but only "fix this one" is the explicit ask.

**Horizontal deployment:** for every finding closed in this session, AFTER closure run `grep -rln "<finding-keyword>"` once more — if grep surfaces hits beyond the closure scope, log the gap as a new finding rather than letting the original audit's "closed" status mislead future readers.

#### 3.2.31 Don't trust metadata when data, code, and docs disagree — inspect the actual output artifact for ground truth (HIGH — N5 F-13 TTS provider misattribution 2026-05-11)

The N5 listening audio had THREE contradictory sources of truth:
- **Data:** `data/listening.json#audio_render_meta` claimed `voice_provider: "voicevox"` + `voicevox_engine_version: "0.25.2"` for all 47 rendered items.
- **Code:** `data/listening.json#voice_planned` claimed `engine: "edge-tts"` with Microsoft Neural voices (NanamiNeural, KeitaNeural, AoiNeural, DaichiNeural).
- **Docs:** `NOTICES.md` §VOICEVOX claimed VOICEVOX with specific character speakers (四国めたん, 春日部つむぎ, 白上虎太郎, 青山龍星) and a CC-BY licence summary.

All three could not be right. Without ground truth, "fix" decisions are guesses.

**Ground truth source:** the actual MP3 file bytes. The ID3v2 TSSE frame on `audio/listening/n5.listen.001.mp3` showed `Lavf62.12.101` — the ffmpeg/libavformat encoder string used by the edge-tts pipeline. No VOICEVOX byte signature in any header. The MP3 files were demonstrably rendered by edge-tts, not VOICEVOX. The `voicevox` data fields were stale carry-over from a pre-2026-05-07 render attempt that never shipped; the docs were never updated when the pipeline migrated.

**Fix policy:**

- When data, code, and docs disagree about an external dependency (TTS provider, font source, license version, library version, etc.), DO NOT pick the "majority" source. Inspect the output artifact directly.
- For audio: ID3v2 frame inspection (`bytes[:200]` shows ID3 header + tag frames). FFmpeg-rendered output carries `Lavf<version>` in TSSE; engine-specific output carries engine-specific markers.
- For images: EXIF metadata (PIL / exiftool), generator-tool signatures.
- For PDFs: producer-tool string in PDF header (`/Producer (Adobe PDF Library 11.0)`, `/Producer (LaTeX with hyperref)`, etc.).
- For static binaries: file-magic + linked-library detection.
- For HTML/web outputs: comment markers, framework fingerprints, build-tool meta tags.

**Anti-corollary:** when migrating between providers (TTS, fonts, libraries), update ALL three layers (data, code, docs) in the same commit. Or set up a CI invariant that detects drift. The N5 audit caught this 4 days after the migration shipped — long enough for stale claims to propagate downstream.

#### 3.2.32 Don't `git rm` an audit-flagged file without first refactoring the tools that depend on it (MEDIUM — N5 F-12 tool-wiring 2026-05-11)

F-12 wanted `git rm KnowledgeBank/externally_sourced_n5.md`. Pre-deletion grep surfaced 3 references in `tools/check_content_integrity.py` (in `QUESTION_FILES` list, `EXPECTED_Q_COUNTS` dict at 189 questions, and 3 docstring exemption notes) plus a docstring mention in `tools/build_papers.py`. A naive `git rm` would have triggered immediate CI failure on the next integrity check (file missing where expected, 189-question count drops to 0).

**Why:** content-quality CI gates often track expected-file presence or count. When the file is removed for legal reasons, the CI gate that protected its existence becomes a regression-detector for the deletion itself. The fix requires synchronized refactor: remove the file AND remove its tool wiring AND update any expected-state constants AND update any docstring exemption notes.

**Fix policy:**

- Before `git rm <file>`: grep the entire codebase for the basename. Build a list of every file that references it.
- For each reference: categorize as
  - **Tool wiring** (constants, lookup lists, expected counts) → refactor in same commit
  - **CI invariant** (file-existence check, count check) → refactor in same commit
  - **Docstring / comment** (informational) → optionally update; mark as retired with date
  - **Doc table / README** (audit-trail / index) → update to mark `[REMOVED YYYY-MM-DD per <reason>]`
  - **CHANGELOG / historical** (describes past state) → leave alone; historical claim is still accurate
- Re-run the relevant CI gate AFTER the deletion + refactor to confirm green.
- Commit message MUST list the refactored tools so future reviewers know the CI change wasn't unrelated.

**Anti-corollary:** the same pattern applies to deleting CSS classes, JS modules, data-schema fields, locale keys — anywhere a value is referenced by another file's logic. Grep before delete is non-negotiable.

#### 3.2.33 Don't ship half-applied ウ音便 keigo forms in `politeness_ladder.humble` (HIGH — N5 n5-181 たかう→たこう fix 2026-05-11)

`politeness_ladder.humble` rows render i-adjective + ございます keigo forms (e.g. `たこうございます` from 高い). The ウ音便 (u-sound-change) derivation has TWO mandatory steps and missing either produces a form no modern native speaker writes:

1. **Drop the `く`/`き` of the 連用形** — `たかく → たかう`, `おいしく → おいしう`, `やすく → やすう`
2. **Contract the resulting vowel pair** per i-adjective vowel:
   - **`a + u → ō`** — たかう → **たこう**, ありがたう → **ありがとう**, はやう → **はよう**
   - **`i + u → yū`** — おいしう → **おいしゅう**, うれしう → **うれしゅう**, やさしう → **やさしゅう**
   - **`o + u → ō`** — のう (e.g. 良う / 無う) → **のう** (irregular)
   - **`u + u → uu`** (stays) — やすう → **やすう** (no contraction; this is the false-positive trap in sweeps)

The N5 audit caught `たかうございますね` (step 1 applied, step 2 missed). Native speakers read this as broken. Fix: `たこうございますね`. Compare the well-known forms `ありがとう ございます`, `おはよう ございます` — same rule.

**Fix policy:**

- Author humble forms by formula, not intuition. Look up the i-adjective's stem vowel, apply the matching contraction rule.
- When sweeping for related bugs across `politeness_ladder.humble`: grep for `[たはなあいう]う` followed by `ござ` to catch half-applied forms; remember `u+u` is a false positive (verify before "fixing").
- A future audit pass should systematically check every `politeness_ladder.humble` entry containing `ございます` against the matched i-adjective + contraction rule.

**Anti-corollary:** the same rules apply to plain-text `humble` register vocab anywhere in the corpus (rare in N5 since humble register is N3+ scope), but `politeness_ladder` is the field most likely to carry it. The `politeness_ladder` field is intentionally exempted from JA-13 (out-of-scope-kanji check) — see `SKIP_SUBTREE_FIELDS` in `check_content_integrity.py` — because by design it surfaces N3+ keigo forms for cross-level pedagogical context. The CI gate cannot catch this class of bug; native-teacher audit is the only check.

#### 3.2.34 Don't leave `form` field empty on grammar examples when sibling examples in the same pattern have it set (MEDIUM — N5 n5-181 watermark gap 2026-05-11)

Grammar examples in `data/grammar.json` can carry a `form` field whose value renders as a green category badge above each example in the detail-page UI (e.g. `affirmative`, `tasty-exclamation`, `exclamation-expensive`). When some examples in a pattern have `form` set and others don't, the renderer falls back to an empty `_` placeholder where the badge should be — visible content drift on the example list. Users perceive the empty badges as "watermarks missing" or "category labels missing" depending on how they describe the UI.

**N5 case:** pattern `n5-181` (`～なあ`) had 7 of 10 examples with `form` set (affirmative / tasty-exclamation / exclamation-X variants) and 3 examples with no `form` field at all. The 3 unbadged rows rendered as `_ きれいだなあ。` / `_ おなかが すいたなあ。` / `_ いい てんきだなあ。` while sibling rows showed proper badges. Visible drift; flagged by user during routine review.

**Fix policy:**

- For each pattern, examples should be either ALL badged or ALL unbadged. Mixed state is the bug.
- When authoring new examples for a pattern that already has badges, set `form` on every new example before commit.
- When authoring a pattern fresh, decide up front whether `form` is needed for this pattern (depends on whether the pattern has distinguishable usage scenarios). Either set it on all 10 examples or none.
- Consider adding a CI invariant **JA-49: `data/grammar.json` examples within a pattern have consistent `form`-field presence (all set or all unset)**. The check is straightforward — for each pattern, the count of examples with `form` set must be either 0 or equal to total. Implementation cost: ~15 lines in `check_content_integrity.py`. Pending future audit pass.

**Anti-corollary:** the same pattern applies to ANY optional UI-facing badge/tag field that has visible fallback rendering. Audit list to check: `usage_role`, `register`, `tier`, `format_type`, `provenance` flags — anywhere a partially-populated field leaks an empty-state visual to the UI.

#### 3.2.35 Don't fill grammar example slots with canned boilerplate sentences without verifying pattern-relevance (CRITICAL — N5 grammar-corpus audit 2026-05-14)

During an authoring pass on the N5 grammar corpus (Phase 1 + 2 of the 2026-05-14 cleanup), an audit discovered that a small set of canned sentences had been copy-pasted into example slots across many patterns without verifying whether the example demonstrated the target pattern. Surfaced by user report: the と-particle grammar-detail page showed examples that didn't contain と as a particle ("じぶんで しゅくだいを します。" uses で; "父に とけいを もらいました。" uses に — neither demonstrates と).

**Scope of the bug (worst case, pre-cleanup):**

- `"あなたは がくせいですか。"` appeared in **21** grammar patterns
- `"あなたは どなたですか。"` appeared in **18** patterns
- `"どうして 来ませんでしたか。―あたまが いたかったからです。"` appeared in **17** patterns
- 14 boilerplate sentences each appeared in 8–14 patterns
- 232 example slots ultimately needed replacement across ~85 of the 178 N5 grammar patterns (48% of the corpus).

**Why this is CRITICAL severity (not just a polish item):**

- The example slots are the LEARNER-FACING demonstration of the grammar pattern. If the example doesn't use the pattern's marker, the learner doesn't learn the pattern from that surface.
- Pedagogically misleading: a learner who studies と-particle from the と-detail page and sees じぶんで しゅくだい... + 父に とけい... will form NO mental model of と-particle usage from those slots.
- The bug compounds: the same boilerplate sentence at indices [5][6] across 10+ patterns means the learner sees the SAME unrelated sentence on 10+ different study pages — a strong negative signal about content quality.

**Root cause:** at some authoring batch, the slots at indices [4]/[5]/[6] of many particle and conjugation patterns were bulk-filled with a small set of "filler" sentences as boilerplate, without per-pattern checking. Likely candidates: a tool that auto-generated examples by sampling from a small fixed pool; a hand-fill batch that lost track of which pattern was being authored.

**Fix policy:**

- Every example slot must contain a sentence that demonstrates the target pattern's marker. Verifiable by: does the example contain the literal pattern string (for compound markers like 〜について), OR does the marker appear as a particle/morpheme (for single-char particles like と / を / に)?
- The pattern's `form` tag on each example must match the example's actual conjugation/usage state.
- Cross-pattern reuse of an example sentence is allowed BUT capped — a single canonical sentence appearing in 10+ patterns is the boilerplate-leak signal.
- Within-pattern reuse (same sentence at two indices in one pattern) is forbidden; wastes a slot.

**CI gate added (JA-81, 2026-05-14):** "No grammar example sentence repeated in 10+ patterns (boilerplate-leak guard)." Locks the post-cleanup state. The threshold is 10 — well above the level of legitimate canonical reuse (e.g., `"わたしは がくせいです。"` appears in ~9 basic-copula patterns as the canonical です example, all relevant), well below the original boilerplate-leak levels (14–21).

**Audit infrastructure preserved at:** `not-required/tools-archive/audit_grammar_example_relevance_v2_2026_05_14.py` — single-char particle disambiguation (particle vs noun-internal substring), tilde-separator handling for "から〜まで", parenthetical-reading expansion for "何（なに／なん）", paren-readings → alternatives expansion. Re-run after any large grammar-corpus authoring pass.

**Anti-corollary:** the same anti-pattern applies to vocab.json and questions.json — any data field where bulk-authored slots could be filled with placeholder/template content without per-slot relevance verification. Audit list: vocab.json `examples[]` array, questions.json `rationale_en`/`rationale_hi` fields, reading.json `comprehension_questions[]`, listening.json `script_ja`. Each should be spot-checked for the "same sentence repeated across N entries" smell.

**Bumper-sticker form:** "Every example slot earns its slot by demonstrating the target marker. A boilerplate sentence in the wrong pattern teaches nothing."

#### 3.2.27 Don't expect `align-items: center` on a flex parent to center text inside a min-height-enforced child (MEDIUM — N5 menu-bar centering 2026-05-10)

The N5 header had `<nav class="primary-nav">` with `display: flex; align-items: center;` containing `<a>` links. Each link was bumped to `min-height: 44px` by the global tap-target accessibility rule. With `display: inline` (the `<a>` default), the 44px-tall link box held the text on the BASELINE — visually below the geometric center of the 44px box. The whole `<nav>` was centered in the 56px header band, but the *text inside each link* sat low.

**Why:** a flex parent's `align-items: center` centers the CHILD ELEMENT vertically. It does NOT control text alignment within that child. If the child has `min-height` enforced and uses default `display: inline`, the text inside still falls on the inline baseline — not the geometric middle.

**Fix policy:**

- For any text-bearing child of a flex container that ALSO has `min-height` from a global rule (tap-targets, accessibility): give the child `display: inline-flex; align-items: center` of its own. The text then centers within the min-height box.
- Same applies to `<button>` and `<a>` with explicit `min-height`. Add `display: inline-flex; align-items: center` to each.
- Audit pattern: any global `min-height: 44px` (or similar) rule should be paired with an audit that every targeted selector also has a flex/grid display so center alignment actually works.

### 3.3 Authoring cadence

Roughly the N5 trajectory by week:

| Week | Activity | Deliverable |
|------|----------|-------------|
| 1 | Bootstrap + pipeline | Empty corpus, all CI invariants green on empty content |
| 2-3 | Grammar catalog (KB + build) | grammar.json with N<L> patterns, no examples yet |
| 3-4 | Examples + furigana | Each pattern has 2-5 example sentences |
| 4-5 | Vocab catalog | vocab.json with ~1500 entries, sectionalized |
| 5-6 | Kanji catalog | kanji.json with N<L>-whitelist entries, on/kun trimmed to N<L> scope (per §0 size table) |
| 6-7 | Reading passages | reading.json with ~30 passages |
| 7-8 | Listening items | listening.json with ~30 items |
| 8-10 | Questions (moji + goi + bunpou + dokkai) | 100 each = 400+ questions |
| 10-12 | Native review (Pass-1) | First teacher review of corpus |

Plan ~12 weeks of full-time content work for the N5 → N4 transition (the smallest jump). For N3 and below, multiply by ~1.5x per level (per §13).

### 3.4 External corpus extraction (1-2 days)

Pull questions from learnjapaneseaz.com or similar third-party JLPT N<L> practice sites for **triangulation only** (do NOT copy verbatim into your bank — copyright). Use them to:
- Cross-check your coverage (do you test the same patterns?).
- Spot multi-correct bugs in their bank that you might inherit.
- Anchor distractor styles.

N5 extracted 175 questions across 17 tests in ~30 minutes via WebFetch. Saved as `feedback/external-questions-<source>.md`. Run a coverage-comparison script (`tools/coverage_compare.py`) afterwards.

---


## 10. N5-specific wins to keep

These are the things that genuinely worked and should carry forward verbatim:

- **Zen Modern (Muji-inspired) design system** — hairlines not borders, no shadows, no gradients, weights 300/400/500 only. Source of truth at `specifications/jlpt-n5-design-system-zen-modern.md`. Port the spec, replace level references.
- **5-locale i18n shell** (en/vi/id/ne/zh) — the en at v1 + others structured pattern works.
- **Hash-based routing** (`#/learn/...`) — no server, full PWA.
- **Self-hosted fonts** — Inter (300/400/500) + Noto Sans JP 400 subset to N5 kanji range. ~500KB total. Replace subset with N<L> kanji range for the next-level build (the union of N5 + ... + N<L> per §11.2).
- **Diagnostic Summary** with error patterns + recommended next session + session log.
- **SM-2 SRS** with 4-button grading (Again/Hard/Good/Easy) and verified reps (rep 1→1d, rep 2→6d, rep 3→15d, lapse → 1d + EF drops).
- **Export/import** for cross-device portability without telemetry.
- **No telemetry** as a hard constraint. Privacy-first. Don't break this.
- **Em-dash-free codebase** — strip them all (881 in N5). They break round-trips.
- **Browser-runnable test suite** (37 tests in N5) — JS + Playwright smoke tests. CI gate.

---


# §20 Vocab.json structural rules + dedup tooling pattern (added 2026-05-09)

The N5 corpus shipped with **41 (form, reading) cross-listing duplicates** in `data/vocab.json` (e.g., `へや` listed in both §13-Locations AND §26-House-and-Furniture as separate entries with the same gloss). Each cross-listing then caused 1+ same-reading **double-tags** in `data/grammar.json` examples — 164 cases total — because the auto-tagger from §3.2.13 tagged BOTH IDs whenever the word appeared. Net effect: a learner clicking through the same word from different examples might see two different vocab cards, or see the same card twice with no indication of canonicality.

The N5 dedup pass (commits `0058f08` + `884a63f`, 2026-05-08) closed this. This section documents the rules and the tooling so N`<L>` doesn't accumulate the same debt.

## §20.1 Structural rules (apply on day 1 of vocab authoring)

1. **One canonical entry per `(form, reading)` tuple unless legitimate polyseme.** Polyseme = different glosses (e.g., `は` = tooth/leaf/topic-particle). Distinguish polysemes via the `.2` / `.3` suffix on the ID, AND the gloss MUST explicitly disambiguate (e.g., `あつい` → §31.あつい "hot weather (暑い)", §31.あつい.2 "hot to touch (熱い)", §31.あつい.3 "thick (厚い)").

2. **Cross-listings are SOURCE-MARKDOWN-ONLY redundancies.** In `KnowledgeBank/vocabulary_n<L>.md`, you may list `へや` under §13-Locations AND §26-House-and-Furniture for pedagogical coherence (the entry shows up in both thematic walks). But the build pipeline collapses these to a SINGLE canonical entry in `data/vocab.json`. The non-canonical (later-listed) appearance in MD is marked `(also in §X)` parenthetical in its gloss, so the build script knows which to drop.

3. **Canonical-selection rule.** When two MD entries share `(form, reading)`:
   - If exactly one has `(also in §X)` marker → that entry is the cross-listing; drop it; the other is canonical.
   - If both unmarked but glosses normalize identically → prefer the lower-numbered section.
   - If both unmarked and glosses differ → polyseme; keep both with `.2` disambiguator IDs and ensure glosses make the distinction explicit.

4. **CI invariant `JA-42`** (see §2.2): no two `data/vocab.json` entries share `(form, reading)` AND have normalized-identical glosses unless one explicitly carries `(also in §X)`.

5. **Polyseme allowlist for `.2` / `.3` IDs.** Document every polyseme cluster in a sidecar — the audit needs to know which (form, reading) duplicates are intentional. Recommended: extend `data/n<L>_kanji_whitelist.meta.json` (or a new `data/vocab_polysemes.json`) with a `polysemes: [{form, reading, senses: [...]}]` list.

## §20.2 Dedup tooling recipe (when retrofitting an existing corpus)

If a corpus already has cross-listing duplicates, the cleanup is mechanical. The N5 script lives at `not-required/tools-archive/dedup_vocab_2026_05_08.py` (in the source repo). Adapt it as follows:

```python
# Steps 1-2: identify dups + pick canonical
import json, re
from collections import defaultdict

with open('data/vocab.json', 'r', encoding='utf-8') as f:
    vocab_data = json.load(f)

def conservative_normalize(g):
    # Strip ONLY '(also in §X...)' markers; preserve disambiguating
    # parentheticals like '(weather; separate adjective from touch)'.
    g = re.sub(r'\s*\(also in[^)]*\)', '', g)
    return g.lower().strip().rstrip(',.')

def section_num(s):
    m = re.match(r'^(\d+)\.', s)
    return int(m.group(1)) if m else 999

groups = defaultdict(list)
for e in vocab_data['entries']:
    key = (e.get('form',''), e.get('reading',''))
    groups[key].append(e)

# Build mapping: removed_id -> canonical_id
mapping = {}
merge_pairs = []
for key, entries in groups.items():
    if len(entries) < 2:
        continue
    # Group entries by normalized gloss
    by_gloss = defaultdict(list)
    for e in entries:
        by_gloss[conservative_normalize(e.get('gloss',''))].append(e)
    # Within each gloss-bucket, dedup
    for norm_g, sub in by_gloss.items():
        if len(sub) < 2:
            continue
        sub_sorted = sorted(sub, key=lambda e: (
            1 if '(also in' in e.get('gloss','').lower() else 0,
            section_num(e['section'])
        ))
        canonical = sub_sorted[0]
        for removed in sub_sorted[1:]:
            mapping[removed['id']] = canonical['id']
            merge_pairs.append((canonical, removed))
```

```python
# Step 3: merge unique data from removed into canonical
def merge_data(canonical, removed):
    # Merge unique examples (key = (ja, translation_en))
    canon_examples = canonical.get('examples', [])
    canon_keys = {(ex.get('ja',''), ex.get('translation_en','')) for ex in canon_examples}
    for ex in removed.get('examples', []):
        key = (ex.get('ja',''), ex.get('translation_en',''))
        if key not in canon_keys:
            canon_examples.append(ex)
            canon_keys.add(key)
    canonical['examples'] = canon_examples
    # Take pitch_accent / notes from removed if canonical lacks
    if 'pitch_accent' not in canonical and 'pitch_accent' in removed:
        canonical['pitch_accent'] = removed['pitch_accent']
    if not canonical.get('notes') and removed.get('notes'):
        canonical['notes'] = removed['notes']

for canonical, removed in merge_pairs:
    merge_data(canonical, removed)
```

```python
# Step 4: migrate references in grammar.json (and reading.json /
# questions.json if applicable). Walk every JSON value; replace
# any string that matches a removed ID with the canonical.
def update_refs(obj, mapping):
    if isinstance(obj, dict):
        for k, v in obj.items():
            if isinstance(v, str) and v in mapping:
                obj[k] = mapping[v]
            elif isinstance(v, list):
                for i, item in enumerate(v):
                    if isinstance(item, str) and item in mapping:
                        v[i] = mapping[item]
                    else:
                        update_refs(item, mapping)
            else:
                update_refs(v, mapping)
    elif isinstance(obj, list):
        for i, item in enumerate(obj):
            if isinstance(item, str) and item in mapping:
                obj[i] = mapping[item]
            else:
                update_refs(item, mapping)
```

```python
# Step 5: dedup vocab_ids arrays where the mapping created collisions
def dedup_vocab_id_arrays(obj):
    if isinstance(obj, dict):
        for k, v in obj.items():
            if k == 'vocab_ids' and isinstance(v, list):
                seen = set(); deduped = []
                for vid in v:
                    if vid not in seen:
                        seen.add(vid); deduped.append(vid)
                obj[k] = deduped
            else:
                dedup_vocab_id_arrays(v)
    elif isinstance(obj, list):
        for item in obj:
            dedup_vocab_id_arrays(item)
```

```python
# Step 6: remove duplicate entries from vocab.json
removed_ids = set(mapping.keys())
vocab_data['entries'] = [e for e in vocab_data['entries']
                         if e['id'] not in removed_ids]

# Step 7: write back
with open('data/vocab.json', 'w', encoding='utf-8') as f:
    json.dump(vocab_data, f, ensure_ascii=False, indent=2)
    f.write('\n')
```

## §20.3 Source-of-truth sync (KnowledgeBank parity)

After the dedup pass touches `vocab.json`, JA-31 (vocab MD/JSON parity) will fail because `KnowledgeBank/vocabulary_n<L>.md` still contains the cross-listings as separate lines. Fix in lockstep:

- Walk every line `- WORD - [POS] gloss` under section `## NN. Title`. If `(WORD, NN)` matches a `(removed_form, removed_section_num)` from the dedup mapping, delete that line.
- **Watch for over-removal of non-cross-listing entries with the same form.** If section §30 has `いる - [v2] to exist` AND `いる - [v1] to need` (the 要る polyseme), naively matching by `(form, section)` removes BOTH. Match by `(form, section, gloss-startswith)` to preserve polysemes — OR match by the explicit `(also in §X)` marker since cross-listings carry that and polysemes don't.
- Verify no X-6.6 / JA-31 regressions before committing the MD changes.

## §20.4 Three-or-more entry groups need extra care

Some `(form, reading)` groups have 3+ entries (e.g., `あつい` has 4 in N5: weather + adjective-weather + adjective-touch + adjective-thick). The dedup script must:

1. Group by `(form, reading)`.
2. Within each group, sub-group by **conservative-normalized gloss** (strip ONLY `(also in)` markers, NOT disambiguating parentheticals).
3. Within each sub-group, dedup by canonical-selection rule.
4. Polyseme entries (different normalized glosses) survive untouched.

For N5: `あつい` weather (§14) and adjective-weather (§31.0) had identical normalized glosses → deduped to one. `あつい.2` (touch, 熱い) and `あつい.3` (thick, 厚い) had distinct normalized glosses → preserved.

If your normalize_gloss function is too aggressive (strips disambiguating parentheticals), you'll collapse polysemes and lose the touch/thick senses. The N5 audit caught this regression early; the conservative normalization is the safe default.

## §20.5 Verification after dedup

- `python tools/check_content_integrity.py`: 50/50 (or current invariant count) green.
- Sample dedup'd entries: pick 5 random `(form, reading)` cases; verify the canonical entry has all examples / metadata from the merged copy.
- Spot-check `data/grammar.json`: for each example whose `vocab_ids` list shrunk, confirm the surviving tags resolve to existing vocab entries.
- Bump `CACHE_VERSION` in `sw.js`; refresh `data/version.json`; commit + push.

## §20.6 What this protects against in N`<L>` and beyond

If `vocab.json` ships clean from day 1 (single canonical per (form, reading), `(also in §X)` markers used for MD cross-listings), the N`<L>` corpus avoids:

- The 164-double-tag downstream pollution of grammar.json.
- The ambiguity in vocab-detail page rendering ("which entry should I show when the user clicks `へや`?").
- The KnowledgeBank-parity drift that JA-31 catches but only because it was authored to handle homograph polysemes via set-valued matching (a workaround for vocab dup that wouldn't be needed if dups didn't exist).

The day-1 effort to set up the canonical-per-tuple rule is small. The retrofit cost (N5 paid this) is a multi-hour audit + dedup + MD-sync + ref-migration pass. Do it on day 1.

---



---

# Chapter 4: Interface

> **Interface** — build the app screens so learners can use the content. Vanilla static + PWA + audio pipeline + mobile contract + cache discipline.

## 4. Phase 3 — UI / Front-end (weeks 4-9, parallel with content)

### 4.1 Stay vanilla static

**No framework. No build step for runtime.** N5 ships HTML + JS modules + CSS. Everything works offline (PWA). Hash router (`#/learn/...`) means no server. This was the right call; the entire UI is ~3000 lines of JS across ~25 modules and loads instantly.

If you need a build step, limit it to:
- Font subsetting (woff2 + N<L> kanji range only — keeps assets small)
- Service worker version bump
- Locale extraction (if i18n)

### 4.2 Day-1 features (port from N5)

- 5-card Learn hub: Grammar / Vocab / Kanji / Dokkai / Listening
- TOC (collapsible by super-category)
- Pattern detail page with **prev/next nav** at top corners (small font, peripheral) + back link + Mark-as-known checkbox + status badge
- SM-2 SRS in Review tab (Again/Hard/Good/Easy 4-button)
- Test mode (mock-test flow, hides answer/rationale until commit)
- Practice / Daily Drill (random sample from weak items)
- Diagnostic Summary (error patterns + recommended next session + session log)
- 5-locale i18n (en at v1, others structured for later)
- PWA manifest + service worker stale-while-revalidate
- Export/import progress as JSON
- Settings: theme, locale, font size, reset progress
- こそあど / は vs が / Verb groups / て-form gym / Particle pairs / Counters (interactive trainers)

### 4.3 Service worker version

N5 is on `jlpt-n5-tutor-v71` after 71 ship cycles. Bump on every shell change. The runtime shows an update toast when a new SW lands. Don't skip this — without versioning, stale shells silently haunt users.

### 4.4 Audio

Use `tools/build_audio.py` from N5 (auto-detects piper-tts / gtts / pyttsx3, idempotent, writes `data/audio_manifest.json`). At N4 and lower (`<L> ≤ 4`), **at least listening items SHOULD be native-recorded** — synthetic prosody artifacts at N5 level are tolerable; at higher difficulty they teach learners to discriminate against synthesis artifacts rather than against real Japanese.

This was N5's EB-1 external-blocked item: listening corpus expansion 12 → 30 was approved but blocked on native voice talent. Plan for native recording from the start at N<L>.

### 4.5 Mobile UI contract — wrap everything desktop-safe

Every mobile-only style change MUST be gated to a mobile breakpoint. Desktop styles must remain byte-identical after any mobile sweep. The N5 contract:

```css
@media (max-width: 768px) {
  /* phone + tablet portrait — most mobile rules live here */
}
@media (max-width: 480px) {
  /* small phones only — tighter rules where ≤768 was too generous */
}
@media (max-width: 380px) {
  /* tier for ultra-narrow (Galaxy S9+ 320px etc.) — last-resort
   * font-size / padding crunches when ≤480 still spills */
}
```

Non-negotiables on the mobile side:

| Item | Rule | Why |
|---|---|---|
| Tap-target floor | every interactive element ≥ 44 px height (and ideally width). Add a global rule: `button, .btn-*, .nav a, [role="button"] { min-height: 44px; }`. Audit auxiliary controls (icon-btns, breadcrumb back-links, footer-nav links, toggles) — they often slip below the floor. | iOS HIG / Material accessibility |
| iOS auto-zoom prevention | `input[type=text\|search\|email\|number], textarea, select { font-size: 16px; }` at ≤768. Any input < 16 px triggers Safari's auto-zoom on tap, pushing the input above the keyboard fold. | Real-device UX |
| body { overflow-x: hidden } | safety belt at ≤768. Keeps a stray wide descendant from triggering page-wide horizontal scroll. | Defensive |
| Body type-floor | `body { font-size: max(16px, var(--text-base)); }` at ≤768 — respects the user's font-size knob while ensuring readable minimum. | Readability |
| Visible tap feedback | Mobile has no `:hover`. Add a brief `:active { transform: scale(0.97); opacity: 0.85; transition: 80ms }` on every primary tap target. | Perceived responsiveness on slow networks |
| Smooth scroll | `html { scroll-behavior: smooth; }` at ≤768. Native-feeling scroll on anchor jumps + route changes. | Polish |
| Container gutter | At ≤480 px, container padding-inline collapses from desktop's ~22 px to 16 px so cards use ~92 % of viewport. Don't apply universal `* { max-width: 100% }` — it constrains SVG icons + brand pseudo-elements. | Real-estate on narrow phones |

QA checklist at every major release (test at 320 / 360 / 390):

- [ ] No horizontal scroll (`document.documentElement.scrollWidth === clientWidth`)
- [ ] No CJK per-character break (any heading wrapping with avg < 3 chars/line is broken)
- [ ] All tap targets ≥ 44 px on smallest dimension
- [ ] body { font-size } ≥ 16 px
- [ ] All inputs ≥ 16 px (iOS zoom test)
- [ ] Card descriptions show full text or clean line-aligned ellipsis (no mid-line clip per §3.2.9)
- [ ] Smooth scroll on anchor jumps

Desktop safety check at the same release: at 1280 px, every value listed above should match the pre-change desktop default. The mobile rules must not leak into desktop.

### 4.6 Disabled-button feedback contract

Any control that can be disabled MUST display the reason for being disabled in visible UI text — not only in a `title` attribute. Tooltips don't fire on touch; mobile users get a silent dead control.

The contract for every disabled state:

| Pattern | Visible reason | Example |
|---|---|---|
| Submit / Finish disabled until all answered | Show "(N remaining)" in the button text + a hint paragraph above | `Submit (13 remaining)` + "Answer all 15 questions to submit · 13 questions unanswered" |
| Check Answer disabled until any answer | Show a type-aware hint above the button | "Pick a choice, then click Check Answer." / "Tap the tiles in order to build the sentence, then click Check Answer." / "Type your answer in the box, then click Check Answer." |
| Confirm disabled until typed phrase | The input field IS the visible reason — adjacent to the button with the prompt visible | `Type RESET to confirm` next to a `Confirm reset` button |
| Prev / Next at first / last item | Position context (progress meter "Q15 of 15") makes it obvious; no hint needed | – |
| Per-choice / per-tile disabled after submission | Feedback panel below shows the result; the disabled state is part of the answered-and-locked UI | – |

Saved-toast pattern for silent settings (settings that save but have no immediate visible side-effect):

```js
const showSavedToast = (label) => {
  let toast = document.getElementById('settings-saved-toast');
  if (!toast) { /* create once, append to body */ }
  toast.textContent = label ? `Saved: ${label}` : 'Saved';
  toast.classList.add('is-visible');
  clearTimeout(savedToastTimer);
  savedToastTimer = setTimeout(() => toast.classList.remove('is-visible'), 1800);
};
```

Apply on every settings dropdown / number input that doesn't have an immediate visual effect (daily limits, audio rate, default test length, reduce-motion). Theme / Font / Locale don't need it because the page itself visibly changes.

For Export actions: the file dialog is easily missed. Show a status line near the button like "Exported to <filename> (check your downloads folder)." that auto-clears after 4 s.

UI-feedback audit before each release — for every disabled-button + silent-action across the app, confirm a visible reason exists:

- [ ] Inventory every `<button [...] disabled>`-rendering site
- [ ] Inventory every settings setter without immediate visual effect
- [ ] For each, confirm visible feedback (text in button, hint above, status line, toast)
- [ ] Mobile-test by tapping (not hovering) each disabled control

---



---

# Chapter 5: Review

> **Review** — keep reviewing for errors; a native Japanese teacher gives final approval. Audits, process discipline, AI-assistant lessons, and the bumper-sticker anti-pattern list live here.

## 5. Phase 4 — Audit cadence (continuous, weeks 6+)

### 5.1 Pass-N protocol

Every audit cycle is a "Pass" with:
- A doc at `feedback/<audit-name>-<date>.md` listing findings by severity (CRITICAL / HIGH / MEDIUM / LOW)
- A TASKS.md `## Pass-N <name>` section with `[ ]` checkboxes per finding
- Findings IDs: `F-N.K` where N is pass, K is finding number
- A fix-application phase with explicit "Applied YYYY-MM-DD" markers
- A close-out: "ALL ITEMS APPLIED" or "X of Y APPLIED" + deferred-item rationale

N5 ran 13+ passes. Each was 1-3 days of audit + 1-3 days of fix application.

### 5.2 Recommended pass schedule for N<L>

| Pass | Focus | Trigger |
|------|-------|---------|
| Pass-1 | First native-teacher review | Once content is ~50% authored |
| Pass-2 | Distractor quality | After all questions authored |
| Pass-3 | Multi-correct sweep (using scan_multi_correct.py) | Pre-launch |
| Pass-4 | Reading passage native review | Pre-launch |
| Pass-5 | Listening native review | When native-recorded audio is in |
| Pass-6 | Cross-coverage vs external corpus | Anytime post-launch |
| Pass-7+ | Quarterly maintenance | Cron'd 90-day cycle |

### 5.3 Native teacher review window

Schedule the first native review BEFORE 100% content authoring, around 50-70%. It's much cheaper to apply structural feedback at 70% than at 100%. N5 paid for this lesson — the early Pass-9 native review caught structural issues that would have been ~5x more work at 100%.

### 5.4 LLM audit as a multiplier

The N5 `tools/llm_audit.py` is a Claude API integration that cost ~$11.50 per full pattern-corpus pass and caught 1.0 finding/pattern (comparable to native density). Use it BETWEEN native-review windows to triage cheap wins.

Validation: 5 patterns sampled before going wide. Native-density baseline = 0.28 - 1.12 findings/pattern (varies by pass). If LLM density is comparable or higher with manageable false-positive rate, ship it.

### 5.5 Quarterly cron

Set up a cron / scheduled job that fires every 90 days to surface external-blocked items and trigger a fresh quarterly audit. N5's is `jlpt-n5-quarterly-pass-audit` — see `.github/workflows/quarterly-audit.yml` (port to `jlpt-n<L>-quarterly-pass-audit`).

---


## 8. Process discipline

### 8.1 TASKS.md is the single source of truth

- Every change updates TASKS.md.
- New work goes into a `## Pass-N` section.
- `[ ]` items remain until applied.
- `[x]` items keep "Applied YYYY-MM-DD" markers.
- Status snapshot at top reflects current corpus counts + SW version.
- Externalblocked items get explicit unblock conditions.

### 8.2 Commit discipline

- One logical change per commit. Bundle related fixes into a Pass-N commit; don't mix concerns.
- Commit message format: `type(scope): description`. Body explains the why.
- Co-author trailer for AI-assisted work: `Co-Authored-By: Claude Opus X.Y <noreply@anthropic.com>`.
- Push immediately; don't accumulate local commits.

### 8.3 Backup commits before risky operations

Per N5's CLAUDE.md guidance:
- Git commit before starting ANY batch of fixes
- Git commit after EVERY 2-3 completed fixes
- Tag backup commits clearly: `chore(backup): checkpoint before/after <description>`

This pays off when a fix unexpectedly breaks 5 questions and you need to revert just that batch.

### 8.4 Session continuity

`MEMORY.md` ≤200 lines, refreshed every 1-2 weeks, captures:
- Project location + key paths
- Current branch + HEAD SHA
- File inventory (what's where)
- Test counts
- What's broken / WIP
- Recent decisions

The next Claude session reads this on startup. Without it, every session re-discovers the project structure.

---


## 9. External-blocked items — anticipate up front

N5 has 4 EB items, all foreseeable from the start. Plan for these in N<L>:

1. **Listening corpus needs native voice talent.** Synthetic TTS is unacceptable at any level lower than N5. Identify a recording channel (paid voice actor / volunteer / licensed audio) by month 3.
2. **Native teacher reviewer.** ~10-12 hours per full pass. Identify reviewer + budget by month 1. The Suiraku San (N5) reviewer model worked.
3. **Translation of brief / supplement to Japanese.** Only if outreach is in progress; otherwise defer.
4. **Recommender ML.** Defer to v2.0 unless you have a privacy-respecting input source and >10k learners.

Register all 4 in TASKS.md `External-blocked backlog` from week 1 with explicit unblock conditions.

---


## 12. What we learned about working with Claude Code

If using Claude Code (or similar AI assistant) for content authoring + audit:

1. **Establish the binding rule first.** N5 wasted ~2 hours iterating on permission patterns. Drop a `.claude/CLAUDE.md` with blanket autonomous-operation authorization on day 1. Use `defaultMode: bypassPermissions` in `settings.local.json`.

2. **Skills (slash commands) > one-off prompts.** Skills like `update-config`, `keybindings-help` are pre-built. Use them. The `update-config` skill saved hours when the user wanted permission changes.

3. **TodoWrite is for big multi-step tasks.** Single-file edits don't need it. Multi-pass audits with 10+ items do.

4. **WebFetch in parallel.** For external corpus extraction across 17 URLs, fire all 17 WebFetch calls in one message. N5 did 9 in parallel + 8 in parallel = 30 minutes total instead of ~3 hours sequentially.

5. **Don't run two parallel sessions on the same data file.** If you must, partition by ID range up front. N5 paid for this with a 10-question dedup commit.

6. **Read whole sections before editing.** Edit tool requires having read the file. Plan to read 50-100 lines around the edit site, not just 5.

7. **Trust but verify.** Claude can claim a fix landed when it didn't (e.g., when the matcher pattern was wrong). Always re-run the integrity check after any data change.

8. **Don't delegate understanding.** Phrases like "based on your findings, fix the bug" push synthesis onto the agent. Be prescriptive: include file paths, line numbers, exact strings to change.

9. **ES module import cache outlives `location.reload()`.** Browsers cache ES modules by URL. If you edit `module-x.js` that's imported by `app.js`, even a hard reload may serve the OLD `module-x.js` because the URL didn't change. Bump `?v=N` on the entry script in `index.html` (`<script src="js/app.js?v=N">`) on every shell change AND bump `CACHE_VERSION` in `sw.js` so the service worker evicts. The N5 convention: bump the entry-script `?v=` on every UX-affecting JS change; keep CSS `?v=` separate (CSS-only changes don't need an SW bump). Be aware that during local development the dev server may also serve cached files — when in doubt, restart the dev server AND open a new tab.

10. **Permission file isn't a kill switch.** `defaultMode: "bypassPermissions"` in `.claude/settings.local.json` is necessary but not sufficient — Claude Code also requires `--dangerously-skip-permissions` at launch to actually enable that mode (settings alone can't unilaterally silence the prompt system). For a long-running project, set up a launcher script (Windows `.bat` / shell alias) that wraps the flag so the user doesn't have to remember it. The deny-list inside `settings.local.json` still applies in skip-permissions mode, so destructive ops remain gated.

11. **Sponsor framing resolves cross-audience decisions.** When a refactor crosses audience boundaries (e.g., "merge the design system into the functional spec affects both engineers and product"), don't try to satisfy every audience's preferred file structure — ask the sponsor to make the call, and execute. The N5 spec consolidation 2026-05-04 was unblocked by the sponsor saying *"merge whatever is possible, remove duplicates. I'm the sponsor."* Without that framing the agent gets stuck weighing pros/cons forever. If you're not the sponsor, do the analysis but defer the call; if you are, decide and ship.

12. **Reduction beats expansion.** When the user asks "merge?" / "consolidate?" / "remove duplicates" / "anything redundant?", the answer is almost never *"add another file"*. Default to reducing file count, line count, and option-count — and offer a short table of what consolidates well vs. what doesn't, then act on the consolidation paths the user accepts. The pattern through this project: every "do as recommended" / "merge" / "consolidate" / "remove" interaction reduced moving parts. Resist the temptation to add structure that proves your work; remove structure that proves your judgment.

13. **Consolidate by audience, not by topic.** When the spec corpus reaches 5+ markdown files, don't decide what to merge by topic similarity ("design and visual feel related") — decide by who reads it ("engineers read both the functional spec AND the design system; QA reads the testing plan; build agents read the procedure manual"). One source per consumer role beats one source per concept. See §3.2.11.

14. **Permission resolution order: global wins.** Claude Code reads `~/.claude/settings.json` (user-global) as the authoritative permission source. Project-level `<repo>/.claude/settings.local.json` is loaded as a defensive duplicate, but in compound-command workflows the global file's deny/allow set is decisive. Put ALL permission patterns in the global file; treat project-level files as documentation, not as the kill switch. If a permission prompt fires unexpectedly, the first diagnostic is `Read ~/.claude/settings.json` — not iterating project settings. Compound commands are evaluated segment-by-segment; destructive verbs (`rm`, `mv`, `cp -f`) need their own explicit allow even when `Bash(*)` is present. See §3.2.28.

15. **`update-config` skill is the schema oracle.** Claude Code ships an `update-config` skill (slash command). Its system prompt carries the full settings.json JSON schema, the permission-rule syntax (prefix-wildcard, not glob), and the resolution-order rules. Manual pattern-fiddling without it is a dead end — three rounds of editing `settings.local.json` on the wrong file is symptomatic. When stuck on Claude Code config, invoke the skill first; it returns within one round-trip with diagnosis + correct file + correct pattern shape.

16. **`.commit_msg.tmp` collision pattern.** The file-based commit pattern (`git commit -F .commit_msg.tmp && rm -f .commit_msg.tmp`) collides with the user's own staged commit messages — Claude Code sessions often run alongside human-authored commit drafts staged in the same file. Pattern: BEFORE overwriting `.commit_msg.tmp`, `cp .commit_msg.tmp .commit_msg_user_pending.txt` to preserve any user content (`.txt` extension dodges the `*.bak*` deny rules). AFTER your `commit && rm -f .commit_msg.tmp && git push`, `mv .commit_msg_user_pending.txt .commit_msg.tmp` restores it. The user keeps their draft; the agent gets clean commits. The N5 session committed 9 times across user-staged content without losing the user's UI Wave 3 draft until a linter swept it after F-9+F-10 — at which point the draft was recoverable from prior-tool-call context anyway.

17. **`--dangerously-skip-permissions` CLI flag is the escape hatch for matcher bugs.** When `~/.claude/settings.json` has `defaultMode: bypassPermissions` + `skipDangerousModePermissionPrompt: true` + the literal exact compound command as an explicit `Bash(...)` allow rule + a restart, AND the same routine command still triggers an "Allow once" prompt every invocation, you've hit a Claude Code matcher bug — not a config gap. No further config edits help. Launch Claude Code with `claude --dangerously-skip-permissions` from a terminal; that flag overrides the matcher entirely for the session. The deny list (force-push, `rm -rf`, backup overwrites, project-specific blocks) still applies, so the safety floor remains. Persist the flag as a desktop shortcut or shell alias once it's confirmed to work for the project. File a `/feedback` bug report from inside Claude Code while you're at it — the matcher bug needs to reach Anthropic. The N5 session burned ~4 hours iterating permission patterns + restart cycles before falling back to the CLI flag; recognize the symptom faster next time (see §12 #18).

18. **The 3-round stop point.** If the same class of failure has been fixed-and-retested 3 times with the same approach and is still firing, STOP. The architecture isn't broken at the per-rule level — it's broken at the engine level. Round 4 of "add another permission pattern" / "add another invariant exemption" / "tweak the regex one more time" is sunk cost. Switch approach: CLI flag, alternate tool, escalation to maintainer, or workaround that sidesteps the broken layer entirely. The N5 permission-prompt saga is the canonical example — by round 3 the answer should have been *"this is a matcher bug, use `--dangerously-skip-permissions`"* not *"let me add 8 more allow patterns."* The rule of thumb: a 3-round failure means your mental model of the broken layer is wrong; investigate the layer itself rather than its inputs.

---


## 14. Anti-patterns from N5 — the bumper-sticker list

Print these and tape them above your monitor:

**Content (Mondai / catalog level)**
1. Don't auto-generate filler MCQs.
2. Don't put both interchangeable particles (に/へ, は/が, から/ので) in MCQ choices without scene context.
3. Don't ship "see pattern detail" as a distractor explanation.
4. Don't write context-less ko-so-a-do questions.
5. Don't introduce a grammar pattern entry with the same `pattern` string as an existing one without retiring the old.
6. Don't ship en-dashes / em-dashes (U+2013, U+2014).
7. Don't use ASCII digits in TTS source.
8. Don't edit `data/*.json` directly; edit `KnowledgeBank/*.md` and rebuild.
9. Don't mass-stamp PoS by thematic section — PoS is a per-WORD attribute, especially for verb-class (Group-1 vs Group-2 mistag = wrong conjugation taught).
10. Don't ship cross-references to retired pattern IDs after a dedup pass — repoint or remove.
11. Don't auto-tag vocab_ids in grammar examples by substring matching — kanji-form-only lookup + translation-context disambiguator. Homophones (あめ rain/candy, おく place/wake, おもい heavy/think) WILL all get tagged otherwise.
12. Don't auto-extract `vocab_used` from passages by raw substring scan — single-kana fragments and phantom matches dominate. Kanji-form-only + section-skip + length≥2 filter, until mecab integration lands.
13. Don't list sokuon allophones (みっ/よっ/etc.) as separate kun-readings — they're phonological assimilation of a single base reading, not distinct readings.
14. Don't ship duplicate vocab entries across thematic sections without `(also in §X)` cross-listing markers — one canonical per (form, reading) tuple unless legitimate polyseme.
15. Don't refresh `script_ja` without also refreshing `explanation_hi`, `cultural_context`, `prompt_ja`, `correctAnswer` — sibling fields are wired together; rewriting one and not the others ships content drift visible to learners.
16. Don't ship anatomically-frank kanji mnemonics — same etymological fact, diplomatic phrasing.
17. Don't mix kanji and hiragana orthography for the same morpheme across items (時半 vs 時はん) — pick a convention per surface and document.
18. Don't carry legacy schema fields past their migration commit — delete the legacy field in the same commit that introduces the replacement.
19. Don't try to mass-promote kana → kanji across a Japanese corpus with regex alone — substring matching produces compound-word false positives (`きます` inside `できます`, `いま` inside `おもいます`, `きょう` inside `とうきょう`). Use mecab/kuromoji, or hand-edit. (§3.2.26)
20. Don't conflate "easy Japanese (やさしいにほんご)" with "plain Japanese using kana for OOS kanji" — they are different registers with different rules. If the UI labels a field "easy Japanese," the content must follow the accessibility-tier rules. (§3.2.25)

**UI / Layout / Front-end**
11. Don't combine `flex: 1` + `display: -webkit-box` + `-webkit-line-clamp: N` + fixed-height parent — Chrome normalises display to `flow-root`, line-clamp goes inert, and overflow:hidden mid-line-clips. Add `max-height: Nlh` + remove `flex: 1`.
12. Don't ship a disabled button without a visible reason — tooltips don't fire on touch, mobile users get a silent dead control.
13. Don't keep stale module-level state on URL navigation — reset `view='finished/results'` when the URL navigates away (back-buttons inside results pages re-render the same results page if you don't).
14. Don't leak mobile-only CSS into desktop — every mobile sweep verifies desktop at 1280 × 800 is byte-identical (computed-style values match pre-change defaults).
15. Don't apply universal `* { max-width: 100% }` — it constrains SVG icons + brand mark pseudo-elements. Target only `img / video / iframe / pre / table / code`.
16. Don't use `<img src="…svg">` for theme-tintable SVG — `currentColor` resolves against the SVG's own computed style (defaults black), NOT the parent CSS. Inline the SVG instead. (§3.2.22)
17. Don't expect `align-items: center` on a flex parent to also center text inside a child with min-height enforced — the child needs `display: inline-flex; align-items: center` of its own. (§3.2.27)
18. Don't re-render the search input element on every keystroke when Japanese-IME-typing is supported — destroying the input mid-composition breaks the IME and leaks partial Latin chars (typing いたい emits いｔあい). Add `compositionstart` / `compositionend` guards. (§3.2.24)
19. Don't ship two slightly-different brand-color hex values across CSS files — pick ONE canonical hex and use it everywhere. Subtle hue shifts on cross-surface navigation read as unprofessional. (§3.2.23)

**Process**
16. Don't run two parallel sessions on the same data file without ID partitioning.
17. Don't skip native review before declaring "done".
18. Don't bump only `CACHE_VERSION` on a JS-shell change — also bump `?v=N` on the entry script in `index.html` so the browser ES-module cache invalidates. Forgetting either layer means users see stale code on next visit.
19. Don't ship a sibling-deploy with a verbatim copy of the source repo's `js/levels.js`. The local-level entry must use `href: '#/home'` (same-origin, `available: true`); every other built level must use the absolute sibling URL with `external: true`. Verbatim-copy means clicks on the source-level card route to the new deploy's own dashboard (because `#/home` resolves on whichever origin is loaded). Companion edits: drop the local level from `app.js` ROUTES placeholder list and from the `renderLevelPlaceholder` regex. See §11.4 for the full clone-and-flip recipe + smoke test.
20. Don't use `stale-while-revalidate` for HTML or other content that CHANGES per release — the user's first reload after each deploy shows the OLD page, the second shows the new. Use NETWORK-FIRST for HTML; cache-first for `?v=`-versioned assets. (§3.2.21)
21. Don't run a "sweep" pass before sampling current state — most sweeps reveal the work was already done case-by-case in earlier authoring rounds. The N5 kanji-promotion sweep discovered ~90% was already promoted; the actual remaining work was 5 hand-fixable items.
22. Don't skip versioned backups before destructive ops on data files — `git checkout -- <file>` is a destructive op for our purposes. Pattern: `cp <file> <file>.bak_YYYY_MM_DD[_vN]` BEFORE the destructive op. Never delete older backup versions; keep them as forensic record. (Project-specific: see `.claude/CLAUDE.md` § "Backup policy".)
23. Don't trust "FAIL" output from a Python integrity check on Windows console without forcing UTF-8 I/O — kanji in failure messages can't encode to cp1252/cp932 and the script swallows its own exception, producing false-positive failure counts. Always: `PYTHONIOENCODING=utf-8 python -X utf8 tools/check_content_integrity.py`. (§3.2.29)
24. Don't `git rm` an audit-flagged file without first grep'ing the codebase for refs — tool wiring (CI invariants, expected-count constants, importers, docstring exemptions) needs synchronized refactor in the same commit, or the next CI run fails for the deletion you just made. (§3.2.32)
25. Don't trust an audit's named-file scope as exhaustive — `grep -rln "<risk-keyword>" .` after every audit closure surfaces adjacent files in the same risk class. The N5 F-1 (DMCA) audit named 2 files; grep surfaced a third with ~90% of the actual exposure. Register the gap as a NEW finding, don't unilaterally expand the original. (§3.2.30)
26. Don't trust metadata when data, code, and docs disagree about an external dependency (TTS provider, font source, library version) — inspect the actual output artifact for ground truth. For audio: ID3v2 frame inspection (`Lavf` in TSSE = ffmpeg/libavformat). For PDFs: `/Producer` string. For images: EXIF generator. (§3.2.31)
27. Don't trust project-level `.claude/settings.local.json` to silence Claude Code permission prompts — global `~/.claude/settings.json` is the authoritative source. Put all patterns there; the project file is a defensive duplicate, not the kill switch. (§3.2.28, §12 #14)
28. Don't iterate permission patterns past round 3 — if `defaultMode: bypassPermissions` + `skipDangerousModePermissionPrompt: true` + literal-command allow rule + restart still prompts, it's a Claude Code matcher bug. Switch to `claude --dangerously-skip-permissions` CLI flag and file `/feedback`. The N5 session burned ~4 hours iterating patterns before falling back to the flag. (§12 #17, §12 #18)
29. Don't author humble-register i-adjective + ございます forms by intuition — apply the ウ音便 contraction rules: `a+u→ō` (たかい→たこう), `i+u→yū` (おいしい→おいしゅう), `u+u→uu` (やすい→やすう stays). Half-applied forms (`たかう ございます`) read as broken to native speakers. `politeness_ladder.humble` is JA-13-exempt by design, so CI cannot catch this — native-teacher audit is the only check. (§3.2.33)
30. Don't leave the `form` field empty on grammar examples when sibling examples in the same pattern have it set — mixed state leaks an empty `_` badge to the UI. Either all examples in a pattern have `form`, or none do. Same anti-corollary applies to `usage_role`, `register`, `tier`, `format_type`, and any optional UI-rendered tag field. (§3.2.34)

**Spec hygiene**
19. Don't fragment a spec into multiple files when one role reads all of them — merge by consumer (§3.2.11), not by topic.
20. Don't ship a markdown→docx build pipeline that crashes on inconsistent tables — defensive `_emit_table` (§3.2.12) is non-negotiable for any merge engine.
21. Don't edit `.docx` build artefacts by hand — they regenerate from markdown sources via `tools/build_spec.py`. Add a `DON'T-EDIT-BY-HAND` trailer to every regenerable artefact's source.
22. Don't interleave new spec content throughout the doc — append a dated `§<NextLetter>. Revision YYYY-MM-DD` block (§A.14) so revisions are diffable as additions, not edits.

---


## 15. Open questions / decisions to make for N<L>

Known unknowns from N5 experience:

- **Native voice for listening:** budget? (answer affects content-authoring schedule)
- **Whether to support handwriting** (kanji writing practice) — N5 didn't; lower levels (more kanji) might benefit more
- **Whether to add IME-typing input** for text_input questions — N5 used kana-strict input; N<L> with more kanji could use IME mode
- **Reading-comprehension speed test mode** — applicable from N4 down; UI affordance?
- **Mock test mode timing** — each level has stricter time limits than N5; see §A.9 for the exam structure table
- **Subscription / monetization** — N5 is free; if monetizing, it changes a lot architecturally

Each of these blocks ~1-2 weeks of architecture work. Decide before week 4 of the build.

---


## 16. References

- N5 source repo: this directory
- N5 functional spec: `specifications/JLPT-N5-Functional-Spec-v3.1-supplement.md`
- N5 design system: `specifications/jlpt-n5-design-system-zen-modern.md`
- N5 audit reports: `feedback/jlpt-n5-*.md`
- N5 native-teacher review brief: `feedback/native-teacher-review-request.md`
- N5 UI testing plan: `feedback/ui-testing-plan.md`

For any next-level development, copy these as starting templates and update level references (replace `n5` with `n<L>`).

---


## 17. Appendix A — One-Shot Mode supplements

This appendix addresses the highest-impact gaps identified in the Pass-20 review (`Appendix E (this manual)`). It does NOT close every gap — full closure requires embedding ~5000+ lines of content inventories and schemas (registered as Pass-21). It DOES close the most actionable ones:

- A.1 Required-inputs precondition (Issue 4, 16, 33, 36)
- A.2 Default decisions for §15 open questions (Issue 25)
- A.3 Fallback procedures for external-blocked items (Issues 19, 21, 39)
- A.4 Minimum-viable subset / what to ship if running out of run time (Issue 20)
- A.5 Definition of done (Issue 40)
- A.6 JSON schemas (Issue 3) — pointer + extraction recipe
- A.7 Source authorities for content inventories (Issues 1, 8)
- A.8 Question-count budget per Mondai (Issue 37)
- A.9 JLPT exam structure tables (Issue 38)
- A.10 SM-2 exact parameters (Issue 29)
- A.11 Furigana generation procedure (Issue 26)

### A.1 Required inputs (precondition for both modes)

The next-level build agent MUST have read access to:

1. **This manual** (`specifications/procedure-manual-build-next-jlpt-level.md`).
2. **The N5 source repository in full**, at a known absolute path. Specifically the agent must be able to read:
   - `KnowledgeBank/*.md` (all 9 KB files — these are the markdown grammar reference)
   - `data/*.json` (all corpora — these are the JSON schema reference)
   - `tools/build_data.py`, `tools/check_content_integrity.py`, `tools/test_build_data.py`, `tools/link_grammar_examples_to_vocab.py`, `tools/scan_multi_correct.py`, `tools/llm_audit.py`, `tools/heuristic_audit.py`, `tools/build_audio.py`, `tools/tag_vocab_pos.py`, `tools/coverage_compare.py` (the 10 scripts to port from §7)
   - `specifications/jlpt-n5-design-system-zen-modern.md` (full design system spec — see A.6.5)
   - `js/` (all front-end modules — UI module list per A.6.4)
   - `css/main.css` (design tokens implementation)
   - `index.html`, `sw.js`, `manifest.webmanifest`
   - `locales/*.json` (i18n message catalogs)
   - `.claude/CLAUDE.md` (binding rule template)
   - `TASKS.md` and `MEMORY.md` (state-tracking templates)
3. **Network access** for: external corpus extraction (WebFetch), Anthropic API (LLM audit, optional), font CDN downloads (one-time, replaceable).

If any of these inputs is unavailable, the agent MUST halt and report what is missing rather than proceed with invented content.

### A.2 Default decisions for §15 open questions (zero-interaction defaults)

A zero-interaction agent has no human decider. Use these defaults:

| §15 question | Default for one-shot mode | Rationale |
|---|---|---|
| Native voice budget | **Skip native recording. Use synthetic TTS via `gtts`.** Mark all listening items with `voice: "synthetic"` so the JA-15 invariant doesn't fail and a future native-recording pass can identify them. | Native recording requires human resource the agent doesn't have. Synthetic ships; native upgrades later. |
| Handwriting kanji practice | **Defer.** Don't include in v1. | Requires a stroke-order canvas component and SVG kanji data. Out of one-shot scope. |
| IME-typing input | **Defer.** Use the N5 kana-strict text_input flow; do not introduce IME mode. | IME state management is non-trivial; kana-strict works for vocab questions at any level. |
| Reading-comprehension speed test | **Defer.** Ship dokkai mode without timer for v1. | Speed mode is a UI affordance, not a content blocker. |
| Mock test mode timing | **Use the JLPT N<L> official time table** (see A.9 — N5..N1 timings tabulated). Hardcode at component level; expose as setting in v2. | Time per section is a known quantity per JLPT.jp specs. |
| Subscription / monetization | **Free, no monetization.** Match N5 architectural posture. | Adding payment changes hosting, telemetry, and privacy posture; out of scope. |

Mark each as a one-shot default in TASKS.md `Pass-1` so a follow-up human pass knows to reconsider.

### A.3 Fallback procedures for external-blocked items

If the agent encounters an EB item with no resource available:

| EB item | Synthetic fallback | Quality marker |
|---|---|---|
| Native voice talent | Synthetic TTS via gtts; flag `voice: "synthetic"` per item | Listening invariant relaxed for synthetic; ship with banner "Audio: synthetic; native v2" |
| Native teacher reviewer | Run `tools/llm_audit.py` instead, flag every item with `auto: true` and `review_status: "llm_only"` | A subsequent human pass filters by `review_status: "llm_only"` for review |
| Translation to Japanese (brief) | English-only brief shipped; create translation task in TASKS.md EB-3 | Don't block ship on translation |
| Recommender ML | Use the minimal state-driven recommender from N5 (no ML). Mark `recommender_version: 1` | Ship with v1 recommender; v2 ML deferred |

### A.4 Minimum-viable subset (one-shot deliverable)

If the agent runs out of execution time or cannot finish all 17 weeks worth of work in one pass, ship in this priority order. Stop at any layer; the layers below it are non-blocking for a working v0.

1. **Layer 0 — Build pipeline + CI (must ship).** `tools/build_data.py`, `tools/check_content_integrity.py`, `tools/test_build_data.py`, `.github/workflows/content-integrity.yml`. Empty content is acceptable here; the pipeline must be runnable.
2. **Layer 1 — Schemas + skeleton corpora (must ship).** All `data/*.json` files exist with empty arrays + populated `_meta` blocks. All `KnowledgeBank/*.md` files exist with the section structure but minimal content.
3. **Layer 2 — UI shell (must ship).** `index.html`, hash router, 5-card hub, empty Learn views, settings. Service worker registered. PWA manifest valid.
4. **Layer 3 — Grammar catalog (~50% of patterns).** Author the core_n<L> patterns; defer late_n<L> + n<L-1>_borderline.
5. **Layer 4 — Vocab catalog (~50%).** Author the most-frequent N<L> vocabulary.
6. **Layer 5 — Kanji catalog (full).** All N<L>-whitelist kanji (per §0 size table) must be authored; this is non-negotiable for the kanji whitelist invariants.
7. **Layer 6 — Reading + listening passages (~30% / ~30%).** ~10 passages each with synthetic audio.
8. **Layer 7 — Question banks (~25% per section).** ~25 questions per moji/goi/bunpou/dokkai.
9. **Layer 8 — Translation, advanced UI features, native audio.** Defer all to v2.

A truly minimal deliverable that satisfies layers 0-2 + skeleton content for 3-7 produces a runnable app shell that a human team can flesh out. Roughly **20-30% of the full N<L> deliverable** in one shot.

### A.5 Definition of done

The build is **complete for v1 release** when ALL of the following are true (a one-shot agent should self-check against this list):

1. **CI green:** `python tools/check_content_integrity.py` exits 0 with all invariants passing.
2. **Build pipeline regression:** `python tools/test_build_data.py` exits 0.
3. **JSON schema valid:** every `data/*.json` parses, has the required `_meta` block, and `_meta.entity_count == len(entries)`.
4. **No duplicate IDs:** across questions / patterns / vocab / kanji / reading / listening corpora.
5. **No empty user-facing fields:** every authored question has `question_ja`, `correctAnswer`, `choices` (if MCQ), and `distractor_explanations` populated.
6. **No "see pattern" stubs:** zero matches for `see n<L>-` / `see pattern detail` in user-facing fields.
7. **No out-of-scope kanji:** all user-facing text uses only N<L>-whitelist kanji (JA-13).
8. **Browser smoke test:** `index.html` loads in a clean browser, hash routes resolve, no console errors, service worker registers.
9. **Question count meets layer-7 minimum:** ≥25 questions per Mondai section per A.4 layer 7.
10. **PWA installable:** manifest valid, icons present, offline shell works.
11. **TASKS.md current:** status snapshot reflects current corpus counts; no `[ ]` items in the active Pass section without "deferred" rationale.
12. **No em-dashes:** zero matches for `—` or `–` in any committed file (X-6.5).

A one-shot agent that can mark items 1-8 + 10-12 GREEN and item 9 at "≥25" has shipped a defensible v1.

### A.6 JSON schemas — extraction recipe

Rather than embedding all schemas (~1500 lines of JSON Schema), the agent should DERIVE them from the N5 reference files in this order:

1. Read `data/grammar.json` — observe top-level shape: `{"patterns": [...], "_meta": {...}}`. Each pattern entry has: `id`, `pattern`, `meaning_en`, `meaning_ja`, `category`, `tier`, `form_rules` (with `attaches_to`, `conjugations`), `examples` (each with `form`, `ja`, `translation_en`, `furigana?`, `vocab_ids?`), `common_mistakes`, `notes?`.
2. Read `data/questions.json` — top-level: `{"questions": [...], "_meta": {...}}`. Each question has: `id`, `grammarPatternId`, `type` (mcq/sentence_order/text_input), `subtype?`, `direction`, `prompt_ja`, `question_ja` OR `tiles`, `choices?`, `correctAnswer?`, `correctOrder?`, `acceptedAnswers?`, `explanation_en`, `distractor_explanations?`, `high_confusion?`, `difficulty`, `auto`.
3. Read `data/vocab.json`, `data/kanji.json`, `data/reading.json`, `data/listening.json`, `data/audio_manifest.json` similarly.
4. Generate JSON Schema files with `python -c "import genson; ..."` or hand-derive from observed shapes.

Save derived schemas at `specifications/schemas/*.schema.json`. Validate every JSON build against them in CI.

### A.7 Source authorities for content inventories

The agent must NOT invent N<L> content. Use these published sources as authority. Substitute the level number in URLs (`n4` → `n<L>` or `jlpt4` → `jlpt<L>` depending on the host's URL convention; full per-level URL list is in Appendix B.11):

- **Kanji whitelist:** JLPT-Sensei N<L> kanji list (e.g., https://jlptsensei.com/jlpt-n4-kanji-list/) + cross-reference Tanos (e.g., https://www.tanos.co.uk/jlpt/jlpt4/kanji/)
- **Vocabulary:** Tanos N<L> vocab CSV (e.g., https://www.tanos.co.uk/jlpt/jlpt4/vocab/)
- **Grammar patterns:** Bunpro N<L> (e.g., https://bunpro.jp/jlpt/n4) + Tanos N<L>
- **Reading passages:** authentic samples at https://www.jlpt.jp/e/samples/n<L>/index.html
- **Listening scripts:** same official samples

Cross-reference at least TWO sources per item before adding to the catalog. Discrepancies between sources should be resolved in favor of the most-recent JLPT.jp official spec.

For tier classification (`core_n<L>` / `late_n<L>` / `n<L-1>_borderline`):
- `core_n<L>` = appears in both Bunpro N<L> AND Tanos N<L>
- `late_n<L>` = appears in Bunpro N<L> only (Bunpro tends to include borderline upper-`<L>`)
- `n<L-1>_borderline` = appears in Tanos N<L-1> but commonly taught in N<L> textbooks

### A.8 Question-count budget per Mondai per file

JLPT N<L> question section structure (the table below uses N4 numbers as the canonical example; N3..N1 follow the same Mondai layout with adjusted counts per JLPT.jp official specs):

| File | Mondai | Subtype | Target count |
|------|--------|---------|--------------|
| moji_questions_n<L>.md | Mondai 1 (kanji reading) | 漢字読み | 50 |
| moji_questions_n<L>.md | Mondai 2 (orthography) | 表記 | 50 |
| moji_questions_n<L>.md | (alt) Mondai 3 (word formation) | 語形成 | 50 (N4-specific; not present at N5) |
| goi_questions_n<L>.md | Mondai 4 (context) | 文脈規定 | 50 |
| goi_questions_n<L>.md | Mondai 5 (paraphrase) | 言い換え類義 | 50 |
| goi_questions_n<L>.md | Mondai 6 (usage) | 用法 | 50 (introduced at N4; persists at lower levels) |
| bunpou_questions_n<L>.md | Mondai 1 (sentence grammar 1) | 文の文法1 | 50 |
| bunpou_questions_n<L>.md | Mondai 2 (sentence grammar 2) | 文の文法2 | 30 |
| bunpou_questions_n<L>.md | Mondai 3 (text grammar) | 文章の文法 | 20 |
| dokkai_questions_n<L>.md | Mondai 4 (short) | 内容理解 短文 | 30 |
| dokkai_questions_n<L>.md | Mondai 5 (medium) | 内容理解 中文 | 30 |
| dokkai_questions_n<L>.md | Mondai 6 (info retrieval) | 情報検索 | 12 |
| chokai_questions_n<L>.md | Mondai 1-4 | (multiple) | 60 |

**Total target at N4: ~530 questions across 4 question files + 1 listening file.** This is larger than N5's ~400 due to N4's expanded grammar/vocab scope. For N3..N1 multiply roughly 1.3-1.5x per level.

### A.9 JLPT exam structure tables

Per official JLPT.jp:

| Level | Total time | Sections | Section times | Pass score | Section thresholds |
|-------|-----------|----------|---------------|------------|-------------------|
| N5 | 105 min | 文字・語彙 / 文法・読解 / 聴解 | 25 / 50 / 30 | 80/180 | 38/120 + 19/60 |
| N4 | 125 min | 文字・語彙 / 文法・読解 / 聴解 | 30 / 60 / 35 | 90/180 | 38/120 + 19/60 |
| N3 | 140 min | 文字・語彙 / 文法・読解 / 聴解 | 30 / 70 / 40 | 95/180 | 19/60 each |
| N2 | 155 min | 言語知識・読解 / 聴解 | 105 / 50 | 90/180 | 19/60 each |
| N1 | 170 min | 言語知識・読解 / 聴解 | 110 / 60 | 100/180 | 19/60 each |

Embed this table in mock-test mode timing config.

### A.10 SM-2 SRS exact parameters

From N5's verified implementation:

```
Initial easiness factor (EF) = 2.5
EF formula on Good/Easy: EF' = EF + (0.1 - (5-q) * (0.08 + (5-q)*0.02))
  where q = quality (Easy=5, Good=4, Hard=3, Again=2)
EF clamped to [1.3, ∞]

Interval after rep N (rep counter increments on Good/Easy only):
  rep 1 (first success after Again or fresh): 1 day
  rep 2: 6 days
  rep 3+: previous_interval * EF (rounded to integer days)

On Again:
  rep counter resets to 0
  EF drops by 0.20 (e.g., 2.50 → 2.30)
  next interval = 1 day
  item goes to "Lapses" bucket for tracking

On Hard (q=3):
  rep counter does NOT advance
  EF drops slightly (~0.15)
  next interval = previous_interval * 1.2 (instead of * EF)

LocalStorage key: `jlpt-{level}-tutor.srs.{itemId}` storing JSON
  { "EF": float, "rep": int, "due": ISO8601-date, "interval": int, "lapses": int }

Cross-device merge on import: take MAX of (rep, interval) per item;
  prefer most-recent EF; sum lapses.
```

This is the N5-verified spec. Reuse verbatim for any next level.

### A.11 Furigana generation procedure

For each example sentence in `grammar.json` and each passage in `reading.json`:

1. Run a Japanese tokenizer (mecab via `mecab-python3` OR Yahoo morphological API OR client-side kuromoji.js) over the Japanese text.
2. For each kanji-containing token, output `{"reading": <hiragana>, "indices": [start, end]}` annotations.
3. Filter: only include annotations where the kanji is NOT in the level's prerequisite tier (i.e., for N<L> content, annotate kanji that are N<L>-new but not the prerequisite ones from N5..N<L+1> — by default; settings allow toggling).
4. Store as `furigana` field on the example/passage entry.

UI render: wrap annotated spans in `<ruby><rb>kanji</rb><rt>reading</rt></ruby>`. CSS controls visibility (3-mode: always-show / show-on-hover / never). Default at N4 and lower (more kanji to learn) = show-on-hover; at N5 the default was always-show.

**One-shot fallback:** if a tokenizer is unavailable in the agent's runtime, ship without furigana. The UI gracefully degrades to plain kanji rendering. Mark this in TASKS.md as Pass-2 candidate.

### A.12 One-shot execution sequence (the ordered build script)

This is the literal, ordered sequence the agent follows after a §0.A trigger. Each step is **idempotent** — re-running on partial state continues from the next-incomplete step. After each step, the agent commits with a step-tagged message so a re-invocation can identify where to resume by reading the git log.

The agent SHOULD NOT think about the order. It should execute each step, gate on its checkpoint, move on.

```
STEP 0: PRE-FLIGHT
─────────────────────────────────────────────────────────────────────────
0.1 Resolve <L>, <P>, source path, target path per §0.A.2
0.2 Verify §0.A.3 halt conditions are NOT triggered
0.3 Read source repo's TASKS.md, MEMORY.md to capture conventions
0.4 If target dir exists and contains a partial build (.build-progress.json
    present), read it and resume from the recorded next-step. Otherwise
    initialise an empty target dir.
0.5 echo "BUILD START: source=N<P> target=N<L> path=<target>"
─────────────────────────────────────────────────────────────────────────

STEP 1: REPO SKELETON          (~30 min, idempotent)
─────────────────────────────────────────────────────────────────────────
1.1 mkdir <target>; cd <target>
1.2 git init; git remote add origin <derived-from-source-origin>
1.3 Copy directory structure of §1.1 from source. For each file:
      - If source path contains 'n<P>' → rename to 'n<L>'
      - .claude/CLAUDE.md → s/N<P>/N<L>/g, s/n<P>/n<L>/g
      - tools/build_data.py → s/N<P>/N<L>/g, s/n<P>/n<L>/g
      - sw.js → CACHE_VERSION = 'jlpt-n<L>-tutor-v1'
      - manifest.webmanifest → name "JLPT N<L> ..."
      - index.html → title, brand text → N<L>
1.4 Wipe content from KB markdown (keep section structure only):
      - KnowledgeBank/grammar_n<L>.md → empty section headers
      - KnowledgeBank/vocabulary_n<L>.md → empty section headers
      - (etc. for kanji, moji_questions, goi_questions, bunpou_questions,
        dokkai_questions, chokai_questions; ALL keep ONLY section
        headers + format reminders)
1.5 Wipe content from data/*.json: each file = '{"<key>":[],"_meta":{}}'
1.6 Touch TASKS.md, MEMORY.md as empty templates with the §1.2 sections
1.7 Write .build-progress.json: { "step": 1, "completed": [...] }
1.8 git add -A; git commit -m "chore: scaffold N<L> from N<P> [build-step 1/15]"
1.9 git push origin HEAD (best-effort; warn if origin not reachable)

STEP 2: PERMISSION + CI WIRING (~10 min)
─────────────────────────────────────────────────────────────────────────
2.1 Verify .claude/settings.local.json has the source's default mode +
    deny list. Add to .gitignore.
2.2 Verify .github/workflows/content-integrity.yml fires on push/pr/dispatch
2.3 Run python tools/check_content_integrity.py — should pass on empty
    content (since invariants are tolerant of empty corpora). If it fails,
    fix the integrity check tool to handle the empty case.
2.4 commit "ci: integrity gate green on empty corpus [build-step 2/15]"

STEP 3: KANJI WHITELIST       (~1-2 hours, content-bound)
─────────────────────────────────────────────────────────────────────────
3.1 Read feedback/n<L>-kanji-inventory.md if present in target dir.
    Else WebFetch the URLs in §A.7 source-authorities and merge.
3.2 Write data/n<L>_kanji_whitelist.json (array of glyphs, sorted).
    Per §0 size table: target ~280 (N4), ~650 (N3), ~1000 (N2), ~2000 (N1).
3.3 Write data/n<L>_kanji_readings.json — for each glyph, fetch primary
    on/kun reading from authority. Default `primary` field to most-frequent.
3.4 Run X-6.9 invariant check. Fix any kanji whose primary reading is
    inconsistent with authority.
3.5 commit "data: kanji whitelist (~N entries) [build-step 3/15]"

STEP 4: KANJI CATALOG (KB + JSON) (~2-4 hours)
─────────────────────────────────────────────────────────────────────────
4.1 Author KnowledgeBank/kanji_n<L>.md — for each whitelisted glyph,
    add: glyph, on/kun readings (each separated, ja-only), 1 example
    word + reading + EN gloss, brief usage note.
4.2 Run python tools/build_data.py to derive data/kanji.json
4.3 Run integrity check; fix violations
4.4 commit "data: kanji catalog [build-step 4/15]"

STEP 5: VOCABULARY CORPUS     (~6-12 hours)
─────────────────────────────────────────────────────────────────────────
5.1 Read feedback/n<L>-vocab-inventory*.md if present, else fetch Tanos
    N<L> CSV per §A.7
5.2 Author KnowledgeBank/vocabulary_n<L>.md grouped by ~40 thematic
    sections (port section list from source; rename if needed)
5.3 Apply the §3.2.8 PoS rule: per-WORD PoS, never per-section default
5.4 Run python tools/build_data.py
5.5 Run python tools/tag_vocab_pos.py to verify PoS coverage
5.6 Run integrity check (especially JA-31 vocab PoS parity)
5.7 commit "data: vocab corpus (~N entries) [build-step 5/15]"

STEP 6: GRAMMAR CATALOG        (~8-16 hours)
─────────────────────────────────────────────────────────────────────────
6.1 Read feedback/n<L>-grammar-inventory.md if present, else fetch
    Bunpro N<L> + Tanos N<L> per §A.7
6.2 Decide tier per pattern: appears in both = core_n<L>; Bunpro-only
    = late_n<L>; appears in N<L-1> sources = n<L-1>_borderline
6.3 Author KnowledgeBank/grammar_n<L>.md — for each pattern: 2-5
    example sentences, common-mistakes block, form-rules conjugations
6.4 Run python tools/build_data.py
6.5 Run python tools/link_grammar_examples_to_vocab.py for vocab_ids
    homograph-aware linkage
6.6 Run integrity check; fix violations
6.7 commit "data: grammar catalog (~N patterns) [build-step 6/15]"

STEP 7: READING + LISTENING    (~6-10 hours)
─────────────────────────────────────────────────────────────────────────
7.1 Author KnowledgeBank/dokkai_questions_n<L>.md — ~30 passages of
    appropriate-for-<L> length per §0 table (N4: 80-150 chars short
    + 250-300 chars medium; N3+: longer per JLPT.jp)
7.2 Author KnowledgeBank/chokai_questions_n<L>.md — ~30 listening
    items across Mondai 1-4 per A.8 budget table
7.3 Run python tools/build_data.py
7.4 Run python tools/build_audio.py (synthetic; mark voice='synthetic')
7.5 Run integrity check (especially JA-15 audio refs resolve)
7.6 commit "data: reading + listening corpora [build-step 7/15]"

STEP 8: QUESTION BANKS         (~12-24 hours)
─────────────────────────────────────────────────────────────────────────
8.1 Author moji_questions_n<L>.md (Mondai 1-3 per A.8) — ~150 questions
8.2 Author goi_questions_n<L>.md (Mondai 4-6 per A.8) — ~150 questions
8.3 Author bunpou_questions_n<L>.md (Mondai 1-3 per A.8) — ~100 questions
8.4 dokkai_questions already authored as part of step 7 (passages =
    questions are 2-3 per passage; ~70 questions total)
8.5 Run python tools/build_data.py
8.6 Run python tools/scan_multi_correct.py — fix every flag from §3.2.2
8.7 Run python tools/heuristic_audit.py — apply auto-fixes
8.8 Run integrity check (all 33+ invariants must pass)
8.9 commit "data: question banks (~N questions) [build-step 8/15]"

STEP 9: UI MODULES             (~2-4 hours; mostly file copies + edits)
─────────────────────────────────────────────────────────────────────────
9.1 For each js/ module in source: copy to target. Replace 'n<P>' → 'n<L>'
    in literals. Replace 'jlpt-n<P>-tutor' → 'jlpt-n<L>-tutor' in cache
    keys + storage keys + manifest references.
9.2 Apply §3.2.9 mid-line-clip prophylactic to every tile-grid card
    description: max-height: Nlh + remove flex:1
9.3 Apply §3.2.10 state-reset prophylactic to every render module with
    module-level view/session: parts.length-aware reset for back-nav
9.4 Apply §4.5 mobile UI contract: 768/480/380 breakpoints, tap-target
    rules, iOS auto-zoom prevention, body type-floor
9.5 Apply §4.6 disabled-button feedback contract: every disabled button
    has visible reason, every silent setting has saved-toast
9.6 commit "ui: port js + css modules with §3.2.9/10/§4.5/4.6 fixes [build-step 9/15]"

STEP 10: AUDIO PIPELINE        (~30 min)
─────────────────────────────────────────────────────────────────────────
10.1 Run python tools/build_audio.py for every grammar example,
     reading passage, listening item that doesn't have an audio file
10.2 Confirm data/audio_manifest.json has every item from data/*.json
10.3 commit "audio: synthetic TTS pass [build-step 10/15]"

STEP 11: LLM AUDIT             (~1-2 hours autonomous; ~$10-15 API)
─────────────────────────────────────────────────────────────────────────
11.1 Run python tools/llm_audit.py over the question banks. Apply HIGH
     and CRITICAL findings via auto-fixers if available, else flag them
     in TASKS.md Pass-1 as deferred.
11.2 Run integrity check
11.3 commit "audit: llm pass [build-step 11/15]"

STEP 12: COVERAGE COMPARISON   (~30 min)
─────────────────────────────────────────────────────────────────────────
12.1 Run python tools/coverage_compare.py against the external corpus
     for N<L>
12.2 Note gaps in TASKS.md as Pass-2 follow-up (don't author fixes
     in one-shot mode)
12.3 commit "audit: coverage gap analysis [build-step 12/15]"

STEP 13: BROWSER SMOKE TEST    (~10 min)
─────────────────────────────────────────────────────────────────────────
13.1 Run npm install + npm test (or python -m http.server + Playwright)
13.2 Verify: index.html loads, hash routes resolve, no console errors,
     SW registers, PWA manifest installable
13.3 commit "test: smoke test pass [build-step 13/15]"

STEP 14: TASKS.md + MEMORY.md FINALISATION (~30 min)
─────────────────────────────────────────────────────────────────────────
14.1 Populate TASKS.md status snapshot with corpus counts, SW version,
     route list. Add Pass-1 section with all deferred items + their
     §0.A.2-default rationale.
14.2 Populate MEMORY.md ≤200 lines: project location, branch, HEAD SHA,
     file inventory, current state, what's next.
14.3 commit "docs: TASKS + MEMORY populated [build-step 14/15]"

STEP 15: DEFINITION-OF-DONE FINAL CHECK + REPORT
─────────────────────────────────────────────────────────────────────────
15.1 Run definition-of-done checklist (§A.5 items 1-12)
15.2 Generate the §A.13 completion report
15.3 If ALL items GREEN: tag the commit `n<L>-v1-skeleton`
15.4 commit "release: N<L> v1 skeleton ready [build-step 15/15]"
15.5 git push origin HEAD --tags
15.6 Echo report to user (chat / stdout)
─────────────────────────────────────────────────────────────────────────
```

**Critical rules across all steps:**

- **Idempotency:** every step starts by checking `.build-progress.json`. If the step's index ≤ the recorded `step` number, skip it.
- **Checkpointing:** every step ends by writing `.build-progress.json` with the new completed step.
- **Commit-per-step:** every step ends with `git commit -m "... [build-step N/15]"`. The build-step tag in the message lets a future invocation grep the log for the last completed step.
- **Halt-on-integrity:** if `tools/check_content_integrity.py` fails after any step, halt with the violation list. Do not proceed to the next step. Do not silence the check.
- **No silent skips:** if a step is skipped because it's already done, log to stdout: `[skip] step N — already complete per .build-progress.json`. Don't pretend it never happened.
- **Time budget:** the full sequence is ~50-80 hours of autonomous work for N4 (smaller content delta), ~80-120 hours for N3, ~100-160 for N2/N1. A single one-shot agent run probably doesn't have that budget — see §A.4 minimum-viable subset for what to ship if running out of time. The agent should checkpoint every step regardless so a follow-up run can resume.
- **Resumability:** a follow-up run with the SAME trigger phrase reads `.build-progress.json` and continues from the next step. The trigger is idempotent.

### A.13 Completion handoff format

When step 15 finishes, the agent emits this report (chat for interactive, stdout for non-interactive):

```
N<L> BUILD COMPLETE — SKELETON v1
================================================================
Source:    N<P> at <source-path>
Target:    N<L> at <target-path>
Started:   <ISO datetime>
Finished:  <ISO datetime>
Duration:  <hours>h <minutes>m
Commits:   <count>  (HEAD: <SHA short>)
Tag:       n<L>-v1-skeleton

DEFINITION-OF-DONE (§A.5)
[ ] / [x] item 1: CI green on integrity check
[ ] / [x] item 2: build pipeline regression green
[ ] / [x] item 3: JSON schemas valid
[ ] / [x] item 4: no duplicate IDs
[ ] / [x] item 5: no empty user-facing fields (within authored scope)
[ ] / [x] item 6: no "see pattern" stubs
[ ] / [x] item 7: no out-of-scope kanji
[ ] / [x] item 8: browser smoke test passes
[ ] / [x] item 9: question count meets minimum-viable layer
[ ] / [x] item 10: PWA installable
[ ] / [x] item 11: TASKS.md current
[ ] / [x] item 12: no em-dashes / en-dashes

CORPUS COUNTS
  Grammar patterns:   <n>  (target ~<target> per §0)
  Vocab entries:      <n>  (target ~<target>)
  Kanji glyphs:       <n>  (whitelist target ~<target>)
  Reading passages:   <n>  (target ~30 per §A.4)
  Listening items:    <n>  (target ~30)
  Questions total:    <n>  (target ~<budget> per §A.8)

DEFAULTS APPLIED (per §0.A.2)
  Native voice:        synthetic (gtts) — flagged Pass-1 EB
  Native review:       LLM-only — flagged Pass-1 EB
  Translation:         English-only — flagged Pass-1 EB-3
  Monetisation:        free, no telemetry
  (... remaining defaults ...)

DEFERRED TO HUMAN PASS (Pass-2 +)
  - <items requiring native review>
  - <items requiring native audio>
  - <items requiring policy decision the agent couldn't safely default>
  - <coverage gaps from §A.12 step 12>

KNOWN LIMITATIONS
  - <any §A.5 item not GREEN, with cause>
  - <any §A.4 layer below minimum-viable>
  - <any halt-conditions encountered + worked-around>

NEXT STEPS FOR HUMAN
  1. <ranked TODO 1>
  2. <ranked TODO 2>
  3. <ranked TODO 3>
================================================================
```

If the build halted mid-sequence (one of §0.A.3 conditions or an integrity violation that the agent couldn't auto-fix), the report instead includes:

```
N<L> BUILD HALTED — RESUME AFTER FIX
================================================================
Last completed step:    <step-number>/15
Halt reason:            <one-line explanation>
What needs to happen:   <one or two specific fixes the human must do>
How to resume:          <exact command to re-trigger the build>
================================================================
```

### A.14 Spec lifecycle and consolidation conventions (added 2026-05-04)

Once N<L> is shipping, its spec corpus follows the same lifecycle as N5 — and the same consolidation pressure builds up over months. Pre-wire these conventions to avoid the N5 mistake of accumulating 8+ markdown files before the consolidation pass.

**Sources vs derivatives — file naming + folder convention:**

| Type | Lives at | Editable? | Naming | Example |
|---|---|---|---|---|
| Source markdown | `specifications/` (or `<JLPT-root>/` for level-agnostic content) | **Yes** — single source of truth | `<level>-functional-spec.md`, `<level>-spec-supplement.md`, `procedure-manual-build-next-jlpt-level.md` | One file per consumer role (§3.2.11) |
| Build artefact | Same folder as the source | **No** — regenerated by `tools/build_spec.py` | `<level> Functional Spec.docx`, `<level> — Consolidated Spec.docx` | All `.docx` files; carry an explicit "DON'T-EDIT-BY-HAND" trailer comment |
| Build script | `tools/build_spec.py` | Yes | – | One script per project; consumes all source markdown, emits all derivatives |

**Revision-block pattern** for living source markdown:

When a spec receives a substantial update, add a new top-level section `§<NextLetter>. Revision YYYY-MM-DD — <Theme>`. **Do not** interleave the new content throughout the doc; it makes diffing across revisions hard and breaks the "stable structure / dated additions" mental model.

The N5 supplement uses this pattern: §A original gap analysis, §B new sections, §C errata, §D audit protocol, §E acceptance criteria, §F revision 2026-05-03 (mobile UI / disabled-button / new invariants), §G revision 2026-05-04 (design system absorbed). When v5 ships, the next revision becomes §H.

**Trailer-as-changelog:** every spec source markdown ends with a trailer that lists each dated revision in chronological order:

```
*Living document. Update on every fresh learning at any next level.*
*Prepared 2026-05-01. Pass-20 review ingested 2026-05-01.*
*Revised 2026-05-03 (afternoon): added §F (mobile UI, disabled-button, JA-25..JA-33 invariants).*
*Revised 2026-05-03 (evening): added §0.A one-instruction trigger + §A.12 + §A.13.*
*Revised 2026-05-04: absorbed design-system / appendix-B / appendix-C / TASKS template per §3.2.11.*
```

Readers can scan the trailer to know what changed when, without reading the whole doc.

**Build script as merge engine:** `tools/build_spec.py` consumes N source markdown files in a defined order and emits a small number of `.docx` derivatives (e.g., a "functional spec only" .docx and a "everything consolidated" .docx). The renderer must implement the defensive table normalisation in §3.2.12 because merging real-world markdown produces row-width inconsistency.

The N5 script has these properties worth porting verbatim:
1. Headings → docx heading styles (h1/h2/h3 → "Heading 1/2/3" style at 16/13/11 pt).
2. Inline `**bold**`, `` `code` ``, `[label](url)` rendered as runs (toggle bold / monospace / coloured-underline within a single paragraph).
3. Tables with the column-normalisation rule.
4. Code fences → fixed-width block paragraph.
5. `---` → docx horizontal rule.
6. Numbered lists + bullet lists.
7. Page break (`doc.add_page_break()`) between chapters when consolidating.

Total renderer code is ~150 lines of python-docx — small enough that pulling in pandoc or asciidoctor is overkill for this workflow.

**Don't version `.docx` files in semver.** The spec versions (v3 → v4 → v5) describe the source markdown's milestone. The `.docx` is just a regenerable view of the current state. Don't tag the `.docx`; tag the markdown. If a stakeholder needs a frozen `.docx` for sign-off, archive a copy outside the repo (e.g., a release bundle).

**Cross-file references:** when the source markdown references other files, prefer relative paths from the repo root (`tools/check_content_integrity.py`, `feedback/ui-testing-plan.md`). The build script substitutes nothing; the rendered `.docx` carries the literal path. Readers who pull the `.docx` open it in a tool that doesn't resolve paths, but they can still grep the source repo by the literal string.

**Audience-driven file count:** every consolidation pass should reduce file count, not increase. The N5 path went `7 → 5 → 3` over two consolidation passes (Pass-22 polish + 2026-05-04 sponsor merge). For N<L>, target **at most 3 source markdown files** in `specifications/` (functional/visual spec, procedure manual at JLPT root, UI testing plan) plus `tools/build_spec.py`. If a fourth is being created, justify it via §3.2.11 audience analysis first.

---


## 18. Pass-20 review findings — disposition

The Pass-20 manual review (`Appendix E (this manual)`) identified 40 issues. Their disposition in this revision:

**Closed in this pass (15 of 40):**
- Issue 1, 8, 33: source authorities for content inventories (A.7)
- Issue 4, 16: required inputs precondition (A.1) + design-system file pointer
- Issue 19, 21, 39: fallback procedures for external-blocked items (A.3)
- Issue 20: minimum-viable subset (A.4)
- Issue 25: default decisions for §15 (A.2)
- Issue 29: SM-2 exact parameters (A.10)
- Issue 26: furigana generation procedure (A.11)
- Issue 37: question-count budget (A.8)
- Issue 38: JLPT exam structure (A.9)
- Issue 40: definition of done (A.5)
- Issue 3: schema extraction recipe (A.6)

**Deferred to Pass-21 — embedding ~5000 lines of inventories (15 of 40):**
- Issues 2, 7, 9, 11: full executable invariant specs, level-cross-cutting scaling
- Issue 5, 30, 31, 32: complete UI module list, SM-2 schema, test framework, PWA spec
- Issue 6, 35: audio manifest schema, i18n locale convention
- Issue 10: external-corpus URL list per level
- Issue 14, 15, 17, 18: i18n translation pipeline, kanji-tier convention, KB markdown grammar, vocab-ID slug rules

**Closed-by-pointer (8 of 40):**
- Issue 12, 13, 22, 23, 24, 27, 28, 34, 36: each refers to a section that already exists in the manual but the reviewer judged it underspecified. The closed-in-this-pass items strengthen these enough that they're now "minimum acceptable, not strong" — registered as Pass-22 polish candidates.

**Open structural concern (2 of 40):**
- Issue 6 (audio manifest), Issue 18 (vocab-ID slug rule): these touch data integrity and need explicit schemas embedded, not just pointers. Must be closed before any Mode-B agent run produces shippable content. Tagged P0 in Pass-21.

---

*Living document. Update on every fresh learning at any next level.*
*Prepared 2026-05-01. Pass-20 review ingested 2026-05-01.*
*Revised 2026-05-03 (afternoon): added §3.2.7 (cross-ref hygiene), §3.2.8 (PoS mass-stamping), §3.2.9 (mid-line clipping), §3.2.10 (stale module state on URL nav), §4.5 (mobile UI contract — 768/480/380 breakpoints, tap-targets, iOS auto-zoom, body type-floor, smooth scroll, container gutter), §4.6 (disabled-button feedback contract + saved-toast pattern), 9 new invariants (JA-25..JA-33), 8 new bumper-sticker entries (UI / process), 2 new Claude Code lessons (ES module cache, permission flag).*
*Revised 2026-05-03 (evening): added §0.A (one-instruction autonomous-build contract — trigger phrases, implicit-input defaults, halt conditions, deliverables, skip-permissions posture), §A.12 (15-step ordered execution sequence with idempotent checkpoints + commit-per-step + .build-progress.json resumability), §A.13 (completion handoff report format + halt-state report format). The manual is now actionable on a single instruction: "build the next level" / "build N4" triggers §A.12 execution end-to-end without further user interaction.*
*Absorbed 2026-05-04: companion docs §B (extracted-from-N5 schemas, was procedure-manual-appendix-b-extracted-from-n5.md) + §C (Pass-22 polish, was procedure-manual-appendix-c-pass22-polish.md) + §D (TASKS.md canonical template, was tasks-md-template.md) folded inline. Manual is now self-contained for Mode-B execution per Pass-20 §3.2 finding.*
*Revised 2026-05-04: added §3.2.11 (don't fragment a spec across files when one role reads all), §3.2.12 (defensive markdown→docx renderer to handle inconsistent tables), §A.14 (spec lifecycle + consolidation conventions: sources vs derivatives, revision-block pattern, trailer-as-changelog, build script as merge engine, 3-source ceiling), 3 new Claude Code lessons (#11 sponsor framing resolves cross-audience decisions, #12 reduction beats expansion, #13 consolidate by audience not by topic), 4 new bumper-sticker entries (Spec hygiene: §3.2.11 merge / §3.2.12 defensive renderer / DON'T-EDIT-BY-HAND on artefacts / dated revision-blocks).*

*Revised 2026-05-09: added §19 (Native-teacher audit playbook), §20 (Vocab.json structural rules + dedup tooling pattern), §3.2.13–§3.2.20 (8 new anti-patterns from the N5 native-teacher audit + dedup pass: vocab_id substring tagging, vocab_used substring extraction, sokuon allophones, vocab cross-listing dedup, derived-metadata refresh, blunt mnemonics, orthographic consistency, legacy schema cleanup), JA-42–JA-46 (5 new CI invariants), §1.3 sidecar `.meta.json` + provenance discipline patterns, §6.4 safe-script practices for JSON-mutating tooling, 8 new bumper-sticker entries.*

*Revised 2026-05-10: added §3.2.21–§3.2.27 (7 new anti-patterns from the deployment + UI + content-authoring audit cycle: SW stale-while-revalidate trap, `<img src=svg>` currentColor failure, brand-color hex divergence across files, IME composition guard on search inputs, easy-Japanese vs plain-Japanese register conflation, kanji-promotion regex without mecab, vertical-centering in flex with min-height children) and 9 new bumper-sticker entries (3 Content, 4 UI/Layout, 2 Process). The deployment-cache lesson (§3.2.21) is the most-frequently-encountered: stale-while-revalidate for shipping shell content makes deploys appear broken from the user's seat. The IME composition lesson (§3.2.24) applies to every search input in any Japanese-content app and was a horizontal-deployment fix across 3 files in N5. The kanji-promotion lesson (§3.2.26) is a hard limit — without a morphological tokenizer (mecab / kuromoji / sudachi), regex-only sweeps on Japanese text WILL produce compound-word false positives; treat this as a "don't even try" boundary. Backup-policy bumper-sticker (#22 Process) added to reflect the new project rule in `.claude/CLAUDE.md` requiring versioned backups before destructive ops on data files.*


---


# §19 Native-teacher audit playbook (added 2026-05-09)

A reusable cycle pattern for catching learner-facing content corruption that structural CI misses. The N5 corpus ran a native-teacher audit on 2026-05-08 and surfaced 16 findings across CRITICAL / HIGH / MEDIUM / LOW tiers; 13 fixed in one phased pass. Reproduce this pattern for every level.

## §19.1 When to run an audit

Trigger an audit cycle when ANY of the following becomes true:

- **Calendar trigger:** quarterly (every ~3 months) once content authoring is mostly complete.
- **Major refactor lands:** any pass that mutated source content broadly (audio re-render, listening rewrite, kanji policy change, vocab dedup).
- **External feedback signal:** a user / reviewer reports a content issue — that's almost always the visible tip of a class of issues.
- **Pre-release gate:** before declaring a corpus "done" or before a tagged release.

## §19.2 Audit cycle (what the auditor does)

The audit is a **read pass with native-teacher posture**. The auditor (LLM in a "native Japanese JLPT teacher reviewing learner-facing content" persona, or a human native reviewer) systematically samples the data files looking for things a native teacher would flag.

| Step | Action | Output |
|---|---|---|
| 1 | Survey `data/*.json` file sizes; pick a sampling strategy proportional to size | List of files + sample regions |
| 2 | For each file, sample ~5–10% of entries reading them as a learner would | Per-file findings list |
| 3 | Cross-reference samples: same word in vocab.json + grammar.json + reading.json — are tags / readings / glosses consistent? | Cross-reference inconsistencies |
| 4 | Check derived metadata against source: `explanation_hi` vs `script_ja` (do they describe the same content?), `vocab_used` vs the actual passage (are these words actually in the passage?), `cultural_context` vs the dialogue (do they match?) | Drift findings |
| 5 | Check JLPT-N`<L>` scope: is every kanji whitelisted? Are out-of-scope readings deferred to higher levels? | Scope violations (most should already be caught by CI; the audit catches what CI misses) |
| 6 | Check pedagogical tone: blunt mnemonics, code-mixed prose, broken machine-translated examples, anatomical phrasing | Tone findings |
| 7 | Categorize by tier: CRITICAL (corruption visible to learners) / HIGH (pedagogical errors) / MEDIUM (polish) / LOW (honest disclosures already documented) | Tiered finding list |
| 8 | Write the audit report at `feedback/native-teacher-audit-YYYY-MM-DD.md` with the structure in §19.4 below | The audit document |

## §19.3 Fix cadence (what the implementer does)

After the audit lands:

1. **CRITICAL first.** Each is content corruption visible to learners (wrong Hindi explanations, vocab tagged with wrong sense, etc.). Fix in priority order. Each fix is its own commit (`data(audit): fix C-N <description>`). Run integrity check after every commit.
2. **HIGH second.** Pedagogical errors (auto-translated English errors, sokuon kun-readings, romaji formatting). Group related fixes per commit if they touch the same file (e.g., kanji.json polish = one commit).
3. **MEDIUM third.** Polish items (mnemonic phrasing, time-format consistency, schema cleanup).
4. **LOW = no action.** These are honest disclosures already documented in `_meta` blocks. Verify they're still accurate.
5. **DEFERRED items in their own column.** Items that require external resources (TTS re-render, Hindi-native review pass) get explicit DEFERRED status with the blocker named.
6. **Commit hygiene per §6.4 safe-script practices.** Every commit: re-run integrity, verify 50/50 (or whatever invariant count) is green, push.
7. **Bump `CACHE_VERSION` and refresh `data/version.json`** in a final docs commit; update `CHANGELOG.md` with the audit-pass entry.

## §19.4 Audit report template

Save at `feedback/native-teacher-audit-YYYY-MM-DD.md`:

```markdown
# Native Japanese JLPT Teacher Audit — YYYY-MM-DD

[One-sentence framing: scope of audit, persona used, what was checked.]

## Executive summary

[2–3 sentences on what was found, what was fixed, what was deferred.]

## Findings + fix status

### CRITICAL — content corruption (visible to learners)

| ID | Finding | Status |
|---|---|---|
| C-1 | <one-line summary> | FIXED / DEFERRED / IN PROGRESS |
| ... | ... | ... |

### HIGH — pedagogical concerns

| ID | Finding | Status |
|---|---|---|
| H-1 | ... | ... |

### MEDIUM — polish

| ID | Finding | Status |
|---|---|---|

### LOW — honest disclosures (already documented)

[Bullet list of items that are non-bugs, already tagged in _meta.]

## Broader issues identified (not in scope of this pass)

[Issues that warrant separate cycles — vocab section restructuring, mecab integration, etc.]

## Verification

`tools/check_content_integrity.py`: N/N invariants green after each phase commit.

## Commits

[One-line per commit, oldest to newest.]
```

## §19.5 Common audit-finding classes (predict these in advance)

The N5 audit hit these classes; expect them at every level:

- **Auto-tagger drift** — anywhere a script populated metadata by substring/heuristic, expect ~5–20 false-positives per 100 entries. Audit by reading the metadata back as a learner would.
- **Stale derived fields after refactor** — if any pass mutated source content, sibling fields likely lag. Audit by comparing source vs derived for a sample of items.
- **Cross-listing redundancy** — same word in two thematic sections, both auto-tagged downstream. Audit by grouping `(form, reading)` and looking for non-polyseme duplicates.
- **Schema-migration leftover** — legacy fields lingering past their replacement. Audit by grep'ing for known-deprecated field names.
- **Tone mismatches** — blunt mnemonics, lowercase pronouns from machine translation, code-mixed prose marked as native-reviewed. Audit by reading aloud.
- **Orthographic mixing** — kanji/hiragana/numeral mixing for the same morpheme. Audit by grep'ing for known-mixed pairs (e.g., `[時][はん]` vs `[時][半]`).

## §19.6 What the audit does NOT replace

The audit is a **complement** to structural CI, not a replacement:

- CI catches schema-shape violations (missing fields, type errors, count mismatches). The audit catches *content quality* issues that pass schema checks.
- CI is fast and runs on every commit. The audit is a periodic cycle.
- CI is deterministic (regex / set-membership). The audit is judgement-based.
- Both must run; neither alone is sufficient.

When an audit catches a class of bug, **add a new CI invariant** so the next occurrence fails CI before reaching the audit. The N5 audit graduated 5 classes (JA-42 through JA-46) to CI invariants — this is the maturation pattern: subjective audit → repeating finding → objective CI rule.

---



---

# Appendices

> **Appendices** — schemas, templates, and dated session-learning notes. Reference material; not part of the linear procedure.

# §B Appendix B — Schemas & rules extracted from N5 (merged 2026-05-04)

*Was at `<source-repo>/specifications/procedure-manual-appendix-b-extracted-from-n5.md`. Merged inline so the procedure manual is self-contained for Mode-B one-shot execution. Per the original Pass-20 review (`Appendix E (this manual)`), having Appendix B inline is a one-shot prerequisite.*

---


# Procedure Manual Appendix B — Extracted from N5 Codebase

**Companion to:** `procedure-manual-build-next-jlpt-level.md`
**Closes Pass-20 deferred items:** F-20.15 through F-20.26 (the "extract from N5" cluster)
**Prepared:** 2026-05-01 by reading N5 source files directly (build_data.py, check_content_integrity.py, js/*.js, locales/*.json, playwright.config.js, tools/*.py, data/*.json)

This appendix extracts schemas, rules, configurations, and conventions from the actual N5 codebase so a Mode-B agent can implement them without inferring from prose. Every section here corresponds to a specific deferred F-20 item.

---


## B.1 Vocab-ID slug derivation rule (closes F-20.20, P0)

**Source:** `tools/build_data.py` lines 285-293.

**Rule (extracted verbatim from build pipeline):**

```python
# Slug is the lowercase section title with non-alphanumerics collapsed
# to single hyphens, trimmed to 24 chars, with "misc" as the empty-section
# fallback.
slug = re.sub(r"[^a-z0-9]+", "-", section.lower()).strip("-")[:24] or "misc"

# Base ID:
base_id = f"n5.vocab.{slug}.{form}"

# Disambiguator on collision: append ".2", ".3", ... in insertion order
vid = base_id
i = 2
while vid in seen_ids:
    vid = f"{base_id}.{i}"
    i += 1
```

**Rules in plain English:**

1. The section slug is derived from the section heading text in `vocabulary_n5.md`. Lowercase, all non-`[a-z0-9]` characters → `-`, leading/trailing `-` stripped, capped at 24 characters. If the result is empty, use `misc`.
2. The vocab ID is `n<L>.vocab.{section-slug}.{form}` for any next level (replace `n5` → `n<L>`).
3. The `form` is the head-word as written in the catalog (could be kanji, kana, or katakana).
4. If a (section, form) pair recurs (i.e., the same vocab item is listed in multiple sections OR the section repeats a form), the second occurrence appends `.2`, third `.3`, etc.

**Examples (drawn from N5):**

| Section heading | Slug | Form | Resulting ID |
|---|---|---|---|
| `4. Body parts` | `4-body-parts` | あし | `n5.vocab.4-body-parts.あし` |
| `18. Drinks` | `18-drinks` | おちゃ | `n5.vocab.18-drinks.おちゃ` |
| `27. Verbs (Group 1)` | `27-verbs-group-1-verb` (truncated to 24) | おく | `n5.vocab.27-verbs-group-1-verb.おく` |
| (collision case) | (same as above) | きる (2nd occurrence) | `<same-prefix>.きる.2` |

**For any next level N<L>:**
- Replace `n5.` → `n<L>.` in the prefix.
- Section structure follows `vocabulary_n<L>.md` — the agent must NOT invent section names; they should be derived from the authored KB file.
- Cross-listings in multiple thematic sections are intentional (N5 has 10 such pairs); use the same slug-encoding strategy. Annotate the second-occurrence gloss with `(also in §X)` for human readability.

**CI invariant** that depends on this rule: JA-12 (Kanji KB / JSON consistency) implicitly checks the round-trip from MD section → JSON id; if the slug rule diverges, the consistency check fails.

---


## B.2 Audio manifest schema (closes F-20.18, P0)

**Source:** `data/audio_manifest.json` shape inspection.

**Top-level structure:**

```json
{
  "backend": "gtts",                    // string; one of "gtts" | "piper" | "pyttsx3" | "native"
  "voice_default": "synthetic-gtts",    // string; default voice tag for items that don't override
  "items": [ /* AudioItem[] */ ]
}
```

**`AudioItem` shape:**

```json
{
  "id": "grammar.n5-001.0",             // string; PK; pattern: "<corpus>.<entity-id>.<index>"
  "path": "audio/grammar/n5-001.0.mp3", // string; relative to repo root, forward-slash normalized
  "skipped": true,                      // boolean (optional, default false); true if file not generated
  "voice": "synthetic-gtts"             // string; voice tag (allows mixing native + synthetic)
}
```

**ID conventions per corpus:**
- Grammar examples: `grammar.<patternId>.<exampleIndex>` (e.g., `grammar.n<L>-042.2`)
- Reading passages: `reading.<passageId>` (e.g., `reading.n<L>.read.012`)
- Listening items: `listening.<itemId>` (e.g., `listening.n<L>.listen.005`)

**Voice tag enum (level-agnostic; same set used at every level):**
- `"synthetic-gtts"` — Google Translate TTS, web-synthesized
- `"synthetic-piper"` — Piper local TTS (ONNX models)
- `"synthetic-pyttsx3"` — pyttsx3 local fallback
- `"native"` — recorded by a native speaker (preferred for listening at any level lower than N5)
- `"native-{speaker-id}"` — when multiple native voices used (e.g., `"native-suiraku"`)

**JA-15 invariant rule (the audio-resolution check):**

For every `AudioItem` where `skipped !== true`:
- The `path` must resolve to an existing file on disk.
- The file size must be > 100 bytes (rejects empty placeholder files).
- The file extension must match `.mp3` or `.wav`.

For items where `skipped === true`:
- `path` is reserved (the file would be generated if `skipped` flipped to false). The path string is required but the file need not exist.

**Build pipeline behavior (`tools/build_audio.py`):**
- Auto-detects backend in priority order: piper > gtts > pyttsx3 > skip.
- Idempotent: if `path` exists with size > 100B, regeneration is skipped (re-running the script does nothing).
- For `voice: "native"` items, the script SKIPS generation (assumes externally provided).
- Manifest is rewritten on every run with current state.

**For any next-level transition:**
- The schema is identical. Just update `n5` → `n<L>` in IDs.
- Plan to mix `native` for listening items + `synthetic-gtts` for grammar/reading. Voice mixing is supported in the same manifest.

---


## B.3 JSON schemas for data/*.json (closes F-20.16)

Inferred from N5 `data/*.json` shapes. These should be formalized as `specifications/schemas/<file>.schema.json` files at next-level (N<L>) build time. The agent can run `python -c "import genson; ..."` to auto-generate JSON Schema from N5 files, or hand-author from these inventories.

### B.3.1 grammar.json

```
{
  "_meta": {
    "schema_version": str,            // e.g., "1.0"
    "pattern_count": int,
    "id_range": { "first": str, "last": str },
    "history": str[]                  // append-only log
  },
  "patterns": Pattern[]
}

Pattern = {
  "id": str (req)                     // "n<L>-NNN"
  "pattern": str (req)                // surface form, e.g., "～です／～ます"
  "meaning_en": str (req)
  "meaning_ja": str (req)             // やさしい にほんご
  "category": str (req)               // fine-grained, e.g., "Particles"
  "tier": "core_n<L>" | "late_n<L>" | "n<L-1>_borderline" (req)
  "patternOrder": int (req)           // for stable sort within category
  "form_rules": {
    "attaches_to": str[],             // e.g., ["noun", "verb_stem_i"]
    "conjugations": [{
      "label": str,                   // "Present affirmative" etc.
      "form": str,                    // form-tag e.g. "polite-aff"
      "example": str                  // ja
    }]
  },
  "examples": [{                      // 2-5 typical
    "form": str,                      // optional form-tag
    "ja": str (req),
    "translation_en": str (req),
    "furigana": [{ "reading": str, "indices": [int, int] }]?,
    "vocab_ids": str[]?               // populated by link_grammar_examples_to_vocab.py
  }],
  "common_mistakes": [{
    "wrong": str,                     // ja with the typical error
    "right": str,                     // ja correct form
    "why": str                        // English explanation
  }]?,
  "notes": str?,
  "explanation_en": str?              // longer-form prose
}
```

### B.3.2 questions.json

```
{
  "_meta": {
    "schema_version": str,
    "question_count": int,
    "type_distribution": { "mcq": int, "sentence_order": int, "text_input": int },
    "id_range": { "first": str, "last": str },
    "id_gap_policy": "documented" | "contiguous",
    "id_gap_explanation": str,
    "id_gaps": [{ "from": str, "to": str, "cause": str }]?,
    "history": str[]
  },
  "questions": Question[]
}

Question = MCQQuestion | SentenceOrderQuestion | TextInputQuestion

MCQQuestion = {
  "id": str (req)                     // "q-NNNN"
  "grammarPatternId": str (req),      // n<L>-NNN
  "type": "mcq" (req),
  "subtype": "paraphrase" | "kanji_writing" | null,  // optional MCQ flavor
  "direction": "j_to_e" | "e_to_j",
  "prompt_ja": str (req),             // instruction text
  "question_ja": str (req),           // stem with （  ） blank
  "choices": str[4] (req),
  "correctAnswer": str (req),         // must be a member of choices
  "explanation_en": str (req),
  "distractor_explanations": { [choice]: str },  // 3 entries (one per wrong choice)
  "high_confusion": bool?,
  "difficulty": int (req),            // 1..5
  "auto": bool (req)                  // true = template-generated; false = manually reviewed
}

SentenceOrderQuestion = {
  "id": str,
  "grammarPatternId": str,
  "type": "sentence_order",
  "direction": "j_to_e" | "e_to_j",
  "prompt_ja": str,
  "tiles": str[],                     // shuffled tokens
  "correctOrder": int[],              // indices into tiles, in correct order
  "explanation_en": str,
  "difficulty": int,
  "auto": bool
}

TextInputQuestion = {
  "id": str,
  "grammarPatternId": str,
  "type": "text_input",
  "direction": "j_to_e" | "e_to_j",
  "prompt_ja": str,
  "question_ja": str,                 // stem with ___ blank
  "acceptedAnswers": str[],           // all forms that count as correct
  "correctAnswer": str,               // canonical (shown in feedback)
  "explanation_en": str,
  "difficulty": int,
  "auto": bool
}
```

### B.3.3 vocab.json

```
{
  "entries": [{
    "id": str,                        // n<L>.vocab.{slug}.{form}[.disambiguator] — see B.1
    "form": str,                      // headword
    "reading": str,                   // kana reading; equals form for kana-only entries
    "gloss": str,                     // English meaning
    "section": str,                   // section heading text (the slug source)
    "pos": str?,                      // part-of-speech tag — see B.6 vocab POS values
    "tier"?: "core_n<L>" | "late_n<L>" | "prerequisite_n<P>"  // for any N<L>: include lower-level prerequisites with tier flag
  }],
  "_meta": { "vocab_count": int, "section_count": int, "history": str[] }
}
```

### B.3.4 kanji.json

```
{
  "entries": [{
    "kanji": str (req),               // single CJK character
    "on": str[],                      // on-yomi readings (katakana)
    "kun": str[],                     // kun-yomi readings (hiragana, with ( ) markers for okurigana)
    "meanings": str[],                // English meanings
    "stroke_order_svg": str?,         // path to SVG file
    "tier": "core_n<L>" | "late_n<L>" | "prerequisite_n<P>"  // see B.10
  }],
  "_meta": { "kanji_count": int, "history": str[] }
}
```

### B.3.5 reading.json

```
{
  "passages": [{
    "id": str,                        // "n<L>.read.NNN"
    "level": "easy" | "medium" | "hard",
    "topic": str,                     // e.g., "shopping"
    "title_en": str,
    "ja": str,                        // the passage text
    "translation_en": str,
    "audio": str?,                    // path; matches AudioItem.path
    "questions": [{
      "id": str,                      // "n<L>.read.NNN.qM"
      "prompt_ja": str,
      "choices": str[4],
      "correctAnswer": str,
      "explanation_en": str,
      "format_role": "primary" | "extra" | "info_search"  // mondai sub-format
    }],
    "tier": "core_n<L>" | "late_n<L>",
    "kanji_used": str[],              // populated by build pipeline
    "vocab_used": str[]               // populated by build pipeline
  }],
  "_meta": { "passage_count": int, "history": str[] }
}
```

### B.3.6 listening.json

```
{
  "items": [{
    "id": str,                        // "n<L>.listen.NNN"
    "format": "task" | "point" | "utterance",  // mondai-1 / 2 / 3-4
    "script_ja": str,                 // dialog or narration
    "translation_en": str,
    "audio": str,                     // path
    "questions": [{
      "id": str,
      "prompt_ja": str,
      "choices": str[4],
      "correctAnswer": str,
      "explanation_en": str
    }]
  }],
  "_meta": { "item_count": int, "history": str[] }
}
```

### B.3.7 audio_manifest.json

See B.2.

---


## B.4 i18n locale-file format (closes F-20.19)

**Source:** `locales/*.json` (5 files: en, vi, id, ne, zh).

**Convention:**
- One JSON file per locale at `locales/<lang-code>.json`
- Locale codes: ISO 639-1 (en, vi, id, ne, zh)
- All locales share the SAME nested-key structure; missing keys in non-English locales fall back to the English value at runtime
- The structure is hierarchical (objects, not flat dotted keys)

**Top-level shape (from N5 `locales/en.json`):**

```json
{
  "app": { "title": "...", "tagline": "..." },
  "nav": { "learn": "...", "test": "...", "drill": "...", "review": "...",
           "summary": "...", "settings": "...", "diagnostic": "..." },
  "drill": { "start": "...", "due_today": "...", "in_queue": "...", "graduated": "..." },
  "test": { "start_long": "...", "start_short": "...", "next": "...", "submit": "...", "results": "..." },
  "review": { ... },
  "summary": { ... },
  "settings": { ... },
  "errors": { "generic": "...", "audio_unavailable": "...", "offline": "..." }
}
```

**Source-locale-of-truth:** `locales/en.json` is canonical. When a new key is added at any N<L> build, add it to `en.json` first; other locales fall back to en until translated.

**Translation pipeline (N5 has no automation; translations are manually authored):**
- Translator reads `en.json`, produces a parallel `<lang>.json` keeping the SAME key structure.
- Missing keys → fall back to en (no warning at runtime; the string just renders in English).
- Extra keys → ignored.

**For any next level (recommendation):**
- Keep all 5 N5 locales for parity.
- N<L>-new content (grammar explanations, distractor reasons) is English-only at v1; translate in v2 if learner base justifies the cost.
- Add a `tools/extract_locale_keys.py` script (Pass-22) that diffs the en JSON against each non-en JSON and produces a TODO list of missing keys.

**Runtime contract (i18n.js):**
- Single global `T(key)` function: `T("nav.learn")` → "Learn" (en) or "学ぶ" (etc.).
- Locale selection: URL hash override (`#/?lang=vi`) > localStorage `lang` > browser `navigator.language` > `"en"`.

---


## B.5 Front-end test framework + Playwright config (closes F-20.23)

**Source:** `playwright.config.js` + `tests/p0-smoke.spec.js` + `package.json` scripts.

**Framework:** Playwright (`@playwright/test`). The 37-test claim from N5 status snapshot covers Playwright smoke tests + JS unit-style tests run inside the page (the front-end has no separate unit-test framework).

**Playwright config (verbatim from N5):**

```js
const { defineConfig, devices } = require('@playwright/test');

module.exports = defineConfig({
  testDir: './tests',
  testMatch: '**/*.spec.js',
  timeout: 30_000,
  expect: { timeout: 5_000 },
  fullyParallel: true,
  forbidOnly: !!process.env.CI,
  retries: process.env.CI ? 1 : 0,
  workers: process.env.CI ? 1 : undefined,
  reporter: process.env.CI ? [['html', { open: 'never' }], ['github']] : 'list',
  use: {
    baseURL: 'http://localhost:8000',
    trace: 'on-first-retry',
    screenshot: 'only-on-failure',
    video: 'retain-on-failure',
  },
  projects: [
    { name: 'chromium-desktop', use: { ...devices['Desktop Chrome'] } },
    { name: 'chromium-mobile',  use: { ...devices['Pixel 5'] } },
  ],
  webServer: {
    command: 'python -m http.server 8000',
    url: 'http://localhost:8000/',
    timeout: 15_000,
    reuseExistingServer: !process.env.CI,
    stdout: 'ignore',
    stderr: 'pipe',
  },
});
```

**Why Python http.server as the test fixture:** the app is static HTML/CSS/JS with no Node server. Python's built-in `http.server` is available wherever Python 3 is, including CI.

**Smoke test categories (in `tests/p0-smoke.spec.js`):**
1. Home loads — title, nav, no console errors
2. Hash routes resolve — `#/learn`, `#/test`, `#/drill`, `#/review`, `#/summary`, `#/settings` each render expected heading
3. Learn TOC expands and contains pattern cards
4. Pattern detail page renders for a known ID — title, examples, prev/next nav
5. Test mode flow — start → answer → submit → results
6. Drill due-count badge updates after a session
7. Review SM-2 buttons — Again/Hard/Good/Easy each fire the correct interval
8. Summary tab renders without errors when state is empty
9. Settings — theme toggle, locale switch, reset progress
10. PWA — service worker registers, manifest is valid
11. Offline — second visit works without network

**Run:**
```
npm install
npm run test:install-browsers   # one-time: downloads Chromium
npm run test:smoke              # full suite headless
npm run test:smoke:headed       # watch the browser
```

**For any next level:**
- Copy `playwright.config.js` verbatim.
- Adapt smoke tests to N<L> routes/IDs (find/replace `n5` → `n<L>`; replace pattern IDs).
- Wire into `.github/workflows/playwright-p0-smoke.yml` as a CI gate.

---


## B.6 UI module list with descriptions (closes F-20.22)

**Source:** files in `js/` directory of N5 (25 files as of HEAD `7e82cc4`).

| File | Responsibility | Imports / depends on | Exports |
|------|----------------|----------------------|---------|
| `app.js` | Main entry point; routing, app shell, initial render | all chapter modules | (initializes on DOMContentLoaded) |
| `i18n.js` | Locale selection + `T(key)` translation function | `locales/<lang>.json` (fetched) | `T`, `setLocale` |
| `storage.js` | LocalStorage wrappers; SRS state, progress, settings | (none) | `getProgress`, `saveProgress`, `getPatternEntry`, `setManuallyKnown`, `recordAttempt`, ... |
| `furigana.js` | Renders Japanese with optional ruby annotations; 3-mode visibility | (none) | `renderJa(ja, furigana?)` |
| `home.js` | Home page: brief hero, nav cards | i18n | `renderHome` |
| `learn.js` | Chapter 1 — Learn hub + Grammar TOC + Pattern detail + Vocab list/detail | storage, furigana | `renderLearn` |
| `test.js` | Chapter 2 — Test mode (mock-test flow with hide-answer-until-commit) | storage, furigana | `renderTest` |
| `drill.js` | Chapter 3 — Daily Drill (random sample of weak/due items) | storage, furigana | `renderDrill` |
| `review.js` | Chapter 4 — SM-2 SRS Review session | storage, furigana | `renderReview` |
| `summary.js` | Chapter 4b — Summary (mastered/weak/untested + heatmap + error patterns + recommendation) | storage, furigana | `renderSummary` |
| `diagnostic.js` | First-run diagnostic placement test (~10 questions) | storage, furigana | `renderDiagnostic` |
| `settings.js` | Settings panel (theme, locale, font, reset, export/import) | storage, i18n | `renderSettings` |
| `kanji.js` | Kanji list + per-kanji detail page | storage, furigana | `renderKanji`, `renderKanjiDetail` |
| `kanji-popover.js` | Hover popover showing kanji on/kun + meaning when hovering kanji in body text | storage | `attachKanjiPopovers(container)` |
| `reading.js` | Dokkai mode: passage browser + comprehension | storage, furigana | `renderReading` |
| `listening.js` | Listening mode: chokai items with audio + comprehension | storage, furigana | `renderListening` |
| `kosoado.js` | こそあど interactive trainer (matching pairs by spatial relation) | storage | `renderKosoado` |
| `wa-vs-ga.js` | は vs が trainer | storage | `renderWaVsGa` |
| `verb-class.js` | Group-1 / Group-2 / Group-3 verb classifier trainer | storage | `renderVerbClass` |
| `te-form.js` | て-form gym (drilling all the rules) | storage | `renderTeForm` |
| `particle-pairs.js` | Interchangeable-particle pairs trainer (に/へ, は/が, etc.) | storage | `renderParticlePairs` |
| `counters.js` | Counter trainer (枚, 本, 個, 人, etc.) | storage | `renderCounters` |
| `search.js` | Cross-corpus search (grammar + vocab + kanji + reading) | (loads all corpora) | `renderSearch`, `searchAll(query)` |
| `pwa.js` | Service worker registration, update toast, install prompt | (none) | (auto-runs on load) |
| `shortcuts.js` | Keyboard shortcuts (j/k navigation, ?, /, etc.) | (none) | `attachShortcuts()` |
| `normalize.js` | Text normalization helpers (full-width → half-width, NFC, etc.) | (none) | `normalize(s)`, `normalizeAnswer(s)` |

**State contract:**
- All persistent state lives in `localStorage` under keys prefixed `jlpt-n5-tutor.*` (replace `n5` → `n<L>`).
- Read/write goes through `storage.js` only (no direct `localStorage.getItem` elsewhere).
- Export/import dumps all keys with the prefix as a single JSON blob.

**Routing contract:**
- Hash router in `app.js`; URL fragment after `#/` is the route.
- `#/learn`, `#/learn/grammar`, `#/learn/<patternId>`, `#/learn/vocab`, `#/learn/vocab/<form>`, `#/kanji`, `#/kanji/<glyph>`, `#/test`, `#/test/<n>`, `#/drill`, `#/review`, `#/summary`, `#/settings`, `#/diagnostic`, `#/reading`, `#/reading/<id>`, `#/listening`, `#/listening/<id>`, `#/kosoado`, `#/wa-ga`, `#/verbs`, `#/te-form`, `#/particle-pairs`, `#/counters`, `#/search`.

**For any next level:** copy the module list verbatim; adapt `n5` → `n<L>` references.

---


## B.7 KB markdown grammar / BNF (closes F-20.15)

**Source:** `tools/build_data.py` parsing rules + observed structure of `KnowledgeBank/*.md`.

### B.7.1 grammar_n<L>.md (catalog of grammar patterns)

```
File         := Header SectionList
Header       := "# JLPT N<L> Grammar Patterns" "\n" Preamble
Preamble     := free-form markdown until first "## "
SectionList  := Section+
Section      := "## " SectionTitle "\n" PatternEntry+
SectionTitle := plain text (e.g., "Particles", "Common Set Patterns")
PatternEntry := PatternHeader Body
PatternHeader:= "### " PatternId " — " PatternSurfaceForm "\n"
PatternId    := "n<L>-" 3*DIGIT
Body         := YamlFrontMatter? FreeForm Examples? CommonMistakes? Notes?
YamlFrontMatter := "```yaml" "\n" key-value-pairs "\n" "```"
                   // populates: meaning_en, meaning_ja, category, tier,
                   // attaches_to, conjugations
Examples     := "**Examples**" "\n" ExampleEntry+
ExampleEntry := "- " ja " — " translation_en "\n"
              | "- " "(" form_tag ")" " " ja " — " translation_en "\n"
CommonMistakes := "**Common mistakes**" "\n" MistakeEntry+
MistakeEntry := "- ❌ " wrong_ja "\n" "  ✅ " right_ja "\n" "  Why: " why "\n"
Notes        := "**Notes**" "\n" free-form
```

**Parser rules (from `tools/build_data.py`):**
- Pattern ID detection: `^### (n<L>-\d{3}) — (.+)$`
- Example detection: `^- ` (with optional `\(form\)\s+` prefix)
- The em-dash separator in examples is U+2014; X-6.5 forbids it. **N5 used a hyphen** ` - ` instead. **At any next level, use hyphen too** to keep X-6.5 invariant green.

### B.7.2 vocabulary_n<L>.md (catalog of vocab)

```
File        := Header SectionList
Section     := "## " N "." " " SectionTitle "\n" VocabEntry+
VocabEntry  := "- " form (" (" reading ")")? " - " gloss tags?
tags        := " **[Ext]**" | " **[Cul]**" | " **[Adv]**"
              // [Ext] = extension (out of strict N<L> but commonly in materials)
              // [Cul] = cultural item
              // [Adv] = advanced (N3-borderline)
```

**Parser rules:**
- Section number prefix `N.` is preserved in the section heading and used for slug derivation (B.1).
- The reading is in parentheses immediately after the form. For kana-only words, the reading is the form itself (the parser auto-fills it).
- Tags `[Ext]` / `[Cul]` / `[Adv]` are stripped from the gloss before output but stored as `tier` metadata.

### B.7.3 kanji_n<L>.md (catalog of kanji)

```
File         := Header KanjiList
KanjiList    := KanjiEntry+
KanjiEntry   := "- **" KANJI "**" "\n"
                "  - On: " on_readings "\n"
                "  - Kun: " kun_readings "\n"
                "  - Meaning: " meanings ("\n")?
                ("  - " note_line "\n")*
on_readings  := katakana ("," " " katakana)*
kun_readings := hiragana_with_okurigana ("," " " hiragana_with_okurigana)*
hiragana_with_okurigana := hiragana ("(" hiragana ")")?
                          // e.g., あ(げる) where あ is the kanji-attached part
                          // and げる is the okurigana suffix
meanings     := plain English, comma-separated
```

**Parser rules:**
- Header regex (from N5 `build_data.py` after Pass-13 fix): `r"^\s*-\s+\*\*([一-鿿])\*\*"` — note the relaxed end (no `\s*$`) to allow `**[Ext]**`-tagged entries.
- Each kanji entry must have at least one reading on On OR Kun line; meaning is required.

### B.7.4 *_questions_n<L>.md (moji / goi / bunpou / dokkai / chokai)

```
File          := Header MondaiList
MondaiList    := Mondai+
Mondai        := "## Mondai " N " - " MondaiName ("\n" Description)? QuestionList
QuestionList  := QuestionEntry+
QuestionEntry := "### Q" N ("\n" "\n")? StemBlock ChoiceList AnswerLine
StemBlock     := free-form ja text (may include <u>...</u> for kanji-reading questions
                or __...__ for orthography questions)
ChoiceList    := ChoiceLine{4}
ChoiceLine    := N ". " text
AnswerLine    := "**Answer: " N "**" (" - " rationale)?
                // rationale is optional; required for HIGH-confusion questions
```

**Parser rules:**
- Question ID derived from file + Mondai number + Q number; e.g., `bunpou-Q94`. The build pipeline maps these to `q-NNNN` IDs in the unified `questions.json`.
- For `dokkai`: stems may reference passage IDs; the parser cross-references to `reading.json` IDs.

### B.7.5 reading_n<L>.md (passages with comprehension questions)

```
File         := Header MondaiList
Mondai       := "## Mondai " N " - " MondaiName "\n" PassageEntry+
PassageEntry := "### Passage " N " (Q" QStart "-Q" QEnd ")" "\n"
                "> " ja_passage "\n"
                "> " (continuation_lines)*
                QuestionList
QuestionList := QuestionEntry+
QuestionEntry:= "#### Q" N "\n" prompt_ja "\n" ChoiceList AnswerLine FormatRoleLine?
FormatRoleLine := "**Format role:** primary" | "**Format role:** extra"
                                                   | "**Format role:** info_search"
```

**Parser rules:**
- `> ` prefix on each passage line is the Markdown blockquote convention; the parser strips it before storing.
- `format_role` defaults to `primary` if absent; explicit value required for info_search (Mondai 6).

### B.7.6 chokai_n<L>.md (listening — same as reading_n<L> but with audio path required)

Same shape as reading_n<L> with these additions:
- `**Audio:** audio/listening/n<L>.listen.NNN.mp3` line per item (parser populates `audio` field)
- `**Format:** task | point | utterance` line (mondai-1 / 2 / 3-4)

---


## B.8 Invariant rule specifications (closes F-20.17)

**Source:** function-by-function extraction from `tools/check_content_integrity.py`. Each rule below is the actual logic — implementable from this spec without reading the N5 source.

### X-6 series (catalog-level invariants)

| Invariant | Rule | Violation message |
|---|---|---|
| X-6.1 Catalog completeness | Every grammar pattern has `examples.length >= 1` AND `form_rules.attaches_to.length >= 1` | "{patternId} missing {field}" |
| X-6.2 Year-form consistency | The forms 今年 / こんねん / ことし follow the per-file policy (catalog uses ことし; questions use ことし or kana). Specific rule: `今年` MUST be read as ことし in any furigana annotation. | "{file}:{line} reading mismatch: '今年' annotated as '{actual}' (must be 'ことし')" |
| X-6.3 No mixed kanji+kana words | Words must be wholly kanji+okurigana OR wholly kana, not mixed forms like 大さか, 図しょかん, 学こう. Detection: regex `[一-鿿]+[ぁ-ん]+[一-鿿]` in word-boundary contexts. | "{file}:{line} mixed-kana word: '{word}'" |
| X-6.4 Lint script present | `tools/check_content_integrity.py` exists and is executable. Bootstrap-only check. | "lint script missing" |
| X-6.5 No em-dashes | No file contains U+2014 (`—`) or U+2013 (`–`). | "{file}:{line} em-dash at column {col}" |
| X-6.6 Ru-verb exception flags | Group-1 verbs that LOOK like Group-2 (帰る, 入る, 切る, 知る, 走る, 要る, etc.) MUST be flagged in BOTH the section header AND on each individual entry. | "{file}: vocab entry '{form}' is a known Group-1 ru-verb exception but lacks the **(group 1)** flag" |
| X-6.7 No false synonymy | The strings `Direct synonym|directly equivalent|same as` in goi rationales — except for whitelisted true-synonym pairs. | "{file}:{line} synonym overclaim: '{snippet}'" |
| X-6.8 No ASCII digits in TTS source | The fields used as TTS source (grammar.examples[].ja, reading.passages[].ja, listening.items[].script_ja) must have all numbers as kanji (一二三...) or kana (いち, に, さん). ASCII digits 0-9 forbidden. | "{file}:{path} ASCII digit '{d}' in TTS source" |
| X-6.9 Primary-reading sanity | Each kanji's primary on-yomi (first in `on[]`) and kun-yomi (first in `kun[]`) must be the most-frequent reading per the Tanos N<L> (or appropriate level) data. | "{kanji} primary on/kun divergence from level authority" |

### JA series (Japanese-language-accuracy invariants)

| Invariant | Rule |
|---|---|
| JA-1 Stem-kanji scope | Every kanji in `questions[].question_ja` AND `questions[].prompt_ja` must be in `data/n<L>_kanji_whitelist.json` (the level-specific whitelist) |
| JA-2 Particle-set sanity | For MCQs where `correctAnswer` is a single particle (length ≤ 2 chars, all in the particle set), all distractors must also be valid particles from the set: `{は, が, を, に, で, と, も, へ, から, まで, より, の, ね, よ, か, や, ぐらい, ごろ, など, しか, だけ, ばかり, でも, ても}` |
| JA-3 Furigana / catalog match | Every `furigana[].reading` in grammar.examples MUST be a valid kana sequence (regex `^[ぁ-んー]+$`); `indices` MUST be in-bounds of the `ja` string |
| JA-4 Vocab reading uniqueness | Within a single section, no two entries may have the SAME (form, reading) pair (cross-section duplicates are allowed and intentional — see B.1) |
| JA-5 Answer-key sanity | For every MCQ: `correctAnswer in choices`. For sentence_order: `correctOrder` is a permutation of `range(len(tiles))`. For text_input: `correctAnswer in acceptedAnswers` |
| JA-6 No two-correct-answers | For every MCQ where `choices` contains both members of a known interchangeable pair AND `correctAnswer` is one of the pair members AND `question_ja` contains no scene-context parenthetical — flag as multi-correct. Pairs: `(に, へ)` for motion verbs, `(は, が)` for stative predicates, `(から, ので)` for reason clauses, `(に, と)` for でんわ-recipients, `(まで, から)` for time ranges, ko-so-a-do quartets without spatial scene |
| JA-7 No duplicate stems in file | No two questions share the same `question_ja` (or `prompt_ja + question_ja` if both are content-bearing). Exception: same stem in different `type` (mcq vs text_input parallel pair, like q-0001 / q-0418) is allowed |
| JA-8 Q-count integrity | `_meta.question_count == len(questions)` |
| JA-9 Engine display contract | The runtime test engine (test.js + drill.js + review.js) hides `**Answer:** N` and any rationale lines until `submit()` is called. CI test that loads a question and asserts the answer is NOT in the visible DOM before commit |
| JA-10 No "(see n<L>-)" redirect text | The strings `(see n<L>-` and `see pattern detail` and `Wrong choice - see` are forbidden in any user-facing field (`question_ja`, `prompt_ja`, `explanation_en`, `distractor_explanations.*`) |
| JA-11 No duplicate MCQ choices | For every MCQ, `len(set(choices)) == len(choices)` |
| JA-12 Kanji KB / JSON consistency | The set of kanji headers in `KnowledgeBank/kanji_n<L>.md` must equal the set of `kanji` fields in `data/kanji.json` |
| JA-13 No out-of-scope kanji | Every CJK character in `questions[].question_ja`, `questions[].prompt_ja`, `questions[].distractor_explanations.*`, `vocab.entries[].gloss`, `grammar.patterns[].notes`, `grammar.patterns[].explanation_en` must be in the N<L> whitelist |
| JA-14 No auto-ruby in renderer | The string `auto-ruby` or any code path that auto-applies furigana to whitelisted kanji must NOT exist in `js/furigana.js`. (Auto-furigana was removed in Pass-13; this guards regression.) |
| JA-15 Audio refs resolve | Every `audio_manifest.json` `items[].path` where `skipped !== true` must exist on disk with size > 100B. See B.2 |
| JA-16 Kanji example whitelist | For each kanji entry in `data/kanji.json`, every kanji in its example sentences must be either the target kanji itself OR in the N<L> whitelist OR in any prerequisite-level whitelist (i.e., the union of N5..N<L> per §11.2) |
| JA-17 Grammar examples have vocab_ids | Every `grammar.patterns[].examples[]` must have a `vocab_ids` field populated by `tools/link_grammar_examples_to_vocab.py` (homograph guard linkage) |
| JA-18 Reading explanation kanji ⊂ passage | Every kanji in `reading.passages[].questions[].explanation_en` must appear in the passage's `ja` text |
| JA-19 Reading info-search has format_type | Mondai-6 (情報検索) reading questions must have `format_role: "info_search"` |
| JA-20 Reading choices kanji ⊂ passage | Every kanji in `reading.passages[].questions[].correctAnswer` AND in the choices must appear in the passage's `ja` text |
| JA-21 Late-tier grammar markers require tier=late_n<L> | At any level N<L>, any pattern in `data/grammar.json` whose `pattern` string is in the late-N<L> set (per Bunpro vs Tanos contrast — see Appendix A.7) must have `tier: "late_n<L>"` or `tier: "n<L-1>_borderline"`. The level-parametric equivalent of N5's late_n5 check |
| JA-22 No "direct synonym" in goi rationales | Same as X-6.7 but specifically scoped to `KnowledgeBank/goi_questions_n<L>.md` (catches synonym-overclaim regressions; added Pass-15) |
| JA-23 Multi-correct scanner advisory | Same logic as JA-6 but emits as WARN (not FAIL) for native review. Wire as `--warn` mode of the integrity check |
| JA-24 No duplicate pattern strings | No two grammar entries with overlapping `meaning_en` may share the same `pattern` string (catches Pass-19 redundancy class) |

**Augmented sets:** rules JA-1 / JA-13 / JA-16 reference whitelist files. The whitelist files are augmentable per-level; agent-added exceptions MUST include a `# WHY: <reason>` comment justifying inclusion. Pass-22 candidate: enforce comment-presence check.

---


## B.9 Diagnostic Summary algorithm (closes F-20.24)

**Source:** `js/summary.js`.

### B.9.1 Error-pattern detection (renderErrorPatterns)

For each `result` in the test-results log:
1. Look up the pattern's category (`grammarPatternId` → `grammar.json[id].category`).
2. Bucket by category. Count failures vs successes per category.
3. For categories with `failure_rate >= 0.5 AND attempts >= 3`, surface as an "error pattern" with:
   - Category name
   - Failure count / total attempts (e.g., "4/5 = 80%")
   - 3 most-recent failed pattern IDs (linked to detail pages)

### B.9.2 Recommended next session (renderRecommendation)

Decision tree (from N5 `js/summary.js` lines 158-186):
1. If `weakIds.length >= 3`: recommend "Drill weak items (N candidates)" → routes to `#/drill`.
2. Else if there are due SRS items today (count from storage): recommend "Review N due items" → `#/review`.
3. Else if `untestedIds.length >= 5`: recommend "Test new patterns (N untested)" → `#/test`.
4. Else: recommend "Daily Drill — keep your streak going" → `#/drill`.

All recommendations carry an estimated time ("~5 min", "~15 min") computed as `weight * count` where weight is per-mode (drill=1min, review=0.5min, test=2min).

### B.9.3 Session log (renderSessionLog)

- Display the most-recent 20 test sessions with: date, mode (test/drill/review), score, duration.
- Sourced from `storage.getProgress().sessions[]`.
- Retention: localStorage stores all sessions indefinitely (~1KB each, so 1000 sessions = ~1MB; bounded by browser's 5-10MB limit).
- Export/import preserves session log.

### B.9.4 Heatmap (renderHeatmap)

- Per-pattern grid: each cell is a pattern colored by SRS state (`mastered` green, `weak` red, `seen` neutral, `untested` empty).
- Hover shows pattern title + last-seen date.
- Layout: super-category sections, patterns sorted by `patternOrder`.

### B.9.5 Implementation contract for any next level

- Storage shape (from `storage.js`; substitute the level number for `<L>`):
  ```
  jlpt-n<L>-tutor.progress = {
    "patterns": { [patternId]: { isMastered, isWeak, isManuallyKnown, lastAttemptIso, attempts, correctCount } },
    "sessions": [{ date, mode, score, duration, attemptedIds[] }],
    "srs": { [patternId]: { EF, rep, due, interval, lapses } }    // see A.10
  }
  ```
- All Summary tab features (error patterns, recommendation, session log, heatmap) read from this shape — no extra storage required.

---


## B.10 Kanji-tier vs grammar-tier interaction (closes F-20.21, F-20.25)

### B.10.1 Tier values per corpus

| Corpus | Tier values (N4 example; substitute `n<L>` for any other level) |
|---|---|
| Grammar | `core_n<L>` / `late_n<L>` / `n<L-1>_borderline` |
| Kanji   | `core_n<L>` / `late_n<L>` / `prerequisite_n<P>` |
| Vocab   | `core_n<L>` / `late_n<L>` / `prerequisite_n<P>` |

### B.10.2 Whitelist composition rule (recommended)

The `data/n<L>_kanji_whitelist.json` should be the UNION of N5 ∪ N4 ∪ ... ∪ N<L> kanji (level-cumulative; e.g., ~280 entries at N4, ~650 at N3, etc.). Each kanji entry in `data/kanji.json` carries a `tier` field distinguishing prerequisite vs new:

```json
[
  { "kanji": "人", "tier": "prerequisite_n<P>", "on": [...], "kun": [...] },
  { "kanji": "立", "tier": "prerequisite_n<P>", ... },
  { "kanji": "案", "tier": "core_n<L>", ... },
  { "kanji": "達", "tier": "late_n<L>", ... }
]
```

**Why UNION not strict-N<L>-only:**
- Reading passages at any level naturally use a mix of the target-level kanji AND prerequisite-level kanji.
- Forcing strict-N<L>-only would require either kana-only passages (unrealistic) OR prerequisite-level-kanji-as-violations (false positives).
- The `tier` field lets the UI optionally hide prerequisite-N5 from "new kanji" stats while still allowing them in passages.

### B.10.3 JA-13 invariant interaction

JA-13 ("no out-of-scope kanji in user-facing data") consults `data/n<L>_kanji_whitelist.json`. With the union approach, the whitelist contains both target-level and prerequisite-level kanji, so prerequisite use is allowed.

For mock-test mode: the engine should still highlight "this kanji is in your N<L> study list" (tier=core_n<L> or late_n<L>) vs "you should know this from N<P>" (tier=prerequisite_n<P>).

### B.10.4 Cross-level scaling (N3 / N2 / N1)

For each higher level X:
- Kanji whitelist = N5 ∪ N4 ∪ ... ∪ N<L> (the cumulative-down-to-target union)
- Each kanji entry gets `tier: prerequisite_<lower-level>` or `tier: core_X` / `tier: late_X`
- JA-13 invariant uses the union whitelist; no per-level strict mode.

This is the "recommended" composition. An alternative "strict-level-only" mode is possible (whitelist = NX only, JA-13 fails on prerequisites) but it doesn't match how learners actually progress. Stick with union.

---


## B.11 External-corpus URL list per level (closes F-20.26)

**Vetted authoritative sources** (used in N5; level-extensible):

### Per-level grammar references
- **N5:** https://jlptsensei.com/jlpt-n5-grammar-list/, https://www.tanos.co.uk/jlpt/jlpt5/grammar/, https://bunpro.jp/jlpt/n5
- **N4:** https://jlptsensei.com/jlpt-n4-grammar-list/, https://www.tanos.co.uk/jlpt/jlpt4/grammar/, https://bunpro.jp/jlpt/n4
- **N3:** https://jlptsensei.com/jlpt-n3-grammar-list/, https://www.tanos.co.uk/jlpt/jlpt3/grammar/, https://bunpro.jp/jlpt/n3
- **N2:** https://jlptsensei.com/jlpt-n2-grammar-list/, https://www.tanos.co.uk/jlpt/jlpt2/grammar/, https://bunpro.jp/jlpt/n2
- **N1:** https://jlptsensei.com/jlpt-n1-grammar-list/, https://www.tanos.co.uk/jlpt/jlpt1/grammar/, https://bunpro.jp/jlpt/n1

### Per-level kanji references
- **N5:** https://www.tanos.co.uk/jlpt/jlpt5/kanji/, https://jlptsensei.com/jlpt-n5-kanji-list/
- **N4:** https://www.tanos.co.uk/jlpt/jlpt4/kanji/, https://jlptsensei.com/jlpt-n4-kanji-list/
- **N3:** https://www.tanos.co.uk/jlpt/jlpt3/kanji/, https://jlptsensei.com/jlpt-n3-kanji-list/
- **N2:** https://www.tanos.co.uk/jlpt/jlpt2/kanji/, https://jlptsensei.com/jlpt-n2-kanji-list/
- **N1:** https://www.tanos.co.uk/jlpt/jlpt1/kanji/, https://jlptsensei.com/jlpt-n1-kanji-list/

### Per-level vocab references
- **All levels:** Tanos has CSV downloads at the corresponding `/vocab/` URL. Memrise community decks are an alternate source but with variable quality.

### Per-level practice-question references
- **N5:** https://learnjapaneseaz.com/jlpt-n5-grammar-practice.html (used for N5 cross-coverage; 17 tests)
- **N4:** https://learnjapaneseaz.com/jlpt-n4-grammar-practice.html
- **N3:** https://learnjapaneseaz.com/jlpt-n3-grammar-practice.html
- **N2/N1:** sparse on free sites; consider commercial sources (Try! N2, New Kanzen Master)

### Official JLPT samples (always check first)
- https://www.jlpt.jp/e/samples/n5/index.html
- https://www.jlpt.jp/e/samples/n4/index.html
- https://www.jlpt.jp/e/samples/n3/index.html
- https://www.jlpt.jp/e/samples/n2/index.html
- https://www.jlpt.jp/e/samples/n1/index.html

### Fair-use boundaries
- DO: extract for triangulation, coverage analysis, multi-correct-bug detection.
- DO: cite source in `feedback/external-questions-<source>.md` with extraction date.
- DO NOT: copy questions verbatim into the question bank.
- DO NOT: redistribute the source's content (read-only triangulation).
- The `feedback/external-questions-<source>.md` file in our repo is fair-use-acceptable as audit reference material (not learner-facing).

### Attribution requirement
Every external-corpus extract must have:
- Source URL at the top of the feedback doc
- Extraction date
- A note like "Reference material for triangulation only; not used in our question bank."

---


## B.12 Content-inventory extraction recipes (acknowledges F-20.12, F-20.13, F-20.14)

These three items require AUTHORITATIVE source data, not invention. The agent should NOT generate content without source attribution. Instead, use these extraction recipes:

### B.12.1 N<L> kanji whitelist (size per §0 table)

```python
# tools/extract_n<L>_kanji_from_tanos.py — substitute the level digit
import requests, json, re
from pathlib import Path

LEVEL = 4  # change per build: 4 for N4, 3 for N3, 2 for N2, 1 for N1
URL = f"https://www.tanos.co.uk/jlpt/jlpt{LEVEL}/kanji/"
html = requests.get(URL, timeout=30).text
# Tanos publishes a table; parse <td class="kanji">X</td> entries
kanji = re.findall(r'<td[^>]*class="[^"]*kanji[^"]*"[^>]*>([一-鿿])</td>', html)

# Cross-reference with JLPT Sensei (https://jlptsensei.com/jlpt-n{LEVEL}-kanji-list/)
# (script omitted; uses similar regex)

out = sorted(set(kanji))
Path(f"data/n{LEVEL}_kanji_whitelist.json").write_text(
    json.dumps(out, ensure_ascii=False, indent=2), encoding="utf-8"
)
print(f"Wrote {len(out)} N{LEVEL} kanji to whitelist")
```

The agent runs this script as part of Day-1 bootstrap. The expected output count varies by level (per §0 size table); cross-reference with TWO sources to resolve discrepancies.

### B.12.2 N<L> vocab inventory (size per §0 table)

```python
# tools/extract_n<L>_vocab_from_tanos.py — substitute the level digit
import requests, csv
from pathlib import Path

LEVEL = 4  # change per build
URL = f"https://www.tanos.co.uk/jlpt/jlpt{LEVEL}/vocab/n{LEVEL}_vocab.csv"
csv_text = requests.get(URL, timeout=30).text
reader = csv.DictReader(csv_text.splitlines())
rows = list(reader)
# Each row has: kanji, hiragana, English, romaji, category

# Write to KnowledgeBank/vocabulary_n<L>.md per the format in B.7.2
# Group by category, then output entries
# (full script omitted)

print(f"Wrote {len(rows)} N{LEVEL} vocab entries to KB")
```

After running, the agent runs `tools/build_data.py` to derive `data/vocab.json` from the markdown.

### B.12.3 N<L> grammar pattern catalog (size per §0 table)

```python
# tools/extract_n<L>_grammar_from_bunpro.py — substitute level digit
# Bunpro's per-level grammar list is publicly accessible
import requests, re
from pathlib import Path

LEVEL = 4  # change per build
URL = f"https://bunpro.jp/jlpt/n{LEVEL}"
# Bunpro renders a list of grammar items; each links to a detail page
# with examples and meaning. Scrape the index, then per-item.

# (Full script involves WebFetch with structured prompt; ~30 min runtime
# for ~210 items at N4, scaling up at lower levels. Result is a markdown
# file matching B.7.1 grammar.md format.)

# Tier classification per A.7:
#   tier=core_n<L>          if also in Tanos N<L>
#   tier=late_n<L>          if only in Bunpro N<L> (typically borderline upper-N<L>)
#   tier=n<L-1>_borderline  if in Tanos N<L-1> + commonly N<L>-taught
```

### B.12.4 Why the agent must NOT invent content

- Inventing kanji / vocab / grammar items would produce a corpus the agent THINKS is N<L> but isn't authoritative.
- A learner studying with invented content would be tested on items not on the actual JLPT.
- This violates the "production-ready" expectation more than missing content.

The honest one-shot deliverable: run the extraction scripts as part of the build, halt-and-report if the source is unavailable. The agent's responsibility is to FETCH and STRUCTURE authoritative data, not to AUTHOR domain content.

---


## B.13 What this appendix does NOT cover

The remaining Pass-22 polish items (F-20.27 through F-20.35) are Pass-22 candidates and not addressed here:

- Distractor-explanation rubric / template (Pass-22)
- ko-so-a-do scene-context formatting standard (Pass-22)
- JA-2/JA-23 invariant interaction tightening (Pass-22)
- Augmented-set escape valve guard via `# WHY:` comment regex (Pass-22)
- LLM audit prompt template extraction (Pass-22)

Each is well-defined enough that it can be addressed in a focused future commit; the current state is "minimum acceptable, not strong" per the Pass-20 review's assessment.

---

*End of Appendix B. Companion to procedure-manual-build-next-jlpt-level.md.*
*Prepared 2026-05-01 by extraction from N5 codebase. Every section traceable to a specific N5 source file.*


---


# §C Appendix C — Pass-22 polish specifications (merged 2026-05-04)

*Was at `<source-repo>/specifications/procedure-manual-appendix-c-pass22-polish.md`. Inline now. Distractor rubric / ko-so-a-do scene-context standard / JA-2/JA-23 invariant interaction / augmented-set escape-valve guard / auto-generation stop-condition / full PWA spec / same-pattern-string conflict-resolution rule.*

---


# Procedure Manual Appendix C — Pass-22 Polish Specifications

**Companion to:** `procedure-manual-build-next-jlpt-level.md` and `procedure-manual-appendix-b-extracted-from-n5.md`
**Closes Pass-22 items:** F-22.1, F-22.2, F-22.3, F-22.4, F-22.6, F-22.8, F-22.9
**Prepared:** 2026-05-01

This appendix bundles the seven Pass-22 documentation-polish items into a single document so they're easy to find and reference. Two more Pass-22 items have their own homes:
- **F-22.5** LLM-audit prompt extraction → `tools/prompts/llm_audit.prompt.md`
- **F-22.7** TASKS.md template → `specifications/tasks-md-template.md`

---


## C.1 Distractor explanation rubric (closes F-22.1)

**Problem solved:** N5 originally shipped with auto-generated stub distractor explanations like `Wrong choice — see pattern detail.`, which taught nothing and were stripped in Pass-12. The procedure manual told future levels to "author all distractor explanations by hand" but didn't say HOW. This rubric fills that gap.

### C.1.1 Required structure (4 sentences)

Every distractor explanation MUST contain, in this order:

1. **Sentence 1: Role mismatch.** Name what the wrong option's role IS (one of: subject marker, direct object, recipient, source, location, time, instrument, conjunction, copula form, conjugation form, etc.) — and contrast it with the correct option's role.
2. **Sentence 2: Concrete consequence.** Show what would happen if the learner picked this option — what the sentence would mean (or fail to mean).
3. **Sentence 3 (optional): Pattern citation.** If the distinction maps to a documented pattern (e.g., "see n5-008 for direction-vs-companion particles"), cite it. Skip this sentence when the contrast is fully explained by sentences 1-2.
4. **Sentence 4 (optional): Pragmatic nuance.** A single bonus clause if the option is "grammatically possible but unidiomatic" — name the register / context that would make it work, and why it doesn't fit here. Skip this sentence when the option is flatly wrong (most cases).

### C.1.2 Length range

- **Minimum:** 60 characters (forces sentence 1 to be substantive).
- **Maximum:** 180 characters (forces sentence 4 to be optional, sentences 1-3 to be tight).
- **Typical:** 90-130 characters.

### C.1.3 Language register

- English, neutral declarative.
- No second-person ("you would..."), no first-person ("I think..."), no rhetorical questions.
- Use simple present tense for grammar facts ("に marks the destination") and simple past for what-would-happen ("コーヒーが would mean 'coffee likes [you]'").
- Quote Japanese fragments in `「…」` or unstyled when surrounded by English; never wrap in italics or bold.
- No emojis.

### C.1.4 Five worked examples

These are real distractors from the N5 corpus that pass the rubric:

**Example 1 — Particle (recipient):** Correct answer `に` for `わたしは ともだち（  ）プレゼントを あげました`.
- **Distractor を:** `を already marks プレゼント (the thing being given). あげる takes one を for the object, not two. The recipient slot uses に.` (151 chars; sentences 1+2)
- **Distractor から:** `から marks the SOURCE of an action ('from'). 'Friend から' would mean the friend gave something to me — the opposite direction of あげる. Use に for 'to whom'.` (170 chars; sentences 1+2+1 nuance)

**Example 2 — Verb form:** Correct answer `ききながら` for `ラジオを （  ）べんきょうします`.
- **Distractor きいて:** `きいて (te-form) connects sequential actions: 'listen, then study'. It does not express simultaneous action.` (105 chars; sentences 1+2)
- **Distractor きかない:** `きかない is the negative ('don't listen'), and gives the wrong meaning. It also doesn't form the simultaneous-action structure.` (122 chars; sentences 1+2)

**Example 3 — Demonstrative (deictic role):** Correct answer `これ` for `（じぶんの 手の中の 本を 友だちに みせて）　（  ）は ほんです`.
- **Distractor それ:** `それ is for things near the LISTENER. Here the speaker is holding the book in their own hand, so これ (near speaker) is correct.` (123 chars; sentences 1+2 with explicit scene reference)

**Example 4 — Adjective conjugation:** Correct answer `おもしろい` for `この 本は とても （  ）です`.
- **Distractor おもしろく:** `おもしろく is the adverbial / continuing form, used before another verb or adjective. It cannot stand alone before です.` (118 chars; sentences 1+2)

**Example 5 — Counter:** Correct answer `三にん` for `クラスに がくせいが （  ）います`.
- **Distractor 三こ:** `三こ (-ko) is the counter for small objects. People take 〜にん, so use 三にん to count three students.` (101 chars; sentences 1+2)

### C.1.5 What does NOT count as a real distractor explanation

- `Wrong choice — see pattern detail.` (stub; Pass-12 deleted)
- `This is grammatically incorrect.` (no contrast, no role naming)
- `に is the answer.` (restating the correct option, not explaining the wrong one)
- `Choose に instead.` (instructional, not contrastive)

### C.1.6 Process recommendation

For ~530 N4 questions × 3 distractors each = ~1600 distractor explanations:

1. **Author the correct answer's `explanation_en` first** (the "why this is right" prose).
2. **For each distractor, ask: what role does this option play, and why doesn't it fit here?** If you can't answer in one sentence, replace the distractor — it isn't tight enough.
3. **Run the rubric on each:** does it have role mismatch (S1) + concrete consequence (S2)? If not, rewrite.
4. **LLM-author then native-review** is acceptable when budget is tight; LLM produces the 4-sentence draft using this rubric, native teacher refines for naturalness.

---


## C.2 Ko-so-a-do scene-context formatting standard (closes F-22.2)

**Problem solved:** Pass-15 fixed 4 ko-so-a-do questions that had multi-correct answers (no spatial context). The fix was to add parenthetical scene-setting like `（じぶんの 手の中の 本を 友だちに みせて）` before the stem. The format wasn't formally specified; this standard formalizes it.

### C.2.1 Placement

The scene-setting parenthetical ALWAYS precedes the stem with the blank. Format: `（<scene>）　<stem with blank>`. The full-width space (U+3000) between `）` and the stem is mandatory — preserves the scene as a visually-distinct preface.

### C.2.2 Length

- **Minimum:** 8 characters (must establish at least one of: speaker, listener, referent location).
- **Maximum:** 30 characters (longer scenes belong in `prompt_ja` instead of `question_ja`).
- **Typical:** 12-20 characters.

### C.2.3 Kanji policy

The scene text is subject to **the same kanji-scope rule** as any other user-facing field. JA-13 invariant applies. Pass-15 caught three violations: 文 / 字 / 近 introduced inside scenes had to be converted to ぶん / じ / ちか.

For N<L> builds: every kanji in a scene must be in `data/n<L>_kanji_whitelist.json`. If forced to choose between (a) using the natural kanji and (b) keeping the scene short, **prefer kana** — clarity beats orthographic naturalness in scene-setting.

### C.2.4 Tense and grammatical mood

- **Use present tense or imperative** for relational scenes (e.g., 「みせて」 = imperative te-form, 「あんないして」 = imperative).
- **Use plain dictionary form or polite mass-form** for declarative scenes (e.g., 「友だちに 言います」).
- **Avoid past tense** unless the scene is a memory-narration (rare for ko-so-a-do questions).

### C.2.5 Canonical examples per quartet

The four ko-so-a-do quartets, with one canonical scene per correct-answer position (12 examples total — author and native-review these once, then reuse the structure for further questions):

#### これ / それ / あれ / どれ (object-pronouns)

| Correct | Canonical scene + stem | Why this scene forces the answer |
|---------|------------------------|---------------------------------|
| これ | `（じぶんの 手の中の 本を 友だちに みせて）　（ ）は ほんです。` | Speaker holds the referent → これ unique |
| それ | `（じぶんの ペンを みせて、それから 友だちの 手の中の ペンを ゆびさして）「これは わたしの ペンです。（ ）は あなたのですか。」` | Listener holds the referent → それ unique |
| あれ | `（とおくに ある かばんを ゆびさして 友だちに 聞きます）　（ ）は あなたのですか。` | Referent far from both → あれ unique |
| どれ | `（つくえの 上に かばんが いくつも あります）　（ ）が あなたの ですか。` | Referent is to-be-selected from many → どれ unique |

#### この / その / あの / どの (object-determiners)

| Correct | Canonical scene + stem |
|---------|------------------------|
| この | `（じぶんの 持っている ペンを みせて）　（ ）ペンは わたしのです。` |
| その | `（友だちの 手の中の ペンを ゆびさして）　（ ）ペンは あなたのですか。` |
| あの | `（とおくの 山を ゆびさして）　（ ）山は たかいですね。` |
| どの | `（たくさんの ペンの 中から 友だちに 聞きます）　（ ）ペンが あなたのですか。` |

#### ここ / そこ / あそこ / どこ (place-pronouns)

| Correct | Canonical scene + stem |
|---------|------------------------|
| ここ | `（としょかんの 中で 友だちに 言います）　（ ）は としょかんです。` |
| そこ | `（友だちが 立って いる 場所を さして）　（ ）は どんな ところですか。` |
| あそこ | `（とおくの たてものを ゆびさして）　（ ）が ぎんこうです。` |
| どこ | `（じぶんが いる 場所が わからない ときに 友だちに 聞きます）　（ ）に いますか。` |

#### こちら / そちら / あちら / どちら (polite-directions)

| Correct | Canonical scene + stem |
|---------|------------------------|
| こちら | `（おきゃくさんを じぶんの ちかくの せきへ あんないして）　（ ）へ どうぞ。` |
| そちら | `（電話で あいての ばしょの ことを たずねて）　（ ）の てんきは どうですか。` |
| あちら | `（とおくの たてものを ゆびさして）　（ ）が ぎんこうです。` |
| どちら | `（ふたつの コーヒーから えらんで もらいたい とき）　（ ）が いいですか。` |

### C.2.6 What does NOT count as scene context

- `（  ）に いれる ことばを えらんで ください。` — that's a generic instruction (`prompt_ja` material), not scene-setting.
- `みんなが いる ところで` — too vague; doesn't establish speaker / listener / referent positions.
- A title-style label like `【友だち との かいわ】` — that's a topic header, not a scene.

A valid scene establishes at least ONE of: where the speaker is, where the listener is, where the referent is — and the relationship among those three is unambiguous from the prose.

---


## C.3 JA-2 / JA-23 invariant interaction (closes F-22.3)

**Problem solved:** Two particle-related invariants overlap and were ambiguously specified. JA-2 ("particle distractors are valid") and JA-23 (multi-correct scanner). Whether a JA-23-flagged question fails JA-2 (hard gate) or just warns (advisory) was unclear.

### C.3.1 Decision (formalized)

- **JA-2 is a HARD gate.** A question whose particle distractors are not in the canonical particle set fails the integrity check; CI blocks the merge. Rationale: an invalid distractor is a content bug; ship-blocking is correct.
- **JA-23 is ADVISORY (`-W` mode).** A question whose particle choices contain BOTH members of a known interchangeable pair AND lacks scene context is flagged as a multi-correct candidate. CI does NOT block; the violation surfaces in audit reports for native-teacher review. Rationale: some flagged questions are legitimate (the pair test is the point), and false positives shouldn't ship-block.

### C.3.2 Interaction rule

If a question is flagged by JA-23 (multi-correct candidate) AND has a scene context that satisfies §C.2 (canonical scene establishes the answer uniquely), the JA-23 flag is **suppressed**. This is the per-Pass-15 / Pass-19 ground-truth: ko-so-a-do questions with proper scenes pass; without scenes they fail.

Implementation hint for the future code change to `tools/check_content_integrity.py` (NOT applied in this commit; the parallel session is active on that file):

```python
def check_ja_23_multi_correct_advisory(questions, kanji_whitelist):
    """JA-23: advisory check for multi-correct candidates. Returns warnings,
    not failures. Suppress when scene context (per §C.2 standard) is present."""
    INTERCHANGEABLE_PAIRS = [
        ("に", "へ"),         # motion destination
        ("から", "ので"),     # reason
        ("は", "が"),         # topic vs subject
        ("に", "と"),         # recipient vs companion
        ("まで", "から"),     # time-range endpoints
        # Future: extend per native-teacher input
    ]
    KOSOADO_QUARTETS = [
        {"これ", "それ", "あれ", "どれ"},
        {"この", "その", "あの", "どの"},
        {"ここ", "そこ", "あそこ", "どこ"},
        {"こちら", "そちら", "あちら", "どちら"},
    ]
    warnings = []
    for q in questions:
        if q.get("type") != "mcq":
            continue
        choices = set(q.get("choices", []))
        # Particle pair check
        flagged = False
        for a, b in INTERCHANGEABLE_PAIRS:
            if a in choices and b in choices:
                flagged = True
                break
        # Ko-so-a-do quartet check
        if not flagged:
            for quartet in KOSOADO_QUARTETS:
                if quartet <= choices:
                    flagged = True
                    break
        if not flagged:
            continue
        # Suppression: scene context present?
        stem = q.get("question_ja", "")
        if scene_context_pattern.match(stem):  # regex per §C.2.1 placement rule
            continue
        warnings.append(f"{q['id']}: multi-correct candidate (no scene context)")
    return warnings  # WARNINGS only; do not raise
```

### C.3.3 Invariant table update

Update Appendix B.8 row for JA-23:

> **JA-23 Multi-correct scanner advisory** | Same logic as JA-6 but emits as **WARN** (not FAIL). Suppressed when the question has scene context per §C.2.1 placement rule (parenthetical preceding the stem). Extends JA-6 to cover ko-so-a-do quartets and pair-based multi-correct cases that JA-6 doesn't catch.

JA-6 (no two-correct-answers) remains the hard gate for cases the scanner can prove unambiguous.

---


## C.4 Augmented-set escape-valve guard (closes F-22.4)

**Problem solved:** JA-13 / JA-1 / JA-16 invariants reference whitelist files (`n<L>_kanji_whitelist.json`, `n<L>_vocab_whitelist.json`). An agent or contributor could silently add an out-of-scope item to silence a violation. There's currently no enforcement that exceptions be justified.

### C.4.1 Convention

Every entry added to a whitelist file as an **exception** (i.e., an item that's not in the official JLPT level scope but allowed for documented reasons) MUST carry a per-line `# WHY: <reason>` comment. The reason should fit on one line and explain the inclusion.

JSON does not support comments natively, so the whitelist files MUST be authored as JSON-with-line-comments (JSONC) and parsed with a comment-stripping pre-processor, OR as YAML, OR each exception must be added to a parallel `<file>.exceptions.md` document.

**Recommended approach (lowest friction):** keep the whitelist as plain JSON, and maintain a parallel `data/n<L>_kanji_whitelist.exceptions.md` file that lists each exception with its `WHY:` justification. The integrity check tool reads BOTH files: the whitelist for membership, the exceptions doc for accountability.

### C.4.2 Exceptions doc format

`data/n<L>_kanji_whitelist.exceptions.md`:

```markdown
# N<L> kanji whitelist — exception register

Each line documents a kanji that is in the project whitelist but NOT in the
official JLPT N<L> kanji scope. Required for any exception:
  - The kanji glyph
  - WHY: a one-sentence reason
  - REVIEW_DATE: optional date for re-evaluation

## Exceptions

- 文  WHY: appears in two grammar examples that would otherwise need awkward kana phrasing; flagged for native review.  REVIEW_DATE: 2026-Q3
- 近  WHY: required for the standardized こちらへどうぞ scene template (§C.2); too disruptive to swap to ちかく.  REVIEW_DATE: 2026-Q3
```

### C.4.3 New invariant JA-25 (specification only — code not yet written)

Add to `tools/check_content_integrity.py`:

```python
def _check_ja_25_whitelist_exceptions_documented():
    """Every kanji in n<L>_kanji_whitelist.json that is NOT in the official
    JLPT N<L> scope (loaded from data/n<L>_official_scope.json) MUST appear
    in data/n<L>_kanji_whitelist.exceptions.md with a `WHY:` justification.
    Same rule applies to the vocab whitelist."""
    violations = []
    project_wl = set(json.load(open("data/n<L>_kanji_whitelist.json")))
    official_scope = set(json.load(open("data/n<L>_official_scope.json")))
    exceptions = parse_exceptions_md("data/n<L>_kanji_whitelist.exceptions.md")
    for kanji in project_wl - official_scope:
        if kanji not in exceptions:
            violations.append(f"{kanji} in whitelist but not justified in exceptions.md")
        elif "WHY:" not in exceptions[kanji]:
            violations.append(f"{kanji} in exceptions.md but lacks WHY: justification")
    return violations
```

**Status:** spec-side documentation in this section. The actual code change to `tools/check_content_integrity.py` (function `_check_ja_25_whitelist_exceptions_documented` + registration in the `CHECKS` table) was applied in commit landing alongside this appendix. The check is in **bootstrapping mode** until `data/n5_official_kanji_scope.json` lands — without an official-scope reference file, JA-25 cannot compute the project-vs-official delta, so it currently passes vacuously. Once the official-scope file is authored (a one-time task: paste the JLPT.jp canonical 103 kanji into a JSON array), JA-25 begins enforcing accountability for every entry the project adds beyond official scope.

### C.4.4 Why this matters

Without the WHY-comment guard, the scope-enforcement story is one-sided: the integrity check catches naive violations, but a contributor can defeat it by adding the violating item to the whitelist. The WHY-comment turns "silencing the check" into a deliberate, reviewable action with accountability. Every exception becomes a small audit-doc entry that quarterly review can re-evaluate.

---


## C.5 Auto-generation stop-condition formalization (closes F-22.6)

**Problem solved:** Procedure manual §3.2.1 prohibits agent-generated filler MCQs but doesn't define a hard stop condition. Appendix A.4 partially addresses this with the minimum-viable subset (per-layer targets), but a more explicit stop rule prevents over- or under-generation.

### C.5.1 STOP conditions for question generation

The agent stops generating questions in a Mondai/section when ANY of the following is true:

- **(a) Per-Mondai count target hit.** Reached the count from Appendix A.8 (e.g., ≥50 for moji M1, ≥30 for dokkai M5). This is the primary stop.
- **(b) Corpus-coverage threshold met.** Every grammar pattern in `data/grammar.json` has at least one question referencing its `id` via `grammarPatternId`. (For non-grammar Mondai, every kanji / vocab item targeted by the section has at least one question.)
- **(c) External-corpus distribution matched within 20%.** If the external triangulation corpus has X% of its questions targeting particles vs Y% targeting verbs etc., the project corpus matches that distribution within ±20%. Caps "drift toward easy authoring".

When all three conditions are met simultaneously: ship that Mondai. When (a) is met but (b) or (c) is not: continue authoring until at least 80% of (b) is met, then re-evaluate.

### C.5.2 ANTI-stop conditions (do NOT stop just because)

- The bank "looks small" relative to a previous level. Each level's count target is per Appendix A.8; do not pad to match an irrelevant baseline.
- A pattern has no obvious stem template. Author the question or document the pattern as "low-test-coverage" — do NOT generate stub-pattern questions to fill (Pass-14 deleted 38 such stubs at N5).
- The agent's output budget is unspent. Stop when (a)+(b) are met regardless of remaining budget.

### C.5.3 Pre-merge sanity check

Before declaring an authoring batch complete, run:

```python
# tools/_check_authoring_batch_done.py (sketch, not committed)
def is_batch_done(level, mondai):
    target = APPENDIX_A8_TARGETS[level][mondai]
    actual = count_questions_for(mondai)
    if actual < target:
        return False, f"need {target - actual} more questions"
    if not all_patterns_have_questions(level):
        return False, f"{n_uncovered_patterns()} patterns have zero coverage"
    if not external_corpus_distribution_within_20pct():
        return False, f"distribution skew detected"
    return True, "all stop conditions met"
```

Record the result in TASKS.md as `Pass-N <name> stop-condition check: PASS / NEED <items>` so future review knows the authoring stop was deliberate.

---


## C.6 PWA spec extraction (closes F-22.8)

**Problem solved:** Procedure manual §10 had one bullet about PWA. A complete spec follows so any next-level build can implement PWA support without re-discovering the convention.

### C.6.1 manifest.webmanifest

```json
{
  "name": "JLPT N<L> Tutor",
  "short_name": "N<L> Tutor",
  "description": "Learn. Test. Review. Master.",
  "theme_color": "#1F4D2E",
  "background_color": "#FFFFFF",
  "display": "standalone",
  "orientation": "any",
  "start_url": "/",
  "scope": "/",
  "lang": "en",
  "dir": "ltr",
  "icons": [
    { "src": "icons/icon-192.png", "sizes": "192x192", "type": "image/png", "purpose": "any maskable" },
    { "src": "icons/icon-512.png", "sizes": "512x512", "type": "image/png", "purpose": "any maskable" },
    { "src": "icons/icon-1024.png", "sizes": "1024x1024", "type": "image/png", "purpose": "any" }
  ],
  "categories": ["education", "languages"]
}
```

Required fields are `name`, `short_name`, `start_url`, `display`, `icons`. Everything else is recommended. The `theme_color` should match the design system's accent color (Zen Modern uses `#1F4D2E`).

### C.6.2 Icons

- **Master icon:** 1024×1024 PNG with the wordmark + accent rule. Source: `icons/source/icon-master.svg` if SVG-authored.
- **Downscaled:** 512×512 (Android home screen high-DPI), 192×192 (Android lower-DPI / PWA install prompt). Generated via ImageMagick or Squoosh from the master.
- **Maskable:** the 192/512 icons should be authored with safe-area padding (~10% margin) so Android can apply OS-shape masks without clipping. Mark these `"purpose": "any maskable"`.

### C.6.3 Service worker (sw.js)

Cache name versioning: `jlpt-n<L>-tutor-v<N>` where `<N>` increments on every shell change. The N5 ref is at v71 after 71 ship cycles.

Strategy per asset class:

| Asset class | Strategy | Rationale |
|-------------|----------|-----------|
| App shell (`/`, `index.html`, all `js/*.js`, all `css/*.css`) | stale-while-revalidate | Fast offline-friendly load; updates land via the next-page-load |
| Locales (`locales/*.json`) | stale-while-revalidate | Same as shell |
| Content (`data/*.json`) | cache-first with version key | Content rarely changes; cache hits dominate |
| Audio (`audio/**/*.mp3`) | cache-first, on-demand fetch | First-play caches; subsequent plays offline |
| Fonts (`fonts/*.woff2`) | cache-first, immutable | Fonts never change without a SW version bump |
| External (any URL not on this origin) | network-only | Don't cache external content |

### C.6.4 Update toast

When a new SW version activates, the runtime shows a non-blocking toast:

> "A new version of the app is ready. Tap to refresh."

Tap → `location.reload(true)`. Don't auto-reload (loses any in-progress test attempt).

### C.6.5 Offline fallback page

A minimal `offline.html` shipped at root, precached by the SW. Served when a navigation request fails because the network is unreachable. Content: app title, "you're offline" message, link to `/` (which the cached shell answers).

### C.6.6 Pre-cache list

The SW pre-caches at install time:
- `/`, `/index.html`, `/manifest.webmanifest`, `/offline.html`
- All shipped `js/*.js` and `css/*.css`
- `locales/en.json` (other locales lazy-cached on first use)
- All shipped icons
- All shipped fonts (`fonts/*.woff2`)

Do NOT pre-cache `data/*.json` or `audio/**/*.mp3` (too large; these are runtime-cached on first use).

### C.6.7 Smoke-test integration

The Playwright smoke suite includes:
1. SW registers and reaches `activated` state on first load.
2. Manifest is valid JSON and parses.
3. `start_url` resolves to a 200 response.
4. After offline simulation (`page.context().setOffline(true)`), the shell still loads.
5. Update flow: simulate a SW update → assert toast appears → assert reload.

---


## C.7 Same-pattern-string conflict resolution rule (closes F-22.9)

**Problem solved:** Pass-19 cleaned up 10 redundant grammar pattern entries that shared `pattern` strings. Pass-22 wants a rule for what the agent does the next time it considers adding a new pattern entry.

### C.7.1 Pre-add check

Before adding a new pattern entry to `data/grammar.json` (or `KnowledgeBank/grammar_n<L>.md`), the agent runs:

```python
candidate_pattern = "<the proposed `pattern` field>"
existing = [p for p in grammar["patterns"] if p["pattern"] == candidate_pattern]
if existing:
    apply_conflict_resolution(candidate_pattern, existing, candidate_meaning_en)
```

### C.7.2 Conflict resolution decision tree

If `existing` is non-empty (one or more entries already use the same `pattern` string):

1. **Compute meaning overlap.** Take the proposed `meaning_en` and each existing entry's `meaning_en`. Compute Jaccard similarity (set of lowercase words / set of lowercase words). The "overlap" is the maximum across all existing entries.
2. **Decision:**
   - If overlap ≥ 80%: **DO NOT add a parallel entry.** Either (a) enrich the existing entry with whatever the new candidate would have added (more examples, common_mistakes, etc.) and do not create a new entry, OR (b) retire the existing entry and replace with the new one if the new is strictly better. Document the choice in the commit message.
   - If 50% ≤ overlap < 80%: **The split is questionable.** Consult human. If proceeding, narrow each `meaning_en` to make the distinction explicit (e.g., subject-marker vs clause-connector for `が`).
   - If overlap < 50%: **Split is justified.** Add the new entry. Both stay; both have explicit `meaning_en` distinguishing them. The N5 examples (n5-003 が subject vs n5-126 が clause-connector) demonstrate this case.

### C.7.3 Documentation requirement

When a split is made (either of the lower two branches), the commit body MUST include:

```
Pattern split rationale:
- Existing: n<L>-NNN "<existing pattern>" — <existing meaning_en>
- New:      n<L>-MMM "<new pattern>" — <new meaning_en>
Overlap: <Jaccard score>%. Decision: split because <reason>.
```

This makes future audit (the equivalent of Pass-19) much easier — the rationale is in git history rather than reverse-engineered.

### C.7.4 Invariant JA-24 enforces this going forward

JA-24 (no duplicate `pattern` strings with overlapping `meaning_en`) catches violations. The invariant uses the same Jaccard-80% threshold.

---


## C.8 Cross-references

These polish items strengthen but don't replace the existing manual content:

- **F-22.1 distractor rubric** complements §3.2.3 (anti-pattern: "see pattern detail").
- **F-22.2 ko-so-a-do scene format** complements §3.2.4 (anti-pattern: context-less ko-so-a-do).
- **F-22.3 JA-2/JA-23 interaction** clarifies Appendix B.8 invariant table.
- **F-22.4 WHY-comment guard** strengthens Appendix B.8 augmented-set notes.
- **F-22.5 LLM-audit prompt extraction** lives at `tools/prompts/llm_audit.prompt.md`.
- **F-22.6 stop-condition formalization** complements Appendix A.4 minimum-viable subset.
- **F-22.7 TASKS.md template** lives at `specifications/tasks-md-template.md`.
- **F-22.8 PWA spec** complements §10 (the one-line PWA bullet).
- **F-22.9 conflict resolution rule** complements F-19 grammar dedup retrospective.

Together with Appendices A and B, the procedure manual now closes **38 of 40 Pass-20 review items + all 10 Pass-22 polish items** (10/10). Remaining open from the Pass-20 chain: F-20.12 / F-20.13 / F-20.14 (the actual N4 content-authoring work — Tanos / Bunpro fetches — tracked under Pass-21 as the future N4 build pass).

---

*End of Appendix C. Companion to procedure-manual-build-next-jlpt-level.md and procedure-manual-appendix-b-extracted-from-n5.md.*
*Prepared 2026-05-01.*


---


# §D TASKS.md canonical template (merged 2026-05-04)

*Was at `<source-repo>/specifications/tasks-md-template.md`. Day-1 bootstrap template for any new-level build (`<L>` ∈ {4, 3, 2, 1}). Copy this section verbatim into `TASKS.md` at the new repo root and start populating.*

---


# TASKS.md — Canonical Template

**Closes Pass-22 F-22.7.** This is the canonical structural template for the project's `TASKS.md` file. Reference from procedure manual §8.1 instead of "matches N5". Any next-level build (N4, N3, N2, N1) creates its `TASKS.md` from this skeleton.

---

## Required top-level structure

A valid `TASKS.md` has these sections **in this order**, each as a top-level `## ` heading:

1. **`## Live site`** — single-paragraph deployment status (URL, last deploy SHA, hosting provider).
2. **`## Status snapshot`** — bullet list of canonical project metrics (see §Required snapshot fields below). Updated on every significant change; staleness is a known regression risk per Pass-15 / Pass-17 retrospective.
3. **`## Remaining`** (optional) — short-term backlog visible at the top so contributors can see "what's next" without scrolling.
4. **`## External-blocked backlog`** — items that cannot close without external resources. Each item lists its blocker and unblock condition explicitly.
5. **`## Pass-N <name>` sections** — one per audit/work cycle, in **reverse-numeric order** (newest pass at top). Each Pass-N body follows the §Pass-N body structure below.
6. **`## Hard constraints preserved`** (optional) — invariants the project commits to upholding (e.g., "no telemetry").
7. **`## Out of scope`** (optional) — explicit non-goals, with rationale.

Each section is separated by `---` horizontal rules.

## Required snapshot fields

The `## Status snapshot` block MUST include bullet items for at least:

- Catalog state: `M/N patterns enriched, K real questions (no stubs)`
- Question type distribution: `mcq / sentence_order / text_input` counts
- Routes: list of every `#/route`, including sub-paths
- SRS: which algorithm, with verified intervals
- Service worker: cache name (e.g., `jlpt-n<L>-tutor-vN`)
- i18n: locales count
- PWA: installable status
- Tests: test count + framework
- Vocab corpus: entry count + whitelist size
- Kanji corpus: entry count
- Reading corpus: passage count
- Listening corpus: item count
- Audio assets: file count + total size
- Codebase invariants: e.g., "em-dash-free" if X-6.5 is enforced

When any of these change, update the snapshot in the same commit. Staleness in the snapshot has been a recurring regression class — Pass-19 and Pass-22 both registered cleanup work for stale snapshot entries.

## Pass-N body structure

Every `## Pass-N <name>` section follows this layout:

```markdown
## Pass-N <name> - YYYY-MM-DD (<status flag>)

<One-paragraph context: what triggered this pass, where the source / audit
doc lives, scope summary.>

#### Severity bucket headers — one or more of:
#### CRITICAL (N classes — N RESOLVED)
#### HIGH (N classes — N RESOLVED, N OPEN)
#### MEDIUM (N classes — ALL RESOLVED)
#### LOW / Schema (informational)

<Each finding under its severity bucket follows the F-N.K item format
described below.>

#### (Optional sub-sections)
- Recommended fix sequence
- Side-effects
- Tooling
- Cascade items
- Open structural concerns
```

**Status flags** at the top of each Pass section:
- `(REGISTERED, NOT YET FIXED)` — findings catalogued, fixes not started
- `(N of M ITEMS APPLIED)` — partial progress
- `(ALL FIXES APPLIED)` — closed
- `(N CLOSED, M DEFERRED)` — split status with explicit deferral
- `(SKIPPED — <reason>)` — pass was opened then closed without action

## F-N.K item format

Every actionable finding uses this format:

```markdown
- [<status>] **F-N.K** (SEVERITY) **<short title>** — <issue description>. <fix description>. <evidence pointer>.
```

Where:
- `[<status>]` is one of:
  - `[ ]` — open, not started
  - `[x]` — closed (fix applied; date + commit SHA in the description)
  - `[-]` — closed-by-pointer (defers to a different finding ID or external item)
- `F-N.K` is `F-<pass-number>.<within-pass-index>`. Within-pass indices start at 1 and never repeat. If a pass needs to add a finding mid-stream, append a new index — never reuse.
- `(SEVERITY)` is one of `CRITICAL` / `HIGH` / `MEDIUM` / `LOW` per severity guide below.
- **Short title** in bold; one phrase, no period.
- **Issue description**: 1-2 sentences explaining what's wrong.
- **Fix description**: present-tense or "Applied YYYY-MM-DD:" past-tense.
- **Evidence pointer**: file path + line range, or commit SHA, or audit-doc ref.

## Severity guide

| Severity | Definition | Default ship-blocker? |
|----------|------------|------------------------|
| CRITICAL | Directly teaches wrong content; blocks release. | Yes |
| HIGH | Pedagogical error or structural bug; fix in next release. | Yes |
| MEDIUM | Inconsistency or minor inaccuracy; batch in next quarterly pass. | No |
| LOW | Polish / cosmetic; nice to have. | No |

## Update rules (testable)

- **R1** — Every code-changing commit updates either `TASKS.md` (a Pass-N entry's status, the snapshot, or both) or includes "no TASKS.md update needed" justification in the commit body.
- **R2** — A `[ ]` item that is fixed becomes `[x]` in the SAME commit as the fix. Never a follow-up commit.
- **R3** — When a finding cannot be addressed in the current cycle, mark `[ ]` with explicit deferral rationale (`Skipped Pass-N: <reason>`).
- **R4** — Open items per Pass should not exceed 30 in a single section; if more, split into Pass-N.a / Pass-N.b.
- **R5** — Pass-N sections, once closed, do not get re-edited except for typo fixes. New work on the same area opens a new Pass-(N+M) section that links back.

## Empty-skeleton starter

For a fresh next-level build, copy this skeleton:

```markdown
# JLPT N<L> Tutor — Tasks

Last update: YYYY-MM-DD

## Live site

(deployment URL, last SHA)

---

## Status snapshot

- TBD/TBD patterns enriched, 0 real questions
- 0 routed views
- SM-2 SRS in Review (4-button grading)
- Service worker `jlpt-n<L>-tutor-v1`
- 0-locale i18n shell
- (etc — fill as content lands)

---

## External-blocked backlog (YYYY-MM-DD)

(see procedure manual §9 — at minimum: native voice talent, native
teacher reviewer, brief translation, recommender ML)

---

## Pass-1 <first-pass-name> - YYYY-MM-DD (REGISTERED)

(first audit / authoring cycle goes here)
```

## Worked examples

The N5 `TASKS.md` at `<repo-root>/TASKS.md` is the live reference. Notable patterns to mirror:
- Pass-14 (questions.json comprehensive audit) demonstrates the full structure: severity buckets, fix sequence, side-effects, tooling.
- Pass-20 (procedure-manual review) demonstrates the closed/deferred/closed-by-pointer split for a 40-item review.
- Pass-22 (procedure-manual polish) demonstrates promoting closed-by-pointer items to actionable [ ] entries with concrete fix descriptions.

## Anti-patterns to avoid

These caused real pain in N5; do not repeat:

1. **Stale snapshot.** Updating data without updating the snapshot on the same commit. Caught in Pass-15, Pass-17, Pass-22 each — there is now a status-snapshot freshness invariant in `TASKS.md` rule R1.
2. **Sub-heading drift.** Sub-headings like "HIGH (3 classes — 1 RESOLVED, 2 OPEN)" left stale after items close. Caught in Pass-15. R5 says don't re-edit closed Passes; track sub-heading status in the bucket header instead.
3. **Re-using F-N.K indices.** Caught in Pass-15 / Pass-19. R4 / R5 forbid this. Add a new index instead.
4. **Implicit deferral.** Items disappearing without an `[x]` or `[-]` status flag. Caught in Pass-17 / Pass-19. R3 requires explicit closure.

---

*Canonical template prepared 2026-05-01 by extracting from the N5 `TASKS.md` and the Pass-22 retrospective. Update if the format itself evolves at any next level.*

---


# Appendix C — Session learnings 2026-05-10/11 (UI-audit + content-enrichment cycle)

> Added 2026-05-11 after a single chat session that authored ~3,400 new pedagogical entries across all 5 N5 modules, executed a full UI audit, fixed 3 waves of bugs, and uncovered a class of "orphan data" defects. **Read this appendix in addition to §1–§18 + Appendix A/B before starting any Nx build.** It captures the specific traps that cost the most time in this session.


## C.1 The orphan-data defect class — the single biggest lesson

**Symptom:** authored ~3,400 new pedagogical entries across grammar / vocab / kanji / dokkai / chokai. Verified all 50+ CI invariants green. Verified files were committed and deployed to GitHub Pages live. A UI audit later revealed **25 separate fields, totaling ~2,000 entries, that the renderer was never reading.** The data was sitting in JSON; the UI didn't surface it.

**Why this happens:**
- Content batches author data fields.
- Renderer code in `js/learn-grammar.js`, `js/kanji.js`, etc. is changed separately.
- The two never get cross-verified.
- CI invariants (`tools/check_content_integrity.py`) check data SHAPE, not whether the renderer READS that shape.

**Fields that were orphaned in N5 (and how long it took to discover):**

| Field | Authored | Lived orphaned for | Renderer file |
|---|---|---|---|
| `grammar.wrong_corrected_pair[].error_category` (list-form) | 534 entries / 178 patterns | 6 batches × 178 patterns | `js/learn-grammar.js` |
| `grammar.politeness_ladder{casual,polite,humble,respectful}` | 178/178 | 2 batches | `js/learn-grammar.js` |
| `grammar.authentic_citations[]` | 320 citations / 178 patterns | 1 batch | `js/learn-grammar.js` |
| `kanji.stroke_order_trap{trap,correct_order_summary,why_it_matters}` | 106/106 | 2 batches | `js/kanji.js` |
| `kanji.on_kun_pair_drill{standalone,compound,contrast_note}` | 106/106 | 1 batch | `js/kanji.js` |
| `kanji.reading_rule` | 106/106 | 4 batches | `js/kanji.js` |
| `vocab.collocations` (988 curated) | 988/1009 | 4 batches | (vocab renderer doesn't render collocations at all) |
| `vocab.devoiced_vowels`, `pragmatic_functions`, `false_friends`, `counter_register` | 106 / 42 / 163 / 16 | 4 batches each | (vocab renderer doesn't render these) |
| `dokkai.time_target_seconds` (new field) | 54/54 | 1 batch | (dokkai renderer doesn't read) |
| `dokkai.comprehension_strategy_hints` (new field) | 54/54 | 1 batch | (dokkai renderer doesn't read) |
| `dokkai.register_signal`, `target_reading_age`, `discourse_markers_used`, `cultural_callout` | 54/54 each | 1 batch | (orphan) |
| `chokai.listening_strategy_hints`, `speech_rate_classification`, `register_signal_l`, `distractor_pattern_hint`, `speaker_demographics`, `prosody_hints`, `time_target_seconds` | 50/50 each | 1 batch | (all orphan) |
| `data/test_strategy.json` (NEW 36 KB file with T1-T6) | 1 new file | 1 batch | NO `js/strategy.js` existed; never imported into router |

### C.1.1 The rule

> **For every authored data field, you MUST also: (1) write a renderer that reads it, (2) verify it appears in live preview, AND (3) document the field in the UI inventory before declaring the work done.**

### C.1.2 The audit script

Run this BEFORE marking any content task complete:

```python
# tools/audit_field_surface.py
import json, re
from pathlib import Path

DATA_FILES = {
  'grammar.json':   ('patterns',  ['js/learn-grammar.js']),
  'vocab.json':     ('entries',   ['js/learn-vocab.js']),
  'kanji.json':     ('entries',   ['js/kanji.js']),
  'reading.json':   ('passages',  ['js/reading.js']),
  'listening.json': ('items',     ['js/listening.js']),
}

for fname, (root_key, renderer_files) in DATA_FILES.items():
    data = json.loads(Path(f'data/{fname}').read_text(encoding='utf-8'))
    items = data.get(root_key, [])
    # Collect all field names with >5 occurrences
    field_counts = {}
    for it in items:
        for k in it.keys():
            field_counts[k] = field_counts.get(k, 0) + 1
    # Read renderer source
    renderer_src = '\n'.join(Path(f).read_text(encoding='utf-8') for f in renderer_files if Path(f).exists())
    # Field is ORPHAN if data has it but renderer never references its name
    orphans = []
    for f, n in field_counts.items():
        if n < 5: continue  # ignore rare fields
        if f.endswith('_provenance'): continue
        # heuristic: renderer mentions field name
        if not re.search(rf'\b{re.escape(f)}\b', renderer_src):
            orphans.append((f, n))
    if orphans:
        print(f'{fname}: {len(orphans)} orphan field(s):')
        for f, n in sorted(orphans, key=lambda x: -x[1]):
            print(f'  {f}: {n}/{len(items)} entries')
```

Run this after every content batch. Treat any output as a P1 bug.

### C.1.3 Recovery cost — context for prioritization

- Authoring the data: ~16 batches × ~2 hours each = ~32 hours.
- Discovering they were orphaned: 1 UI audit, ~1 hour.
- Wiring them up (Wave 1 of fix): 1 commit, ~1 hour, ~2,000 entries unlocked.

The wiring is cheap. The risk is shipping content that never reaches users. The audit script is the cheap insurance.

---


## C.2 The minified-vs-unminified file pair gotcha

**Architecture in N5:**
- `js/*.js` — human-authored source (unminified).
- `js/min/*.js` — what `index.html` actually loads (terser/esbuild output).
- `index.html` references `js/min/app.js?v=1.12.NN`.

**The trap:**
- Edit `js/learn-grammar.js`.
- Reload preview.
- Nothing changes — because the browser is loading `js/min/learn-grammar.js`, which still has the OLD code.

**The fix:** every edit to a source file in `js/` MUST be mirrored to `js/min/`:

```bash
cp js/learn-grammar.js  js/min/learn-grammar.js
cp js/kanji.js          js/min/kanji.js
cp js/app.js            js/min/app.js
cp js/strategy.js       js/min/strategy.js
# Then bump cache buster in index.html (see C.3).
```

**Don't try to manually re-minify** — the public export names are preserved by terser ESM-aware mode, but rewriting the internal symbols would break inter-module imports. Just copy the unminified version over the min version. The size cost (~+50 KB per file unminified) is negligible.

**Build target for the future:** add a `tools/build_js.py` that wraps esbuild/terser, writes both `js/` (source) and `js/min/` (minified), and is run as part of the release checklist.

---


## C.3 Cache busting on `index.html`

**Symptom:** edit `js/min/learn-grammar.js`. Reload preview. See the OLD code still rendering. Service worker cleared. HTTP no-cache. Still old code.

**Cause:** ES modules are cached aggressively by the browser keyed on URL (including query string). The script tag in `index.html` loads `js/min/app.js?v=1.12.71`. The browser pins all transitive imports to that version forever.

**Rule:** every commit that touches a `js/min/` file MUST bump the `?v=` query string in `index.html` for BOTH the stylesheet and the script tag.

```html
<link rel="stylesheet" href="css/main.min.css?v=1.12.NN">
<script type="module" src="js/min/app.js?v=1.12.NN"></script>
```

`sed -i 's/v=1.12.71/v=1.12.72/g' index.html` is the right pattern.

The build_js.py mentioned in C.2 should bake this in: auto-increment the patch on every successful build.

---


## C.4 New schema patterns established in this session

### C.4.1 Grammar pattern enrichment fields (use these for Nx)

```json
{
  "id": "n<L>-002",
  "pattern": "は",
  "wrong_corrected_pair": [
    {
      "wrong": "私が 学生です。 (in self-introduction)",
      "correct": "私は 学生です。",
      "why": "は marks topic in introduction; が introduces NEW info.",
      "error_category": "particle",
      "provenance": "llm_curated"
    }
    // … ≥3 entries minimum, ≥3 distinct error_category values across them
  ],
  "politeness_ladder": {
    "casual":     "わたしゃ がくせいだ。 (very casual)",
    "polite":     "わたしは がくせいです。",
    "humble":     "わたくしは がくせいで ございます。",
    "respectful": "こちらは やまだ先生で いらっしゃいます。"
  },
  "authentic_citations": [
    {"source": "Genki I L1", "context": "Topic particle introduced with わたしは [name]です。", "provenance": "llm_curated"},
    {"source": "Minna I Ch.1", "context": "基本文型 1: NはNです。", "provenance": "llm_curated"}
  ]
  // … plus existing fields: meaning_en, meaning_ja, meaning_hi, l1_notes, explanation_en, explanation_hi, examples, common_mistakes (legacy), essay (top-30), genki_lesson, tier, category, form_rules, review_status, frequency_rank
}
```

**Categorical taxonomy for `error_category`:**
`particle | conjugation | lexicon | word_order | register | counter`
The renderer's `categoryBadge()` will localize each via `t('grammar_detail.cat_<category>')`. Define those keys in `locales/en.json` and `locales/hi.json`.

**Politeness ladder coverage:** all 178/178 patterns get one even when register-neutral. For invariant words (particles, demonstratives, counters, question words), the ladder shows how the SURROUNDING UTTERANCE shifts register tier — same word, embedded in casual/polite/humble/respectful framing.

**Authentic citations sourcing:**
- Genki I (Banno et al., 3rd ed., 2020) Lessons 1-12
- Genki II Lessons 13-14 (N5 borderline)
- Minna no Nihongo Shokyū I/II Chapters 1-25
- A Dictionary of Basic Japanese Grammar (Makino & Tsutsui)
- Authentic media: ちびまるこちゃん / ドラえもん / サザエさん (children's anime/manga)
- "Genki Greetings / Minna 挨拶集" for ritual phrases (おはよう, いただきます, etc.)
- "Daily speech" / "Standard conversation idioms" for casual register

### C.4.2 Kanji enrichment fields

```json
{
  "glyph": "日",
  "stroke_order_trap": {
    "trap": "Bottom horizontal closes the box LAST.",
    "correct_order_summary": "1: left vertical. 2: top + right (bracket). 3: middle horizontal. 4: bottom horizontal (closes box).",
    "why_it_matters": "Same convention as 田/口/国: enclose first, close last."
  },
  "on_kun_pair_drill": {
    "standalone": {"form": "日", "reading": "ひ",   "gloss": "day (kun)"},
    "compound":   {"form": "日本", "reading": "にほん", "gloss": "Japan (on+on)"},
    "contrast_note": "日 reads ひ (kun) standalone, にち/じつ (on) in most compounds."
  },
  "reading_rule": "Generic rule: standalone → kun; compound → on. For 日: 日 (ひ kun) standalone vs 日本 (にほん on+on) compound.",
  "n5_compounds": [...]  // auto-derived from vocab.json scan
  // … plus existing: on, kun, meanings, radical, radical_decomposition, mnemonic{summary,visual,reading,provenance}, examples, sentences, stroke_count, stroke_order_svg, lookalikes, frequency_rank
}
```

**`lookalikes` policy:**
- Visual-confusion clusters ONLY. Semantic-only pairs go in a separate `semantic_pairs` field (not yet added in N5).
- Every glyph that has zero N5 visual neighbors gets `lookalikes: []` PLUS `lookalikes_note: "<glyph> has no close visual confusion partner among N<L> kanji."` — explicit emptiness rather than missing field.

**Stroke-order-trap categories worth pre-populating:**
- Direction conventions (一 L→R, 中 vertical-LAST)
- Mirror-pair distinctions (右/左 stroke 1, 上/下 stroke 1)
- Box-closure rule (口/日/田/月/国/車 — enclose, fill, close-LAST)
- Hat-first conventions (六/今/会/食/空/家/百)
- Left-radical-first (亻/言/木/糸/禾)
- `辶`-radical-LAST (道/週)

### C.4.3 Dokkai (reading) pedagogical fields

```json
{
  "id": "n<L>.read.001",
  "spacing_mode": "wakachi_full",  // wakachi_full | wakachi_partial | standard
  "cultural_callout": [
    {"tag": "self_introduction", "label_en": "Self-introduction (jikoshoukai)", "matched_trigger": "よろしく", "note": "..."}
  ],
  "time_target_seconds": {
    "reading_seconds": 60,
    "comprehension_seconds": 40,
    "total_seconds": 100,
    "note": "Based on N<L> reading rate ~2.5 chars/sec + 20s per question."
  },
  "comprehension_strategy_hints": [
    "Read once for overall meaning before answering questions.",
    "Underline key nouns and verbs as you read.",
    "Use particle markers (は/が/を/に) to identify subjects/objects.",
    "Re-read difficult sentences ignoring unknown words."
  ],
  "register_signal": {"register": "polite", "signals": ["ます/です polite"], "confidence": "high"},
  "discourse_markers_used": ["それから", "でも", "から"],
  "target_reading_age": {
    "native_equivalent_age_years": "6-8",
    "kanji_ratio": 0.157,
    "char_count": 120,
    "note": "Estimated native-equivalent age band based on 15.7% kanji density and 120-char length."
  },
  "grammar_footnotes": [...]
  // … plus existing: ja, audio, translation_literal, translation_natural, vocab_preview, kanji_used, cultural_context, paragraphs, etc.
}
```

**`comprehension_strategy_hints` are keyed to `format_role`:**
`self_intro | diary | letter | announcement | schedule | instruction | description | dialogue | menu | advertisement | short_text`

Each format gets 3 actionable hints. Generic fallback for unknown roles.

### C.4.4 Chokai (listening) pedagogical fields

```json
{
  "id": "n<L>.listen.001",
  "mondai": 1,                  // 1 | 2 | 3 | 4 — canonical JEES taxonomy
  "format_type": "task_understanding",  // task_understanding | point_understanding | speech_expression | immediate_response
  "format": "task",             // task | point | utterance | response  (canonical short tag)
  "listening_strategy_hints": [
    "Listen for the SPEAKER'S TASK — what action will they take.",
    "Note imperative or volitional markers (てください, ましょう).",
    "The CORRECT answer is what the speaker decides AT THE END.",
    "Watch for change-of-mind cues: でも / じゃ / そうですか."
  ],
  "speech_rate_classification": {
    "category": "n5_standard",  // very_slow | slow | n5_standard | fast | very_fast
    "morae_per_min": 200,
    "note": "On JLPT N<L> standard rate (180-230 mora/min)."
  },
  "register_signal_l": {"register": "polite_standard", "signals": ["..."], "confidence": "high"},
  "distractor_pattern_hint": {
    "pattern": "mentioned_but_rejected",
    "mentioned_count": 2,
    "note": "2 wrong answers appear in audio but are rejected. Track the FINAL decision."
  },
  "speaker_demographics": {"roles_detected": [...], "n_speakers_inferred": 2, "note": "..."},
  "prosody_hints": ["1 question — rising intonation expected on か.", "2 sentence-final ね — confirmation-seeking."],
  "time_target_seconds": {"audio_seconds_estimated": 14, "jlpt_target_seconds_per_question": 75, "estimated_total_seconds": 22, "note": "..."},
  "aizuchi_present": true,
  "aizuchi_tokens": ["うん", "そうですね"],
  "fillers_present": false,
  "pitch_minimal_pair_focus": [...],
  "phonological_target": [...],
  "ambient_context": "cafe",
  "audio_slow": "audio/listening/n<L>.listen.001.slow.mp3"
}
```

**Critical: `format` and `format_type` must be in canonical taxonomy or items appear under a "free-tag" group in the listening list.** No free strings like `"dialogue"`.

### C.4.5 Test-strategy module (NEW)

Add `data/test_strategy.json` at the start of every Nx build. Schema:

```json
{
  "schema_version": "1.0",
  "section_timing":      {...},  // T1: per-mondai time budgets across all 3 JEES sections
  "trap_patterns":       [...],  // T2: ≥30 traps catalogued by module
  "techniques":          [...],  // T3: ≥15 actionable test-taking techniques
  "score_breakdown":     {...},  // T4: section maxes, mins, diagnostic bands
  "diagnostic_drills":   {...},  // T5: ≥9 weak-area drill paths
  "meta_strategy":       {...}   // T6: 5-min summary, study split, schedule, exam-day checklist
}
```

Wire it via a new `js/strategy.js` renderer + route `#/strategy` in `js/app.js` ROUTES dict. Default Nx build should include this from day 1; it's the highest-leverage "test prep" module and no incumbent provides equivalent structured data.

---


## C.5 CI invariant `JA-13` (out-of-scope kanji) and `SKIP_SUBTREE_FIELDS`

**JA-13 enforces: no kanji outside `data/n<L>_kanji_whitelist.json` may appear in user-facing fields of `grammar.json`, `questions.json`, `reading.json`, `listening.json`.**

But many of the new pedagogical fields (`wrong_corrected_pair`, `politeness_ladder`, `authentic_citations`, etc.) intentionally use Japanese illustrative text that may include kanji from higher levels (humble/respectful forms use N3+ verbs like 申す / なさる / 召し上がる; citation `context` strings use bibliographic vocab like 図書館 / 映画).

**The fix that's now in N5:** `tools/check_content_integrity.py` `_check_ja_13_no_out_of_scope_kanji_in_data()` has a `SKIP_SUBTREE_FIELDS` set that exempts these fields:

```python
SKIP_SUBTREE_FIELDS = {
    "common_mistakes", "distractor_explanations",
    "l1_notes", "cultural_context", "summary",
    "authentic_citations", "wrong_corrected_pair",
    "politeness_ladder"
}
```

**When you add new "pedagogical commentary" fields in Nx, add them to this set BEFORE authoring the content.** Pre-commit hooks should fail loudly if a new field with humble/respectful Japanese tries to slip through without an exemption.

**Rule of thumb:** if the field contains illustrative Japanese for pedagogical purpose (showing native-grade language) rather than primary learner content, it belongs in `SKIP_SUBTREE_FIELDS`. If it's a passage / question / direct vocabulary entry, it does NOT — the N`<L>`-only kanji rule still applies.

---


## C.6 Localization parity — the chrome gap

**Symptom (N5 cycle 5 audit):** UI top-nav localized to Hindi correctly. Body content (syllabus cards, study order, progress labels, action buttons, ~14 section headings on grammar detail) all stayed English.

**Cause:** localized data fields (`meaning_hi`, `explanation_hi`, `l1_notes.hi`) were authored, but the renderer code had **hardcoded English strings for UI chrome** (section headings, button labels, table column headers).

**The fix in N5:**
1. Added `home.*` keys (49 entries) and `grammar_detail.*` keys (28 entries) to `locales/{en,hi}.json`.
2. Replaced every hardcoded chrome string with `${esc(t('home.card_grammar_action'))}` style calls.
3. Number formatting: `Intl.NumberFormat(currentLocale() === 'hi' ? 'hi-IN' : 'en-US').format(n)` — Indian grouping (1,00,000) in HI mode.

**For Nx:** when adding ANY new UI text, write the locale key FIRST. Never `<h3>Some Heading</h3>`; always `<h3>${esc(t('module_name.some_heading'))}</h3>`. Lint rule for the build: grep for hardcoded English in `.js` files post-build.

**Data-locale-suffix convention:**
- `meaning_en` / `meaning_hi` — locale-suffixed leaf fields. Renderer uses `currentLocale()` to pick.
- `l1_notes.<locale>` — dict-keyed subtree (locale as KEY). Use for explicitly L1-keyed content.
- Don't mix conventions on the same field.

---


## C.7 Audio pipeline — manifest is the source of truth

**Symptom:** users see audio players stuck at `0:00 / 0:00` on grammar examples — the file doesn't exist on disk.

**Root cause:**
- `tools/build_audio.py` renders audio per example index: `audio/grammar/{patternId}.{i}.mp3`.
- Content batches added new examples at indices 7-9 to bring every pattern to ≥10 examples.
- `build_audio.py` was NOT re-run, so 1,043 of 1,782 grammar example MP3s didn't exist.
- The renderer unconditionally emitted `<audio src="audio/grammar/{patternId}.{i}.mp3">` regardless.

**The fix (now in N5):**
1. `data/audio_manifest.json` is the source-of-truth list of audio paths that have been rendered.
2. `js/learn-grammar.js` loads the manifest once per session (cached), builds a `Set` of paths.
3. `renderGrammarPatternDetail` is now `async` and awaits the manifest BEFORE producing HTML.
4. The renderer only emits `<audio>` if the candidate path is in the Set.

**Lesson for Nx:** every renderer that produces `<audio src="...">` elements MUST consult the manifest first. Treat the audio existence check as a hard requirement, not an optimization.

**Better long-term:** rebuild `audio_manifest.json` after EVERY data change that adds/removes examples. Make it a step in the audit script (C.1.2).

---


## C.8 The "dialogue" free-tag bug

**Symptom:** listening list rendered an extra category "dialogue (3)" alongside the 4 official mondai (かだいりかい / ポイントりかい / はつわひょうげん / そくじおうとう).

**Cause:** 3 chokai items had `format: "dialogue"` (a non-canonical value invented ad-hoc when those items were authored). The list-page renderer groups by `format` field; any unrecognized value falls through to a raw fallback label.

**The fix:**
- Mapped the 3 items to canonical `format` values based on their existing `format_type`.
- Preserved the original "dialogue" in `format_original` for traceability.

**Lesson for Nx:** enforce the format/format_type enums via CI. The taxonomies are CLOSED:

```python
ALLOWED_FORMAT = {'task', 'point', 'utterance', 'response'}
ALLOWED_FORMAT_TYPE = {'task_understanding', 'point_understanding',
                       'speech_expression', 'immediate_response'}
```

Add JA-XX invariant: `every listening item's format ∈ ALLOWED_FORMAT and format_type ∈ ALLOWED_FORMAT_TYPE`. Same pattern for any other enum field (`pacing_status`, `speech_rate_classification.category`, `register_signal.register`).

---


## C.9 Empty `form` field on kanji examples — a content-authoring trap

**Symptom:** on 7 of 12 example rows for kanji 日, the kanji-form column was visibly empty in the rendered table. Reading and gloss filled; form blank.

**Cause:** the examples were authored where only the `reading` was filled (e.g., `reading: にちようび`, `gloss: Sunday`). The kanji form (`日曜日`) was left empty.

**The fix:** filled the form field for the affected examples (34 rows across 10 kanji).

**Lesson for Nx:** add invariant `JA-XX`: every kanji example MUST have a non-empty `form` AND `reading` AND `gloss`. Three sister fields; never one without the others.

---


## C.10 Pattern title quality — no placeholder labels

**Symptom:** grammar list showed 4 patterns with generic titles "Verb" and "Adjective + Noun" (n5-135, n5-136, n5-162, n5-163).

**Cause:** these patterns are duplicates or aliases of others (V-plain + N relative clause, V-plain + まえに, etc.). Authors used generic POS labels rather than describing the construction.

**The fix:** rewrote titles to be descriptive ("V-plain + N (relative clause)", "V-plain + まえに", "V-た + あとで").

**Lesson for Nx:** never use bare POS labels as pattern titles. Every pattern title must be either:
- The specific morpheme(s) in question (`〜です／〜ます`, `〜ましょうか`, `〜なくちゃ`), OR
- A specific construction name (`V-plain + N relative clause`, `〜より〜のほうが`).

Lint rule: forbid `pattern ∈ {"Verb", "Adjective", "Noun", "Adjective + Noun"}`.

---


## C.11 Commit workflow for Claude Code Desktop

**Symptom:** Claude Code Desktop prompts for permission EVERY time on commits with inline heredoc messages:
```bash
git commit -m "$(cat <<'EOF'
multi-line message
EOF
)"
```
even though `settings.local.json` has `defaultMode: "bypassPermissions"` and explicit allow rules covering the pattern.

**Cause:** Desktop's permission engine treats multiline-stdin heredoc commands as a special case and prompts regardless of glob rules. Terminal Claude Code does NOT have this issue.

**The fix (now binding in N5 `.claude/CLAUDE.md`):** use file-based commit messages, NEVER inline heredoc:

```bash
# 1. Write commit message via Write tool
.commit_msg.tmp  ← multi-line content

# 2. Use git commit -F (single-line command, no heredoc)
cd "<repo path>" && git add <files> && git commit -F .commit_msg.tmp && rm -f .commit_msg.tmp && git push origin master
```

This single-line shape matches existing allow rules cleanly and was validated across 5+ consecutive commits without a single prompt.

**For Nx:** copy the same binding rule into `<NxRepo>/.claude/CLAUDE.md` from day 1.

---


## C.12 Backup-file protection policy

**Set in N5 `.claude/CLAUDE.md` 2026-05-10:**

1. **Never overwrite an existing backup file.** Save as new versioned name (`grammar.json.bak_2026_05_10`, `_v2`, `_v3`, ...).
2. **Never delete an older backup version.** Once written, backups stay until user explicitly cleans them.
3. **Before any destructive op** (`git checkout -- <file>`, overwrite-via-Write), check for and create a versioned backup if one doesn't already exist for this revision.
4. **Replacing or deleting any user-untouched file** still requires asking.

Enforced via `~/Documents/VS Code/.claude/settings.local.json` deny rules:
- `Write(**/*.bak*)`, `Write(**/*.backup*)`, `Write(**/*_backup_*)`, `Write(**/backups/**)`
- `Edit(...)` mirror.
- `Bash(rm/mv/cp <backup-patterns>)`, `PowerShell(Remove-Item/Move-Item/Copy-Item ...)`.

If a deny rule fires when you actually need to act on a backup, surface to user — don't try to work around the deny.

**For Nx:** copy these deny rules to the new project from day 1.

---


## C.13 Quality bars for Nx — minimum coverage targets

Use these as the "complete module" definition. Mirror the N5 closure approach:

### Grammar (target: ~150-220 patterns at Nx; level-dependent)
- Every pattern has **≥10 examples** with `vocab_ids` populated (JA-17).
- Every pattern has **≥3 `wrong_corrected_pair` entries with ≥3 distinct `error_category` values**.
- Every pattern has **`politeness_ladder` with at least 3 of 4 tiers populated** (some patterns are register-invariant and only get 2 tiers).
- Every pattern has **≥2 `authentic_citations`** from the canonical source list (Genki, Minna, DBJG, authentic media).
- Every pattern has **`meaning_en`, `meaning_ja`, `meaning_hi`** (or just `meaning_en` if no HI locale yet) + matching `explanation_*` fields.
- The top-30 most-tested patterns get an **`essay`** (Tofugu-style pedagogical commentary).

### Vocab (target: ~1,000-1,500 entries at Nx)
- Every entry has **curated `collocations`** (≥6 idiomatic phrases, POS+semantic-class aware). Zero auto_generated_template entries acceptable.
- Every entry has **`pitch_accent`** with NHK convention `{mora: N, drop: D}`.
- Verbs (≥30 core verbs at N5) get **`honorific_chain`** with all 4 tiers.
- ~10-20% of vocab gets **`false_friends`** clusters.
- ~5-10% of vocab gets **`devoiced_vowels`** Tokyo-standard markers.
- Multi-function words get **`pragmatic_functions`** taxonomy.
- All counters get **`counter_register`** with casual/formal pair.

### Kanji (target: 169 at N4, 367 at N3, 367 at N2, 1232 at N1)
- Every kanji has **`stroke_order_trap`** with `{trap, correct_order_summary, why_it_matters}`.
- Every kanji has **`on_kun_pair_drill`** with `{standalone, compound, contrast_note}`.
- Every kanji has **`lookalikes`** (or `lookalikes: []` + `lookalikes_note` for truly unique).
- Every kanji has **`reading_rule`** (rule-of-thumb pedagogical text).
- Every kanji has **`n5_compounds`** (or `n<L>_compounds`) — auto-derived from vocab.
- Verb-kanji get **`okurigana_cuts`**.
- Every kanji has **`mnemonic{summary, visual, reading, provenance}`**.

### Dokkai (target: 50-100 passages at Nx)
- Every passage has **`audio`** (one MP3 per passage; the audio_manifest must list it).
- Every passage has **`vocab_preview`** (auto-derived from vocab.json scan).
- Every passage has **`grammar_footnotes`** (per-sentence pattern callouts).
- Every passage has **`cultural_callout`** (canonical-12 taxonomy).
- Every passage has **`time_target_seconds`**, **`comprehension_strategy_hints`** (format-role-keyed), **`register_signal`**, **`target_reading_age`**, **`discourse_markers_used`**.
- Every passage has **`spacing_mode`** (`wakachi_full` | `wakachi_partial` | `standard`).
- Every passage has **`translation_literal` AND `translation_natural`**.

### Chokai (target: 50-100 items at Nx)
- Every item has **`audio` AND `audio_slow`** (1.0× and ~0.7× versions).
- Every item has **`mondai` ∈ {1,2,3,4}** + **`format_type` ∈ canonical 4-value enum**.
- Every item has **`ambient_context`** (auto-classified or authored).
- Every item has **`listening_strategy_hints`** (4 hints keyed to mondai).
- Every item has **`speech_rate_classification`**, **`register_signal_l`**, **`distractor_pattern_hint`**, **`speaker_demographics`**, **`prosody_hints`**, **`time_target_seconds`**.
- Items targeting aizuchi/filler/pitch/phonological drills get those specific fields.

### Test-strategy (new module)
- `data/test_strategy.json` with T1-T6 fully authored from day 1.
- `js/strategy.js` renderer + `#/strategy` route wired into `app.js` ROUTES.

---


## C.14 The order-of-operations for Nx (revised based on this cycle)

> **Critical change from §1-§5:** WIRE-AS-YOU-AUTHOR. Don't author 16 batches of data and discover at the end that the UI never read 60% of it.

Recommended per-module sequence (apply to each of grammar / vocab / kanji / dokkai / chokai independently):

### Phase 0 (per module): Schema + renderer skeleton FIRST
1. Define the schema for every field you plan to author (use C.4 as starter set, add level-specific extensions).
2. Update the renderer to read every field — even if you ship with `<section>` rendering an empty array or "0 entries" placeholder. The wiring is in place.
3. Add CI invariants for closed-enum fields (format_type, error_category, etc.).
4. Add the field to `JA-13 SKIP_SUBTREE_FIELDS` if it carries pedagogical Japanese.
5. Update `locales/{en,hi}.json` with section labels + tier labels for the new fields.
6. Commit this skeleton. Run `tools/audit_field_surface.py` (C.1.2) — should report 0 orphans.

### Phase 1 (per module): Author one tier at a time
7. Author the easiest tier first (e.g., for grammar: existing patterns get `wrong_corrected_pair` ≥3 entries). Run CI. Verify in live preview.
8. Author the next tier (`politeness_ladder`). Run CI. Verify in live preview.
9. Continue per-tier until coverage target hit.
10. **After every tier**, re-run the orphan audit script. Any new orphan = STOP and fix renderer.

### Phase 2 (per module): Audio + final sweep
11. Run `tools/build_audio.py` to render all example/passage/item audio.
12. Verify `data/audio_manifest.json` reflects on-disk reality (rebuild it if necessary).
13. Live-preview every detail page, click every audio player, scan for broken `0:00/0:00`.
14. Run `tools/check_content_integrity.py` — all invariants must be green.
15. Spot-check 3-5 random patterns/items in each module against the live deploy.

### Phase 3 (cross-module): Hindi locale + meta pages
16. Add the new module's locale keys to `locales/{en,hi}.json` (both files in lockstep).
17. Add data-locale-suffix fields (`meaning_hi`, `explanation_hi`, etc.) for every authored entry.
18. Toggle to HI mode and walk every page. Hardcoded English chrome = bug.
19. Update `home.js` (or equivalent) syllabus card counts to reflect the new module's data sizes.

### Phase 4 (final): Cache buster + commit
20. Mirror `js/*.js` → `js/min/*.js` for every modified file.
21. Bump `?v=` in `index.html` stylesheet + script tags.
22. Commit using file-based message pattern (`git commit -F .commit_msg.tmp`).
23. Push. Verify on live deploy (GitHub Pages takes ~1-2 min).
24. Fetch the live data file via `curl` and re-run the field-surface audit against the LIVE deploy. Confirms there's no missing-asset race.

---


## C.15 Anti-patterns from this session (bumper-sticker list)

1. **Authoring data without wiring the renderer** — see C.1. The most expensive mistake of the session.
2. **Forgetting to mirror `js/*.js` → `js/min/*.js`** — see C.2. Edits invisible at runtime.
3. **Forgetting to bump `?v=` in index.html** — see C.3. Browser keeps cached module forever.
4. **Heredoc commit messages on Claude Code Desktop** — see C.11. Blocks overnight automation.
5. **Free-text taxonomy values** ("dialogue" as format) — see C.8. Falls through to raw label in UI.
6. **Placeholder pattern titles** ("Verb") — see C.10. Ugly in the list view.
7. **Empty `form` field while reading is filled** on kanji examples — see C.9. Blank cells in tables.
8. **Adding new pedagogical fields without exempting them in JA-13** — see C.5. CI fails on commit.
9. **Hardcoded English UI chrome strings** — see C.6. Locale toggle leaves them stranded.
10. **Rendering `<audio>` without consulting the manifest** — see C.7. Broken players showing 0:00.
11. **Overwriting existing backup files** — see C.12. Destroys recovery history.

---


## C.16 What this appendix does NOT cover

Things that remained working correctly in N5 and need no change for Nx:
- Service worker / PWA caching (unchanged).
- FSRS-4 SRS algorithm (unchanged).
- Diagnostic placement check (unchanged).
- Mock-test paper-pack structure (unchanged — but content authoring follows Appendix A).
- Branding override layer (unchanged).
- Authentic-content corpus (still optional add-on).

Things that are still open issues at the time of writing this appendix (transparently flagged):
- Vocab module renderer does NOT yet display `collocations`, `false_friends`, `pragmatic_functions`, `devoiced_vowels`, `counter_register`. The DATA is curated and complete, but Wave 4 of the UI-fix sequence has not been done (deferred — see UI-audit bug report). When working on Nx, COPY THE N5 DATA SCHEMAS but ALSO WIRE THE RENDERER (vocab detail page in `js/learn-vocab.js`). Don't repeat N5's orphan-data trap.
- Dokkai module renderer does NOT yet display the 5 new pedagogical fields (`time_target_seconds`, `comprehension_strategy_hints`, `register_signal`, `target_reading_age`, `discourse_markers_used`). Same fix pattern as vocab: wire `js/reading.js` before authoring.
- Chokai module renderer does NOT yet display the 7 new pedagogical fields. Same fix pattern: wire `js/listening.js` before authoring.
- Grammar audio gaps: 1,043 example MP3s never rendered. UI hides broken players (C.7 fix), but to actually expose audio for those examples, re-run `tools/build_audio.py`.

**For Nx: rectify ALL of the above on day 1. Wire the renderer THEN author the data. Don't ship without verifying every field surfaces in live preview.**

---

*Appendix C prepared 2026-05-11 after the UI-audit + content-enrichment session that authored 3,400+ entries, discovered the orphan-data defect class, fixed 3 waves of bugs, and produced the audit-script + wire-as-you-author discipline.*

---


# Appendix D — 2026-05-12 / 2026-05-13 Audit Cycle Learnings

This appendix captures lessons from the two-day audit cycle (commits `76a7465` through `f46263c`, 32 total commits) that took the 2026-05-12 N5 richness audit to terminal state (18 Done, 3 Avoid, 0 pending across 21 audit items). Major themes: **audio pipeline canonicalization**, **content-quality lift methodology**, **anti-item CI enforcement**, **legal-posture documentation**, and **provenance honesty discipline**.


## D.1 Audio engine canonicalization — VOICEVOX over gtts

The N5 corpus shipped grammar audio in three states across its lifetime:
- **Pre-audit-cycle (gtts)**: 1782 grammar example MP3s rendered with Google's gTTS library — robotic single voice, mechanical for example sentences but functional.
- **Audit found "0/1782" claim**: The audit reported `examples[].audio` field was null on all 1782 entries. **CRUCIAL DISCOVERY: this was technically true about the data field but the on-disk MP3 files already existed.** The audit had identified the data-wiring gap, not a missing-audio gap. Same defect class as the C.1 orphan-data trap, but in reverse — orphan FILES, not orphan data.
- **Post-cycle (VOICEVOX)**: 1782 grammar + 100 listening (50 normal + 50 slow) + 259 kanji per-yomi = 2141 files rendered with VOICEVOX engine v0.25.2, 6 distinct characters used across listening for age-band variety.

### D.1.1 Lesson for Nx: check disk before re-rendering

When an audit reports "audio missing," **always check both the data field AND the on-disk files** before re-rendering. Specifically:

```bash
# Check disk
ls audio/<surface>/*.mp3 | wc -l
# Check data field
python -c "import json; G=json.load(open('data/grammar.json',encoding='utf-8'))['patterns']; \
  print(sum(1 for p in G for ex in (p.get('examples') or []) if ex.get('audio')))"
```

If the disk has files but the field is null → wire the field (5-minute fix). If disk is empty → render. Distinguishing these saves hours.

### D.1.2 VOICEVOX engine startup (Windows + WinGet build)

The engine is installed via `winget install HiroshibaKazuyuki.VOICEVOX.CPU`. Default location:

```
C:\Users\<user>\AppData\Local\Microsoft\WinGet\Packages\
  HiroshibaKazuyuki.VOICEVOX.CPU_Microsoft.Winget.Source_8wekyb3d8bbwe\
  VOICEVOX\
    VOICEVOX.exe         # GUI launcher (auto-starts engine)
    vv-engine\run.exe    # Engine binary (separate)
```

**Engine startup**: Use the GUI launcher via PowerShell to avoid `Access is denied` errors on direct `vv-engine\run.exe` invocation:

```powershell
$voicevoxPath = "$env:LOCALAPPDATA\Microsoft\WinGet\Packages\HiroshibaKazuyuki.VOICEVOX.CPU_*\VOICEVOX\VOICEVOX.exe"
Start-Process -FilePath $voicevoxPath -WindowStyle Hidden
```

Then poll until `:50021` responds:

```bash
until curl -s --max-time 2 http://localhost:50021/version >/dev/null 2>&1; do sleep 5; done
echo "Engine ready: $(curl -s http://localhost:50021/version)"
```

First-time startup: **2-4 minutes** while the engine loads neural-model weights. Don't kill the wait loop early.

### D.1.3 Render pipeline pattern (canonical)

For each audio surface (grammar / listening / kanji yomi / reading), the pattern is:

```python
# 1. POST /audio_query with text + speaker_id → returns prosody JSON
qurl = f"http://localhost:50021/audio_query?speaker={SPEAKER}&text={urllib.parse.quote(text)}"
with urllib.request.urlopen(urllib.request.Request(qurl, method="POST"), timeout=30) as r:
    query = json.loads(r.read())

# 2. Mutate prosody for natural N5 pacing
query["speedScale"] = 0.95          # slightly slower than default
query["pauseLengthScale"] = 0.9     # keep audible inter-sentence breath
query["prePhonemeLength"] = 0.0     # no leading pad
query["postPhonemeLength"] = 0.0    # no trailing pad

# 3. POST /synthesis with the mutated query → returns WAV bytes
surl = f"http://localhost:50021/synthesis?speaker={SPEAKER}"
with urllib.request.urlopen(urllib.request.Request(surl, data=json.dumps(query).encode("utf-8"),
        method="POST", headers={"Content-Type": "application/json"}), timeout=60) as r:
    wav = r.read()

# 4. Transcode WAV → MP3 via ffmpeg
subprocess.run(["ffmpeg", "-y", "-loglevel", "error", "-i", wav_path,
    "-acodec", "libmp3lame", "-ab", "128k", str(out_mp3)], check=True)
```

**Performance**: CPU build renders ~1 file per 5-10 sec. With 4-worker ThreadPoolExecutor on a typical laptop, 1782 grammar files take ~50 min. Single-threaded fall-back is fine — VOICEVOX engine is the bottleneck, not Python.

### D.1.4 Multi-speaker render for dialogue surfaces

The listening corpus is dialogue-heavy (50 items, ~5-10 segments per item with 男:/女:/narrator role tags). For age-band variety, pick 6 speakers across age × gender:

| Speaker ID | Character | Style | Age band | Gender |
|---|---|---|---|---|
| 8 | 春日部つむぎ (Tsumugi) | ノーマル | adult | F |
| 11 | 玄野武宏 (Kurono) | ノーマル | adult | M |
| 2 | 四国めたん (Metan) | ノーマル | young | F |
| 3 | ずんだもん (Zundamon) | ノーマル | young | M |
| 10 | 雨晴はう (Hau) | ノーマル | adolescent | F |
| 13 | 青山龍星 (Aoyama) | ノーマル | mature-young | M |

**Cycle the F/M pair across items** to distribute speakers (items 1-9 use Tsumugi+Kurono, items 10-17 use Metan+Zundamon, etc.). This achieves the audit's ≥6-distinct-voices target on the listening corpus without rendering every item with all 6 speakers.

**Implementation**: parse `script_ja` for role-prefix lines (男:/女:/narrator), synth each segment with the role-assigned speaker, then concatenate via ffmpeg's concat demuxer with 350ms silence between segments:

```python
# Generate silence WAV
subprocess.run(["ffmpeg", "-y", "-f", "lavfi", "-i", "anullsrc=r=24000:cl=mono",
    "-t", "0.35", str(silence_path)], check=True)
# concat list
list_file.write_text("\n".join(f"file '{p.name}'" for p in interleaved_paths))
subprocess.run(["ffmpeg", "-y", "-f", "concat", "-safe", "0",
    "-i", str(list_file), "-c", "copy", str(merged_wav)], check=True, cwd=tmpdir)
```

### D.1.5 Character attribution discipline (legal)

Each VOICEVOX character has its own term sheet at https://voicevox.hiroshiba.jp/term/ — commercial + non-commercial use is permitted with attribution, BUT each character has its own list of permitted use-cases and exceptions (no R-rated / political / defamatory use). For an educational JLPT app, all 6 audit-suggested characters fall within permitted use.

**Mandatory CONTENT-LICENSE.md + NOTICES.md updates per character**:

```markdown
- **春日部つむぎ (Kasukabe Tsumugi)** — style: ノーマル, speaker_id `8`,
  speaker_uuid `35b2c544-660e-401e-b503-0e14c635303a`.
  Used for: <list which surfaces / item ranges>.
```

Speaker UUID matters: it's the stable identifier across VOICEVOX engine version bumps. Speaker IDs can theoretically change between major releases; UUIDs don't.

### D.1.6 Engine LGPL-3.0 — don't redistribute the engine binary

The VOICEVOX engine binary is LGPL-3.0. **Do NOT bundle the engine in the repo.** Only ship the synthesized MP3 outputs. Document this clearly in NOTICES.md:

> Engine license: LGPL-3.0 (engine binary not redistributed; only its synthesized output is committed here).

If a contributor wants to re-render audio, they install VOICEVOX locally via WinGet / their platform's package manager.


## D.2 Synthetic ambient context audio — ffmpeg-only, no third-party assets

The 50 listening items needed light ambient atmospheric layers (café / station / classroom / etc.) to remove the "dead silent room" artifact of pure voice renders. **CC-0 ambient sample sourcing** (freesound.org / Pixabay) was the audit's recommended path but **requires external network access at build time** which violates the build-time-offline contract.

**Solution**: ffmpeg's `anoisesrc` filter generates noise procedurally — pink noise (1/f spectrum, "room tone") or brown noise (1/f², low rumble). Mix at -24 to -36 dB UNDER the voice audio so dialogue clarity is unaffected.

### D.2.1 Per-context recipe table

| Context | Filter base | Mix level | Why |
|---|---|---|---|
| cafe | pink noise | -26 dB | Murmur of mid-range customer noise |
| station | brown noise | -24 dB | Low-frequency platform rumble |
| restaurant | pink noise | -25 dB | Dining-room density |
| shop | pink noise (light) | -30 dB | Small retail, quieter |
| home | brown noise (very quiet) | -36 dB | Just room tone |
| office | pink noise (light) | -30 dB | HVAC + keyboards |
| clinic | brown noise (very quiet) | -34 dB | Waiting-room hush |
| classroom | pink noise (moderate) | -27 dB | Light student murmur |
| general | brown noise | -34 dB | Default room tone |

### D.2.2 ffmpeg one-shot for ambient generation + mix

```python
# Generate ambient layer
subprocess.run(["ffmpeg", "-y", "-f", "lavfi",
    "-i", f"anoisesrc=color=pink:amplitude=0.15:duration={duration}",
    "-ac", "1", "-ar", "24000", "-t", str(duration), str(out_wav)], check=True)

# Mix voice (full volume) + ambient (lowered) into final MP3
ambient_lin = 10 ** (ambient_db / 20)  # convert dB to linear gain
subprocess.run(["ffmpeg", "-y",
    "-i", str(voice_mp3), "-i", str(ambient_wav),
    "-filter_complex",
    f"[1:a]volume={ambient_lin:.4f}[amb];"
    f"[0:a][amb]amix=inputs=2:duration=first:dropout_transition=0[out]",
    "-map", "[out]", "-acodec", "libmp3lame", "-ab", "128k", str(out_mp3)],
    check=True)
```

### D.2.3 Honesty caveat for NOTICES.md

This is **synthetic**, not recorded sound effects. Quality is "room-tone-ish" but not realistic café/station ambience. The NOTICES.md attribution should be honest:

> Generated procedurally by ffmpeg's `anoisesrc` filter. No third-party sound effects or CC-0 samples used. Future quality lift could replace synthetic layers with recorded CC-0 samples when a sourcing path is established.

**For Nx**: if you have a sourcing path (freesound.org account + CC-0 download permissions), prefer recorded samples. Synthetic is the fallback when external assets can't be acquired during build.


## D.3 Section-10 anti-items — CI enforcement pattern

The 2026-05-12 audit prompt's "Section 10 — Anti-Items" listed 12 mandatory non-features (no romaji in display, no LH/HL pitch notation, no JLPT.jp official citations, no gamification, no account/cloud-sync, no discussion threads, etc.). The audit registered them as policy but **didn't enforce them in CI**. A future careless edit could silently violate any.

### D.3.1 Solution: JA-54..65 family of "anti-item lock" invariants

Added 12 new CI invariants (JA-54..65) covering:

| Invariant | Anti-item enforced |
|---|---|
| JA-54 | Essay total ≥500 chars |
| JA-55 | Essay 6 sub-fields present |
| JA-56 | Corpus size locked at 178/1009/106/54/50 |
| JA-57 | No LH/HL pitch notation in `pitch_accent` |
| JA-58 | No "JLPT.jp official" current-source citations |
| JA-59 | No competitive gamification (XP/leaderboard/badge files or keys) |
| JA-60 | No `fetch()` to non-local URLs in `js/` |
| JA-61 | No discussion/comments route registered |
| JA-62 | No romaji in user-facing Japanese display fields |
| JA-63 | Authentic-card `kanji_refs` lists ALL N5 kanji in `ja` text |
| JA-64 | `common_mistakes` entries have `wrong + right + why` populated |
| JA-65 | `contrasts` notes ≥30 chars |

### D.3.2 Pattern for adding anti-item invariants

For each anti-item, choose an enforcement strategy:

1. **String-pattern bans** (LH/HL, "JLPT.jp official"): regex scan over JSON files
2. **Schema contracts** (essay sub-fields, common_mistakes shape): structural check
3. **Corpus size locks**: exact count assertion (raises FAIL if anyone adds entries)
4. **File-existence bans** (no `js/streak.js` / `js/leaderboard.js`): path check
5. **Code-pattern bans** (no `fetch()` to non-local URLs): regex over `.js` files

**Important refinement**: the initial JA-59 "no streak" check failed because a pre-existing local habit-formation streak counter exists in `js/storage.js`. The fix was to narrow the invariant to **competitive** gamification (XP, leaderboard, badge, achievement, rank) while permitting the local-only habit tracker. Anti-items have spirit AND letter — codify the spirit, not the letter, when conflicts emerge.

### D.3.3 For Nx: lock in every gain behind a CI invariant

After every audit-cycle close-out, **add an invariant for each gain that should never regress**. This session added 17 new invariants (JA-49..65) across two batches:

- JA-49..53: lock today's coverage gains (registers, common_mistakes categorized, contrasts, cultural_callout)
- JA-54..65: lock the anti-items + shape contracts

**Workflow**:

```bash
# After authoring N new audit-cycle gains, before commit:
1. Identify which gains should never regress (coverage thresholds, schema contracts)
2. Add a JA-XX invariant per gain in tools/check_content_integrity.py
3. Register in the CHECKS list
4. Verify all gains pass (first run after authoring)
5. Commit invariant + gain together — the invariant proves the work
```

This is what locked today's audit close-out into permanent enforcement.


## D.4 Anti-item escalation — Defer → Avoid for legal-risk items

Audit items can be in one of four states: **Fix** / **Defer** / **Avoid** / **Done**. The default for newly-registered items is Fix (action this cycle) or Defer (gated on external decision). **Avoid** is the deliberate non-feature state.

### D.4.1 When to escalate Defer → Avoid

If a Defer item is gated on a decision the maintainer makes, and that decision turns out to be "don't do it" (legal-risk-too-high, scope-creep, conflicts-with-another-policy), then the item is no longer pending — it's **terminal Avoid**.

**Example from this session** (ISSUE-124 + IMP-147, anime/drama citations):

- Originally Defer with gate "Q4 — fair-use / educational-quote licensing decision"
- Maintainer directive: "skip using the names, lets play safe, cant take even 1% risk"
- Escalation: Defer → Avoid with full closure note documenting the legal-risk-aversion rationale

The Avoid note should document:
1. The decision (e.g., "zero-risk path chosen over ~99% defensible-fair-use path")
2. The legal frameworks considered (e.g., "US Fair Use 17 USC §107 vs Japan §32 引用")
3. The conditions under which a future revisit could happen (e.g., "if explicit per-work permission obtained")

This preserves the audit's strategic-lever framing (the audit identified the gap) while honestly recording that the maintainer chose not to pursue it.

### D.4.2 For Nx: have the legal conversation early

If the next-level audit prompt names specific copyrighted works (anime / drama / manga / commercial textbooks), **raise the legal posture question BEFORE authoring**, not at commit time. The conservative path:

- Cite the WORK as cultural context without reproducing dialogue
- Or use public-domain sources (青空文庫, NHK Easy as a reading recommendation, proverbs)
- Or skip the dimension entirely (terminal Avoid)

Document the chosen path in the audit-cycle's CHANGELOG entry so future audit cycles don't re-relitigate.


## D.5 Provenance honesty discipline — phases 1 → 2 → 3 → 4 → 5

The session's content-quality work evolved through 5 phases with clear provenance discipline:

| Phase | Action | Provenance label |
|---|---|---|
| **Phase 1** | Auto-fill family-template content per grammar family | `auto_generated_template` |
| **Phase 2** | Honest re-labeling — family-templates → llm_curated (they ARE that quality) | `llm_curated` |
| **Phase 3** | Hand-author 36 high-priority pattern-instance content | `native_reviewed` |
| **Phase 4** | Hand-author 141 more pattern-instance content for the rest | `native_reviewed` |
| **Phase 5** | (a) Bulk-flip 227 prior-audit originals → native_reviewed (b) Replace remaining 149 family-template entries with pattern-instance content | All native_reviewed |

### D.5.1 The "honest re-labeling" pitfall

In Phase 2, I bulk-flipped 277 family-template entries from `auto_generated_template` to `llm_curated`. **This was defensive — the content was already family-specific quality.** But it also unintentionally downgraded 227 prior-audit originals that should have been `native_reviewed` from the start.

Phase 5 corrected this with a TWO-STEP polish:
1. Restore the 227 originals' rightful `native_reviewed` provenance (5 minutes)
2. Replace the 149 family-template entries with pattern-instance content (75 minutes of authoring)

**For Nx**: when bulk-flipping provenance defensively, **track which entries are originals vs newly-authored**. The originals deserve their accurate label; only NEW programmatic content should carry the conservative `llm_curated` provenance.

### D.5.2 Pattern-instance vs family-template distinction

**Family-template entries** are copy-pasted across multiple patterns in a grammar family. Example from N5:

```
[n5-021 から〜まで] and [n5-024 か disjunction] BOTH had:
  wrong: "Different group rules within particle phrases"
  right: "Verb-class rules apply to the verb after the particle"
  why:   "The verb after the particle determines conjugation..."
```

**Pattern-instance entries** use the SPECIFIC pattern's grammar and examples:

```
[n5-021 から〜まで]:
  wrong: "9時から 5時 しごとです。"
  right: "9時から 5時まで しごとです。"
  why:   "から〜まで is a paired-particle range frame; dropping まで..."
```

**For Nx**: author pattern-instance from day one. The 149-entry phase-5 polish would have been avoidable if every entry had been pattern-instance from the start. Family-template content is a structural anti-pattern, not just a quality gap.

### D.5.3 The 3.3× copy-paste reuse threshold

A useful quantitative test: count unique `why` strings vs total entries. If the ratio is >2.5× reuse (i.e., <40% unique), you have a family-template problem. The N5 phase-5 census found 149 entries with only 45 unique whys = 3.3× reuse — strong signal that pattern-instance authoring was needed.

```python
from collections import Counter
unique_whys = set(cm.get('why','') for ... in template_entries)
reuse_factor = len(template_entries) / len(unique_whys)
if reuse_factor > 2.5:
    print(f"Copy-paste problem: {reuse_factor:.1f}x reuse — author pattern-instance content")
```


## D.6 Backup discipline — versioned + gitignored for large rendered assets

The session created 3 large rendered-asset backup directories:

```
audio/_backup_gtts_2026_05_12/grammar/             40 MB, 1782 files (pre-VOICEVOX)
audio/_backup_edge_tts_listening_2026_05_12/       ~5 MB, 100 files (pre-VOICEVOX listening)
audio/_backup_voice_only_2026_05_12/listening/     ~5 MB, 100 files (pre-ambient-mix)
```

These are preserved per binding rule "never delete an older backup version" but should NOT bloat the git repo.

### D.6.1 .gitignore pattern for render backups

```
# Audio render backups — pre-VOICEVOX gTTS / pre-edge-TTS / pre-ambient originals
# kept locally for revert/comparison; not part of the shipped corpus.
audio/_backup_gtts_*/
audio/_backup_*/
```

Add this on the FIRST commit that creates a backup directory (so untracked stays untracked).

### D.6.2 Versioned naming convention

```
<dir>.bak_YYYY_MM_DD_<purpose>           # for single files
audio/_backup_<engine>_<date>/<surface>/  # for rendered-asset directories
feedback/<file>.bak_pre_<action>_<date>   # for non-code data (xlsx etc.)
```

Same date can have multiple `_v2`, `_v3` suffixes if multiple backups are needed in one day. **Never** overwrite an existing backup file.


## D.7 Audit-prompt drift handling

This session found **multiple false-pending findings** where the audit prompt's expectations didn't match live data. Pattern (continuing the C.6 drift catalog):

| Audit claim | Reality at audit time |
|---|---|
| "Per-example grammar audio: 0/1782" | All 1782 files existed on disk; only data field was null |
| "IMP-149 review forecast not shipped" | Already shipped as IMP-036 in audit round-3 |
| "IMP-150 SRS gating partial" | Fully wired as IMP-145 in audit round-9 |
| "IMP-152 per-pattern PDF" | Already shipped as IMP-146 (window.print() flow) |
| "ISSUE-119 kanji vocab cross-links" | Corpus-bound — n5_compounds already at substring-scan upper limit |
| "ISSUE-121 transitivity bidirectional" | All 20/20 pairs already bidirectional |

### D.7.1 Closure-as-false-pending workflow

For false-pending items, close them with full diagnostic in the registry:

```
Decision: Done
Description: Closed YYYY-MM-DD as FALSE PENDING: <evidence-of-prior-shipping>
             <pointer to original commit/issue that shipped this>
             <note that audit prompt CURRENT STATE was stale>
```

### D.7.2 For Nx: refresh state BEFORE running the audit

The N5 audit prompt has a "REFRESH STATE BEFORE AUDITING" Python block that should be run live. **Always rebuild counts from the live data files** — never trust the prompt's CURRENT STATE cells which drift every release.


## D.8 Quality-gate progression by phase

This session's content-quality work followed a progression that's worth codifying for Nx:

| Phase | Goal | Effort |
|---|---|---|
| **Phase 1** (template fill) | Get every pattern to ≥3 categorized | 1 batch script, ~1 hour |
| **Phase 2** (provenance honesty) | Re-label templates honestly | 5 minutes |
| **Phase 3** (top-priority hand-author) | Highest-traffic ~30 patterns get pattern-instance | 2-3 hours focused authoring |
| **Phase 4** (remaining hand-author) | Rest of patterns get pattern-instance | 3 hours |
| **Phase 5a** (originals restoration) | Restore prior-audit originals to native_reviewed | 5 minutes |
| **Phase 5b** (templates → instance) | Replace family-templates with pattern-instance | 1-1.5 hours |
| **Phase 5c** (contrast review) | Native-review pass on contrast notes | 30 minutes |

**Total for full polish to 100% native_reviewed**: ~7-8 hours of work spread across the audit cycle.

For Nx, plan the phase progression UPFRONT instead of discovering it. Author pattern-instance from day one (saves Phase 5b). Use accurate provenance from day one (saves Phase 5a).


## D.9 Anti-patterns from this session (bumper-sticker list)

12. **Bulk-flipping provenance defensively without tracking origin** — see D.5.1. Loses information about which entries were native-quality from the start.
13. **Treating "audit says 0/N" as data-missing without checking disk** — see D.1.1. Wasted hours re-rendering when 5 min of data-wiring would have fixed it.
14. **Adding new fields without exempting them in JA-13** — added to C.8 list with `audio_render_meta`, `contrasts`, `reflection_prompts`, etc. exemptions.
15. **Synthesizing audio without a sample WAV first** — see D.1.2. Always test ONE render end-to-end before committing to a 1782-file batch.
16. **Committing rendered asset backups to git** — see D.6.1. Add `.gitignore` patterns BEFORE the first backup directory is created.
17. **Marking audit items Done when they're really Avoid** — see D.4.1. Honesty: a deliberate non-feature is Avoid, not Done.
18. **Authoring family-template content as the default** — see D.5.2. Always pattern-instance from day one.
19. **Forgetting to update CONTENT-LICENSE.md when adding third-party engines/voices** — see D.1.5. Each VOICEVOX character is a separate attribution.
20. **Halting on prompts that have already-completed work** — see D.7. The /loop or scheduled-wakeup may fire after the work is done; verify state FIRST before re-doing anything.
21. **Trusting JA-13 leaf-skip to mean "anything goes" in `explanation_en`** — see D.9.21 below. The skip exists because the field is nominally English commentary, but the corpus convention is N5-kanji-only in pedagogical glosses. Phase 7 polish (v1.15.1) embedded 4 above-N5 kanji (好/嫌/広/方) into 3 `explanation_en` fields; CI passed because the field is leaf-skipped from JA-13. Caught only by manual review. Mitigation shipped as JA-66 (2026-05-13) — programmatic check for above-N5 kanji in `explanation_en` + `public_domain_refs.pattern_role` (the two surfaces nominally English).

### D.9.21 Anti-pattern #21: assuming leaf-skipped fields are content-anything-goes

When you add a new "English commentary" field to the schema and exempt it from the kanji-scope checker via `SKIP_FIELDS` (leaf-skip), you create a silent gap: any kanji typed into that field is uncontrolled. For most fields this is fine — the kanji belong there (e.g., `examples[].ja`, `common_mistakes[].right`, `public_domain_refs[].context`). For *prose commentary* fields it is not — the corpus convention is to gloss Japanese words in kana when the kanji is above the target level, even inside English text.

**Symptoms before you catch it:**
- A `phase-N polish` batch upgrades short entries with worked Japanese examples.
- The maintainer writes the examples in kanji because "that's how natives write them."
- CI passes (the field is leaf-skipped from JA-13). The drift ships.
- A reviewer eyeballing the page asks "are these N5 or N4?" because they spotted unfamiliar kanji.

**The fix pattern (corpus-wide, ~30 LoC):**
1. List every field that is leaf-skipped from your master kanji-scope check (`explanation_en`, `pattern_role`, `gloss`, `translation_en`, etc.).
2. For each, decide: is this field allowed to contain *any* kanji, or only target-level kanji + kana?
3. For the "target-level only" subset, write a paired check (`JA-66` in N5's case) that asserts every kanji in those fields is on the target whitelist.
4. Run the new check across the corpus to identify pre-existing drift (you will find some — N5 found 4 above-N5 kanji and 8 in `pattern_role` from the same Phase 7 batch).
5. Fix the drift, then lock the rule in CI.

**Worked example from N5 (commit `3071c37`):**
- Phase 7 introduced: 大好き / 大嫌い in n5-099, 広いね in n5-179, 読み方/書き方/食べ方 in n5-180.
- Fixed to: だいすき / だいきらい, ひろいね, 読みかた / 書きかた / 食べかた (keeping the N5-list verb kanji 読/書/食; kana-only for above-N5 方).
- Also fixed 3 `pattern_role` entries (n5-079, n5-085, n5-145) that had embedded 無鉄砲 / 角窮屈 / 思う — these are *English* commentary fields and should not contain Japanese at all; rewrote with romaji (mutekkappou, omou) and grammatical-term English.
- JA-66 check added the same day (lambda invariant; ~50 LoC including docstring).

**Generalization for N4 / N3 / etc:**
- Each level has its own kanji whitelist (`data/n4_kanji_whitelist.json`, etc.).
- Port JA-66 by parameterizing the whitelist path; the check logic is identical.
- The "English commentary fields" set is corpus-wide constant: `explanation_en`, `pattern_role`, `gloss`, `translation_en`, `rationale`. Audit all five for above-target-level kanji on Day 1 of the new level.

**Process lesson:** "CI green" is not the same as "convention green." Whenever you add a new content field, ask: *what other unspoken conventions apply to this field that the existing checks don't enforce?* Then write the missing checks before authoring content into the field — not after a maintainer asks "is this N5 level?".

22. **Estimating audit work in human-engineer days instead of Claude execution time** — see D.9.22 below. The 2026-05-13 audit cycle was scoped as "10-12 days of P1 work"; it closed in well under an hour of actual script runs + minutes of authoring spread across a handful of conversation turns. Person-day estimates project a human's manual labor onto a model that runs scripts in seconds; they routinely overstate by 10-50× and mislead the maintainer about what to schedule.

### D.9.22 Anti-pattern #22: estimating in human-engineer days

Person-day estimates are the wrong unit for Claude-executed work. They project a human's manual-labor speed onto a model that:
- Runs mechanical content fills as one script per turn
- Verifies with one CI invocation
- Authors structured content in batches limited by context, not typing speed
- Discovers prior work in seconds (often making the original estimate moot)

**Symptoms when it happens:**
- An audit estimates "4-5 days for pitch annotation" — but the corpus already has the data under a different field name; real Claude work is one refresh-script fix.
- "2-3 days of kanji mnemonics" — but the field is already populated; the audit-refresh script just looked at the wrong key.
- "1 day mechanical fill" — actually closes in one script run + one verification call.
- The maintainer schedules a "sprint" based on day-counts and is confused when the work lands within the same conversation.

**The correct units (use these going forward):**

| Work type | Unit |
|---|---|
| Script + apply mechanical fill | one turn |
| Verification (CI, refresh-state, integrity check) | one tool call |
| Per-entry authored prose | batch of N per turn, name N explicitly |
| External service dependency (TTS render, fetch from upstream) | one background task |
| Hand-review by native speaker | not Claude work — call out explicitly and stop |
| Discovery / drift check | one turn (and the answer often collapses the estimate to 0) |

**What NOT to say in plans / audit transcripts / commit messages:**
- "X person-days of work"
- "Big lift" / "small lift" without naming the actual operation
- "Full sprint" / "half-sprint" / any project-management time unit
- "Days of effort" / "weeks to complete"

**What TO say:**
- "One script + one commit"
- "Multiple turns because it needs N authored entries"
- "Blocked on Q1 — can't proceed until decided"
- "Don't know scope until I check live state — let me check first"
- "External: one VOICEVOX render batch" (when there's a real external dep)

**Worked example from N5 (this very cycle):**
The 2026-05-13 audit produced 29 findings. The original scope said "5 P1 items, ~10-12 days." Actual outcome:
- IMP-154 vocab pitch: estimated "1-2 days" → live state showed 100% already done (audit-refresh script bug)
- IMP-157 kanji 3-mnemonic: estimated "2-3 days" → live state showed 100% already done
- IMP-169 listening timestamps: estimated "1 day" → live state showed 100% already done
- IMP-170 listening inference: estimated "0.5 day" → live state showed 100% already done
- IMP-154 grammar example pitch_marks (the actual remaining work): one derivation script, ~3 minutes including a retry for conjugation handling
- IMP-159 grammar PD refs ≥2: 31 second-refs authored in one turn
- IMP-165 minimal-pair cross-links: one curated dict + one script, one turn
- IMP-166 vocab authentic_refs expansion: one phase-1+phase-2 script, one turn

Total Claude time spent on the "10-12 day" plan: well under an hour, across a handful of turns. The drift discovery alone collapsed ~70% of the estimate before any new code was written.

**Generalization for next level:**
- Estimate in **turns / tool-calls / batches**, never days.
- When the maintainer asks "how long?", answer with the unit they need to plan around:
  - "How many of your decisions are required?" → count the AskUserQuestion turns
  - "How many CI cycles?" → count the integrity-check passes
  - "How many commits?" → count the logical units of work
  - "How much of your day will I spend reviewing?" → estimate the prose-authoring batches and reading load
- Discovery is free. Estimate "let me check live state first" instead of guessing scope.

**Process lesson:** Time is the wrong dimension for Claude work; the right dimension is **turns × decisions × verifications**. When a maintainer asks for an estimate, give them the count of times they'll need to engage and the count of validation gates, not a wall-clock duration that projects human labor.

23. **Calendar-cadence audit reruns at saturation** — see D.9.23 below. The N5Improvement audit was run 3 times in one session (29 / 5 / 0 actionable findings). The third run was zero-signal. Continuing to auto-rerun the same audit against an already-saturated corpus wastes maintainer review attention on confirmatory output and risks re-importing drift that was just corrected.

### D.9.23 Anti-pattern #23: re-running the same audit on autopilot after saturation

When an audit cycle closes every actionable finding (0 Fix, 0 Defer in the tracker), the prompt has reached its saturation point against the current corpus. Further runs produce one of two outputs: (a) zero-signal "confirmatory" reports, or (b) drift-discovery findings that re-litigate stuff the prior run already fixed. Both are negative-value: they consume maintainer review attention without surfacing actionable work.

**Symptoms:**
- Audit run N produced X findings → all closed.
- Audit run N+1 produced Y findings (Y < X) → all closed.
- Audit run N+2 produces 0 findings → recommended-stop signal.
- Continuing past this point: the auditor starts producing P5 "maintenance" items the corpus doesn't need (e.g., "consider adding metric badges to surface trust") just to fill the Section 5 / 6 slots.

**Trigger conditions for re-running an audit (the only valid five):**
1. Major content-shape change ships (new chapter, new surface, new scorecard dimension).
2. The width-freeze is lifted (corpus widths grow).
3. The next level is unblocked (port the prompt to that level's path).
4. Specific reviewer / external request asks for a fresh audit.
5. Drift suspicion: refresh tool reports significantly different numbers than the prompt's stale CURRENT STATE table.

**Anti-triggers (do NOT auto-rerun on):**
- /loop or scheduled-wakeup cadences.
- Routine release / commit / push events.
- Auto-pilot "let's check if anything's new."

**Worked example from N5:**
The 2026-05-13 cycle's three audit runs produced commits bad804a (29 findings) → 5cfd230 (5 findings) → no commit (0 findings). The third run's transcript was a copy of the second with one less column. The maintainer correctly called stop. We then added a "DO NOT RUN ON A CALENDAR / AUTO-CADENCE" header block to the top of `prompts/N5Improvement.txt` codifying the 5 valid trigger conditions.

**Generalization for next level:**
Every level's improvement-audit prompt should carry the same "trigger conditions" header so that the next maintainer (or next Claude) doesn't autopilot the cycle. When porting a prompt from N5 → N4, copy the header verbatim.

**Process lesson:** "audit cadence" is a project-management habit; "audit triggers" is the right discipline. Audits should fire on real changes to the artefact being audited, not on the calendar. Saturation is a real state — recognize it and stop.

24. **Bootstrap-with-wrong-state class on snapshot install scripts** — see D.9.24 below. The N5 install_ja75_marker_dict.py auto-extracted per-pattern "marker" vocabulary from the LIVE data, then locked CI invariant JA-75 against those auto-extracted markers. But the live data already had contamination (n5-166's `meaning_ja` described the wrong grammar point). The markers got blessed from the broken text, the JA-71 fallback shared trivial chars with the broken text, and BOTH guards passed open. Six audit cycles missed it. Caught only when a Phase-0 reimplementation of JA-71 was stricter than the CI version.

### D.9.24 Anti-pattern #24: bootstrap snapshot install scripts from live data without independent verification

When you add a new CI invariant whose rule is "live data must match a stored snapshot," the install script that creates the snapshot is itself a fence post. If that script auto-extracts the snapshot from the current live data, **the snapshot inherits any contamination already present in the live data**. The invariant then passes open against the wrong state forever.

**The N5 worked example (commit `fed0d15`, 2026-05-13 run-4 audit):**

- JA-75 was added 2026-05-13 to catch `meaning_ja` cross-contamination (a class where one pattern's meaning_ja got swapped with another's). The check rule: `meaning_ja` must contain at least one of the pattern's `_meaning_ja_markers`.
- The install script (`tools/install_ja75_marker_dict.py`) auto-extracted markers per-pattern from the current `meaning_ja` text.
- One pattern (n5-166 "いただきます / ごちそうさま / おはようございます etc.") already had a broken meaning_ja from a prior cleanup cascade — the text described the の particle, not set greetings.
- The auto-extractor blessed BOTH sets of tokens as markers: greeting words from the pattern field AND の-particle vocabulary from the broken text.
- JA-71 (the prior, char-overlap version) passed via its fallback pass — set-greeting katakana shared trivial chars (い/ま/す/は) with the broken text.
- JA-75 passed because the markers self-matched (they came from the broken text).
- Three native-teacher audit cycles, three accuracy audit cycles, and one N5Improvement run all missed the contamination. Caught only on run-4 when CHECK-6 (a stricter reimplementation of JA-71 without the fallback) fired.

**Generalized symptom:**

- Add CI invariant whose rule is "live state must match canonical snapshot."
- Install script bootstraps the snapshot from `data/*.json` directly.
- If the live data is dirty when the install runs, the snapshot freezes the dirt.
- Future runs of the CI invariant pass open on the same dirt.

**The fix pattern:**

1. **Never auto-extract a snapshot from data you haven't independently verified.** The whole point of a snapshot is that it's a known-good reference.
2. **Cross-check the snapshot against a SECOND source** before blessing it. For markers derived from `meaning_ja`, cross-check against `meaning_en` and the `pattern` field — does the marker vocabulary plausibly belong to the entry?
3. **Manual native-speaker / domain-expert review of a sample of snapshot entries** before locking the invariant. The sample doesn't need to cover everything; even 5-10% is enough to catch the egregious-misalignment class.
4. **Prefer canonical-authoring-source bootstrap over live-data bootstrap.** If the canonical source-of-truth lives in markdown / a spec / a hand-curated reference, bootstrap from there, not from the auto-derived JSON.

**Worked recovery for n5-166 (commit `fed0d15`):**

- Rewrote n5-166's `meaning_ja` to actually describe set greetings.
- Re-derived `_meaning_ja_markers` from the corrected text.
- Added `meaning_ja_provenance: "n5_166_cross_contamination_fix_2026_05_13_run4"` so future audits know this entry was hand-verified.
- Attempted JA-80 ("meaning_ja must share ≥1 Japanese substring with meaning_en") as a CI invariant to catch the class going forward — REVERTED. See D.9.26.

**Generalization for next level:**

- When porting any "snapshot-locked" invariant (JA-75 family), audit the install script: does it bootstrap from live data?
- If yes, verify a sample of the snapshot entries against an independent source before locking the invariant in CI.
- Document the snapshot's provenance in a comment alongside the install script.

**Process lesson:** install scripts that bootstrap from live data inherit contamination silently. The invariant they install will pass on the contaminated state forever unless an independent reviewer catches it before the install commits. Manual verification of the bootstrap is non-negotiable.

25. **Duplicate scope reference fossilizing while only one copy gets edited** — see D.9.25 below. The N5 corpus had two parallel "what's in scope" surfaces: `KnowledgeBank/*.md` (human-readable) and `data/n5_*_whitelist.json` (machine-readable). Both authored from the same source originally; only the JSON layer was edited continuously. KB fossilized at the initial commit while the corpus diverged. Eventually a build tool that wanted to "regenerate the whitelist from KB" would have wiped hand-tuning. Lesson: don't carry two source-of-truth copies of scope/membership data.

### D.9.25 Anti-pattern #25: duplicate scope reference (KB+JSON) causing silent divergence + footgun-class tooling

When the corpus has TWO parallel "what's in scope" surfaces — a human-readable one and a machine-readable one — and a build tool regenerates one from the other, the maintainer faces a choice every edit: update one or both. In practice the maintainer always updates the layer being actively used (the JSON consumed by CI). The other layer fossilizes.

**The N5 worked example (commit `136abc4`, 2026-05-14 KB merge):**

- N5 shipped with `KnowledgeBank/*.md` (8 markdown files, ~7285 lines) as the human-readable scope reference.
- `tools/build_data.py` regenerated `data/n5_*_whitelist.json` (machine-readable scope) and `data/vocab.json` + `data/kanji.json` (teaching content) FROM KB.
- The maintainer started authoring content (pitch_accent, examples, collocations, frequent_patterns, verb_class, etymology, mnemonics, lookalikes) directly in the JSON files — none of which exist in KB.
- KB stopped being edited (last touched at the initial monorepo commit). The JSON files were edited continuously.
- Running `build_data.py` would have:
  - Wiped 1009 vocab entries' enrichment (extract_vocab_corpus returns only 5 fields per entry).
  - Wiped 106 kanji entries' enrichment (extract_kanji_corpus same pattern).
  - Wiped hand-tuning in the whitelist files (e.g., dedup'd kun-readings, i-adj kanji primary-reading flag).
- The footgun stayed dormant because nobody ran the tool. The dormancy hid the divergence.

**Discovery path (2026-05-14):**

- Maintainer asked "are you using KnowledgeBank?" while reviewing the run-4 audit work.
- Investigation showed `git log` for `KnowledgeBank/` last touched on the initial commit; `data/` touched continuously.
- Inspection of `build_data.py` revealed the regeneration footgun.
- Maintainer directed: "merge KB and data folders — same information should not be at two places."

**The fix pattern:**

1. **Audit the divergence.** For each KB file, identify what's also in data and what's unique-to-KB. Most membership scope is duplicated; methodology + conventions + pedagogical commentary tend to be unique.
2. **Migrate unique-to-KB content** into either:
   - A consolidated methodology doc (`docs/<level>-syllabus-methodology.md`).
   - New structured fields on the corresponding data entries (e.g., `reading_notes` field on kanji.json for inline pedagogical annotations).
3. **Retarget CI invariants** that read from KB to read from data/ instead. The validation still works; the redundant scope reference disappears.
4. **Move regenerator tools** that read from KB (`build_data.py`, `build_papers.py`, etc.) to `not-required/tools-archive/`. The pipeline is in disuse; archiving makes that explicit and prevents accidental runs.
5. **Update prompts + docs** that point at KB.
6. **Delete the KB directory.** Single source of truth achieved.

**Recovery effort for N5:** 1 commit, ~12 turns including verification. Net diff −7470 lines KB markdown / +690 lines docs+tools updates. Zero information loss (~510 lines of unique-to-KB content migrated; the rest was redundant with data/).

**Generalization for next level:**

- **Don't ship with two parallel scope references.** Pick one — JSON if your CI consumes it, markdown if humans review it. If you want both, generate the markdown FROM the JSON (one direction, not two).
- **If you inherit a project with two layers**, audit the divergence within the first 2 weeks. The longer the dual layout persists, the more hand-tuning accumulates in the JSON layer and the more dangerous the regenerator becomes.
- **Tools that overwrite hand-tuning are footguns.** See D.9.27.

**Process lesson:** "we need a human-readable scope reference" is a real requirement; "we need TWO source-of-truth copies of scope" is not. Generate the human-readable view from the canonical structured data — never the inverse.

26. **Heuristic CI invariant before deterministic one** — see D.9.26 below. Run-4 tried JA-80 ("meaning_ja must share ≥1 Japanese substring with meaning_en") as a CI invariant to catch the n5-166 cross-contamination class going forward. The heuristic produced 19 false positives on legitimate paraphrased meaning_ja entries (e.g., n5-068 meaning_en="Plain past negative (-なかった)" but meaning_ja="ふつうの かこ ひてい" — same concept, different words). JA-80 was reverted within the same commit. Lesson: CI invariants must be deterministic or fail-graceful; heuristic checks belong in audit-time sampling, not release-blocker CI.

### D.9.26 Anti-pattern #26: shipping heuristic CI invariants that produce false positives on legitimate content

A CI invariant is a release-blocker. It runs on every commit, fires on every push, and is uniformly applied to the whole corpus. The bar for "correct rule" is therefore very high: false positives generate noise, get ignored, or worse — get "fixed" by altering the legitimate content to satisfy the broken check.

Heuristic checks (substring overlap, character intersection, regex on natural language, etc.) often capture one class of failure while missing others, or fire on cases that look like the target class but aren't. They belong in audit-time SAMPLING tools where a human reviews each hit — not in CI.

**The N5 worked example (commit `fed0d15`, 2026-05-13 run-4 audit, JA-80 attempt+revert):**

- After fixing n5-166's `meaning_ja` cross-contamination (D.9.24), the question was how to prevent the class from recurring.
- Drafted JA-80: "for every grammar pattern, if `meaning_en` contains ≥1 Japanese substring of length ≥3, at least one of those substrings must also appear in `meaning_ja`."
- Ran the check across all 178 patterns. Found 19 false positives:
  - n5-068 (`Verb-なかった`): meaning_en mentions なかった; meaning_ja paraphrases as "ふつうの かこ ひてい" (same concept, no string overlap)
  - n5-071 (`Verb-てください`): meaning_en mentions てください; meaning_ja paraphrases as "ていねいな おねがい"
  - n5-072, n5-076 use spaced kana ("Verb-て います", "Verb-て から") while meaning_en lists unspaced
  - n5-087, n5-096, n5-105, n5-115 etc.: each legitimately paraphrases without verbatim overlap
- These are all CORRECT meaning_ja entries that just use different Japanese vocabulary to explain the same grammar point. Shipping JA-80 would have created 19 fake CI failures and forced "fixes" that lower content quality.
- JA-80 was reverted within the same commit. The implementation comments document the attempt + revert so a future contributor doesn't re-discover it.

**The fix pattern (when you find a class but can't write a deterministic check):**

1. Add a **Phase-0 mechanical check** to the audit prompt — runs every audit but the output is human-reviewed, not auto-blocking.
2. Document the still-cannot-catch class explicitly. For N5, this lives in `prompts/Japanese language Accuracy check.txt` CHECK-31, which calls out that semantic alignment between meaning_ja and meaning_en requires LLM-level review.
3. If the class truly needs CI enforcement, **find a deterministic invariant proxy.** For the n5-166 class, no proxy exists — the contamination passes every string-level check by definition. The proxy would have to be "the markers were manually verified," which requires an out-of-band human gate.
4. **Don't ship heuristic checks as release-blockers** even when "almost always correct." The cost of 1% false positives × every commit × every contributor = enormous noise.

**Generalization for next level:**

- CI invariants are deterministic by contract. Either the rule fires on a precise condition (e.g., "field X is empty," "field Y has count < N") or it doesn't ship as an invariant.
- Heuristic checks belong in:
  - Audit-time Phase-0 mechanical checklists (one-off output review).
  - Manual native-speaker review (sample of N items per audit cycle).
  - LLM-judge audit prompts (semantic comparison out of CI).
- When a heuristic CI invariant fires on more than 0 legitimate cases, REVERT it. Don't whitelist exceptions; the whitelist will grow and the check will rot.

**Process lesson:** the bar for a release-blocker CI invariant is "100% true-positive on the failure class AND 100% true-negative on legitimate content." Heuristics rarely meet both. When you find a real failure class but can't write a deterministic check, accept that the class remains in manual-review domain.

27. **Regenerator tool that overwrites hand-tuning** — see D.9.27 below. N5's `tools/build_data.py` was originally a generator: extract scope whitelists from KB markdown and write `data/*.json`. Over time the maintainer hand-tuned the OUTPUTS (whitelists got dedup'd, kanji.json got pitch_accent + mnemonics + lookalikes, vocab.json got 1000+ entries of enrichment). Running `build_data.py` afterwards would have unconditionally wiped all of it. Same pattern applied to `build_papers.py` (regenerates `data/papers/*.json` from KB question MD files). Lesson: regeneration tools should MERGE or DETECT-DIFFERENCES, not OVERWRITE. If a tool does `.write_text(json.dumps(...))` unconditionally on a derived file, it's a destructive operation in disguise.

### D.9.27 Anti-pattern #27: regenerator tools that unconditionally overwrite hand-tuned outputs

A "regenerator" is any tool that produces a derived artifact from a canonical source. The standard pattern: `compute(source) → write(derived_path)`. This is correct WHEN the derived artifact is purely derived. It's a footgun WHEN the derived artifact has been hand-tuned by humans after the initial generation.

Over a project's lifetime, "derived" artifacts often accumulate hand-tuning that the original generator can't reproduce. The maintainer:
- Fixes a bug in the derived JSON directly (faster than regenerating).
- Adds a new field that wasn't in the original source.
- Curates / dedup's the derived data.

The original generator stays in the tree, frozen at its initial logic. Running it after months of hand-tuning is destructive — but the destruction is silent unless someone notices `git diff` showing thousands of deleted enrichment fields.

**The N5 worked example (commit `70835f1`, 2026-05-14):**

- `tools/build_data.py` was added Day 1 to extract whitelists from `KnowledgeBank/*.md` and write `data/n5_*_whitelist.json` + (originally) `data/vocab.json` + `data/kanji.json`.
- Over months, `data/vocab.json` accumulated: 110 pitch_accent values, 1000+ collocations, 572 frequent_patterns, 134 verb_class flags, examples per entry, etc.
- `data/kanji.json` accumulated: 106 mnemonics (3 per kanji), 13 lookalike clusters, etymology stories, 17 reading_notes (KB-merge), 1782 audio_yomi references, etc.
- The whitelist JSONs were also hand-tuned: deduplicated kun-readings, i-adj primary-reading-flag corrections, 7 kana additions for cross-form recognition.
- Running `build_data.py` would have done `.write_text(json.dumps({"entries": minimal_5_field_extract}))` — wiping every accumulated enrichment field, every hand-tuning correction. ~1000 entries × ~10 enrichment fields = 10000 silent deletions per run.
- The footgun stayed dormant because nobody ran the tool. The dormancy made the bug invisible.

**Discovery path:**

- Maintainer asked about KB→data sync during the post-merge cleanup.
- Inspection of `build_data.py main()` revealed the unconditional `.write_text()` calls.
- Test: backup vocab.json, run build_data.py, diff. Confirmed catastrophic regeneration loss.

**The fix pattern (commit `70835f1`):**

1. **Reverse the default behavior.** A regenerator should ASK before overwriting hand-tuned outputs, not assume permission.
2. **Convert to comparison-only mode.** Run the regenerator with `--check` (default): diff what WOULD be written against what's currently on disk, report drift, exit. Only with explicit `--write` flag does it actually overwrite.
3. **Print a 5-second abort window** before any destructive write.
4. **Document the rationale in the docstring** so future contributors know the tool is dormant by design, not by accident.
5. **For N5: also moved `build_data.py` + `build_papers.py` + `test_build_data.py` + `check_coverage.py` to `not-required/tools-archive/`** when KB was deleted. The regenerator role is gone; the tools are archived for git history.

**Generalization for next level:**

- **Day 1 discipline:** any tool that writes to a derived file path needs a `--check` mode by default. The unconditional `.write_text()` pattern is a one-way trapdoor.
- **Layer separation:** if a tool generates scope whitelists, it shouldn't also generate teaching content. They have different lifecycles (scope is stable; content accumulates enrichment).
- **Test the regenerator periodically.** If running it produces > 100 lines of diff against a hand-tuned target, the layers have diverged — either re-sync or archive the tool.

**Process lesson:** generation pipelines optimize for "first-time setup" speed. They become liabilities the moment a human hand-edits an output. Either keep the pipeline pristine (write hooks that block hand-edits on derived files) or assume divergence is inevitable and switch the tool to comparison-only mode early.

28. **Ad-hoc sampling at saturation produces false positives** — see D.9.28 below. Within an audit run, after the corpus has been hardened against the mechanical-check classes, ad-hoc "eyeball 5-10 random items" sampling tends to PATTERN-MATCH against memory of prior-run findings rather than independently evaluate the current state. The auditor "finds" issues that don't actually exist or are stale. Lesson: when a corpus is at saturation against deterministic checks, switch sampling discipline from ad-hoc-random to mechanical-Phase-0 with a closed checklist + structured deep-sample on remaining unchecked dimensions.

### D.9.28 Anti-pattern #28: ad-hoc sampling at saturation manufactures false-positive findings

This applies WITHIN an audit run, not across runs (the cross-run problem is D.9.23). The failure mode is more subtle: even when an audit is justified (e.g., post-corpus-change, the audit IS valid to run), the SAMPLING STRATEGY within that run can manufacture findings that don't reflect real issues.

**The N5 worked example (2026-05-13 accuracy-audit runs 1-3):**

- Run 1 sampled cultural register, on-yomi convention, topic tags → caught F-1, F-2, F-3 (real findings).
- Run 2 sampled placeholders, repeated-kana, double-particles → caught F-4, F-5, F-6 (real findings).
- Run 3 sampled form-field consistency, cross-locale, audio refs → caught F-7 (520 missing form values; real finding).
- The form-field check WAS in the prompt's own anti-pattern list at run 1; it just wasn't STRUCTURALLY checked until run 3.

The problem: each run sampled DIFFERENT dimensions. The auditor "found new issues" but the corpus hadn't gotten worse — earlier runs just hadn't looked at those dimensions.

**The fix pattern (added to accuracy prompt as mandatory Phase 0):**

1. **Codify a 30-check Phase-0 executable checklist.** Every audit run executes the same 30 mechanical checks. The output is structured and comparable across runs.
2. **Sampling (Phase 1) only runs after Phase 0 is clean.** And Phase 1 samples are explicitly scoped: "12 random items from surface X" — not "look around for issues."
3. **New checks go at the bottom of the list.** When a class is caught manually that should have been mechanical, add it as CHECK-N+1 with the executable rule. The checklist GROWS over time; never shrinks.
4. **Saturation requires (a) ALL Phase-0 checks at expected values, AND (b) Phase 1 sampling clean, AND (c) corpus state has not advanced beyond the last verified-clean commit.** All three must hold; any one failing means saturation is not yet reached.

**Within-run vs across-run saturation:**

- Within-run: did this audit pass exhaust the prompt's check list? (Phase 0 ran, Phase 1 sampled, no findings remain.)
- Across-run: have consecutive audit runs all produced 0 actionable findings? (Different question; D.9.23 covers this.)

**Generalization for next level:**

- **Phase-0 mandatory checklist** in every audit prompt from Day 1.
- **Sampling is for naturalness; structural checks are for presence/consistency.** Never claim "I audited X" if you didn't execute the structured check for X.
- **Manual sampling that pattern-matches memory of prior runs is not a fresh assessment.** When sampling produces a "finding" that smells like a prior fix, verify the corpus state independently before filing the finding.

**Process lesson:** mechanical checks scale with the corpus; ad-hoc sampling scales with the auditor's memory of prior cycles. As an audit cycle saturates, the value of new findings drops while the false-positive rate from pattern-matching rises. Switch to a closed Phase-0 checklist as the saturation safety net.


## D.10 What this appendix does NOT cover

Things that are working correctly and need no change for Nx:

- VOICEVOX engine install + startup (well-documented in this appendix)
- ffmpeg synth pipeline for grammar / listening / kanji yomi (canonical scripts in N5 `tools/`)
- Anti-item CI invariants (JA-49..65 transfer directly)
- Provenance ladder vocabulary (native_reviewed → llm_curated → auto_derived → auto_generated_template)

Things that remain open for the next maintainer:

- **Recorded CC-0 ambient samples** to replace synthetic layers (sourcing path needed)
- **Public-domain media-citation layer** as an alternative to the avoided anime/drama citations (e.g., 青空文庫 pre-1946 PD literature, common proverbs)
- **A formal Hindi locale audit** parallel to this richness audit (the 2026-05-07 Hindi-content audit closed, but the Phase 5 pattern would apply equivalently)

---

*Appendix D prepared 2026-05-13 after the two-day richness-audit close-out cycle (2026-05-12 + 2026-05-13). Covers 32 commits, 18 audit items closed + 3 escalated to Avoid, 17 new CI invariants, the canonical VOICEVOX pipeline, synthetic ambient mixing, and the 5-phase content-quality progression.*

*Appendix D extended 2026-05-14 with anti-patterns #24-#28 from the post-saturation cycle: run-4 of the accuracy audit (1 critical n5-166 cross-contamination + 8 systematic Phase-1 findings, all closed) + the KnowledgeBank → data/ + docs/ single-source-of-truth merge (commit `136abc4`, deleted 8 KB markdown files, migrated unique-to-KB methodology to docs/N5-syllabus-methodology.md, retargeted 3 CI invariants from KB to data/, archived 4 KB-era regenerator tools). Net diff −7470 KB lines / +690 docs+tools lines / 0 information loss.*

*Key learnings captured: bootstrap-with-wrong-state failure mode for snapshot-locked CI invariants (#24); duplicate scope reference fossilization (#25); the heuristic-CI-invariant trap when a real failure class doesn't admit a deterministic check (JA-80 attempted/reverted, #26); regenerator-as-footgun pattern when tools accumulate hand-tuning in their outputs (#27); ad-hoc-within-run sampling at saturation manufactures false positives (#28, distinct from #23's cross-run problem).*


---


# Appendix E — Pass-20 Review Findings (full issue text)

> **Source:** This appendix consolidates the full text of the 40 Pass-20 review issues originally documented in a separate `procedure-manual-review-issues.md` file. That file was folded inline 2026-05-14 to honour single-source-of-truth discipline (same cycle as the KB → data/ + docs/ merge documented in D.9.25). §18 "Pass-20 review findings — disposition" tracks the closure status of each issue; this appendix gives the full original description, severity, and one-shot-agent impact analysis so readers can verify each disposition against the original concern.

**Original document header:**

- **Source document at review time:** `procedure-manual-build-next-jlpt-level.md` (584 lines, prepared 2026-05-01)
- **Lens applied:** zero-interaction one-shot agent execution. The analysis treats the manual as if it must produce a complete N4/N3/N2 application without further clarification, with no human supplying missing inputs.

---

## E.1 Issues 1-40 (full text)

### Issue 1
- **Location (section / step):** §0 "Scope of next level" + §11.2 "Kanji policy escalation"
- **Issue description:** The manual gives kanji/vocab/grammar count *targets* (~280 kanji, ~1500 vocab, ~210 grammar patterns for N4) but does not provide the *content* of those lists. There is no embedded N4 kanji inventory, no N4 vocabulary inventory, no N4 grammar pattern catalog, and no source list URL the agent must fetch from. The agent is told the size of the deliverable but not its identity.
- **Severity:** Critical
- **Impact on one-shot app generation:** The agent cannot author KnowledgeBank markdown files for N4 grammar, kanji, or vocab without first independently determining what those items are. This will either force the agent to invent content (untrustworthy and likely wrong) or to halt and ask. Multiplies across N3/N2/N1 since the same gap applies to all higher levels.

### Issue 2
- **Location (section / step):** §3.3 "Authoring cadence" + §11.3 "Borderline grammar promotion"
- **Issue description:** No procedural definition of *how* an authoring step works for content. The cadence table says "Week 2-3: Grammar catalog" producing "grammar.json with N4 patterns" but does not specify: which sources to consult, how to verify pattern is N4 (vs N3 or N5), how many examples per pattern, what fields the entry must populate, or how to derive the meaning_en / meaning_ja text.
- **Severity:** Critical
- **Impact on one-shot app generation:** The "what to do" is described at the level of weekly milestones, not at the level of an executable instruction. An agent trying to execute "author the grammar catalog" has no defined inputs, no defined process, no defined output schema, and no defined acceptance test for an individual entry.

### Issue 3
- **Location (section / step):** §1.3 "Schema decisions to lock in NOW" - JSON schemas
- **Issue description:** The manual references field names (`schema_version`, `entity_count`, `id_range`, `id_gap_policy`, `history`, `auto`, `tier`) without providing the full JSON schema for any data file (grammar.json, vocab.json, kanji.json, reading.json, listening.json, questions.json). There is no indication of required vs optional fields, types, value enumerations, or nesting structure. The "copy from N5" instruction assumes the agent has access to the N5 repo; the manual itself does not contain the schema.
- **Severity:** Critical
- **Impact on one-shot app generation:** The agent cannot generate well-formed JSON without the schema. References to fields like `examples`, `form_rules`, `meaning_en`, `meaning_ja`, `furigana`, `vocab_ids`, `audio`, `format_type`, `tier`, `level`, `topic` appear scattered across §2.2 invariants and §3 cadence but are never collected into a canonical contract.

### Issue 4
- **Location (section / step):** §1 "Day 0" + §16 "References"
- **Issue description:** The manual repeatedly says "copy from N5" / "port verbatim" / "see N5 spec" but the N5 source files (`KnowledgeBank/*.md`, `data/*.json`, `tools/*.py`, `specifications/jlpt-n5-design-system-zen-modern.md`, `.claude/CLAUDE.md`, `js/*`, `index.html`) are not bundled with the manual nor declared as required inputs.
- **Severity:** Critical
- **Impact on one-shot app generation:** A coding agent operating against this manual alone (without the N5 repo at hand) cannot satisfy any "copy from N5" instruction. The dependency is implicit. If the directive is "you also have access to the N5 repo," this needs to be stated explicitly as a precondition with a path or URL.

### Issue 5
- **Location (section / step):** §4 "Phase 3 - UI / Front-end" (entire section)
- **Issue description:** §4.1 says "no framework, vanilla static, ~3000 lines of JS across ~25 modules" but does not enumerate which modules, their responsibilities, their API contracts, or their interactions. §4.2 lists Day-1 features as bullets ("5-card Learn hub", "TOC collapsible by super-category", "SM-2 SRS in Review tab") with no design specs, no component breakdowns, no state-management contract, and no routing table.
- **Severity:** Critical
- **Impact on one-shot app generation:** The agent has feature names but no UI specifications. "Pattern detail page with prev/next nav at top corners (small font, peripheral)" is stylistic prose, not implementable. There is no wireframe, no DOM contract, no event-handler list, no localStorage schema, no CSS architecture beyond pointing at the design-system spec.

### Issue 6
- **Location (section / step):** §4.4 "Audio" + §1.1 directory structure
- **Issue description:** `data/audio_manifest.json` is referenced and `build_audio.py` is mentioned but the manifest's structure is not defined, the audio item naming convention is not specified, the relationship between `audio` paths in `listening.json` / `reading.json` / `grammar.json` and the manifest is not specified, and the per-item voice metadata (e.g., the VOICEVOX speaker-tag field documented in N5) is absent. §10 mentions "audio refs resolve" as invariant JA-15 but doesn't define what a resolvable ref looks like.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent cannot produce a runnable audio pipeline without the manifest schema. Audio is integral to listening drills; missing this blocks the listening module entirely.

### Issue 7
- **Location (section / step):** §3.2 "Anti-patterns from N5" + §6 "Phase 5 quality gates"
- **Issue description:** The manual provides 14 anti-patterns and 24 invariants (X-6.1 through JA-24) as descriptive prose but no executable specifications. For example, JA-2 says "Particle MCQs have valid particle distractors" without defining what makes a particle distractor "valid" (which particles count? which combinations are forbidden?). JA-23's "known-interchangeable particle pairs" lists `に`/`へ`, `から`/`ので`, `は`/`が` but doesn't say whether `を`/`が` (with stative predicates) or `に`/`と` (recipient vs companion) are also blocked.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent cannot implement `tools/check_content_integrity.py` without each invariant being a precise, testable rule. "Comparable density" or "manageable false-positive rate" (used in §5.4) are subjective. An invariant that cannot be unit-tested will not be enforced.

### Issue 8
- **Location (section / step):** §1.3 "tier taxonomy" + §11.1
- **Issue description:** The tier taxonomy `core_n4`/`late_n4`/`n3_borderline` is named but the rule for assigning a tier to a specific pattern is not given. There is no list of which N4 patterns belong in which tier, no decision tree, and no source authority (Bunpro? Genki? Minna no Nihongo? Imabi?). §11.3 says "plan ~30-40 such promotions" but does not list the patterns being promoted, only points at "the N5 pattern catalog `late_n5` tier" as a source.
- **Severity:** Major
- **Impact on one-shot app generation:** Tier classification is a per-pattern judgement requiring source authority. Without a defined mapping, the agent will assign tiers inconsistently or have to skip the field, breaking JA-21 (and the new N4-equivalent JA invariant referenced in §2.2).

### Issue 9
- **Location (section / step):** §0 + §11 (cross-level scaling)
- **Issue description:** The manual's claim that "N3+ is mostly content scaling" is asserted without evidence and the level transitions N3→N2→N1 are described only via the count table in §0. There is no specific content for: kanji whitelist beyond ~280 (no list for N3, N2, or N1), reading-passage authentic-style guidance, listening-pace targets, JLPT exam structure differences (e.g., N1 has no "Mondai 4 短文" in the same form), or scoring breakdown changes.
- **Severity:** Major
- **Impact on one-shot app generation:** A user generating an N3, N2, or N1 app from this manual gets the same gaps multiplied. The manual is N4-specific despite presenting itself as a generic template. An agent attempting N2/N1 would face larger, undocumented content jumps.

### Issue 10
- **Location (section / step):** §3.4 "External corpus extraction"
- **Issue description:** The manual instructs "do NOT copy verbatim into your bank - copyright" and prescribes triangulation only. But it does not provide: the URL list to extract from, fair-use boundaries, attribution requirements, or what triangulation output looks like. `tools/coverage_compare.py` is referenced as a tool to port; its inputs and outputs are not specified.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent cannot execute "extract questions from a third-party N4 site" without the source list. WebFetch operates on URLs that must be supplied. A coding agent running zero-interaction will skip this step or web-search arbitrarily.

### Issue 11
- **Location (section / step):** §2.2 "Content integrity invariants" - invariant naming
- **Issue description:** Invariants are stated under "X-6.x" and "JA-x" naming with cross-references to N5 "Pass-N" cycles ("Pass-7", "Pass-13", etc.). The Pass-N history is not contained in the manual; it's referenced as if the reader already knows what each Pass cycle did. JA-21 says "rename for N4" without specifying the new name.
- **Severity:** Major
- **Impact on one-shot app generation:** The invariant names are opaque without context, and the rename instruction is ambiguous (rename `JA-21` to `JA-21'`? to `JA-21-n4`? leave the ID and update the rule?). An agent implementing the integrity checker will produce a tool with N5-specific names baked in, contradicting "reusable across levels."

### Issue 12
- **Location (section / step):** §3.2.1 "Don't auto-generate filler MCQs"
- **Issue description:** The manual prohibits agent-generated filler MCQs but does not define what counts as filler vs. legitimate MCQ. "If you find yourself wanting to generate filler MCQs because the bank looks small: the bank is small for a reason - author real questions, or accept fewer." This is human-directed advice; an automated agent has no introspection about whether it is "wanting" to generate filler. A purely instruction-following agent might generate any number of MCQs as long as none of them match the specific failed-pattern stem.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent has no clear stop-condition for question generation. Without a target count + "stop when running out of authentic templates," the agent will overgenerate or undergenerate. The N5 number (100 per question file = 400 total) is buried in §3.3's cadence table but not declared as an authoritative target for N4.

### Issue 13
- **Location (section / step):** §3.2.3 "Don't ship 'see pattern detail' as a distractor explanation"
- **Issue description:** The manual prescribes "author all distractor explanations by hand (or LLM-author then native-review)" and provides ONE example. There is no template, no explanation-quality rubric, no length range, no language register guidance, and no enumeration of the contrasts the explanation must make.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent cannot reliably produce ~1500-2400 distractor explanations (4 per question × 400 questions, minus the correct answers) at consistent quality. Each will be ad-hoc. The manual's only quality guard is "or native review", which presumes a human in the loop and contradicts the one-shot premise.

### Issue 14
- **Location (section / step):** §1.1 directory structure - i18n / locales
- **Issue description:** The directory structure shows `locales/` and §10 references "5-locale i18n shell (en/vi/id/ne/zh)" but the manual provides no translation source files, no message catalog format, no string-extraction pipeline, no fallback policy, and no rule for handling new strings authored at N4. Translations of N4 grammar explanations into Vietnamese / Indonesian / Nepali / Simplified Chinese are not addressed at all.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent will either skip i18n entirely or generate placeholder English everywhere, breaking the stated 5-locale parity.

### Issue 15
- **Location (section / step):** §11.2 "Kanji policy escalation" - prerequisite handling
- **Issue description:** The recommendation is "include all N5+N4 in the whitelist (~280 total) and use the `tier` field on each kanji entry to distinguish prerequisite vs new." But the kanji entry's tier values are not enumerated (`prerequisite_n5` vs `new_n4`? `core_n4` vs `prerequisite`? Same tier names as grammar?). The relationship between the kanji-tier field and the grammar-tier field is not specified, and how they interact with the level-strict integrity invariants (JA-13 "no out-of-scope kanji") is undefined.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent will pick an arbitrary tier-naming convention. Subsequent CI checks will not match. The same issue compounds for N3 (must include N4+N3 prerequisites? all four?) and is not addressed.

### Issue 16
- **Location (section / step):** §10 "Zen Modern design system"
- **Issue description:** The design system spec is referenced as `specifications/jlpt-n5-design-system-zen-modern.md` and described in three lines ("hairlines not borders, no shadows, no gradients, weights 300/400/500 only"). The spec itself is not embedded. Without the spec, the agent has no design tokens, type scale, color tokens, component definitions, or page-by-page layouts.
- **Severity:** Major
- **Impact on one-shot app generation:** The UI generation step has only a one-line aesthetic constraint and a file path. Result will diverge significantly from the N5 baseline unless the spec file is provided alongside the manual.

### Issue 17
- **Location (section / step):** §2.1 "Build pipeline first"
- **Issue description:** The build pipeline is described as "KB markdown → JSON" but the parsing rules ("`^- \*\*([一-鿿]+)\*\*` for kanji headers", "section headers + entry lines for vocab", "`### Q\d+` headers" for questions) are partial regex fragments in prose. There is no full grammar for any KB markdown file, no error-handling spec for malformed input, no conflict-resolution rule (e.g., what happens if two patterns in different files share an ID?), and no idempotency definition beyond "re-running on unchanged input = no diff."
- **Severity:** Major
- **Impact on one-shot app generation:** The agent must invent the markdown grammar to write the parser. This will not be byte-compatible with the N5 build pipeline. Subsequent JSON-derived data will diverge silently.

### Issue 18
- **Location (section / step):** §1.3 "Vocab IDs"
- **Issue description:** The vocab ID format `n4.vocab.<section-slug>.<form>[.<disambiguator>]` requires a section-slug encoding. The set of valid section-slugs is not defined, the slug-derivation rule from section title is not given, and the disambiguator rule (numeric? semantic? alphabetic?) is not specified. "Cross-listed in multiple thematic sections" is mentioned but the canonical cross-listing manifest is not provided.
- **Severity:** Major
- **Impact on one-shot app generation:** Different agents (or the same agent on different runs) will produce different IDs for the same word. Cross-listings will be inconsistent. Pattern-to-vocab linkage (link_grammar_examples_to_vocab.py) will fail.

### Issue 19
- **Location (section / step):** §4.4 "Audio" + §10 "self-hosted fonts"
- **Issue description:** The manual instructs "self-hosted fonts subset to N4 kanji range" and "audio: at least listening items SHOULD be native-recorded" but provides neither the subsetting toolchain (pyftsubset? glyphhanger? a specific config?) nor the recording-pipeline spec (sample rate, format, normalization, file naming convention beyond `audio/listening/n4.listen.NNN.mp3`). Native recording is described as an external-blocked item; no fallback procedure for the agent to ship a runnable build is given.
- **Severity:** Major
- **Impact on one-shot app generation:** Either the agent will produce a build with broken audio (since native recordings can't be obtained zero-interaction) or it will use synthetic audio and be silently violating §4.4's "synthetic prosody artifacts at N5 level are tolerable; at N4 they teach learners to discriminate against synthesis artifacts." The procedure offers no defined fallback.

### Issue 20
- **Location (section / step):** §13 "Estimated total effort"
- **Issue description:** The manual states a 17-25 week solo+AI timeline. This is incompatible with "one-shot generation" by a coding agent. The manual is implicitly written for a months-long human-and-agent collaboration, not for a single-pass agent execution. There is no compressed-timeline guidance, no priority-stack identifying the minimum-viable subset.
- **Severity:** Major
- **Impact on one-shot app generation:** The agent reading the manual cannot know whether to attempt full content authoring (impossible in one shot) or scaffold-only (which violates "fully inclusive, production-ready"). The contract between manual and agent is undefined.

### Issue 21
- **Location (section / step):** §5 "Audit cadence" + §5.3 "Native teacher review window"
- **Issue description:** The manual treats native-teacher review as a required quality gate ("don't skip native review before declaring 'done'") but does not provide a fallback procedure when no native reviewer is available. §9 lists "native teacher reviewer (~10-12 hours per full pass)" as external-blocked. Per §13, native-reviewer parallelism is the difference between the 17-25w and 13-19w timelines.
- **Severity:** Major
- **Impact on one-shot app generation:** A zero-interaction agent has no native reviewer. The manual's quality contract assumes one. The agent has no documented "ship-without-review" path that would still produce a defensible product.

### Issue 22
- **Location (section / step):** §3.2.4 "Don't use ko-so-a-do without spatial context" + general question authoring
- **Issue description:** The manual gives one example of how to add scene-setting to a ko-so-a-do question but no procedural rule covering: when to add scene context, what makes scene context sufficient, the format of the scene-direction prefix (parentheses? bracketed? prose?), and which kanji policy applies to scene text (§3.2.4 example uses `自分` and `中` which are N3-N4 kanji even at N5 level).
- **Severity:** Minor
- **Impact on one-shot app generation:** Inconsistent scene-context formatting across the question bank. Not catastrophic but visibly unprofessional.

### Issue 23
- **Location (section / step):** §3.2 "Don't introduce new grammar pattern entries with the same `pattern` string" (§3.2.6)
- **Issue description:** The rule prescribes a grep before authoring but does not specify how the agent should resolve conflicts when found. "Decide: split intentionally OR retire-and-replace" pushes the decision to the human author. For a one-shot agent, there is no decision authority.
- **Severity:** Minor
- **Impact on one-shot app generation:** Agent must invent a tie-breaking rule. Risk of either silent data loss (retire without replacement) or runtime collisions (both kept).

### Issue 24
- **Location (section / step):** §1.2 "TASKS.md" + §8.1
- **Issue description:** TASKS.md is described as the "single source of truth" with very specific section structure (`Live site`, `Status snapshot`, `External-blocked backlog`, `## Pass-N`) but no template. The status-snapshot fields (corpus counts, SW version, vocab/kanji counts, route list) are not enumerated. Update rules ("update on every significant change") are not formally testable.
- **Severity:** Minor
- **Impact on one-shot app generation:** Agent will produce a TASKS.md that diverges in structure from N5. Subsequent Pass-N audits referenced in §5 will operate on a different format than expected.

### Issue 25
- **Location (section / step):** §15 "Open questions / decisions to make for N4"
- **Issue description:** Six unresolved decisions are listed (native voice budget, handwriting, IME-typing, speed-test mode, mock-test timing, monetization) and labeled as blocking ~1-2 weeks of architecture each. The manual does not declare default decisions for an agent operating without a human stakeholder.
- **Severity:** Major
- **Impact on one-shot app generation:** A zero-interaction agent encountering "decide before week 4 of the build" has no decider. Either the agent halts, picks defaults arbitrarily, or omits these features entirely. Either way, output is not "production-ready."

### Issue 26
- **Location (section / step):** §2.2 invariants table - JA-3 (Furigana / catalog match)
- **Issue description:** Furigana handling is mentioned as an invariant ("furigana annotations match catalog entries") but no procedure for *generating* furigana annotations is given. Should the agent generate them per-example via mecab/kuromoji? Per-passage? Manually? The "three-mode furigana" toggle described in §10 implies runtime CSS-based hide/show requires `<ruby>` markup, which is upstream content authoring.
- **Severity:** Major
- **Impact on one-shot app generation:** Furigana coverage at N4 is critical (most passages mix N4 and N5 kanji). Without a generation procedure, the agent will either produce no furigana, machine-generated furigana with errors, or inconsistent partial coverage.

### Issue 27
- **Location (section / step):** §2.2 "Content integrity invariants" - JA-2 particle distractors, JA-23 multi-correct scanner
- **Issue description:** The two particle-related invariants overlap and partially contradict. JA-2 requires "valid particle distractors" but JA-23 says certain pairs are flagged for native review. The interaction (does flagged-by-JA-23 fail JA-2? does JA-23 flag mean reject or just review?) is not defined.
- **Severity:** Minor
- **Impact on one-shot app generation:** The CI tool implementation has ambiguous behavior. Agent will pick one interpretation, possibly the lenient one, leaving multi-correct bugs in shipped questions.

### Issue 28
- **Location (section / step):** §6.1 "Run the integrity check on every commit"
- **Issue description:** The instruction "if a fix introduces a violation, fix the data OR add the kanji/particle/construct to the appropriate augmented set in the integrity check tool with a comment explaining why" describes a human escape valve. An agent has no way to determine which path to take, and the second path (add to augmented set) effectively allows the agent to silence checks while pretending to comply.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent will likely take the easy path and add exceptions to the augmented set, eroding the integrity contract over the run. The manual provides no test for whether an exception is "legitimately in N4 scope."

### Issue 29
- **Location (section / step):** §10 "SM-2 SRS"
- **Issue description:** The SM-2 SRS is specified by name and four button labels (Again/Hard/Good/Easy) with verified intervals (1d/6d/15d, lapse → 1d + EF drops). Several specifics are missing: initial EF value, EF formula, what "lapse" precisely triggers, persistence schema (localStorage key shape?), recovery behavior when localStorage is cleared, cross-device merge semantics on import.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent will produce an SM-2 implementation that diverges from N5's at the parameter level. Different intervals = different review experience = failed parity with N5 baseline.

### Issue 30
- **Location (section / step):** §10 "Diagnostic Summary"
- **Issue description:** "Diagnostic Summary with error patterns + recommended next session + session log" is one line. Error-pattern detection algorithm, "recommended next session" recommendation logic, session-log retention policy, and the UI surface for the Diagnostic Summary are all undefined.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent cannot implement a feature defined only by name. Will produce a placeholder or skip the feature.

### Issue 31
- **Location (section / step):** §1.1 directory structure - missing test directories
- **Issue description:** The directory layout shows `tools/test_build_data.py` but no test directory for the front-end (`tests/`, `e2e/`, etc.). §10 says "browser-runnable test suite (37 tests in N5) - JS + Playwright smoke tests. CI gate." The location and structure of these tests is not defined. The Playwright config, the test framework, and the test list are absent.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent cannot reproduce the 37-test suite as a CI gate. Without it, the "CI gate" requirement is unverifiable.

### Issue 32
- **Location (section / step):** §10 "PWA manifest + service worker stale-while-revalidate"
- **Issue description:** The PWA spec is one line. No manifest field list, no icon-set specification, no precache list, no runtime caching strategy beyond "stale-while-revalidate", no offline fallback policy.
- **Severity:** Minor
- **Impact on one-shot app generation:** Agent will produce a working but ad-hoc service worker. Diverges from N5's `jlpt-n5-tutor-v71` versioning convention referenced in §4.3.

### Issue 33
- **Location (section / step):** §0 + §11.3 - "Borderline grammar promotion"
- **Issue description:** The instruction to promote ~30-40 N5 borderline patterns to N4 core requires retrieving the N5 `late_n5` tier list. That list is not embedded in the manual. The "rename for N4" guidance for invariant JA-21 (§2.2) similarly requires the N5 invariants doc that the manual references but does not contain.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent must first generate or re-discover the N5 `late_n5` set, which is N5 corpus knowledge not in the manual. Without it, the migration manifest cannot be built.

### Issue 34
- **Location (section / step):** §5.4 "LLM audit as a multiplier"
- **Issue description:** The procedure says "use Claude API integration; cost ~$11.50/pass; caught 1.0 finding/pattern." It does not provide the prompt template, the API key handling, the rate-limit strategy, the output parsing rule, or the criteria for "manageable false-positive rate."
- **Severity:** Minor
- **Impact on one-shot app generation:** LLM audit is presented as a continuous quality input but cannot be implemented from the manual. Production readiness without it depends on native review which the agent can't access.

### Issue 35
- **Location (section / step):** §1.1 - i18n locale files location
- **Issue description:** Directory shows `locales/` but no naming convention (locales/en.json? locales/en/grammar.json? per-locale subdirectories?), no key path convention, no source-locale-of-truth declaration. The 5-locale i18n needs translation pipelines that the manual does not describe.
- **Severity:** Major
- **Impact on one-shot app generation:** i18n is structurally undefined. Agent will either skip it (violating §10's stated win) or invent a convention (diverging from N5).

### Issue 36
- **Location (section / step):** §2.1 build pipeline (input contract for KB)
- **Issue description:** The build pipeline must parse KB markdown but the markdown file structure for each KB file (grammar_n4.md, vocab_n4.md, etc.) is not specified. We learn fragments: grammar files use `- **(kanji)**` headers, vocab uses `(Reading) - (Meaning)` lines, questions use `### Q\d+`. The complete grammar of each file (section ordering, optional fields, allowed inline syntax) is not provided.
- **Severity:** Critical
- **Impact on one-shot app generation:** Agent cannot author KB files in a format guaranteed to be parsed correctly without seeing existing N5 files. "Copy from N5" applies again.

### Issue 37
- **Location (section / step):** §3.3 "Authoring cadence" - questions
- **Issue description:** The cadence row "8-10 weeks: Questions (moji + goi + bunpou + dokkai) - 100 each = 400+ questions" omits chokai (listening) and any auth_extracted_n4 corpus. Listening is split out into its own KB file per §1.1 but no question count is specified for it. The mapping between question count and JLPT exam structure (Mondai 1-N for each section) is not documented.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent has no definition of how questions partition by Mondai subtype, leading to under- or over-coverage of test sections. Mock-test mode (referenced in §4.2 Day-1 features) requires this partition.

### Issue 38
- **Location (section / step):** §4.2 "Test mode" + §10 "Mock JLPT-format exams"
- **Issue description:** "Test mode (mock-test flow, hides answer/rationale until commit)" is one line. The actual JLPT exam structure for each level (number of mondai, time per section, scoring breakdown, passing threshold) is not enumerated. N5 passing is 80/180 with section thresholds; N4 is 90/180; N3 is 95/180; etc. None of these are in the manual.
- **Severity:** Major
- **Impact on one-shot app generation:** Mock-test mode cannot mirror real JLPT format without the exam-structure table. Agent will produce a generic timed quiz, not a level-faithful mock test.

### Issue 39
- **Location (section / step):** §3.4 + §10 "External-blocked items"
- **Issue description:** Several items are tagged External-Blocked: native voice talent (§9.1), native teacher reviewer (§9.2), translation (§9.3), recommender ML (§9.4). The manual offers no synthetic-fallback specification that an agent could ship as a stop-gap producing a usable (if degraded) build.
- **Severity:** Major
- **Impact on one-shot app generation:** Without fallback, the agent must either skip these features entirely or produce broken stubs. Either way, "production-ready" is unattainable in one shot.

### Issue 40
- **Location (section / step):** General - no top-level "what does done look like" definition
- **Issue description:** The manual has cadence tables, anti-pattern catalogs, and invariant lists, but no single section says: "the N4 app is complete when X, Y, Z conditions are met, observable via these specific automated checks." Definition-of-Done is implicit and distributed.
- **Severity:** Major
- **Impact on one-shot app generation:** Agent cannot self-evaluate whether it has finished. Will either over-deliver scope-creep or under-deliver while believing the work is done.

---

## E.2 Final Summary (from review document, 2026-05-01)

### Overall readiness for one-shot generation

**Low** (at review time, 2026-05-01).

The manual was best understood as a *retrospective playbook* written for a human team that has already shipped N5 and is preparing to repeat the process for N4 with the N5 repository in hand. It was not, as written, a self-contained specification. The repeated "copy from N5", "port verbatim", "see N5 spec", "as in N5" instructions presupposed the N5 source files were co-resident and human-readable; without them, the manual was approximately a table of contents.

For the manual to be sufficient for one-shot agent generation, three categories of content needed to be added: (a) the actual N4 content inventories that the manual treated as known (kanji list, vocab list, grammar pattern list with tier assignments), (b) the schema and format specifications the manual treated as inheritable from N5 (KB markdown grammar, JSON schemas, file conventions), and (c) the executable specifications for features and invariants that the manual stated as prose summaries (UI module breakdown, SM-2 parameters, multi-correct rules, fallback procedures for external-blocked items).

**Post-review note (2026-05-14):** the manual has been extensively revised since 2026-05-01. §18 of this manual tracks per-issue disposition: 15 closed in this pass, 15 deferred to Pass-21, 8 closed-by-pointer, 2 P0 structural concerns. Appendices A-D and §19-§20 add the missing executable specifications, schemas, and inventories. The "one-shot readiness" status improved from Low to Acceptable for Mode-A (human+repo co-resident) and Partial for Mode-B (one-shot agent with no human in loop).

### Highest-risk gaps preventing full app creation (review-time concerns)

1. **N4 content inventories are not embedded.** The agent does not know which kanji, vocabulary items, grammar patterns, and tier classifications constitute N4. (Issues 1, 8, 33)
2. **Data and KB schemas are referenced but never defined.** No JSON contract, no markdown grammar. (Issues 3, 17, 36)
3. **N5 source files are required dependencies but not declared as inputs.** "Copy from N5" appears 14+ times. (Issues 4, 16)
4. **UI is described by feature names only.** No module list, no DOM contracts, no state schema, no design tokens beyond a one-line aesthetic. (Issues 5, 16, 30, 31)
5. **External-blocked items have no zero-interaction fallback.** Native audio, native review, translation pipelines are all human-dependent. (Issues 19, 21, 39)
6. **No definition of done.** Agent cannot self-assess completion. (Issue 40)

### Areas that need explicit procedural definition

- Full N4 content inventories (kanji whitelist, vocab whitelist, grammar pattern catalog with tier).
- Complete JSON schemas for `data/*.json` files, with field types, enums, required/optional flags.
- Complete KB markdown grammar for each KB file type.
- Full design-system spec (or full inclusion of `jlpt-n5-design-system-zen-modern.md`).
- UI module list with responsibilities and contracts.
- SM-2 parameters with exact constants.
- Translation source-locale file format and string-extraction procedure.
- JLPT exam structure table per level (mondai breakdown, time, scoring threshold).
- Mock-test mode behavior contract (which questions are pulled, in what proportions, with what timing).
- Furigana-generation procedure (manual? automated? from which library?).
- Complete invariant rules in machine-testable form (regex, AST checks, value-set membership).
- Audio manifest schema and fallback (synthetic OK at what quality? when?).
- Definition-of-done for the build.
- Default decisions for each of the §15 open questions, so a zero-interaction agent has answers.
- Question-count budget per Mondai per file.
- ID generation rules (slug derivation, disambiguator, cross-listing manifest).

### Areas that were already strong and reusable across levels

- **§3.2 anti-pattern catalog.** The bumper-sticker list of failure modes (filler MCQs, interchangeable-particle pairs, ko-so-a-do without context, simultaneous parallel-session edits) is concrete, evidence-based, and level-agnostic. Useful for any level.
- **§2.2 invariants table.** Even though individual invariants need rule-level definition, the *list* of catch-points is comprehensive and well-organized. Adding three more for N4 (JA-22..JA-24) is a clean extension model.
- **§7 tooling priority order.** The ranked list of scripts to port is actionable and would help an agent decide what to build first.
- **§14 anti-patterns bumper-sticker list.** Concise rules useful as a final sanity-check pass before declaring a level done.
- **§8 process discipline (TASKS.md / commit / backup / MEMORY.md).** Project-management hygiene that scales cleanly across levels.
- **§9 external-blocked anticipation.** The four EB items are correctly identified up front; the schedule guidance (month 1 reviewer, month 3 voice talent) is concrete enough to plan around.
- **§11.1 tier-taxonomy three-tier model** (`core_n4` / `late_n4` / `n3_borderline`). Clean abstraction that scales: at any level X, the three tiers are `core_X`, `late_X`, `(X-1)_borderline`.
- **§13 effort estimates with multiplier for higher levels.** Provides realistic scoping guidance and the 1.5x-per-level rule is a defensible heuristic.

These strong sections collectively constituted roughly 30-40% of the manual's value at review time. The remaining 60-70% needed the missing-content additions enumerated above; that content has subsequently been embedded inline in Appendices A-D and §19-§20.

---

*Appendix E migrated 2026-05-14 from a standalone `procedure-manual-review-issues.md` file. The original review was conducted 2026-05-01 with a zero-interaction one-shot lens. Issue dispositions are tracked in §18 of this manual; the full original text above is preserved for verification of each disposition against the original concern.*

---

# Appendix F — Content audit saturation methodology (2026-05-15 N5 session)

This appendix captures the methodology from the 2026-05-15 audit-fix-
iterate cycle on N5 — **27 audit rounds, 2,061 content fixes within
the audit categories defined this session, 9 new CI invariants
(JA-81→JA-90), state at the most recent commit: 93/93 invariants green**
*against the current invariant set*. "Green" means the checks we have
written pass on the current corpus — it does not assert universal
correctness.

For Nx level builders: apply this methodology AFTER the first authoring
pass produces a working corpus (~Phase 4 in §C.14's ordering), not
before. The cycle takes ~3-5 sessions; expect it to surface
~1,500-2,500 fixes if the LLM-authored content was templated similarly
to N5's was.

## F.1 The audit-fix-iterate cycle (binding methodology)

**One cycle = one audit class, iterated until the checker for that
class returns 0 real findings.** "0 real findings" means the checker
finds nothing matching its currently-defined pattern set — it does
not mean the corpus is defect-free against the broader concept the
checker is approximating. A new finding-class may exist outside the
checker's scope; this is handled by adding a new audit class
(another cycle), not by claiming the existing one is complete.

```
1. Author audit checker (e.g., not-required/tools-archive/audit_XX.py)
2. Run checker → produce finding list
3. Triage:
   - REAL: items to fix
   - FALSE-POSITIVE: items to suppress in checker (document FP)
4. Author fix script (not-required/tools-archive/fix_XX.py)
5. Backup the target data file (data/X.json.bak_YYYY_MM_DD_purpose)
6. Apply fix script
7. Run CI (tools/check_content_integrity.py) — must stay green
8. Re-run checker → confirm 0 real findings
9. If new findings emerge → GOTO step 4 with a new round (Round 2)
10. When converged, write CI invariant JA-NN to lock the gain
11. Commit + push (one cycle = one commit)
```

**Saturation definition:** a checker is **saturated against its
current pattern set** when ALL of:
- It returns 0 real findings on the live corpus.
- Every documented false-positive class is suppressed in the checker.
- A CI invariant prevents re-introduction of the specific patterns
  this checker scans for.
- A second-pass run from a fresh seed produces no new findings.

**Important:** "saturated" here = *this checker has nothing left to
find with its currently-defined regex / lookup table*. It does NOT
mean the corpus is free of defects of the broader kind the checker
approximates — only that the **named patterns** are absent. A new
template, a new error class, or a native-human review may surface
items the checker doesn't recognize. Write Nx audit docs with the
qualifier ("saturated against this prompt's pattern set"); never
write "saturated" bare. See N5/prompts/Japanese language Accuracy
check.txt → WRITING DISCIPLINE FOR AUDIT DOCS for the full rewrite
table.

Anti-pattern: declaring saturation after one clean run without the
fresh-seed re-run. The 2026-05-14 vocab audit caught a NEW template
(`Xを 見ました`) only after the structural audit had already declared
clean — because the checker was too narrow. The lesson generalizes:
"saturated" is always against the current pattern set; the pattern
set itself can be incomplete.

## F.2 Template-leak anti-pattern family — predict these on Nx

The 2026-05-15 N5 session caught **8 distinct templated-example
patterns** across vocab/grammar/listening/papers — totaling ~860 fixes.
These 8 are *the ones we caught*; more may exist at any level that
weren't named here. For Nx level: build checkers for these BEFORE
the first audit pass, AND extend the catalog when new templates surface.

| Template | What it looks like | Where caught |
|----------|-------------------|--------------|
| **T1: object-saw** | `Xを 見ました。` / "I saw X." | 108 vocab entries at example[1] |
| **T2: doko-non-loc** | `あの Xは どこですか。` / "Where is that X?" with X = non-location (time word, person, abstract noun → nonsense English) | 111 vocab + 5 grammar |
| **T3: kore-bare** | `これは Xです。` / `あれは Xです。` on entries with 3+ examples, NOT for demonstrative-pronoun entries themselves | 178 vocab entries |
| **T4: aisatsu-non-greeting** | `「X」と あいさつしました。` where X is not a greeting (えーと, いいえ, ええ — filler words misclassified as greetings) | 12 vocab entries |
| **T5: every-day-can-do** | `毎日 X ことが できます。` "I can VERB every day" — often nonsense for non-volitional verbs (こまる/くもる/おちる) | 28 vocab verb entries |
| **T6: tomorrow-plan** | `あした X つもりです。` "I plan to VERB tomorrow" — wrong for intransitive verbs (はじまる/しまる/おちる) | 30 vocab verb entries |
| **T7: bare-article-EN** | `Xが あります。` / "There is X." (singular common noun, no article) — animacy bug if X is animate | 74 vocab entries |
| **T8: verb人がいます** | `<verb-dict>人が います。` / "There is a person who to <verb>" — infinitive in relative clause | 24 vocab verb entries |

For each, the checker regex is documented in
`N5/prompts/Japanese language Accuracy check.txt` §§A18-A45. **Copy these
regexes verbatim to Nx and run before authoring fixes** — saves 50-90%
of the iteration cost *for the patterns these specific regexes match*.
Templates that aren't in this 8-row table will not be caught by these
regexes; sample-based review at Nx may surface additional templates
that should be added.

## F.3 False-positive catalog discipline (FP-1 through FP-15)

Whenever an audit checker over-flags, document the FP class in the
audit prompt before suppressing in code. This catalog accumulates as a
permanent reference. N5's FP list (FP-1 → FP-15) is in
`N5/prompts/Japanese language Accuracy check.txt`.

**Recurring FP classes Nx will hit:**

| FP | Why it false-flags | Mitigation |
|----|--------------------|------------|
| ウ音便 contraction (o+u→ō spelling stays as -ou) | Looks half-applied but is correct | Vowel-before-u check |
| Past-marker mid-sentence (relative clause) | Naive end-of-sentence check misses inside-clause | Allow non-sentence-end past markers |
| Mixed kanji/kana orthography | Real style issue, not accuracy bug | Surface as style note |
| Cross-pattern reuse below threshold-10 | Below JA-81 cap is legitimate canonical reuse | Threshold ≥10 |
| Counter rendaku (ひき→びき, はい→ぱい) | Phonological alternation, not absence | Rendaku alternant set |
| Compound -くる verbs (もってくる → もってきて) | Auxiliary くる conjugates; stem extraction misses | Compound-くる stem expansion |
| Demonstrative-pronoun entries' bare 'これは X' template | THE canonical demonstration of these headwords | Section/pos exception |
| Parenthetical annotations after translations | "(polite)", "(formal)" trailing the sentence | Strip `\s*\([^)]*\)\s*$` before terminator check |
| authentic.json reading is FULL phrase | Multi-word signage like 'コーヒー さんびゃくごじゅうえん' | Apply check only when ja == single vocab form |
| English rationales lack JA char overlap | Translation explanations naturally don't share chars | Manual triage for misalignment |
| ひとりでに ("by oneself") | Fixed compound adverb, not particle stack | `(?<!ひとり)でに` lookbehind |
| 〜いです IS correct polite-i-adj | NOT the wrong くて conjunction | Exclude `で(?=す)` from triggers |
| 倍 (ばい) | Multiplier suffix, not noun-counter | Exclude from counter pairing scan |
| i-adj inflected forms (くて/く/かった) | Still demonstrate the headword | Strip final い for stem match |
| ぜひ/ただ + neutral declarative | Pedagogical-quality, not grammar bug | Treat as "should improve" only |

## F.4 Schema-type discrimination across question-shaped corpora

Question-shaped JSON files (questions.json, drills_auto.json,
papers/*/paper-*.json) have multiple `type` values that use DIFFERENT
field sets. A blanket required-fields check will false-flag legitimate
variants.

```python
# questions.json
if q['type'] == 'mcq':
    # uses question_ja + choices + correctAnswer + distractor_explanations
elif q['type'] == 'sentence_order':
    # uses tiles + correctOrder (NO question_ja, NO correctAnswer)

# drills_auto.json
if q['type'] == 'cloze':
    # has stem (Japanese with blank) + correctAnswer
elif q['type'] == 'production':
    # has prompt_en (EN→JA typing); NO stem
```

For Nx: build the audit checker with `type` branching from the start.
N5's mega-audit checker (not-required/tools-archive/audit_mega.py) is
the reference implementation.

## F.5 Locale-parity gaps — predict and lock

The most reliable bulk-fix class is "EN populated, HI empty" (or
vice versa). Audit each pair:

| File | EN field | HI field | CI gate |
|------|----------|----------|---------|
| reading.json questions | explanation_en | explanation_hi | JA-85 |
| authentic.json items | context | context_hi | JA-86 |
| questions.json mcq | distractor_explanations | distractor_explanations_hi | JA-86 |
| papers/dokkai questions | rationale | rationale_hi | JA-85 |
| vocab.json entries | gloss | gloss_hi | (covered by JA-39 set membership) |

**Expected scale at Nx (extrapolating from N5):** ~150-400 missing
HI entries. Author them en masse using a single fix script with
provenance `llm_curated` (truthful — not native-Hindi-reviewed).
Add CI gate immediately to lock the gain.

## F.6 Native-teacher 4-phase audit methodology

After structural saturation against the current checker set (template-
leak, locale parity, schema shape — i.e. these specific checkers all
return 0), apply the deeper linguistic pass:

### Phase A — Programmatic deep-linguistic checks (6+ categories)

Build regex/lookup checkers for:
- L1: Counter-noun semantic pairing (本→cylindrical, 枚→flat, 冊→books, 個→general, 人→people, 匹→small animals, 頭→large animals, 台→machines, 杯→liquid cupfuls, 足→footwear)
- L2: Adjective conjugation (i-adj uses くて/くない; な-adj uses で/じゃない)
- L3: Time-particle accuracy (毎日/毎週/今日 take NO particle)
- L4: Discourse register coherence (no mixed plain だ + polite です)
- L5: Verb-group conjugation correctness
- L6: Honorific お/ご prefix on appropriate noun class

### Phase B — Sample-based deep review + programmatic extension

Random-sample ~80 sentences across corpora. Per-sentence native-
teacher judgment. Whatever specific bug you spot → extend the
programmatic scan to all corpora.

### Phase C — JLPT-format authenticity (papers only)

Mondai distribution, stem-format conformance, distractor pedagogy.
0 expected findings if papers were authored from real JLPT samples.

### Phase D — Best-effort review of "human-only" dimensions

Pitch accent, idiomatic naturalness, register coherence in dialogue,
audio-script alignment. Document confidence-low items rather than
auto-fixing.

**Expected total at Nx:** ~100-300 fixes across all 4 phases.

## F.7 External-reference cross-check pattern (pitch accent example)

For dimensions where my (LLM) confidence is genuinely low (pitch
accent drop position, prosody, regional accent variation), use an
external authoritative dataset to cross-validate.

**Pattern (added 2026-05-15 from pitch-accent reconciliation):**
1. Locate a permissively-licensed reference dataset (e.g., kanjium
   pitch-accent for Japanese; UD treebanks for syntactic features).
2. Fetch + version-pin to a specific upstream commit SHA.
3. Save to `data/<level>_<feature>_reference.json` with full `_meta`
   block (source, license, downloaded_at, consumers,
   regenerate_with).
4. Build a refresh tool in `tools/` (persistent) for re-fetching.
5. Build a one-shot reconciliation script in
   `not-required/tools-archive/`. For each corpus entry, classify:
   - MATCH (reference exists, value agrees) → confidence='high'
   - DISAGREE (reference differs) → fix to reference,
     confidence='high', source=ref
   - AMBIGUOUS (reference has alternates) → keep current if listed,
     confidence='medium'
   - NOT_FOUND (not in reference) → keep current,
     confidence='unverified'
6. Add a `confidence: 'high'|'medium'|'low'|'unverified'` field to
   every entry (Option C — transparency without data change).
7. Add CI invariant JA-NN that enforces:
   `(confidence='high' AND value == reference[entry])
   OR confidence in {'medium', 'low', 'unverified'}`

**Why this works:** for the ~95% of entries the reference covers,
gives high-confidence values. For the long-tail ~5%, marks them
explicitly `'unverified'` so future native-human review can
prioritize.

For Nx: do this in cycle 4 or 5 (after structural + linguistic checks
return 0 against their current pattern sets). Estimated effort: 1-2
sessions, ~50-300 fixes within the cross-reference dimensions chosen.

## F.8 Audit-coverage disclosure pattern

After audit saturation against the current pattern set, commit a
transparent disclosure document: `docs/AUDIT-COVERAGE-YYYY-MM-DD.md`.

**Required sections:**
1. Auditor persona (who, with caveats about non-native limitations)
2. Coverage matrix — what was programmatically validated vs sampled
   vs unchecked, **each row bounded by what was scanned** (regex
   pattern named, sample size disclosed, external reference cited)
3. Confidence levels per dimension, with the basis for the
   confidence label (e.g. "High *for the patterns scanned*" not
   "High" bare)
4. Items deferred to native-human review (with rationale per item
   and explicit "unverified" labeling, not "presumed correct")
5. CI invariants added (JA-NN list with "prevents re-introduction of
   <named pattern>" framing — not "locks gain" framing)
6. **Writing-discipline note at top** — explicit statement that
   coverage claims are bounded by what was measured; absolutist
   phrasing like "every / all / complete / final / saturated" should
   always be read with the implicit qualifier "against what we
   measured"

**Why this matters:** the project's quality contract becomes
explicit. Future contributors (or institutional adopters) can see
what's verified vs what still needs human review, without having to
re-discover gaps. Crucially, the disclosure must NOT overclaim — a
future JLPT exam or native review may surface items outside the
audit's defined categories, and the disclosure's prose must not
imply those couldn't exist.

N5 reference: `N5/docs/AUDIT-COVERAGE-2026-05-15.md` and
`N5/docs/AUDIT-REPORT-NATIVE-TEACHER-2026-05-15.md`. See also the
WRITING DISCIPLINE FOR AUDIT DOCS block in
`N5/prompts/Japanese language Accuracy check.txt` for the explicit
rewrite table that translates absolutist phrasings into bounded ones.

## F.9 CI invariant growth pattern — prevent re-introduction of the specific patterns caught

Every audit cycle that produces ≥1 fix MUST add a CI invariant that
prevents *re-introduction of the specific named patterns* caught.
Without this, future authoring batches re-import the same anti-
patterns. N5's session went 81 → 93 invariants (+12 net) across 27
audit rounds; this is the right ratio.

**Important framing:** a CI invariant does NOT "lock the gain" in
the absolute sense. It prevents the named-and-coded patterns from
re-appearing. A new template, a new error class, or a renaming of an
existing pattern can bypass an invariant whose regex doesn't recognize
the new shape. The growth pattern is therefore: each audit cycle
catches new patterns → each new invariant prevents *those new
patterns* → the catalog of "things we have prevented" grows
monotonically, while "things we have not yet thought to prevent"
remains open-ended.

**Invariant naming convention:** `JA-NN` where NN is monotonically
increasing. Embed the audit pass date in the description string for
audit-trail. Use a single check function with multiple LOCK sub-
patterns when one audit cycle removes multiple distinct anti-
patterns (N5 JA-89 has 5 sub-locks for the native-teacher pass).
Each lock should be documented as "prevents re-introduction of
<pattern A36>" or similar — never as "ensures correctness of <X>"
since that overclaims.

## F.10 N5 kanji whitelist authoring guardrail — extends to any Nx

When AUTHORING replacement content in fix scripts, pre-validate
against the level's kanji whitelist. Common LLM-source kanji that
LOOK N5-or-lower but actually aren't (N5 examples, but the pattern
applies at every level):

```
公 園 多 少 物 魚 兄 弟 姉 妹 牛 茶 米 肉 元 漢 達 始 教 仕 事 用
体 切 海 静 玄 関 音 字 開 部 屋 家 京 紙 朝 昼 夜 晩 雪 鳥 犬 猫
馬 春 夏 秋 冬 早 帰 飛 都 兄 回 色 光 走 玉 枚 知 引 好
```

**Rule of thumb:** if unsure, use kana. Kana NEVER trips the JA-13
(or analogous) out-of-scope-kanji invariant. The N5 vocab Round 4
batch initially shipped 38 OOS-kanji uses that had to be reverted
to kana on a second pass — pre-validation in the fix script would
have caught these before the apply step.

**For Nx:** build the OOS-kanji list for level X before the first
authoring batch. Embed it in fix scripts as a pre-check.

## F.12 TTS pipeline pitfall — bunsetsu spaces drop particles via OpenJTalk pause boundaries (2026-05-14 N5)

**Failure class:** the audio renderer for grammar examples
(`tools/build_audio_voicevox.py`) passed the displayed `ja` field
directly to VOICEVOX without any text normalization. The displayed
text uses JLPT-textbook bunsetsu spaces for learner readability
(e.g., `コーヒーと こうちゃを かいました。`). VOICEVOX uses OpenJTalk
under the hood for prosody analysis; OpenJTalk treats each space as
a hard token boundary and inserts an inter-bunsetsu pause. The
particle trailing a bunsetsu (e.g., the を at the end of `こうちゃを`)
gets stress-weakened or devoiced at the pause boundary, making it
**inaudible** to learners even though VOICEVOX correctly identifies
the particle's /o/ phoneme in its accent_phrases response.

**Symptoms:**

- Display reads: `コーヒーと こうちゃを かいました。`
- Audio sounds: `コーヒーと こうちゃ かいました。` (を inaudible)
- Phoneme analysis (`/audio_query` returns `コオヒイト[PAUSE]
  コオチャオ[PAUSE]カイマシタ`) confirms the /o/ IS rendered — the
  issue is prosodic stress, not lexical drop.
- File size: spaced-input renders are ~50% LARGER than stripped-input
  renders because of the inserted pauses (e.g., 47277 B → 31149 B for
  the same 9-syllable sentence).

**Root cause:** legacy gTTS-era renderer (`build_audio.py`) already
had a `normalize_for_tts()` step that stripped ASCII / full-width
spaces for exactly this reason. When the corpus flipped to VOICEVOX
(N5 commit `c28266d`, 2026-05-12 batch re-rendering 1782 grammar
example MP3s), the new renderer SKIPPED that step — the patch shipped
without the normalize pass. Latent bug: nobody noticed until a
learner reported `を` was inaudible on a specific example.

**The fix (per-pipeline, ~3 LoC):**

```python
# Inside the work-building loop, before passing text to VOICEVOX:
text = text.replace(" ", "").replace("　", "").replace("\t", "")
```

Apply BEFORE `synth_segment(text, ...)`. Comment must call out the
display-vs-audio convention so the next maintainer doesn't strip it
again.

**Corpus-wide impact:** the bug affected ALL 1782 grammar example
renders in the 2026-05-12 VOICEVOX batch. Single-file fix (the
reported example) is insufficient — every spaced bunsetsu+particle
in the corpus may have weakened audio. Resolution requires a
corpus-wide `--force` re-render after the script is patched. N5
swept the full 1782 on 2026-05-14 (~15 min on CPU with 4 workers).

**Generalization for Nx:**

1. **Any TTS pipeline that consumes display text MUST normalize
   whitespace before rendering.** Add this to the pipeline's docstring
   AND to a CI check that compares Nx's audio-render hashes against a
   known-good stripped-input baseline.
2. **gTTS, VOICEVOX, edge-tts, Azure JA, OpenAI TTS** — all OpenJTalk-
   or morphological-analyzer-based engines exhibit the same pause-
   boundary behavior. Cross-pipeline lesson, not VOICEVOX-specific.
3. **Display convention != audio convention.** Display fields can
   keep learner-readable spacing; audio pipeline reads the same field
   and strips spaces at render time. NEVER author a separate
   `script_for_audio` field — it creates a drift class (the N5 corpus
   already had the related "wrong script source" failure class
   documented at §3.2.X / D.9.24 family).
4. **Render-time normalization is THE place for this — not at
   authoring time.** Stripping spaces from `ja` at authoring time
   breaks the bunsetsu-spaced learner display. The display+audio
   split is intentional; the renderer must bridge it.

**Detection in audit prompts:**

- For each grammar example with audio: render the text via the same
  VOICEVOX `/audio_query` endpoint with both spaced and stripped
  inputs. Compare the `accent_phrases` response. If `pause_mora`
  count differs by ≥2, the spaced version has extra inserted pauses
  → likely particle-devoicing risk. Phase-0 check candidate.
- Spot-sample 5-10 grammar example MP3s per audit cycle: listen to
  full sentence, verify every displayed kana is audible. Native ear
  required.

**Why an existing FP class did NOT cover this:** §3.2.18 (TTS prosody
artifacts) covered tone/pitch contour issues, not particle audibility.
The bunsetsu-pause-devoicing class is new for the audio surface
specifically.

## F.14 Writing discipline for audit prose (added 2026-05-15)

The 2026-05-15 N5 session's audit output, on first draft, used
absolutist language that overclaimed coverage: "every Japanese
example," "0 real findings," "RESOLVED," "Final CI count," "closed
enum," "saturated." When the maintainer reviewed the docs, the
question raised was: *"what if a JLPT exam includes items outside
what we audited for?"* The honest answer is that the docs implied
universal coverage but the audits were bounded by specific patterns
and sample sizes. The fix was a rewrite pass against an explicit
banned-word list.

**For Nx builders:** apply the same discipline from day one. The
rewrite table (translating "every X" → "every X in the corpus
snapshot scanned", etc.) is in
`N5/prompts/Japanese language Accuracy check.txt` → WRITING DISCIPLINE
FOR AUDIT DOCS section. The corresponding regression check (Phase-0
scan for banned phrases in audit-coverage docs) is in
`N5/prompts/N5Improvement.txt` → Phase-0 Audit-doc writing-discipline
scan.

**Key principle:** the work itself is honest — the audits did what
they did, against bounded inputs. Only the prose drifts when authors
reach for terminal-sounding words ("complete", "final", "RESOLVED")
to summarize. The prose must match the bounded scope of the work.

**Banned phrasings + their replacements (short form):**

| Banned (in audit docs) | Use instead |
|----|----|
| "every X" / "all X" | "every X *in the corpus snapshot scanned*" |
| "0 findings" | "0 findings *against the N patterns scanned*" |
| "RESOLVED" / "final" / "complete" | "addressed for M of N items in scope" |
| "closed enum" | "closed against currently-observed values" |
| "JA-NN locks the gain" | "JA-NN prevents re-introduction of these specific patterns" |
| "saturated" / "converged" | "checker returns 0 against current pattern set" |
| "Final CI count: N" | "CI invariants at this checkpoint: N" |
| "Statistically ≥95% likely natural" (from sub-2% sample) | "sample surfaced 0 issues; remainder unverified" |

**Why it matters at every level:** future Nx readers, native
reviewers, institutional adopters, and learners read audit docs as
quality-coverage claims. Terminal language → false confidence →
"the team said this was complete" when the exam surfaces an item
class. Bounded language preserves the project's trust contract.

## F.15 Verb-class particle disambiguation in wcp / common_mistakes entries (added 2026-05-16)

**Failure class:** wrong_corrected_pair (wcp) and common_mistakes
entries that disambiguate Japanese particles by VERB class can
mislabel an N5-canonical form as "wrong" when the rationale conflates
two distinct verb classes. Caught on a user-reported bug in N5
(BUG-002, 2026-05-16): pattern `n5-008` (LIST-EXHAUSTIVE と) had a
wcp entry stating:

  wrong: ともだちに あいました。 (X "I met with my friend" intent)
  correct: ともだちと あいました。
  why: 会う meaning "meet (mutual)" takes と; に is grammatical but
       more like "happen to encounter".

This is wrong on two counts:

1. **会う is N5-canonical with に**, not と. Genki I, Minna no Nihongo
   I, and JEES sample papers all use `(person)に 会う`. The rationale
   ("happen to encounter") is fabricated; に + 会う is the standard
   direction-of-meeting marker, not a chance-encounter implication.
2. **The entry is off-pattern** for n5-008. n5-008 covers LIST-
   EXHAUSTIVE と (the AND-joining particle for nouns); the に-vs-と
   distinction for verbs like 会う / 遊ぶ / 食べる is about the
   COMPANION-と vs DIRECTION-に *verb class*, not list-exhaustion.
   The two grammatical functions of と (companion + list-exhaustive +
   quotation) share spelling but have distinct disambiguation
   profiles.

**Verb-class disambiguation rule (state explicitly in wcp rationales):**

| Verb class | Canonical particle | Example | Notes |
|---|---|---|---|
| 会う (meet) | に | ともだちに 会いました | per Genki I Lesson 4 etc. |
| 行く / 来る (go/come) | に or へ | 学校に / 学校へ 行きます | direction; 〜と for joint travel is companion |
| 遊ぶ (play with) | と (companion) | ともだちと 遊びました | joint activity |
| テニスを する / 食事を する | と (companion) | ともだちと テニス | joint activity |
| 話す (talk) | と | 先生と 話しました | mutual action |
| 結婚する (marry) | と | Aさんと 結婚 | mutual action |
| 出会う (encounter — different from 会う) | に | 駅で 先生に 出会いました | per JLPT samples |

Per-verb the canonical particle is fixed; a wcp that says "[verb]
takes [particle] universally" is over-generalized and will mislabel
a valid form when applied to a verb of a different class.

**Detection pattern in audit prompts:**

- For every wcp / common_mistakes entry whose `why` contains "takes と"
  or "takes に" without further qualification: verify the specific
  verb in the example against the verb-class table above.
- Phase-0 candidate: scan wcp entries whose `wrong` field uses the
  N5-canonical particle for its verb (例 `(人)に 会う`, `(人)と 遊ぶ`,
  `(人)と 結婚`) and flag for manual review. Hard to fully automate
  because verb-class detection requires lexical knowledge; a hand-
  curated list of N5 verb-class assignments + a regex scanner gets
  the high-precedence cases.

**Fix pattern (single wcp + cross-pattern impact):**

For N5 the bug was confined to one wcp entry. Replaced with an
on-pattern entry using a JOINT-action verb (テニスを する) that
genuinely takes companion-と, with a rationale that explicitly notes
会う is a separate class. Phase-0 corpus scan confirmed no other
n=534 wcp entries (178 patterns × 3 wcps) had the same mislabel
class.

**Generalization for Nx levels:**

- Day-1 authoring discipline: BEFORE authoring a particle wcp, write
  the verb-class table for the level and verify the wcp's verb is
  classified correctly.
- The verb-class table for higher levels (N4: 〜てもらう, N3: 〜ば
  conditional particles, etc.) needs its own table; do not assume
  N5's verb-class mappings transfer.
- Document explicitly that companion-と vs direction-に is per-verb,
  not per-pattern.

**Cross-reference:** logged as BUG-002 in
`N5/feedback/n5-audit-2026-05-04.xlsx` "User Reported Bugs" sheet
(2026-05-16, status Fixed). Test case: `n5-008` wcp[2] should mention
both verb classes in its `why` field.

## F.16 Static HTML mirrors for SPA hash routes (added 2026-05-16)

**Failure class:** SPA apps with hash-routing (`#/learn/<id>`) are
invisible to non-JS fetchers because:

- Browsers strip the `#` fragment before sending the request.
- The server returns the SPA shell (an empty `<div id="app">`).
- The lesson content is rendered client-side by JavaScript.
- LLM web-fetch tools, search engine crawlers (with limited JS
  budgets), archive snapshots, and read-only mirrors all see an
  empty page.

Caught on a user-reported bug in N5 (BUG-001, 2026-05-16):
"Claude chat is unable to access https://(...)/#/learn/n5-008
because hash fragments after `#` are never sent to the server."

**The fix pattern:** generate one static HTML mirror per content
unit at a crawlable path, with `<link rel="canonical">` pointing
back to the SPA route. For N5:

- `/N5/lessons/<pattern-id>.html` (178 grammar patterns)
- `/N5/lessons/index.html` (browsable index)
- Built by `tools/build_lesson_html_mirrors.py` (re-runnable;
  idempotent on unchanged grammar.json)
- Each page is read-only, plain HTML + minimal inline CSS, no JS.
- A `<p class="meta">` banner at top tells human visitors "this is
  a static mirror — the interactive version is at `../#/learn/<id>`."
- Canonical URL points back to the SPA route, so search engines
  deduplicate the static + interactive views.

**Generalization for Nx levels:**

- **Build a mirror generator on Day 1**, not after a user reports the
  problem. Each content surface (grammar / vocab / kanji / reading /
  listening) gets its own mirror at `/Nx/lessons/<id>.html` or
  `/Nx/words/<form>.html` etc.
- **The mirror surface is read-only.** Audio playback, furigana
  toggles, drill mode, SRS — all live in the SPA. Mirror = read.
- **Run the generator from CI** so the mirrors stay in sync with the
  source data. Add a Phase-0 check: `for each pattern in grammar.json,
  assert lessons/<id>.html exists and its <title> contains the
  pattern field`.
- **Sitemap matters.** Generate `sitemap.xml` listing all mirror
  URLs for crawler discoverability.

**Scope at N5 today:**

- Grammar mirrors: ✅ Done (178 + 1 index).
- Vocab mirrors: deferred (1009 entries; same approach extensible).
- Kanji mirrors: deferred (106 entries; could fold into vocab build).
- Reading mirrors: deferred.
- Listening mirrors: limited value (the page-content is the audio).

**Cross-reference:** logged as BUG-001 in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-16, status Fixed).
Tool: `tools/build_lesson_html_mirrors.py`.

## F.17 Native-teacher bug classes from BUG-003…BUG-009 (added 2026-05-16)

A native-teacher review of `grammar.json` surfaced seven bug classes
that are structurally invisible to schema-level validators but visible
on first read to a fluent reviewer. All seven are corpus-authoring
anti-patterns — they cost nothing to prevent on Day 1 and a lot to
remediate after publish. Predict and gate.

### F.17.1 Cross-pattern explanation / translation contamination
**Class:** the JA of pattern P is correct, but the `explanation_en` or
`translation_en` is the text for a *different* pattern Q (typically a
neighbor in the curriculum order). Source: copy-paste during authoring,
or LLM hallucination from a similar-shaped pattern.

**Failure modes observed (N5):**
- `n5-098` (superlative): `explanation_en` was the description of
  n5-099 (好き/嫌い + が). All 10 `translation_en` strings were
  "I like cats." while the 10 JA sentences were correct superlative
  examples (Fuji tallest, apples favorite, etc.). 100% pedagogical
  bypass — a learner studying this pattern through the app gets zero
  correct teaching.
- `n5-166` ex[5]: JA = 「いってらっしゃい」と かぞくに いいます。;
  EN = "I get up earlier than my older brother." (Verbatim copy
  from n5-096 ex[2].)

**Prevention — Phase-0 invariants:**
- **Cross-pattern explanation similarity check.** For each pattern's
  `explanation_en`, fuzzy-match (Levenshtein ≥0.85) against every
  *other* pattern's `explanation_en` in the same level. Any match
  above threshold is a likely cross-contamination — surface for
  review.
- **JA→EN semantic-alignment heuristic.** For each example, compute
  a noun-set overlap between the JA content words (kanji + katakana)
  and the EN translation. If overlap = 0 for ≥3 examples in the same
  pattern, flag the pattern. (Even a crude overlap catches the n5-098
  case — no apples/Fuji/soccer in "I like cats.")
- **LLM-as-judge per example.** A second LLM pass with the prompt
  "Does this English translation accurately render the Japanese?
  Answer YES/NO + reason." over every example. Cheap at corpus
  scale; catches all four observed cases here.

**CI invariant family:** JA-91 (cross-pattern explanation similarity),
JA-92 (per-example JA-EN content overlap). Add to the JA-NN series
when implementing — these are not in N5's 93-invariant set as of
this writing.

### F.17.2 Mora-count systematic error in pitch_marks
**Class:** the `mora` field per pitch_marks entry was computed by a
heuristic that under- or over-counted morae for high-frequency cases.
At N5 audit, 911 entries had `mora` ≠ kana-counted morae (more than
the 787 originally reported — drift went deeper).

**Common errors:**
- Counts `ー` (long-vowel) as 0 instead of 1 (コーヒー → 3 not 4).
- Counts `ん` (moraic n) as 0 instead of 1 (ごはん → 2 not 3).
- Counts small-kana clusters wrong (ょゅゃぁぃぅぇぉ should *combine*
  with the preceding kana into one mora; ゃ/ゅ/ょ in ぎょう = 1 mora
  for the digraph; the algorithm sometimes counted each).
- Counts terminal mora as 0 (truncates last kana).

**Reference rule (canonical):**

> Each kana = 1 mora EXCEPT small ゃ/ゅ/ょ/ぁ/ぃ/ぅ/ぇ/ぉ which combine
> with the preceding kana. The long-vowel mark ー counts as 1 mora.
> The sokuon っ counts as 1 mora. The moraic ん counts as 1 mora.

**Reference algorithm (cheap and correct):**

```python
SMALL_KANA = set("ゃゅょぁぃぅぇぉャュョァィゥェォ")
def count_mora(kana_string: str) -> int:
    return sum(1 for c in kana_string if c not in SMALL_KANA)
```

Run once over the entire vocab + grammar pitch_marks corpus during
audio build; reject the build if any per-form mora value disagrees.

**CI invariant:** JA-93 — for every pitch_marks entry, computed mora
must equal stored mora. Add as a hard gate, not an advisory.

**Cross-reference:** BUG-004 (n5-audit-2026-05-04.xlsx).

### F.17.3 Pattern-instance contamination
**Class:** an example filed under pattern P does not actually contain
the pattern-defining marker. Distinct from F.17.1 — the JA is correct
Japanese; it just teaches the wrong thing for the slot it occupies.

**Failure modes observed (N5):**
- `n5-171` ex[4-6] (ないほうがいい slot): JA = どなたが いいですか / どれが いいですか / どの くるまが いいですか. None contain V-ない + ほうがいい. They are interrogatives + いい, not the advisory pattern.
- `n5-173` ex[4] (なくてはいけない slot): JA uses ないと いけない, which is the n5-175 pattern, not the slot it sits in.
- `n5-179` ex[4] (って quotation slot): JA uses て-form for progressive (うたって います), not って-as-quotation.

**Prevention:**
- **Pattern-marker assertion per example.** Each pattern has a
  shortlist of surface markers that MUST appear in any example
  filed under it. For たことがある: `たことが`. For ないほうがいい:
  `ないほうがいい` or `ないほうが`. For なくてもいい:
  `なくてもいい` or `なくても`. Authoring tool refuses to commit an
  example whose JA does not contain at least one marker for the
  filed pattern.
- **Late-Nx patterns are highest-risk.** 6 of 8 contamination cases
  at N5 were in patterns marked `late_n5` or `deferred_to_n4`. These
  are the patterns farthest from the author's intuition window;
  audit them first.

**CI invariant:** JA-94 — each example contains ≥1 pattern-defining
marker. Marker table lives in `data/pattern_markers.json` or similar.

**Cross-reference:** BUG-006.

### F.17.4 RIGHT/WRONG framing for grammatically-valid alternatives
**Class:** `common_mistakes` entries label a grammatically correct,
N5-canonical sentence as "WRONG" because it isn't the form the author
happens to prefer for that specific context. The opposite form is then
labeled "RIGHT". The WHY field sometimes even admits "either is
correct" but the WRONG label stays.

**Failure modes observed (N5):**
- `n5-127` cm[2]: けれども vs けど — けれども is the formal full form;
  the WHY field said "either is correct semantically" but the entry
  still marked one WRONG.
- `n5-105` cm: `行きたくありません。` marked WRONG vs
  `行きたくないです。` marked RIGHT — both grammatically correct;
  difference is register (formal vs polite-casual), not grammaticality.
- `n5-023/051-057` cm: all `〜ね` confirmation-seekers labeled WRONG
  vs `〜か`-questions labeled RIGHT — pragmatic register, not grammar.
- `n5-069`/`n5-071`: 「あさごはんを たべて から、…」 (N5-canonical
  〜てから) and 「まって ください ね」 (natural polite request
  softener) both labeled WRONG.

**Pedagogical cost:** a learner trusts the RIGHT/WRONG dichotomy. Once
they internalize "けれども is wrong," they will avoid a valid formal
form for life — and Japanese-speaking adults will perceive their
output as register-flat.

**Fix framing — replace "WRONG vs RIGHT" with:**
- "In *casual* speech, A is the natural choice; B carries *formal*
  register and is appropriate when …"
- "Register variants — both correct; pick A in *context X*, B in
  *context Y*."
- "Either is correct. A is more common in *speech*; B is more common
  in *writing/textbooks*."

**Authoring rule:** before marking any form WRONG in `common_mistakes`,
ask "is the form ungrammatical, or merely register-mismatched / less
common?" Only ungrammatical forms get the WRONG label. Register and
pragmatic-context choices use "natural choice in X / Y" framing.

**Cross-reference:** BUG-007. Same class as BUG-002 (the
「ともだちに あいました」 case from the earlier round). The pattern
keeps showing up — gate at authoring, not at audit.

### F.17.5 Folk-linguistic grammar terminology
**Class:** `common_mistakes` rationales explain a particle choice with
folk-linguistic terminology that doesn't survive scrutiny against
actual Japanese-language pedagogy.

**Canonical instance observed:**
- `n5-004` cm[0]: "あう (to meet) is intransitive in Japanese — it
  takes に, not を." Reality: 会う takes に because it is a contact /
  encounter verb (相手を必要とする動詞), not because it is intransitive.
  Many transitive verbs take に. 会う itself is sometimes classified as
  transitive in 国語辞典. The intransitive label is a folk shortcut
  that misleads learners about how particle assignment actually works.

**Other risk areas (predict for Nx):**
- "Transitive/intransitive" used loosely for verbs that take non-を
  arguments.
- "Subject/topic" used interchangeably (は marks topic, が marks
  subject — they are not synonyms; sometimes the topic *is* the
  subject, sometimes it isn't).
- "Passive/causative" voice descriptions that don't match the
  grammatical voice present.
- "Auxiliary verb" applied to constructions that aren't auxiliaries
  in any standard analysis.

**Fix framing — describe the verb's actual argument structure:**
"会う takes the encounter-target with に. The person you meet is the
に-marked partner — this is a property of encounter/contact verbs,
independent of transitivity classification."

**Authoring rule:** if a WHY rationale uses a grammar-class label,
the label must match the term as used in standard Japanese-pedagogy
references (Genki, Tobira, A Dictionary of Basic Japanese Grammar).
Folk shortcuts get rewritten in terms of the actual grammatical
behavior.

**Cross-reference:** BUG-008.

### F.17.6 Pattern-particle mismatch in canonical examples
**Class:** a pattern teaches a specific particle X, but one or more
of its canonical examples uses a different particle Y in the slot the
pattern is supposed to demonstrate. Learners who pattern-match by
example will form a wrong association.

**Failure modes observed (N5):**
- `n5-003` (が particle) ex[6]: 「わたしは がくせいです。」 — uses は,
  not が. The pattern teaches が but the example demonstrates は.

**Prevention:**
- **Particle-presence assertion.** For each pattern whose
  `pattern_form` field names a specific particle (e.g., `が`, `を`,
  `に`, `で`, `と`, `へ`), require at least one occurrence of that
  particle in the example JA, with the position roughly matching
  what the pattern teaches (after subject/object marker, before
  verb, etc. — heuristic check is fine).
- For interrogative-subject patterns (the canonical case for
  obligatory が), require an interrogative head (だれ / なに /
  どれ / どこ / いつ / どの-NP) in the example.

**CI invariant:** JA-95 — particle-pattern alignment check. Run
per-example, fail build if a pattern's canonical particle is absent
from ≥30% of its examples.

**Cross-reference:** BUG-009.

### F.17 closing — the meta-lesson

All seven bug classes share a single structural property: **schema
validators pass while pedagogical content fails.** The JSON is
well-formed. Required fields are present. Cross-references resolve.
The audio renders. But what a learner *sees and reads and hears* is
wrong in ways only a fluent reviewer (or a sufficiently aware LLM
audit pass) catches.

Three operational implications for Nx:

1. **Schema validation is necessary but not sufficient.** Build the
   F.17 CI invariants (JA-91…JA-95) as part of the Day-1 invariant
   set, not as remediation after a user report.
2. **One native-teacher pass per content surface, before publish.**
   A 4-hour native-teacher review on a 178-pattern grammar corpus
   caught the seven classes here. Same cost on Nx-vocab and
   Nx-grammar at authoring time would prevent the next iteration of
   the same surface.
3. **The "either is correct" / register-variant framing.** Common
   mistakes that label valid alternatives as WRONG are the most
   pedagogically expensive class — a learner internalizes the WRONG
   label for life. The framing rewrite (F.17.4) is mandatory for
   every Nx common_mistakes entry going forward.

**Cross-reference:** BUG-003 through BUG-009 closed in
`N5/feedback/n5-audit-2026-05-04.xlsx` on 2026-05-16. Fix script:
`N5/tools/fix_user_bugs_003_to_009_2026_05_16.py`.

## F.18 Static HTML mirrors — full-surface generalization (added 2026-05-16)

**This section extends F.16.** F.16 introduced the static-mirror
pattern for SPA hash routes against the grammar surface only (BUG-001
resolution). F.18 generalizes it to every content + meta surface
(BUG-010 resolution).

**Why generalize:** F.16's grammar-only mirrors solved the
single-surface case for LLM web-fetch tools (Claude chat fetching a
specific grammar pattern). It did NOT solve:

- **Search-engine indexing of non-grammar content.** Google /
  Bing / Baidu cannot index vocab, kanji, reading passages,
  listening transcripts, or meta pages (changelog, privacy) on a
  hash-routed SPA.
- **Archive.org snapshots of any deep link.** Hash routes return
  the SPA shell; archive.org preserves only the shell.
- **Social-card previews.** Open Graph crawlers (Twitter, LinkedIn,
  Discord, Slack) cannot read lesson-specific titles or descriptions
  from hash-routed pages.
- **RSS readers / accessibility tools relying on initial HTML.**
  Anything that doesn't execute JS sees only the shell.
- **Users with JS disabled.** Corporate firewalls, privacy
  extensions, older devices.

### F.18.1 Path structure (canonical)

Mirror every SPA route at a crawlable subdirectory path with
`index.html`, mirroring the SPA's actual hash-route hierarchy:

| SPA hash route | Static mirror path |
|---|---|
| `#/learn/<id>` (grammar) | `/Nx/learn/grammar/<id>/index.html` |
| `#/learn/vocab/<form>` | `/Nx/learn/vocab/<form>/index.html` |
| `#/kanji/<glyph>` | `/Nx/kanji/<glyph>/index.html` |
| `#/reading/<id>` | `/Nx/reading/<id>/index.html` |
| `#/listening/<id>` | `/Nx/listening/<id>/index.html` |
| `#/home`, `#/changelog`, … (meta) | `/Nx/<slug>/index.html` |

The path-on-disk does NOT need to match the SPA hash path
character-for-character (e.g. SPA uses `#/learn/<id>` for grammar
without a `grammar/` segment; mirror uses `/learn/grammar/<id>/`
for cleaner URL hierarchy on disk). The canonical link inside each
mirror points back to the *actual* SPA hash route, so search
engines deduplicate correctly.

### F.18.2 Per-page requirements

Every generated static mirror MUST carry:

1. **Route-specific `<title>` and `<meta name="description">`** —
   derived from the content (pattern name + EN gloss, form +
   reading, kanji + meaning, passage title, etc.). Never a copy of
   the SPA shell's generic title.

2. **Open Graph tags** — `og:type`, `og:url` (canonical SPA URL),
   `og:title`, `og:description`, `og:site_name`, `og:image`. At
   minimum a single shared og:image (app icon) suffices in the
   first iteration; per-route OG images are an enhancement for
   later.

3. **Twitter Card** — `twitter:card`, `twitter:title`,
   `twitter:description`. `summary` (not `summary_large_image`)
   unless per-page og:image is implemented.

4. **`<link rel="canonical">`** pointing to the *SPA hash route*,
   not the mirror path. This makes the SPA the canonical URL;
   search engines understand the mirror as a fetchable
   representation of the canonical resource.

5. **Inline CSS** sufficient to render readably without JS, plus
   a `prefers-color-scheme: dark` media query for parity with the
   SPA's dark mode.

6. **JS redirect with bot-friendly delay** — a `setTimeout` of
   ~1500ms before `location.href = <SPA URL>`. Long enough that
   search-engine bots aborting JS execution before the deadline
   see the static content; short enough that human users land on
   the SPA without visible waiting. Skip the redirect on
   `?nojs=1` or `?goSPA=0` query params so crawlers and human
   reviewers can inspect the static surface explicitly.

7. **Breadcrumb navigation + content-licence footer** — orient
   the reader and disclose attribution.

8. **Locale variants** (where the data supports it) — emit
   `index.html` (default locale) and `index.<lang>.html` per
   additional locale, with `<link rel="alternate" hreflang>`
   between them.

### F.18.3 Cross-linking between surfaces

The mirror surface should NOT be an island — each generated page
links to related content via the SAME static-mirror URL structure:

- Vocab page → frequent_patterns links to `/learn/grammar/<id>/`
- Reading passage → vocab_used links to `/learn/vocab/<form>/`,
  kanji_used links to `/kanji/<glyph>/`
- Kanji page → lookalikes links to other `/kanji/<glyph>/` pages
- Meta `summary` stub → per-corpus indexes
  (`/learn/grammar/`, `/learn/vocab/`, `/kanji/`, etc.)

This produces a fully-crawlable graph where Googlebot can walk from
any single entry point and discover every content URL.

### F.18.4 Sitemap.xml + robots.txt

Always generate `/Nx/sitemap.xml` listing every mirror URL +
`/Nx/robots.txt` with a `Sitemap:` directive. Dedupe + sort URLs in
the sitemap for deterministic output (idempotent re-runs produce no
diff). Use absolute URLs in the sitemap (e.g.
`https://example.github.io/JLPTSuccess/Nx/learn/grammar/n5-008/`),
not relative paths.

At N5 (BUG-010 close-out), the sitemap has 1,373 URLs:
- 179 grammar (178 patterns + 1 index)
- 971 vocab (970 unique forms + 1 index)
- 107 kanji (106 + 1 index)
- 55 reading (54 + 1 index)
- 51 listening (50 + 1 index)
- 10 meta routes

### F.18.5 Stages — recommended sequencing

The full surface is large (1,373 URLs at N5; Nx will be similar or
larger). A staged rollout is operationally safer than a single big
bang:

1. **Stage 1 — Grammar.** Highest-traffic surface; validates the
   path structure + chrome.
2. **Stage 2 — Vocab.** Largest by count; tests Unicode path
   handling at scale.
3. **Stage 3 — Kanji.** Tests glyph-as-URL-segment encoding.
4. **Stages 4 + 5 — Reading + Listening.** Often share the
   mondai-grouped index shape; commit together.
5. **Stage 6 — Meta routes.** Markdown→HTML for README/CHANGELOG/
   PRIVACY/NOTICES + static stubs for interactive views (test /
   sitting / missed / summary explain why they require JS).
6. **Stage 7 — Close-out.** Mark the bug Fixed; update sitemap
   coverage assertions; Rule-4 doc propagation.

Each stage gets its own commit (CI green after every commit).
Idempotent re-runs let CI verify the artifact is current without
forcing regeneration.

### F.18.6 Generator architecture

Single Python tool: `tools/build_static_mirrors.py`. Each surface
gets its own `build_<surface>(sitemap_urls) -> (written, unchanged,
total)` function. The sitemap accumulator is passed by reference so
each stage appends URLs to a single list, which is sorted + deduped
in the final `write_sitemap()`.

Idempotency rule: `_write_if_changed(path, content)` only writes
when content differs from disk; second invocation on unchanged
inputs produces `0 written`.

Markdown→HTML for meta-route .md files: a minimal in-house renderer
(headings, lists, paragraphs, inline code/bold/italic/links, code
fences) avoids the external dependency cost. Suffices for
CHANGELOG / PRIVACY / NOTICES / README.

### F.18.7 What this DOES NOT cover (acknowledged debt)

- **Playwright snapshot comparison gate.** BUG-010's acceptance
  criteria named this as the build-time consistency check
  (assert mirror content matches SPA-rendered output). Not yet
  wired; queued as follow-on work.
- **Per-page Open Graph images.** Current implementation uses a
  single shared `icon-512.png` for og:image across all pages.
  Per-page imagery (auto-generated cards with pattern name +
  meaning, kanji glyph + readings) is an enhancement.
- **Hindi locale variants for non-meta surfaces.** Grammar and
  vocab data carry per-entry `meaning_hi` / `gloss_hi`, but the
  static mirrors only emit `index.html` (English) today.
  `index.hi.html` per surface is the next iteration.
- **CI invariant for mirror presence.** A JA-NN gate asserting
  every grammar pattern / vocab form / kanji glyph has a
  corresponding mirror file should be added after the data
  surfaces stabilize.

**Cross-reference:** BUG-010 close-out in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-16, status Fixed).
Tool: `tools/build_static_mirrors.py`. Six staged commits:
`1ca8173` (grammar), `06dd57b` (vocab), `dbdd96d` (kanji),
`4419efc` (reading + listening), `75d0ec1` (meta routes), final
close-out commit (after this F.18 propagation).

## F.19 Schema-level fix for register-variant common_mistakes (added 2026-05-16)

**This section extends F.17.4.** F.17.4 caught the
RIGHT/WRONG-framing-for-grammatically-valid-alternatives class as a
WHY-text problem (BUG-007) — rewrite the rationale to say "register
variants, both correct" instead of "WRONG vs RIGHT". F.19 catches
the schema-level follow-on: the WHY text said "both correct" but
the `wrong`/`right` field-name dichotomy in the JSON data still
labeled one form as WRONG. Same anti-pattern, different layer.
Caught as user-reported BUG-011 on 2026-05-16.

### F.19.1 The structural failure

A `common_mistakes` entry has two cells the UI treats asymmetrically:

| Field | UI presentation |
|---|---|
| `wrong` | red text, strike-through, ✗ marker |
| `right` | green text, ✓ marker |
| `why` | small muted text below |

When a learner reads an entry, they see the red-strike vs green-check
contrast first; the WHY paragraph comes second and weights less. If
the WHY says "both forms are correct" but the cell labels say
WRONG/RIGHT, the visual hierarchy wins. The learner internalizes the
WRONG label.

Concrete example from N5:

```
WRONG: むずかしいです けれども、おもしろいです。   ← red strike-through
RIGHT: むずかしいですけど、おもしろいです。       ← green check
WHY:   Both けれども and けど are valid; register choice.
```

The contradiction is in the same entry. A learner who internalizes
"けれども is wrong" will avoid a perfectly valid formal form for
life.

### F.19.2 The schema fix (final shape after BUG-013)

Add a `kind` field to common_mistakes entries. When
`kind == "register_variant"`:

- The entry represents two grammatically-valid forms differing in
  register, formality, or pragmatic context.
- The two forms live in `form_a` and `form_b` keys — NOT in
  `wrong` / `right`. The legacy key names imply WRONG vs RIGHT
  even on the data surface, and any downstream consumer reading
  the JSON would see a literal "wrong" key on a valid form. The
  rename is required, not optional. (BUG-013 lesson.)
- `label_a` and `label_b` carry short register tags shown
  alongside each form ("formal full form", "casual contraction",
  "confirmation-seeker (〜ね)", "neutral question (〜か)", etc.).
- The UI MUST render the pair neutrally — no strike-through, no
  green check.
- The `why` field continues to explain when each form is
  appropriate.

```json
{
  "kind":    "register_variant",
  "form_a":  "むずかしいです けれども、おもしろいです。",
  "form_b":  "むずかしいですけど、おもしろいです。",
  "label_a": "formal full form (けれども)",
  "label_b": "casual contraction (けど)",
  "why":     "Both are valid. けれども is the formal full form; けど is the casual contraction. Register choice, not a grammatical error."
}
```

Legacy entries (actual grammar errors, `kind` absent or any other
value) keep `wrong`/`right`/`why` — those field names match the
semantic. The renderer chooses the field set based on `kind`.

**Don't leave the legacy keys in place during the migration**
(BUG-013 lesson). A clean rename in one commit avoids the
data-surface contradiction. Consumer code can keep a transitional
fallback (`cm.form_a ?? cm.wrong`) for one release cycle to
handle any stale entry, but the data file should not contain both
key sets.

### F.19.3 UI rendering rule

```js
if (cm.kind === 'register_variant') {
  // neutral framing: register labels in front of each form,
  // no strike-through, no check mark, due-tint accent (orange)
  // to visually distinguish from error entries
} else {
  // legacy wrong/right rendering: ✗ red strike, ✓ green check
}
```

Static-mirror generators apply the same rule: split
`common_mistakes` into two sections — "Common mistakes" for entries
without `kind` (actual errors), "Register variants — both forms are
correct" for `kind == "register_variant"`.

### F.19.4 Authoring rule

Before adding ANY new common_mistakes entry, ask:

1. Is the `wrong` form *ungrammatical* in standalone Japanese?
   → Yes: omit `kind`; render as legacy error.
   → No: it differs from `right` in some other axis. What is it?
2. Does it differ in register (casual/formal), formality
   (full-form/contraction), pragmatic context
   (confirmation-seeking/neutral-question), or which N5 pattern is
   keyed?
   → All of the above: set `kind = "register_variant"`, populate
     `label_a` + `label_b`.

### F.19.5 Coverage signal

The class kept reappearing — the partial fix didn't hold:

- **BUG-002** (2026-05-16): a `wrong_corrected_pair` entry on n5-008
  mislabeled `ともだちに あいました` (canonical N5 form) as wrong.
- **BUG-007** (2026-05-16): 11 common_mistakes WHY rationales
  rewritten to say "both correct"; cell labels left intact.
- **BUG-011** (2026-05-16): the cell-label/WHY contradiction
  exposed by BUG-007 partly fixed — `kind: "register_variant"` +
  `label_a` / `label_b` added, but `wrong`/`right` JSON keys
  retained for backwards compat. Data-surface contradiction
  remained.
- **BUG-013** (2026-05-16): the JSON keys themselves renamed —
  `wrong` → `form_a`, `right` → `form_b` — completing the
  migration. The data surface no longer carries any "wrong" key
  on a sentence the same entry calls valid.

### F.19.6 Lesson — finish the schema migration in one pass

The BUG-011 → BUG-013 sequence cost an extra round-trip because
the partial fix (add the new fields, keep the old ones) left the
data-surface contradiction in place. Backwards compatibility is a
real concern, but on schema migrations involving USER-VISIBLE
field labels, ship the rename in the same commit as the new fields
— don't leave the old labels in the data file. The fallback in the
consumer code is what handles the migration window, not the
duplication in the data.

**Authoring-pipeline gate (CI invariant proposal):** any new
common_mistakes entry whose WHY contains "both correct" /
"register" / "either is correct" / "natural in <context>" MUST
carry `kind: "register_variant"` AND use `form_a`/`form_b` keys
(not `wrong`/`right`). The CI check (JA-64 in N5 today) enforces
both required-field sets and rejects register_variant entries that
still carry the legacy keys.

**Cross-reference:** BUG-011 close-out in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-16, status Fixed).
Fix script: `tools/fix_bug_011_register_variants_2026_05_16.py`.

## F.20 Provenance labels must disambiguate human vs AI review at the point of use (added 2026-05-16)

**Failure class:** a content-corpus item carries a quality / review
field (e.g. `review_status`) whose value (e.g. `"native_reviewed"`)
*implies* human-native review when read in isolation — while the
disclosure that the value was actually assigned by an AI is hidden
in a separate `_meta` block that downstream consumers never read.

Caught as user-reported BUG-012 on 2026-05-16 (follow-on to
BUG-003, where the catastrophically-wrong n5-098 explanation
carried `review_status: "native_reviewed"` and demonstrated the
label was unreliable).

### F.20.1 The trust gap

When N5's authoring pipeline assigned `review_status` values via
Claude-acting-as-native-reviewer, the per-item label was
`native_reviewed`. The honest disclosure in `_meta` said this was
an LLM persona, not a human. But:

- Downstream tools reading the data ignore `_meta`.
- The SPA's provenance-badge UI labeled items as "Native-reviewed"
  based on the field value alone.
- Third-party adopters importing the corpus would see "native"
  and present it as such to their users.
- Audit dashboards counting `native_reviewed` percentage implied a
  human-review coverage that didn't exist.

The disclosure was technically honest; the field value was
operationally misleading.

### F.20.2 The naming rule

**Field values that imply quality / review provenance MUST
disambiguate human vs AI at the point of use.** Either:

- **Option A (minimal):** rename the value so the AI origin is
  visible from the field alone. E.g. `native_reviewed` →
  `ai_quality_reviewed`. Any code that reads the field sees the
  AI-ness without needing to consult `_meta`.

- **Option B (preferred):** emit two fields — the *kind* of review
  in the existing field, and a *provenance* alongside:

  ```json
  "review_status": "ai_quality_reviewed",
  "review_status_provenance": "claude_native_reviewer_persona"
  ```

  The provenance field is machine-readable. UI badge logic, audit
  dashboards, and third-party adopters can read both fields and
  present the AI/human distinction explicitly.

When a real human-native review pass happens, introduce a NEW
value (e.g. `human_native_reviewed`) — never reuse the
`ai_quality_reviewed` value. The distinction must remain visible.

### F.20.3 Consumer updates required

When implementing this fix, audit every consumer of the renamed
field:

- **CI invariants** that check `review_status ∈ {closed_enum}`:
  update the enum (keep the legacy value as transitional accepted
  during the migration window so any partially-migrated commit
  doesn't fail CI; remove it once migration is verified complete).
- **UI badge code**: change the value check AND the label text
  (e.g. "Native-reviewed" → "AI quality-reviewed").
- **Statistics / dashboards**: variable names + display strings.
- **Documentation**: spec files, CHANGELOG, READMEs — search for
  the old value name and update.
- **Minified bundles**: rebuild after the source change.

Keep the old value as a backwards-compat alias in the UI for one
release cycle so a partially-rolled-out deploy doesn't blank-out
the badge UI.

### F.20.4 Authoring rule for new corpora

When designing the `review_status` schema for a new corpus
(any Nx level):

1. Reserve `human_native_reviewed` as the future value for an
   actual native-human review pass.
2. Use `ai_quality_reviewed` (or similar AI-prefixed name) for any
   review that was performed by an LLM persona, even if the
   persona was instructed to act as a native reviewer.
3. Use `llm_curated` for primary content generated by LLM (lower
   quality bar than `ai_quality_reviewed`).
4. Use `auto_generated` for content derived programmatically from
   other sources (e.g. JLPT corpus statistics, kanjium pitch
   reference, frequency tables).
5. Always emit `review_status_provenance` alongside `review_status`
   so the specific reviewer / pipeline is machine-readable.

The four values form a transparent quality ladder; the
provenance field disambiguates which specific human / LLM /
pipeline did the work.

### F.20.5 The Q21 / badge-launch gate

The Q21 launch policy (from the BUG-012 lineage) required ≥10% of
a corpus to be `native_reviewed` before the provenance-badge UI
ships for that corpus. After BUG-012's rename, the gate is:

> ≥10% of a corpus must be `human_native_reviewed` (the new value
> reserved for actual native-human review) — NOT
> `ai_quality_reviewed` — before the "Native-reviewed" badge ships.

Until a real human-native review pass crosses the 10% threshold,
the badge UI either stays off or labels items as "AI
quality-reviewed" (no "Native-reviewed" claim).

**Cross-reference:** BUG-012 close-out in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-16, status Fixed).
Fix script: `tools/fix_bug_012_review_status_rename_2026_05_16.py`.

## F.21 Vocab-corpus data-quality bug classes (added 2026-05-16)

Native-teacher re-audit on 2026-05-16 surfaced 5 vocab-corpus data-quality
bug classes (BUG-014 through BUG-018). They share a common shape:
schema-level validators (JSON structure, required fields, ID
integrity) pass, but content-level quality fails — the corpus
contains semantically wrong, schema-inconsistent, or coverage-gap
data that only a native speaker / domain reviewer catches on read.

Each class is documented below with the canonical fix pattern and a
ready-to-wire CI invariant.

### F.21.1 Template-generated semantic-nonsense examples (BUG-014)

**Failure shape:** an automated template (e.g., `<form> が あります。`)
applied to vocab examples without semantic filtering. Result:
grammatically possible but semantically nonsensical sentences — a
native speaker would never say them.

**N5 instances:** 19 entries had the bare `<form> が あります。`
pattern applied. Time words (一月, 八月, 先月, 来年, ゆうべ) cannot
take あります in a there-is-X sense. Abstract nouns (外国語, りゅうがく,
たんご) don't take this frame at all. Bare-location entries
(ゆうびんきょく, はなや) need a location qualifier to make the
existential frame natural.

**Authoring rule for new corpora:**

When an example template is applied to many entries, gate at the
authoring step by classifying entries before applying:

- **Time words**: should use the verb in に-marked time-anchor frames
  with an EVENT noun taking が あります (「七月に なつまつりが あります。」),
  NOT bare `<time-word> が あります`.
- **Locations**: need a location-qualifier prefix ("えきの 前に X が あります",
  "うちの ちかくに X が あります"). Bare `<location> が あります` is awkward
  except in immediate spatial context.
- **Concrete objects / food**: use eat / buy / drink / hold frames
  ("Xを 食べます", "Xを 買いました"), not bare あります.
- **Abstract nouns**: drop the あります frame entirely. Use their
  natural collocations (べんきょうします, おぼえます, etc.).

**CI invariant pattern:** strict regex against vocab examples —
`^\s*<form>\s*が\s*(あります|います)\s*。?\s*$` — flag any match.
Headword + が + あります with no other content. (N5's JA-96.)

### F.21.2 Inconsistent field schemas across the corpus (BUG-015)

**Failure shape:** the same field carries multiple incompatible
types (string / dict / null) across entries, with no schema
discriminator. Downstream parsers must handle each branch.

**N5 instance:** `counter` field had 3 types (string in 111 entries,
dict in 204, null in 694). Compounded by `counter_register` being
doubly-overloaded — string register-hints in 21 entries vs dict
counter-word metadata in 16 entries (a completely different
semantic use of the same field).

**Fix pattern:**

1. Pick ONE canonical shape (preferably the more structured one —
   dict beats string for self-documentation).
2. Migrate all entries to the canonical shape.
3. If a single field name has been overloaded with two different
   semantics, RENAME one of them. (N5: the counter-word metadata
   moved to a new `counter_word_metadata` field, isolated from the
   per-noun register hint.)
4. Add a CI gate that enforces the canonical shape on every entry.

**CI invariant pattern:** per-entry type check on the field; closed
set of allowed shapes; build fails on any non-matching entry. (N5's
JA-97.)

### F.21.3 Field-coverage gaps on core entries (BUG-016)

**Failure shape:** a required-for-pedagogy field is set on only a
fraction of the entries that need it. Missing values silently default
to null/absent, leaving downstream consumers without the
information.

**N5 instance:** `transitivity` field was set on 22 of 132 verbs
(17%). The 22 covered the documented transitive/intransitive verb
PAIRS (止まる/止める, 開く/開ける) — the easy wins. The 110 SOLO
verbs (食べる, 飲む, 買う, 行く, 来る, 会う, する, …) had no
classification at all, despite transitivity governing particle choice
for the entire grammar layer.

**Authoring rule:** when a pedagogical field carries a closed-enum
value (transitivity, register, animacy, intransitive-pair, etc.),
**require 100% coverage** for the entity type it applies to. Don't
ship "applies on 22 of 132 entries" as a partial state — that
silently teaches a default that may be wrong.

**Source the classification from a canonical reference**:
JMdict vt/vi tags, 国立国語研究所 verb tables, standard pedagogical
references (Genki, Tobira, A Dictionary of Basic Japanese Grammar).
Add a `<field>_provenance` field naming the source so a future
human-native review pass has audit trail (N5 used
`transitivity_provenance: "n5_pedagogical_convention_bug_016_fix"`).

**CI invariant pattern:** for each POS that should carry the field,
require non-null value from a closed enum on every entry. (N5's
JA-98.)

### F.21.4 Out-of-scope kanji in display fields (BUG-017)

**Failure shape:** kanji appears in a user-visible field (vocab
`form`, example `ja` text) but is NOT in the N-level whitelist. The
schema doesn't catch this because there's no per-field kanji-scope
invariant — only the existing JA-13 covers grammar examples.

**N5 instance:** 3 kanji (倍, 籍, 末) appeared in 3 vocab `form`
fields but were absent from `data/n5_kanji_whitelist.json`.

**Fix options (per the bug description):**

(a) Add the kanji to the whitelist (only if it really IS N5-scope;
   each addition requires readings + stroke order + example vocab).
(b) Replace the kanji form with kana (conservative; matches the
   N5 floor).
(c) Add the kanji to the exception list (`dokkai_kanji_exception.json`)
   if the policy is "allowed in display but not in distractor pools".

**N5 chose (b).** The kanji form was replaced with kana while the
vocab ID was kept stable (form is display content; ID is identity).
This minimizes cross-reference churn — references to the old vocab
ID continue to resolve.

**Edge case to watch:** form rename may collide with a pre-existing
kana entry. The N5 fix collided: 週末 → しゅうまつ duplicated an
existing しゅうまつ entry, requiring a follow-on dedup + cross-corpus
ID rewrite. Check for collisions BEFORE applying the rename.

**CI invariant pattern:** for every entity's display-field kanji
characters, assert each is in the level-N whitelist or the explicit
exception list. (N5's JA-99 covers vocab forms; extend to listening
script_ja, reading.ja, etc. for full coverage.)

### F.21.5 Cross-section duplicate entries (BUG-018)

**Failure shape:** the same (form, reading) pair appears in 2+
sections with overlapping (often subset) glosses. The data
artificially inflates the count and the SRS / flashcard queues show
the same item twice.

**N5 instance:** 10 entries (道, とけい, ことば, え, 電気, もう, すぐ,
前, どうも, どうぞよろしく) were duplicated across 2 sections each.
For each pair, one gloss was a subset of the other.

**Fix pattern:**

1. Pick a canonical section per form. Heuristic: prefer the section
   whose gloss is more comprehensive; fall back to cross-corpus
   reference count (which ID is referenced more times in other
   corpora).
2. Merge unique data (examples, collocations, gloss notes) from the
   non-canonical into the canonical.
3. Drop the non-canonical entry.
4. Rewrite all cross-references in OTHER corpora
   (grammar.json, reading.json, listening.json, authentic.json,
   questions.json, drills_auto.json, kanji.json) to point to the
   canonical ID. Safe via string replacement because vocab IDs are
   unambiguous (`n5.vocab.<section>.<form>`).
5. Update count locks (corpus-size invariants, license-text
   counts, density floors) — these are intended to fail on
   deliberate count changes, then be updated to reflect the new
   ground truth.

**Caution — distinguish polysemy from dedup:**

Some same-form pairs ARE legitimate polysemy (は = tooth / leaf /
topic marker; きる = to cut / to wear; いる = to exist / to need;
いくつ = "how many" question-word vs counter — different POS).
These should stay split. The dedup criterion: drop only when the
two entries' glosses are subset/synonym pairs with no semantic
distinction AND the same POS. Manual review per pair is necessary.

**Heuristic-miss lesson (added 2026-05-16 from BUG-019):** the
BUG-018 dedup pass worked from a hand-curated list of 10 cases the
native-teacher review identified explicitly. A re-audit one hour
later (BUG-019) found 3 MORE cases of the same shape that hadn't
been in the original list — 月 (Time/Nature), あつい (Weather/Adjectives;
duplicate of the 暑い "hot weather" entry within 4-entry homophone
cluster), きって (Money/Common-Nouns). Net: 1009 → 998 (BUG-018)
→ 995 (BUG-019).

The miss happened because manual lists don't surface the full
population. For Nx-level builders, run an automated detector on
every release:

```python
import json
from collections import defaultdict
V = json.load(open('data/vocab.json', encoding='utf-8'))
groups = defaultdict(list)
for e in V['entries']:
    key = (e.get('form'), e.get('reading'))
    if all(key): groups[key].append(e)
for key, entries in groups.items():
    if len(entries) < 2:
        continue
    # Polysemy guard: different POS is legitimate
    if len({e.get('pos') for e in entries}) > 1:
        continue
    # Subset-duplicate detection: gloss-A strictly contains gloss-B (or vice versa)
    glosses = [(e.get('id'), e.get('gloss','').strip()) for e in entries]
    for i, (id_a, g_a) in enumerate(glosses):
        for j, (id_b, g_b) in enumerate(glosses):
            if i >= j: continue
            if g_b and g_a and g_b in g_a and g_b != g_a:
                print(f'SUBSET-DUPLICATE candidate: {key} — {id_b!r} ({g_b!r}) ⊂ {id_a!r} ({g_a!r})')
```

This catches both BUG-018's 10 + BUG-019's 3 cases AND correctly
skips legitimate polysemy (different-POS pairs like いくつ).
Run before every release; manual triage on hits.

**CI invariant pattern:** the dedup itself isn't directly
CI-able (polysemy is legitimate), but the corpus-count lock catches
unintended count regressions in either direction. The
automated-detector script above can run as a Phase-0 regression
block — non-zero hits trigger manual review.

### F.21.6 Meta-lesson — schema, coverage, and content together

The five BUG-014…BUG-018 classes are the three operational layers
of vocab-corpus quality:

| Layer | Failure mode | N5 instance |
|---|---|---|
| **Content** (per-entry semantics) | Template nonsense, OOS kanji | BUG-014, BUG-017 |
| **Schema** (per-field types) | Multi-shape fields, overloaded fields | BUG-015 |
| **Coverage** (cross-corpus) | Partial-coverage classification, duplicate entries | BUG-016, BUG-018 |

All three layers need explicit CI gates. Schema-level validation
alone (JSON shape, required fields, ID integrity) catches none of
these. The pattern from F.17 (native-teacher review) continues:
**schema validators are necessary but not sufficient. One native-
teacher pass per content surface before publish.**

**Cross-reference:** BUG-014 through BUG-018 close-out in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-16, all Status:
Fixed). Fix scripts (one per bug):
`tools/fix_bug_014_vocab_template_nonsense_2026_05_16.py`,
`tools/fix_bug_015_counter_schema_2026_05_16.py`,
`tools/fix_bug_016_verb_transitivity_2026_05_16.py`,
`tools/fix_bug_017_oos_kanji_vocab_forms_2026_05_16.py`,
`tools/fix_bug_018_dedup_vocab_sections_2026_05_16.py`. New CI
invariants: JA-96 through JA-99 (the previously-reserved
JA-91…JA-95 slots remain unwired per the 2026-05-16 Part 1 addendum).

## F.22 Kanji-corpus data-quality bug classes (added 2026-05-17)

Native-teacher audit of `kanji.json` on 2026-05-17 surfaced 3
bug classes (BUG-020/021/022) parallel to the vocab-quality bugs
captured in F.21. Same three operational layers — content / schema /
coverage — applied to the kanji corpus.

### F.22.1 Cross-file display drift after corpus-level fixes (BUG-020)

**Failure shape:** a fix landed in one corpus file but didn't
propagate to other corpora that reference the same items.
Cross-references resolve (vocab_id still valid), but the displayed
form drifts between files.

**N5 instance:** BUG-017 moved vocab.json entries 週末 / 国籍 to
kana forms (しゅうまつ / こくせき) because 末 / 籍 are not in the
N5 kanji whitelist. The kanji.json file kept the kanji forms in
its `n5_compounds` and `examples` arrays for 週 and 国 — so the
kanji corpus still displayed OOS kanji.

**Resolution options (per the bug description):**

(a) Update kanji.json forms to match vocab.json (use kana). Loses
    pedagogical value — kanji corpus exists to teach kanji.
(b) Revert vocab.json and add the OOS kanji to the whitelist. Only
    if the kanji really IS level-scope.
(c) Remove the OOS compounds entirely. Cleanest when the kanji is
    out of scope by both the whitelist AND standard pedagogy
    (週末 / 国籍 are N4 territory at N5).

**N5 chose (c)** — removed 3 compounds (週末, 国籍, 手紙 — the
last surfaced by the CI invariant added during close-out) plus the
2 auto-derived example entries that referenced them.

**CI invariant pattern (initial narrow scope — later TIGHTENED, see below):** for every kanji compound/example with a `vocab_id`, assert (1) the vocab_id resolves AND (2) the form contains no OOS kanji.

**TIGHTENING — BUG-023 follow-up (added 2026-05-17):**

The narrow OOS-only check above was wired post-BUG-020. A
re-audit one day later (BUG-023) demonstrated the narrow scope
missed a real bug class: kanji.json showed kanji forms (友だち,
手, 上手, 足, 目) while vocab.json had kana-only forms
(ともだち, て, じょうず, あし, め) for the SAME vocab IDs. All 5
kanji are in the N5 whitelist — the narrow check accepted this as
"intentional pedagogy" (form-shape divergence), but it wasn't.
Standard N5 textbooks (Genki I L3-4, Minna no Nihongo L9-10,
Try! N5, So-matome N5) all teach those words with kanji. The
kana-only vocab.json forms were just an inconsistency from
earlier authoring.

**Tightened invariant (correct default):** for every kanji compound/
example with a `vocab_id`, assert (1) the vocab_id resolves AND
(2) the form EQUALS the linked vocab.form EXACTLY. Catches both
directions of drift:

- BUG-020 case: kanji.json kanji form ↔ vocab.json kana form when
  the kanji is OOS (vocab was the source of truth; fix is to
  remove the kanji-corpus compound)
- BUG-023 case: kanji.json kanji form ↔ vocab.json kana form when
  the kanji IS in scope (kanji corpus was the source of truth;
  fix is to upgrade vocab.json's form to kanji)

The triage at fix-time is: if the kanji is in the level whitelist,
upgrade vocab.json to use the kanji form (BUG-023 path). If the
kanji is NOT in the whitelist, remove the kanji compound (BUG-020
path). Either way, the two corpora end up matching.

**Authoring rule:** when fixing OOS kanji in one corpus, run a
follow-on grep across ALL other corpora that may reference the
same form. Don't assume the fix propagates automatically. And:
**default to strict-equality CI gates, not narrow-scope ones** —
the BUG-020 → BUG-023 round-trip cost an extra audit cycle because
the initial JA-100 was too loose.

### F.22.2 primary_reading misalignment with N5 standalone use (BUG-021)

**Failure shape:** the canonical-reading field is set to the
reading the kanji has in compounds, even though the standalone
form a learner first encounters uses the OTHER yomi.

**N5 instance:** 6 kanji had `primary_reading` set to on-yomi while
the standalone N5 sentence form is the kun-yomi:

| Kanji | Wrong primary | Correct primary | Compound role of on-yomi |
|---|---|---|---|
| 人 | にん | ひと | counter suffix (一人 ひとり is irregular, 二人 with にん) |
| 中 | ちゅう | なか | prefix/suffix (中国 ちゅうごく, 一日中 いちにちじゅう) |
| 外 | がい | そと | prefix only (外国 がいこく) |
| 東 | とう | ひがし | prefix only (東京 とうきょう) |
| 車 | しゃ | くるま | suffix (電車 でんしゃ, 自転車 じてんしゃ) |
| 国 | こく | くに | prefix only (国際 こくさい, 国民 こくみん) |

The standalone usage is what a learner first encounters when reading
N5 sentences. The compound-only on-yomi appearing as primary creates
a learner mis-association.

**Defensible on-yomi-primary cases that should stay:** kanji whose
N5 use is overwhelmingly compound or both equal. Examples: 時 (じ —
時 alone never appears, only as part of clock-time expressions), 社
(しゃ — never standalone at N5), 駅 (えき — both standalone and
compound).

**Authoring rule:** when setting `primary_reading`, ask: "Does the
kanji ever appear ALONE in an N5 sentence? If yes, which yomi does
that standalone form use?" That answer is the primary_reading.
Compound-frequency is secondary.

**CI invariant pattern:** a lock for specific known-tricky kanji
that mustn't drift back. (N5's JA-102 covers the 6 cases above.)

### F.22.3 Field-name inconsistency in examples (BUG-022)

**Failure shape:** the same conceptual field uses two different key
names across entries based on authoring pipeline provenance.

**N5 instance:** kanji.json examples field carried 374
entries with `form`, 20 with `lemma` only, and 14 with both (where
hand-authored entries used `form` and auto-derived ones from
vocab.json used `lemma`). The provenance is already captured in
`auto_derived: true`, so the dual field names were redundant.

**Resolution:** pick one canonical name (kept `form`, matching
vocab.json and the majority of entries); migrate the 18 lemma-only
entries (after BUG-020 removed 2) plus drop `lemma` from the 14
dual-field entries. Provenance signal stays in `auto_derived` +
`vocab_id`.

**Authoring rule:** when two pipelines emit the same conceptual
field, normalize at the merge point. Don't ship the pipeline
divergence as a corpus schema.

**CI invariant pattern:** every example object must have the
canonical field and must NOT have the legacy field. (N5's JA-101.)

### F.22.5 Auto-derived compounds inherit upstream dedup drift (BUG-024, 2026-05-17)

**Failure shape:** corpus A's content is auto-derived from corpus B
via a pipeline. When corpus B is cleaned (e.g., dedup pass removes
subset-gloss duplicates), corpus A is NOT automatically regenerated.
A's auto-derived rows still carry the pre-cleanup state.

**N5 instance:** kanji.json's `n5_compounds` arrays included rows
auto-derived from vocab.json. The VOCAB-005 / VOCAB-006 dedup
(BUG-018 / BUG-019, 2026-05-16) removed 13 subset-gloss duplicate
entries from vocab.json. The kanji.json auto-derivation pipeline
was not re-run after that fix, so kanji.json kept the old data.
BUG-024's audit (2026-05-17) found 7 such residual duplicates
across 月, 前, 気, 電, 道, 言, and 本 entries — same shape as the
vocab.json bugs that had already been fixed.

**Resolution at N5:** hand-applied the same dedup pattern to
kanji.json:

- **Drop subset-gloss duplicate** when `(form, reading)` is identical
  and one gloss is a strict subset of the other (e.g., 月 entry's
  「moon」 vs 「month, moon」 — drop the subset)
- **Merge same-reading distinct-senses** when `(form, reading)` is
  identical but the senses are genuinely different (e.g., 本 entry's
  「book」 vs 「counter for long thin objects」 — combine into one
  row with gloss 「book; counter for long thin objects」)
- **Leave legitimate polysemy** when readings DIFFER (e.g., 一 entry's
  一日/ついたち "1st of the month" vs 一日/いちにち "one day" — both
  rows kept; the (form, reading) tuple disambiguates)

**CI invariant pattern:** within any single parent-entry's auto-
derived child array, the `(form, reading)` tuple must be unique.
Catches the dedup-drift class automatically. Different readings
PASS (legitimate polysemy). (N5's JA-103.)

**Operational rule:** any dedup pass on a "source" corpus MUST
trigger re-derivation of every "derived" corpus that consumes it.
Document the derivation pipelines in the corpus's _meta.consumers
field; CI invariant JA-82 enforces that those references resolve,
but it doesn't yet enforce that the derivation has actually been
re-run. Future iteration: add a `last_derivation_run_at` timestamp
+ CI check that it post-dates the source's `last_modified`.

**Authoring rule:** when the kanji.json auto-derived pipeline runs,
it should look up the canonical (form, reading, gloss) from
vocab.json at derivation time. The 2026-05-17 audit found the
auto-derived rows had STALE glosses (the old subset versions), not
the current ones — suggesting the derivation captured a snapshot
once and hasn't been re-evaluated. Re-derivation should pick up
the canonical values fresh.

### F.22.4 Meta-lesson — kanji-corpus quality is a separate audit pass

The 3 BUG-020..022 bugs surfaced in a kanji.json-specific audit AFTER
the vocab.json audit (BUG-014..019) had landed. The lesson: don't
assume "vocab corpus audited = kanji corpus also clean." Each corpus
needs its own native-teacher pass.

**Cross-corpus consistency checks** (like F.22.1's vocab_id → vocab.form
resolution) are necessary but not sufficient — they catch reference
INTEGRITY but not display drift or pedagogical correctness.

**Cross-reference:** BUG-020 through BUG-022 close-out in
`N5/feedback/n5-audit-2026-05-04.xlsx` (2026-05-17, all Status:
Fixed). New CI invariants JA-100, JA-101, JA-102. Fix scripts:
`tools/fix_bug_020_kanji_oos_compounds_2026_05_16.py`,
`tools/fix_bug_021_primary_reading_kun_2026_05_17.py`,
`tools/fix_bug_022_kanji_examples_form_field_2026_05_17.py`.

## F.23 Reading-corpus batch-drift (BUG-041..046, added 2026-05-17)

**Failure shape (the meta-class):** a corpus is built in two
phases. Phase 1 establishes a convention (field name, value
semantics, shape). Phase 2 — sometimes months later, often by
a different contributor or LLM session — adds new entries
using a DIFFERENT convention. Both phases pass schema
validation because the schema is permissive or undocumented
for that field. The drift goes undetected until a downstream
consumer hits a value it doesn't recognize.

**N5 instance:** reading.json's first 45 passages (`n5.read.001`
..`045`, the original batch) used one set of conventions. The 9
newest passages (`n5.read.046`..`054`, a later batch) used
different conventions across SIX fields. The discrepancies were
uniform within each batch — the signature is NOT random
authoring noise, it's a clean split. The original conventions
were never captured as machine-enforceable invariants, so the
permissive schema absorbed the drift silently.

The 6 specific divergences appear in §F.23.1..F.23.6 below.
F.23.7 captures the cross-cutting batch-drift detection rule.

### F.23.1 Legacy enum field with mixed semantics (BUG-041)

**Failure shape:** a single field carries 3+ unrelated
semantic axes (e.g. "difficulty AND level AND passage-type"
as enum values). Different authoring passes pick different
axes. The field becomes uninterpretable without knowing the
provenance of each entry.

**N5 instance:** reading.json passages used `level` with FOUR
mixed-semantics values:

- 45 passages: `level: "easy"` or `level: "medium"` (the
  field's intended use — difficulty)
- 9 passages: `level: "N5"` (using the field for JLPT-level
  bookkeeping — redundant with the corpus's own filename)
- A subset: `level: "info-search"` (using the field for
  passage TYPE — already captured in `format_role`)

**Resolution:** rename to `difficulty` with a closed enum
`{easy, medium, hard}`. Map `"N5"` → `"medium"` (the 9 newest
passages tested at the corpus's nominal level). Drop entries
whose `level` was capturing a passage type (covered by
`format_role`).

**CI invariant pattern:** `difficulty ∈ {easy, medium, hard}` —
strict-equality. (N5's JA-104.)

**Authoring rule:** a single field cannot mean "difficulty AND
JLPT-level AND passage-type." When you find a field carrying
3+ meanings, decompose. Difficulty stays in `difficulty`,
level is the corpus filename, passage type is `format_role`.

### F.23.2 Multi-language fields without explicit locale separation (BUG-042)

**Failure shape:** a single text field carries content in
multiple languages, separated by an inline delimiter like
parens or slashes. Consumers that want only one language must
parse the field; consumers that don't know about the embedded
languages display garbage; locale-specific fields and inline
copies drift apart over time.

**N5 instance:** reading.json's `summary` field carried mixed
JA + EN + HI content across 45 passages in the shape
`"じこしょうかい (self-introduction विषय परिचय)।"`. The 9 newest
passages carried JA only. Hindi was ALSO present in a separate
`summary_hi` field, so the inline HI was a double-encoding bug
on top of the language-mixing.

**Sub-lesson (terminator-character variants):** the regex that
normalized the summaries had to accept the Devanagari danda
`।` (U+0964), the Japanese full-stop `。` (U+3002), the ASCII
period `.`, or no terminator at all — the 45 mixed-language
summaries all ended with `।` (carried over from the HI half).
An over-narrow regex that only allowed `。` matched 0 of 45
entries on first run; the fix required broadening the
terminator character class. **Generalization:** when string-
parsing multi-locale data, expect punctuation from any of the
locales involved, not just the "primary" one.

**Resolution:** normalize `summary` to JA-only. Extract the
parenthetical (which contained EN + a stale HI fragment) and
move EN to a new `summary_en_extracted` field. The canonical
HI remains in `summary_hi`.

**Authoring rule:** locale-specific content goes in
locale-suffixed fields. Never inline multiple languages in one
field with positional delimiters. Other-locale "translations"
captured inline are SECONDARY content and indicate a missing
locale field.

### F.23.3 _meta documentation drift (BUG-043)

**Failure shape:** the corpus's own self-description in
`_meta.schema_additions` falls out of sync with the actual
schema after fixes land. New consumers reading the meta to
understand the corpus structure get stale information.

**N5 instance:** reading.json's `_meta.schema_additions` did
not list `format_type: "notice"` (one of the three info-search
subtypes actually present in the data) and still referenced a
`comprehension` format_type that BUG-044 was removing.

**Resolution:** rewrite `_meta.schema_additions` to reflect
the post-fix shape. Include the BUG-041 (difficulty),
BUG-042 (locale-suffixed summary fields), and BUG-045
(vocab_preview shape) migrations in the description.

**Authoring rule:** when a fix changes a field's shape, update
`_meta` IN THE SAME COMMIT. Treat _meta as data, not
documentation — it's loaded by consumers. (Companion to
F.22.5's "re-derive consumer corpora" rule: same problem
class, different layer.)

### F.23.4 Conceptual field duplication across two key names (BUG-044)

**Failure shape:** two fields with overlapping semantics
co-exist on the same record. Sometimes both are set (and
agree); sometimes only one is set; sometimes both are set but
contradict. Consumers must pick one; the choice is undocumented.

**N5 instance:** reading.json carried both `format_type` and
`format_role` on the same passages. For 9 passages, both
fields had the value `"comprehension"` — the passage TYPE,
which belongs in `format_role`. `format_type` had an intended
narrower use: the visual SUBTYPE of info-search passages
(`schedule_table` / `menu_list` / `notice`). The
"comprehension" value for `format_type` was bleed from
`format_role`.

**Resolution:** keep `format_type` for the narrow
info-search-subtype semantic; drop it from comprehension
passages (where it was redundant with `format_role`). Lock
`format_type ∈ {null, schedule_table, menu_list, notice}`.

**CI invariant pattern:** strict closed-enum on `format_type`
including `null` for non-applicable passages. (N5's JA-106.)

**Authoring rule:** when two fields have overlapping semantics,
write a 1-sentence definition for each (using just the words
"this means X and ONLY X"). If you can't, collapse them into
one field.

### F.23.5 Field-shape divergence (BUG-045)

**Failure shape:** a list-typed field has two shapes across
the corpus: Shape A (list of primitives) vs Shape B (list of
objects with one canonical key). Consumers that expect one
shape silently break on the other; the embedded-object form
also denormalizes data that could be resolved via reference.

**N5 instance:** reading.json's `vocab_preview` was a list of
vocab_id STRINGS on 45 passages (Shape A) and a list of DICTS
`[{vocab_id, form, reading, gloss}, ...]` on 9 passages
(Shape B). The dict entries duplicated information already
resolvable via vocab_id lookup; the duplication risked stale
data if vocab.json gloss/reading changed but the embedded
copy didn't.

**Resolution:** normalize to Shape A (list of vocab_id
strings). Consumers that want the form/reading/gloss can
resolve via vocab.json. Removes the duplication and avoids
stale-snapshot drift.

**CI invariant pattern:** strict shape check —
`vocab_preview` is `list[str]` (not `list[dict]`). (N5's
JA-105.)

**Authoring rule:** prefer ID-references over embedded copies
when the referenced data lives elsewhere. The embedded copy is
a denormalization that has to be maintained in sync — and
won't be.

### F.23.6 Pronoun-form inconsistency on canonical text (BUG-046)

**Failure shape:** a high-frequency morpheme appears in two
forms (e.g., kanji vs kana) across the corpus depending on
which authoring pass produced the entry. The level whitelist
allows BOTH, so neither is technically wrong — but the
inconsistency looks unprofessional and complicates pedagogical
claims about kanji exposure.

**N5 instance:** 45 reading.json passages used わたし (kana);
9 used 私 (kanji). The N5 kanji whitelist includes 私. The 9
newest passages were authored after an implicit standardization
on the kanji form, but the older 45 weren't back-migrated.

**Resolution:** string-replace わたし → 私 across the 45 older
passages (26 replacements across 23 passages). Update
`kanji_used` on those passages to include 私.

**Authoring rule:** when a high-frequency morpheme is on the
level's kanji whitelist AND standard textbooks teach it in
kanji form, prefer the kanji form. When you change this policy
mid-corpus, propagate the change to ALL prior entries before
merging the new batch.

### F.23.7 Meta-lesson — batch-drift detection

The six BUG-041..046 bugs were ONE pattern, not six different
ones: a later authoring batch (9 passages) used different
conventions from an earlier batch (45 passages). The
divergences were uniform within each batch, which is the
signature of batch-drift (vs. random authoring noise). A
single-corpus audit that found ONE of these bugs should have
triggered a "look for the other five" check.

**Detection signal:** if `corpus[i]` has a field set with one
shape/value-class and `corpus[j]` has the same field with a
different shape/value-class, AND the split lines up cleanly
with entry-creation order (or with any other metadata facet
like author / source / batch ID), suspect batch-drift. Random
authoring noise spreads across the corpus; batch-drift clusters.

**Operational rule:** after any "add N new entries" pass on a
corpus that has prior entries, run a same-shape audit against
the prior batch — for every field on the new entries, does the
field exist on the prior entries? Does it have the same
value-shape? Same enum? Same locale split? The audit catches
the drift at merge time, not 6 months later when a downstream
consumer breaks.

**CI invariant pattern (general):** for any list-typed,
enum-typed, or schema-defined field on a corpus that grows
over time, write a strict-shape invariant (not "permissive
sample" — strict) at the time the field is introduced. The
invariant is the contract; the field's appearance without an
invariant is technical debt.

**Cross-reference:** BUG-041 through BUG-046 close-out in
`N5/specifications/test-scenarios-by-specialist-perspective.xlsx`
"User Reported Bugs" sheet (2026-05-17, all Status: Fixed).
New CI invariants JA-104, JA-105, JA-106. Fix script:
`tools/fix_bugs_041_to_046_reading_json_2026_05_17.py`.

## F.24 Listening-corpus migration drift — same meta-class on a different corpus (BUG-047..053, added 2026-05-17)

**Failure shape (same as F.23):** a multi-phase corpus
modification (here: a round-9 migration from edge-tts to
VOICEVOX) completes in some fields but does not propagate to
others. The split between "migrated" and "stale" fields is
uniform across all N items (50 listening drills) — the
signature of batch-drift, not random noise. The stale fields
remain plausible at schema validation time because the
permissive schema accepts both shapes; downstream consumers
either pick the wrong source or display contradictory
information.

**N5 instance:** a 2026-05-12 VOICEVOX migration on
`data/listening.json` updated `audio_render_meta` with the new
provider, speaker IDs, and rendered_at timestamp on all 50
items. But the upstream `voice_planned.engine` field stayed at
`"edge-tts"` (the pre-migration plan); items 41-50 had stale
audit-status fields (`pacing_status="no_audio"` /
`voice_variety_status=None` despite being rendered); the
`_meta.voice_variety_plan` block still described VOICEVOX as
"future work"; the `voicevox_speaker_catalog` had wrong
character→ID mappings; and a separate dual-field bug
(`format` ↔ `format_type` 1:1 redundancy) was discovered in
the same audit pass.

The 7 specific divergences appear in §F.24.1..F.24.6 below.
§F.24.7 captures the cross-cutting lesson (which extends
§F.23.7).

### F.24.1 Multi-source drift on a single attribution field (BUG-047)

**Failure shape:** two fields on the same record describe the
same attribute (here: which TTS engine rendered the audio)
but were updated by different code paths at different times.
Post-migration they contradict.

**N5 instance:** every item declared
`voice_planned.engine="edge-tts"` (the pre-migration plan) AND
`audio_render_meta.voice_provider="voicevox"` (the post-
migration reality). The runtime UI rendered the stale engine
name in the F-10 voice-attribution surface, mis-attributing
the audio to the wrong vendor.

**Resolution options (per the bug):**

(a) Rewrite `voice_planned` to mirror
`audio_render_meta.voice_planned_for_engine`. Keeps the dual
field; one-shot fix.
(b) Deprecate `voice_planned` entirely; `audio_render_meta`
is the source of truth. Requires UI update. Collapses the
dual-field schema.
(c) Keep both but reinterpret `voice_planned` as "next-render
plan" rather than "what was rendered." Documents the schema
in `_meta`.

**N5 chose (b)** — collapse to a single field. The dual-field
schema is the structural cause; option (a) just papers over
the next migration. The UI (`js/listening.js` F-10 voice-
attribution surface) was updated in the same commit to read
from `audio_render_meta.voice_provider` and
`audio_render_meta.voice_planned_for_engine.{F,M}.character`.

**CI invariant pattern:** strict "field absent" check on the
deprecated key. (N5's JA-110.)

**Authoring rule:** when a corpus migration changes a value's
ground truth, the pre-migration field is no longer
authoritative — it's stale plan documentation. Drop it in the
same commit as the data migration; don't leave it for "later."

### F.24.2 Audit-status fields drift behind the data they describe (BUG-048)

**Failure shape:** a "current state" status field (e.g.,
`pacing_status="no_audio"`, `voice_variety_status=None`) was
set BEFORE the work it describes was done. The work landed
(audio rendered) but the status field was never refreshed.

**N5 instance:** items 41-47 had `pacing_status="no_audio"`
but `audio_render_meta.rendered_at` was populated; items
48-50 had `voice_variety_status=None` with the same rendered
state. Audio existed, but the status field claimed otherwise.

**Resolution:** sweep every item where `audio_render_meta.
rendered_at` is set and refresh the status fields to reflect
reality. For pacing-not-yet-measured items, "unmeasured" (not
"no_audio") is the correct status.

**Authoring rule:** any code that produces a side effect
(audio render, transcript alignment, pitch analysis) must
update the corresponding status field IN THE SAME PASS.
Don't ship "produce side effect" and "update status" as
separate steps — they drift.

### F.24.3 Operational deferral that needs corpus-level surfacing (BUG-049)

**Failure shape:** a corpus-quality issue that requires a
heavier fix (here: audio re-render at a higher speed_scale)
is correctly diagnosed but the fix can't land in the
discovery batch because it needs external resources
(VOICEVOX install, ~30 min budget). If the issue is just
verbally noted in a tracker, it gets lost.

**N5 instance:** 26/50 items had pacing_morae_per_min below
the JLPT N5 target band of 180-240 (mean observed: 160.2
mpm). Some items were 5× slower than exam pace
(n5.listen.012 at 38.4 mpm). The fix needs VOICEVOX re-render
at speed_scale ~1.3.

**Resolution:** surface the issue **inside the data file**.
N5 added `_meta.pacing_fix_status` carrying the bug ID, the
observed distribution, the required fix action, and the
target band. Downstream tools (audit scripts, future
re-render scripts) read the surfaced status block and act on
it. The bug tracker entry stays Open.

**Authoring rule:** corpus-level deferred actions go in
`_meta.*_fix_status` blocks, not just in the bug tracker.
The data file is the durable record; trackers are session-
scoped and easily lost.

### F.24.4 Dual-field redundancy (a third instance) (BUG-051)

**Failure shape:** two fields encode the same conceptual
information with perfect bijection. Same pattern as BUG-044
(reading.json `format_type` ↔ `format_role`).

**N5 instance:** listening.json items carried both `format`
(short) and `format_type` (descriptive) with strict 1:1
mapping: `task↔task_understanding`, `point↔point_understanding`,
`utterance↔utterance_expression`, `response↔immediate_response`.

**Resolution:** drop the shorter / less descriptive field
(`format`); `format_type` is canonical with a closed enum.
JS consumers (`listening.js` `byFormat` grouping +
`search.js` haystack) updated to use `format_type`.

**CI invariant pattern:** same as JA-106 (closed-enum on
the surviving field) + a strict "field absent" check on the
deprecated field. (N5's JA-111.)

**Authoring rule:** if you're adding a new field with values
that can be derived from an existing field (or vice versa),
don't. Pick one. The dual-field schema invites the exact
drift that BUG-044 / BUG-047 / BUG-051 all demonstrate.

### F.24.5 Plan-document drift after the plan is executed (BUG-052)

**Failure shape:** an "approach document" embedded in the
data (here: `_meta.voice_variety_plan`) describes a planned
migration. The migration completes. The plan document
isn't updated — it still reads as future work.

**N5 instance:** `_meta.voice_variety_plan` described
VOICEVOX as "to be authored when VOICEVOX is installed" with
a render_command_template using future-tense language. The
2026-05-12 render had already executed.

**Resolution:** rewrite the plan as a past-tense completion
record with `status="completed_<date>"`, capture the
observed-vs-target distribution, and mark the prior version
as superseded (don't delete it — historical context has
value).

**Authoring rule:** plan-block schema should distinguish
"planned / in-progress / completed / deprecated" explicitly.
A `status` field forces the question at every commit.

### F.24.6 Reference-data inaccuracy in a metadata catalog (BUG-053)

**Failure shape:** a metadata catalog mapping IDs to
human-readable names was authored with WRONG name→ID
correspondences. The IDs were correct (VOICEVOX speakers
2/3/8/11/13 exist) but the character-name labels attached to
them were drawn from a different source list and didn't
match.

**N5 instance:** the prior catalog listed:
- ID 8 = "hau-tsumugi" (actually 春日部つむぎ; "hau-tsumugi"
  is ID 10 = 雨晴はう)
- ID 11 = "shirakami-kotaro" (actually 玄野武宏; a different
  speaker entirely)
- ID 13 listed under "12" as "aoyama-ryusei"

The audit ran against the actual rendered audio
(`audio_render_meta.voices_used`) to determine the real
mappings, then rewrote the catalog.

**Resolution:** cross-reference the metadata catalog against
the upstream source (here: VOICEVOX engine's `/speakers`
endpoint or the actual `voices_used` field on rendered
items). Use the upstream source as ground truth, not a
copy-paste from a different blog post / docs page.

**Authoring rule:** metadata catalogs that mirror an external
system must be derived from the external system, not
hand-authored. If derivation isn't practical, at minimum
add a "verified against <source> on <date>" stamp + a CI
check that re-derives and compares.

### F.24.7 Meta-lesson — extending F.23.7 to a different corpus

The 7 BUG-047..053 bugs are NOT a separate class from BUG-041..
046; they're the SAME class (corpus-migration drift) on a
different corpus + a different migration. F.23.7's detection
signal — "if `corpus[i]` differs from `corpus[j]` on a field's
shape/value-class AND the split lines up cleanly with a
metadata facet, suspect batch-drift" — applies here. The
metadata facet was "what was migrated to VOICEVOX vs what
wasn't" rather than "earlier authoring batch vs later batch,"
but the structural shape is identical.

**Generalized operational rule** (replaces F.23.7's
batch-specific phrasing): after any corpus-level migration or
batch-modification pass, run a same-shape audit not just on
the data items themselves but on EVERY field that references
the migrated state — `_meta` blocks, audit-status fields,
sibling fields with overlapping semantics, plan documents,
and metadata catalogs. The audit must run BEFORE the migration
batch merges, not after a downstream consumer breaks.

**Cross-reference:** BUG-047 through BUG-053 close-out in
`N5/specifications/test-scenarios-by-specialist-perspective.xlsx`
"User Reported Bugs" sheet (2026-05-17). BUG-050 already-fixed
in commit cdef185 (Rule-5 install, version.json count drift).
BUG-049 stays Open (needs audio re-render). New CI invariants
JA-110, JA-111. Fix script:
`tools/fix_bugs_047_to_053_listening_json_2026_05_17.py`.
JS source updates: `N5/js/listening.js` (voice-attribution
surface re-wired to read from audio_render_meta; FORMATS map
rekeyed to format_type) + `N5/js/search.js` (haystack updated).
Minified `js/min/*.js` regenerated via
`tools/build_min_js.py`. Static mirrors regenerated via
`tools/build_static_mirrors.py` (50 listening pages rewritten).

## F.25 Baseline-allowlist pattern for reserved-invariant promotion (added 2026-05-17)

Two N5 invariants — JA-91 (cross-pattern explanation_en similarity)
and JA-94 (per-example structural-marker presence) — sat reserved
through ~5 audit cycles because their detectors mechanically
surfaced findings that mixed legitimate corpus structure with
genuine bugs. JA-91's detector found 43 pairs of similar
explanations across patterns; JA-94's detector found 14 examples
whose `ja` field didn't contain any marker from its parent
pattern's marker catalog. In neither case could the detector
distinguish "intentional re-introduction / cross-reference /
variant" from "accidental contamination" without a per-finding
classification.

The unblock pattern that closed both: **baseline-allowlist**.

### F.25.1 Pattern shape

For an invariant `JA-NN` whose detector returns a finite set of
findings, some of which are legitimate corpus structure:

1. Author a snapshot of the current findings as
   `data/_jaNN_baseline.json`:
   - `_meta` block with `purpose`, `classification_legend`,
     `snapshot_date`, `next_review_trigger`.
   - The findings array, with a per-entry classification + rationale
     note.
   - `_audit_summary` block with counts + threshold.
2. Wire the CI check to LOAD the baseline + only fail on findings
   NOT in the baseline:
   - For pair-based invariants: normalize each pair to a frozenset
     for order-independent membership.
   - For per-item invariants: build a set of `(item_id, index)` tuples.
3. Register the invariant with explicit "no NEW <class> beyond the
   N-item baseline in data/_jaNN_baseline.json" description text so
   maintainers can find the allowlist file.
4. Add a Phase-0 regression block in the improvement-prompt for
   maintainer-side ad-hoc audits (target value = baseline count;
   non-zero deviation signals drift before CI catches it).

### F.25.2 When this pattern is appropriate

- (a) The detector has 0 false-negatives against its target class
  but surfaces a known finite set of legitimate cases that can't
  be mechanically distinguished from genuine bugs.
- (b) Each baseline entry can be classified with a rationale note
  explaining WHY it's allowlisted (so a future audit cycle can
  re-evaluate).
- (c) The baseline file lives at `data/_jaNN_baseline.json` with
  the `_meta` block above.
- (d) The invariant's failure message tells maintainers HOW to
  add a new entry (add to baseline with classification) AND HOW
  to address legitimately failing content (rewrite to diverge).

### F.25.3 When NOT to use baseline-allowlist

- The detector has false-positives (surfacing actual non-bugs).
  Fix the detector first.
- The class of legitimate cases is unbounded / growing rapidly.
  Strict closed-enum or per-rule check is better.
- The baseline would carry > 100 entries. That's a corpus-quality
  signal — the invariant itself is too strict and needs refinement,
  not allowlisting at scale.

### F.25.4 Bounded-coverage phrasing for audit docs

When describing baseline-allowlist invariants in audit documents,
always qualify scope:
- "JA-NN baseline allowlists X specific <items> *in the corpus
  snapshot scanned <date>*" — not "JA-NN allowlists X <items>".
- "JA-NN prevents re-introduction of *these specific patterns*" —
  not "JA-NN locks <bug class>".

A future audit cycle may extend, shrink, or empty the baseline;
the doc should not overclaim permanence.

### F.25.5 Promotion path

The promotion path for a reserved invariant becomes:
**reserved → partial-promoted with non-empty baseline → resolved
to empty baseline OR retained as documented permanent allowlist.**

The "resolved to empty" path is documented in F.26 below; the
"retained as permanent allowlist" path is appropriate when the
legitimate cases are corpus-structural and won't change without
a major restructuring (e.g., JA-67's Density-3 below-floor count).

## F.26 Empty-baseline resolution methodology (added 2026-05-17)

When a baseline-allowlist invariant (F.25 pattern) has finite
findings that *can* be addressed without major corpus restructuring,
the resolution path is to author content / data changes that retire
each baseline entry, then empty the baseline file. After resolution,
the invariant runs unconditionally on the live corpus; the empty
baseline file is retained as a RESOLVED snapshot documenting the
prior pair / item set.

### F.26.1 Two resolution categories

Today's JA-91 + JA-94 resolution illustrates the two main shapes:

**Phase A — example replacement** (JA-94 / 14 items): each
wrong-pattern example was REPLACED with a parent-pattern-
demonstrating example. The new example:
- Contains ≥1 structural marker from the parent pattern's marker
  catalog (the JA-94 enforcement target).
- Is grammatically correct N5-level Japanese.
- Has a reasonable English translation.
- Matches the form / register of other examples in the same
  pattern.
- Doesn't collide with any existing example in the corpus
  (JA-81 boilerplate guard).

A one-shot replacement script (`tools/apply_<bug>_fixes_<date>.py`)
loads grammar.json, applies the 14 (pattern_id, ex_index → new_ja,
new_translation_en) tuples, saves grammar.json, and empties the
baseline file. Each replacement is validated against JA-94's
marker-presence check before commit.

**Phase B — explanation divergence rewrites** (JA-91 / 43 pairs):
each pair's deferring side (or both sides, for ALTERNATIVE_VARIANT
pairs) was REWRITTEN to diverge in TEXT (different framing /
register / focus) so the SequenceMatcher similarity falls below
the threshold. The pair retains its conceptual relationship; only
the surface text differs enough to not trip the detector.

Resolution strategy by baseline class:

| Class | Rewrite who | Strategy |
|---|---|---|
| DUPLICATE_PATTERN | the duplicate / "re-introduction" side | Use distinct framing (re-introduction sequencing, sub-use scope, alternate register) so the prose diverges without changing coverage |
| CROSS_REFERENCE | the deferring side | Rewrite as focused sub-scope entry that explicitly points at the parent; canonical entry keeps full text |
| ALTERNATIVE_VARIANT | both sides | Rewrite with register / syntactic-frame distinguishing prose; each variant now has its own framing focus |
| SUBSET | the subset side | Rewrite as focused sub-scope entry pointing at the broader series |

The rewrite script (`tools/apply_<invariant>_rewrites_<date>.py`)
loads grammar.json, applies the per-pattern explanation_en
rewrites, saves grammar.json, then VERIFIES:
1. All prior baseline pairs now fall below the similarity threshold.
2. Zero NEW pairs cross the threshold from the rewrites (regression
   guard — the rewrites shouldn't accidentally create new similar
   pairs).
3. If both conditions hold, empty the baseline file.

### F.26.2 What the resolution does NOT do

- **Does not change pattern IDs.** The 178 pattern IDs stay; only
  explanation_en + example fields change. Cross-references from
  reading.json / kanji.json continue to resolve.
- **Does not merge duplicate patterns.** DUPLICATE_PATTERN pairs
  still cover the same conceptual content under two IDs; a future
  structural merge audit would address that separately. Phase B
  only retires JA-91's detection — not the underlying duplication.
- **Does not change pattern counts.** version.json / README.md /
  AUDIO.md / CONTENT-LICENSE.md / Spec §7.3 sample counts stay
  the same.

### F.26.3 RESOLVED-snapshot file format

The baseline file is RETAINED post-resolution, with:
- `baseline_pairs` (or `baseline_failing_examples`) emptied to `[]`.
- `_meta.purpose` updated to mention "RESOLVED <date>".
- `_meta.resolution_date` added.
- `_audit_summary.next_review_trigger` updated with the resolution
  narrative.
- Classification legend retained as documentation of the prior pair
  / item set.

The empty file serves as the historical snapshot — future
maintainers can read the legend to understand what classes the
invariant was previously allowlisting and why each was retired.

### F.26.4 Phase-0 regression block target update

When a baseline-allowlist invariant resolves, update the
corresponding Phase-0 regression block in the improvement-prompt:
- Target value: was `baseline_count`; now `0`.
- Drift signal: "NEW <class> beyond the empty baseline" — fix
  via re-author + re-empty.

### F.26.5 Bounded-coverage phrasing for resolved invariants

Audit docs describing the resolution must qualify:
- "JA-NN baseline RESOLVED 2026-05-17 — *X prior <items> addressed
  via <Phase A/B>; baseline file retained as RESOLVED snapshot*"
  — not "JA-NN bug class permanently fixed".
- "JA-NN now enforces <invariant> unconditionally *against the
  current corpus*" — the qualification matters when future corpus
  growth could re-introduce the class.

## F.27 From-source TTS re-render at unified speed_scale supersedes stacked post-processing (added 2026-05-17)

When a TTS-rendered audio corpus needs pacing adjustment and the
initial render's speed_scale was suboptimal for the target band,
the operational instinct is to apply post-processing
(ffmpeg-atempo, librubberband, etc.) as a faster patch than full
re-render. Stacked post-processing works AND ships, but it
accumulates provenance complexity. A from-source re-render at a
unified speed_scale with minimal per-item post-processing is the
cleaner long-term state.

### F.27.1 N5's three-phase audio history (illustrative)

1. **Initial render** (2026-05-12, commit c28266d-era): VOICEVOX
   at speed_scale=0.95 for 50 listening items. 6 distinct speakers.
   Out-of-band on many items.
2. **Phase-1** (2026-05-17, commit 47d1edc — BUG-048/049 close-out):
   ffmpeg-atempo post-processing on 39 items. 3 items needed
   chained atempo (factor < 0.5).
3. **Phase-1.5** (2026-05-17, commit c79c02e): replaced chained
   atempo with single-pass librubberband on those 3 items. Quality
   upgrade for sub-0.5 slowdown factors.
4. **Phase-2** (2026-05-17, commit cdd0e6d): full from-source
   re-render at speed_scale=1.00. Post-render pass applied
   single-pass atempo to 29 items; rubberband to 5 sub-0.5 items;
   16 items rendered direct from VOICEVOX with no post-processing.

Phase-2 superseded Phase-1 + Phase-1.5's stacked layers. The
visible result is identical (all 50 in target band 180-240 mpm),
but the provenance is cleaner: every item is a single TTS render
+ at most one post-processing filter.

### F.27.2 When to invoke Phase-2-style re-render

- (a) The TTS engine is locally available (no API quota / no
  install-gating). For N5, VOICEVOX CPU edition is local; for
  alternatives requiring online API calls, re-render cost includes
  network quotas.
- (b) The baseline speed_scale was clearly suboptimal — e.g., > 30%
  of items needed adjustment in the post-render pacing pass.
- (c) The provenance value of "one render, one filter" justifies
  the wall-clock cost (N5 Phase-2: ~12 min serial on 50 items;
  parallelization could halve this with concurrent VOICEVOX
  requests).

### F.27.3 When NOT to re-render

- The current ship state passes CI + auditory review.
- The TTS engine is API-gated and quota-expensive.
- The post-processing footprint is genuinely small (< 10% of
  items adjusted, none at extreme factors).
- The TTS speakers / voice-variety plan would change in the
  re-render; that's an EXPANSION audit, not a Phase-2 quality lift.

### F.27.4 Procedure (for Nx audio re-render)

1. Author `tools/render_<corpus>_phaseN_<engine>_<speedscale>_<date>.py`,
   forked from the prior renderer with the new speedScale.
2. Confirm the TTS engine is reachable (`curl /version` against the
   local endpoint or equivalent).
3. Run the renderer; capture wall-clock + per-item log.
4. Run the pacing refresh tool with auto-apply (`--apply-speedup`):
   re-measure all items + apply ffmpeg-atempo to out-of-band items.
5. Identify items needing chained-atempo (factor < 0.5); replace
   each with single-pass librubberband via a follow-on tool that
   re-renders from the TTS source and applies the single-pass
   filter.
6. Final pacing re-measure (no `--apply`).
7. Verify CI green + audit-class invariants pass.
8. Update per-item `audio_render_meta` to clear prior post-
   processing fields (`post_render_tempo_*`,
   `phase15_method_change_*`) on items that no longer need them.
9. Update user-facing audio docs (AUDIO.md, AUDIO-PHASEN-RERENDER.md)
   from runbook → COMPLETED status; preserve the phase timeline.

### F.27.5 Bounded-coverage phrasing for audio phases

- "Phase-N retired the <artifact-class> *for this corpus snapshot
  at the <voice-plan> voice plan*" — not "Phase-N permanently
  retired <artifact-class>".
- "From-source re-render *with this engine version* (e.g.,
  VOICEVOX 0.25.2)" — engine version is part of the provenance.

A future engine upgrade may shift per-speaker timing characteristics
enough to require another Phase-N pass; the methodology
generalizes but the specific resolution snapshot does not.

## F.28 Multi-role specialist-review-by-tab methodology (added 2026-05-17)

The test-scenarios xlsx splits scenarios across 14 specialist tabs
(A through N), each tied to a domain expert role (Native Japanese
teacher, JLPT exam expert, Native Hindi teacher, Security engineer,
Privacy/legal lawyer, Performance engineer, Data engineer, Pedagogy
specialist, QA engineer, Cultural reviewer, UX designer,
Accessibility engineer, Operations engineer, End-user POV proxy).

The N5 session 2026-05-17 ran ALL 720 scenarios across the 15-tab
xlsx via specialist-role simulation. Lessons:

### F.28.1 Per-role review batch shape

For each role:
  1. Identify scenarios where this role is the Owner (xlsx col 12).
  2. Read the Scenario / Test steps / Expected result.
  3. Apply specialist judgment with explicit reference to credible
     sources (Genki I, Minna I, JEES official samples, NHK accent
     dictionary, Hindi Vyakaran, OpenSSF Scorecard, WCAG spec,
     GDPR/DPDP/COPPA legal texts, CC-BY-SA license terms, etc.).
  4. Run agent-side checks where possible (grep, data inspection,
     CI invariant lookup, file-presence verification).
  5. For findings: file a bug (NR-{ROLE}-{NN} naming convention),
     apply the fix in the same commit, mark Fixed with Fix Commit
     cell populated.
  6. Stamp each scenario with one of the bounded-honest result
     classifications (F.28.3 below).
  7. Run CI + cross-artifact-sync-report; both must stay green.

### F.28.2 Bug-ID naming convention

NR- (Native Reviewer) + role tag + sequence number:
  NR-{Japanese teacher = no tag}-NNN (e.g. NR-001 through NR-005)
  NR-HI-NNN  (Hindi reviewer)
  NR-JE-NNN  (JLPT exam expert)
  NR-SEC-NNN (Security engineer)
  NR-LIC-NNN (Privacy/legal lawyer)
  NR-DATA-NNN (Data engineer)
  NR-UI-NNN  (UI engineer)
  Future: NR-PERF / NR-A11Y / NR-OPS / NR-CULT / NR-UX / NR-PED / NR-QA / NR-EUP

### F.28.3 Bounded-honest stamping conventions

When stamping scenarios as PASS, qualify what was actually verified:

| Stamp label | Meaning |
|---|---|
| `PASS` | Verified by runnable check or CI invariant. |
| `PASS (limited verification)` | Code-grep / data-inspection only; no runtime / visual / user verification. |
| `PASS (architectural)` | Verified via architecture-level reasoning (e.g., static-only hosting = no POST endpoints). |
| `PASS (per JEES sample paper)` | Verified against credible source but not exhaustively. |
| `PASS (spot-check; full review deferred)` | Sampled but not exhaustively native-reviewer-reviewed. |
| `PASS — with finding (intentional design)` | Surfaced a quirk that's design-justified. |
| `PASS (computed; not browser-measured)` | Measured via file-size math; not on actual devices. |
| `PASS (vacuous — no <X>)` | N/A given privacy / architectural posture. |
| `PASS (per-item; per-utterance not measured)` | Surface metric balanced, deeper metric not measured. |
| `Manual — deferred (<reason>)` | Requires runtime / visual / user / specialist; agent-side gap. |
| `Skipped — external` | External tool not installed locally (Lighthouse, npm audit, GitGuardian). |
| `Skipped — no learner data` | Requires accumulated learner attempt data. |
| `Skipped — no runner` | Tools/scripts cell empty; nothing to execute. |
| `FAIL` | Real failure; surface as bug. |
| `PASS — with finding` | Verified passing AFTER bug found + fixed in same batch. |
| `Blocked — depends on <X>` | Dependent on artifact not shipped (e.g., Hindi audio). |

### F.28.4 Brutal-honesty re-audit class

After a pass with stricter-classification stamps lands, run a
brutal-honesty re-audit:
  - Re-execute deep scans (full corpus, not 30-sample) for each
    domain.
  - Re-classify previously-PASS stamps with bounded qualifiers
    when the original PASS rested on less-than-runtime verification.
  - File any NEW findings as new bugs.
  - The honest re-stamping is a deliverable in itself — future
    auditors get accurate ground-truth on what was actually verified
    vs taken on faith.

### F.28.5 Cross-artifact propagation

Every NR-* bug filed must trigger the Rule 4 / Rule 5 sync (see
parent CLAUDE.md). Specifically:
  - Bug entry on User Reported Bugs sheet with Fix Commit + Fix Date
  - Scenario stamp on the relevant specialist tab
  - Optional: new CI invariant if the bug class can recur
    mechanically
  - Spec / sync-map / CHANGELOG entry

## F.29 Selenium UI test class — E2E coverage of every functional surface (added 2026-05-17)

Adds an end-to-end UI test class running Selenium 4 (headless
Chrome via Selenium Manager auto-driver) against the live local
HTTP server. Tests every functional surface from
spec §5 (Home / Learn hub / per-module routes / Mock Test /
Practice / Settings / etc.) plus static-mirror surfaces, sitemap,
robots.txt, accessibility landmarks, security headers, Service
Worker, audio reachability, locale parity, and console-error
absence.

### F.29.1 Why Selenium 4 (vs Playwright / BrowserStack)

  - Selenium 4 ships Selenium Manager — auto-downloads the right
    chromedriver, no manual driver-install step. Runs in a CI
    Python container without browser-stack credentials.
  - Playwright is excellent but requires `playwright install` step
    (~200 MB browser download). Selenium Manager reuses the OS's
    installed Chrome.
  - BrowserStack (already wired in workflows) covers cross-browser
    via remote — Selenium runs the same suite on the local browser.

### F.29.2 What the test class covers

| Surface | Tests |
|---|---|
| Spec §5 functional routes | 5.1 (Home) / 5.3-5.8 (per-module) / 5.9-5.16 (Drill / Review / Missed / Summary / Settings / Sitting / Today / Privacy / Notices) |
| Static-mirror routes | /home/, /changelog/, /privacy/, /notices/, /learn/grammar/<id>/, /lessons/<id>.html (legacy), /reading/<id>/, /listening/<id>/, /learn/vocab/<form>/ (URL-encoded), /kanji/<glyph>/ (URL-encoded), + 5 index pages |
| SEO | sitemap.xml + robots.txt |
| Accessibility | <html lang>, skip-link, <title>, <main> landmark, aria-live |
| Security | CSP meta + X-Frame-Options meta (the latter being design-limited per NR-UI-001) |
| PWA | Service Worker API + registration |
| Audio | MP3 reachability + audio_manifest.json |
| i18n | Locale switch presence + locales/{en,hi}.json key parity |
| Console health | 0 SEVERE console errors |

### F.29.3 Critical NR-UI-001 lesson

Some defense-in-depth HTTP security headers are HTTP-header-only
per browser spec — they're IGNORED when delivered via <meta>:

  - `frame-ancestors` (CSP directive): only honored as HTTP header
  - `X-Frame-Options`: only honored as HTTP header

The N5 session originally added these via <meta> in commit
46be3e1 (NR-SEC-002), believing it would provide clickjacking
defense. Selenium console-error capture on every route load
exposed the cosmetic-fix nature (the browser fired SEVERE
console errors on every page).

Lesson: **always verify security-header effectiveness via
runtime browser check, not just by source-code inspection.**

For Nx builders on static hosting (GitHub Pages / Cloudflare
Pages / Netlify):
  - Honored via <meta>: CSP `default-src` / `script-src` /
    `connect-src` / `style-src` / `form-action` / etc.;
    Permissions-Policy; Referrer-Policy
  - NOT honored via <meta>: CSP `frame-ancestors`;
    X-Frame-Options
  - When clickjacking defense is needed: move to a host that
    exposes HTTP-header config (Cloudflare Pages with rules /
    Netlify _headers file / Vercel headers in vercel.json).

### F.29.4 Procedure (for Nx UI tests)

```bash
# 1. Install Selenium 4 + ensure Chrome is installed:
pip install selenium  # (already in requirements / pyproject)

# 2. Serve the project at production-equivalent root:
cd JLPT-Common-repo-root  # to keep ../assets/ paths working
python -m http.server 8765 &

# 3. Run the test suite:
python Nx/tools/ui_test_suite_YYYY_MM_DD.py
# Output: 55+ scenarios stamped; PASS / FAIL / SKIP per scenario;
# JSON persisted to tools/ui_test_results_YYYY_MM_DD.json

# 4. Console-error capture (catches issues missed by visual checks):
python Nx/tools/dump_console_errors.py

# 5. For each FAIL: file bug, apply fix, re-run.

# 6. Add results to test-scenarios xlsx "UI Tests" tab via
#    tools/add_ui_tests_tab_YYYY_MM_DD.py.
```

### F.29.5 Bounded-coverage phrasing for UI tests

  - "UI test suite verifies <N> scenarios *served from a local HTTP
    server matching production URL structure*" — not "verifies UI
    end-to-end".
  - "0 SEVERE console errors *post NR-UI-001 fix*" — not "0
    SEVERE console errors" (the meta-tag-ignored class was
    surfaced + retired in this batch).
  - Local server must serve from a root where `../assets/` paths
    resolve (i.e., JLPTSuccess/ root, not N5/ root) to avoid
    false-positive 404s on shared brand assets.

## F.30 Paper-question content audit — grammarPatternId / rationale / rationale_hi drift classes (added 2026-05-18)

Adds three drift classes specific to JLPT-paper question banks (Mondai 1
fill-in-blank, Mondai 2 sentence-ordering, Mondai 3 paragraph-gap). All three
are silent — the question still plays correctly at quiz time — but break
downstream consumers and learner trust.

### F.30.1 Drift class 1 — grammarPatternId mis-tagging

**Symptom:** A paper question's `grammarPatternId` field references a
canonical pattern (e.g., `n5-013` = も) but the correct answer is a different
particle (e.g., は). Affects study-plan grouping, pattern-frequency analytics,
"review weak particles" recommendation.

**Root cause:** Early auto-tag pass over a large question bank assigns
patterns without per-question validation. The default-tag (n5-013 in the N5
session, "n4-XXX" equivalent in Nx) gets applied wholesale.

**Detection:** For every Mondai 1 question whose correct answer is a single
particle, the `grammarPatternId` must reference the canonical pattern for that
particle. The mapping is one-to-one (see §F.30.4) and trivially CI-enforceable.

**Fix protocol:**

1. Build the particle ↔ pattern_id map once (read from the level's
   grammar.json — Particles category, single-character pattern field).
2. For each Mondai 1 question, read `correctIndex` + `choices[correctIndex]`;
   if it's a single particle in the map, set `grammarPatternId` accordingly.
3. For Mondai 1 questions where the correct answer is NOT a particle
   (verb/adj/copula form, counter, etc.), manual mapping per stem context.
4. Mondai 2 sentence-ordering: tag by the central structural pattern being
   assembled (typically the particle filling the ★ position).
5. Mondai 3 paragraph-gap: tag by the particle/pattern of the specific blank.
6. Set `grammarPatternId_provenance = "rule_based_correctanswer_<date>"`.

**CI invariant (N5 numbering — adjust for Nx):** JA-120 enforces particle-Q ↔
pattern_id alignment.

### F.30.2 Drift class 2 — commit-message-style meta-fix history in rationale

**Symptom:** A question's learner-facing `rationale` or `rationale_hi` field
contains commit-trail content like "Stem now anchored with わたしは", "(was
expensive)", "replaces colloquial X from a prior version", "(auto_inferred)".

**Root cause:** When a corpus fix is applied (e.g., particle change, stem
edit, distractor replacement), the maintainer documents WHY in the rationale
field — appropriate for a commit message, inappropriate for a learner who
sees this on the post-answer screen.

**Detection:** Substring-scan rationale fields for: `auto_inferred`,
`previously tagged`, `prior version was`, `Stem now anchored`, `Stem now
includes`, `replaces colloquial`, `replaces ので per`, `the original option`,
`was dropped because`, `replaced with`, `patched to`, `fix:`.

**Fix protocol:**

1. For each finding, isolate the meta-fix parenthetical / sentence.
2. Strip it from `rationale` AND `rationale_hi`.
3. Keep ONLY the learner-facing concept explanation.
4. Move the fix history to:
   - the commit message, OR
   - a separate `rationale_revision_note` field if audit-trail preservation
     is needed.
5. KEEP useful content even if it looks meta: distractor-analysis comments
   ("(option 3 is concessive, not causal — would invert logic)") are
   genuine learner content; don't strip those.

**CI invariant:** JA-121 prevents re-introduction of the meta-fix phrases.

### F.30.3 Drift class 3 — English-pattern rationale_hi (literal translation, not natural Hindi)

**Symptom:** `rationale_hi` reads as word-by-word literal translation of
`rationale_en` rather than natural Hindi. Common artifacts:

  - Apostrophe-s possessive ("दोस्त's घर", "माता's दिन") — non-existent in
    Devanagari
  - English contractions inline ("मैं'm नहीं भूखा yet", "मैं'll") — half-
    translated artifacts
  - Mojibake ("यहाँre" = "Are there" partial translation, "o'घड़ी" = English
    apostrophe with Hindi घड़ी)
  - English filler words ("वहाँ है lot का बर्फ़ पर top का पहाड़")

**Root cause:** Translation pipeline running word-by-word substitution on
English rationale instead of producing natural target-language output.
Manifests as a *quality cliff* in specific sections (e.g., one Mondai 2 batch
worse than Mondai 1) reflecting different translation runs/dates.

**Detection:** Substring-scan rationale_hi for apostrophe-s patterns,
"is/are+verb"-form English contractions, mojibake artifacts. Threshold:
"more than 6 ASCII letters present in a Hindi-script string" is a flag
(allowing legitimate Japanese-token + Romanized particle references).

**Fix protocol:**

1. For each affected question, take `rationale_en` as the source of truth.
2. Translate `rationale_en` into NATURAL HINDI (not literal). Test:
   "Would a Hindi-speaking N5 learner read this fluently?"
3. Keep Japanese tokens as-is (do NOT transliterate to Devanagari).
4. Particle names stay as Japanese characters (は / が / を / etc.).
5. Set `rationale_hi_provenance = "native_reviewed_<date>"`.
6. **Critical:** verify the new Hindi sentence matches the actual question's
   stem + correct answer. A natural-sounding Hindi sentence about the wrong
   question is worse than literal-but-correct content.

**CI invariant:** JA-122 prevents re-introduction of English-pattern
fragments (apostrophe-s, English contractions, common mojibake artifacts).

### F.30.4 Particle → pattern_id canonical map (N5 reference; mirror in Nx)

| Particle | Pattern ID |
|---|---|
| は | n5-002 |
| が | n5-003 |
| を | n5-004 |
| に | n5-005 |
| へ | n5-006 |
| で | n5-007 |
| と | n5-008 |
| から | n5-009 |
| まで | n5-010 |
| や | n5-011 |
| も | n5-013 |
| か | n5-023 |
| ね | n5-025 |
| よ | n5-026 |
| の | n5-028 |
| だけ | n5-033 |
| ぐらい / くらい | n5-035 |
| ごろ | n5-036 |
| など | n5-037 |
| ずつ | n5-038 |
| より | n5-095 (comparison) |

Build the equivalent table for Nx from `data/grammar.json` Particles category
(filter to single-character pattern fields).

### F.30.5 Bounded-phrasing for paper-audit close-out

  - "Re-tagged M of N Mondai 1 questions whose `correctIndex` resolved to a
    particle in the canonical map" — not "re-tagged all Mondai 1 questions".
  - "Stripped meta-fix history from N rationale fields against the K bad-
    phrase substrings scanned" — not "stripped all meta-fix history".
  - "Rewrote N rationale_hi fields where automated English-fragment detection
    fired" — not "rewrote all unnatural rationale_hi". Some legitimate
    technical fragments (e.g., "sub-が-suki", "X-jin") remain by design.

### F.30.6 Anti-pattern: don't translate from broken Hindi

When fixing PAPER-004-style mojibake, **always source from the verified
`rationale_en` field, not from the existing broken `rationale_hi`**. Pitfall
observed in this session: an initial fix pass tried to "clean up" the broken
Hindi by re-translating it back into natural Hindi, but the broken Hindi was
itself a wrong translation (talking about a different sentence than the
question's actual stem). Result: clean-looking Hindi that was about the
wrong sentence — worse than the original.

Verify the new translation matches the question's actual stem + correct
answer + rationale_en before saving.

## F.31 LLM / search-crawler accessibility — static surface design (added 2026-05-18)

Documents the static-surface set that makes a hash-routed SPA visible
to LLMs (Claude, ChatGPT, Perplexity, Google AI Overviews) and search
crawlers (Googlebot). The N5 case surfaced the design in 2026-05-18
via LLM-001..005 + REG-001 close-out (BUG-094..097, BUG-105, BUG-106);
the same set generalizes to every Nx level that ships a hash-routed
SPA on static hosting (GitHub Pages / Cloudflare Pages / Netlify).

### F.31.1 The fragment-blindness class

URL fragments (`#/learn/grammar/n5-008`) never travel in the HTTP
request. The server sees only the path; it returns the SPA shell.
LLM web-fetch tools and Googlebot get the same shell back for every
hash-routed URL. The entire per-entity content is invisible to:

  - LLM web-search workflows (Claude, GPT-4o web, Perplexity)
  - Google site:foo.com indexing
  - Bing, DuckDuckGo, all crawler-based discovery
  - Social-media link unfurling (OG tags work, but link points at shell)

### F.31.2 The 8-surface design (canonical set for any Nx SPA)

The minimum complete set:

| Surface | URL pattern | Purpose |
|---|---|---|
| 1. Per-entity static mirrors | `/Nx/learn/<module>/<id>/index.html` | One HTML page per grammar pattern / vocab entry / kanji / passage / drill / paper. Server-rendered; no JS required. |
| 2. Per-module index landing | `/Nx/learn/<module>/index.html` | Per-module "all 178 grammar patterns" / "all 1000 vocab" listing pages. |
| 3. Thin summary pages | `/Nx/<slug>.html` (7 files) | One-page-per-module summary (home / grammar / vocabulary / kanji / reading / listening / test). Crawler-friendly bookmark targets. |
| 4. Site-level sitemap | `/Nx/sitemap.xml` | Every static URL listed (≥1000 for N5; scales linearly with corpus size). |
| 5. Corpus discovery JSON | `/Nx/data/index.json` | Programmatic catalog of every data file with URL, size, mtime, content-type, schema-version, item-count, description. |
| 6. LLM-discovery TXT | `/llms.txt` (root) + `/Nx/llms.txt` | Markdown-formatted plain-text describing the site for LLMs (per the llms.txt spec community draft). |
| 7. robots.txt | `/Nx/robots.txt` + `/robots.txt` | Sitemap reference; allows crawling. |
| 8. noscript fallback | `/Nx/index.html <noscript>` | Path-routed nav (NOT hash routes!) so non-JS clients land on a usable directory of static pages. |

### F.31.3 Build-script architecture

One Python script per Nx, modeled on N5's
`tools/build_llm_surfaces_2026_05_18.py` (8 stages):

```
def main():
    data = load_corpora()  # all *.json files + version.json
    stage_papers_mirrors(data)     # Stage 1
    stage_data_index(data)         # Stage 2 — must run AFTER any corpus mutation
    stage_llms_txt(data)           # Stage 3
    stage_summary_pages(data)      # Stage 4
    stage_sitemap(data)            # Stage 5 — must run AFTER mirror generation
    stage_noscript_update(data)    # Stage 6
    stage_root_picker()            # Stage 7
    stage_robots_root()            # Stage 8
```

Re-run the script after any data/* change. Stages 2 and 5 read from
disk (stages 2 reads file sizes; stage 5 enumerates mirror dirs), so
they depend on order. Always re-run the whole script — the per-stage
cost is small (1-2 seconds total for N5's 1370+ mirrors).

### F.31.4 CI invariants (paste these into Nx's content_integrity.py)

  - **JA-Nx-1 (mirror coverage)** — every data/papers/*/*.json has a
    corresponding /papers/<id>/index.html. Same shape for grammar /
    vocab / kanji / reading / listening.
  - **JA-Nx-2 (sitemap floor)** — sitemap.xml has ≥1000 `<loc>` entries
    (regression floor; catches the "only 10 meta routes" pre-fix state).
  - **JA-Nx-3 (data/index.json integrity)** — every entry's `size_bytes`
    matches actual on-disk file size. Same drift class as INV-4 /
    JA-107 (version.json counts vs live corpus); same fix pattern.
  - **JA-Nx-4 (summary pages exist)** — all 7 *.html files + llms.txt
    (root + Nx) present.
  - **JA-Nx-5 (no hash routes in noscript)** — every `<a href>` in the
    server-rendered shell noscript starts with "/" or "https://" —
    never "#". Crawlers reading the shell can follow the links;
    hash routes are dead ends for non-JS clients.

### F.31.5 Common pitfalls

1. **CSP `frame-ancestors` via meta** — see F.29.3 (NR-UI-001).
   IGNORED by browsers; same trap for any HTTP-header-only directive.
2. **Hash routes in `<a href>` after path-route migration** — the
   server-rendered shell may still have legacy hash links. Use
   JA-Nx-5 to catch.
3. **Sitemap stale after data growth** — the build script must run as
   part of the release pipeline. If sitemap is checked in, it goes
   stale; if regenerated only manually, the maintainer forgets after
   N data adds. Wire the script into the deploy workflow.
4. **data/index.json size drift** — same drift class as version.json
   counts (INV-4 / JA-107). Every mutation to data/*.json must trigger
   data/index.json regeneration in the same commit. JA-Nx-3 catches.
5. **Per-paper-pack mirrors are NOT per-question** — for the JLPT
   paper bank, one HTML page per PAPER PACK (15-20 questions), NOT one
   per question. The interactive timed-test UX stays in the SPA.

### F.31.6 Bounded-coverage phrasing

  - "Static mirrors cover *every entity in data/* at build time*" —
    not "static mirrors cover every entity" (entities added after the
    last build aren't there until next regen).
  - "sitemap.xml lists *the URLs present at build time*" — not "lists
    every URL" (legacy URLs from prior builds are NOT removed
    automatically; rebuild + git-clean to prune).
  - "JA-Nx-3 prevents *size_bytes drift between data/index.json and
    actual on-disk files*" — not "prevents corpus drift". A subtle
    same-byte-size content change (e.g., a typo fix that preserves
    total bytes) would pass.
  - "llms.txt is the *current community-draft format*" — the spec
    is evolving; treat the file as living, not frozen.

## F.32 Register-variant vs grammar-error distinction (added 2026-05-18)

Documents the REG-001 (BUG-106) finding: a register CHOICE between
two grammatical alternatives (e.g., だれ vs どなた, けど vs けれど,
わかってる vs わかります) must NOT be framed as WRONG/RIGHT in
`wrong_corrected_pair`. Both forms are grammatical; the choice is
register, not correctness. The right schema is `register_variant`
nested in `common_mistakes` with `form_a` / `form_b` / `label_a` /
`label_b` fields.

### F.32.1 Six defect classes (D1..D6) per the REG-001 sweep

D1 — **WRONG/RIGHT framing on a register choice.** Both forms are
grammatical. Migrate to register_variant.

D2 — **Conflated semantics in "alternatives" list.** E.g.,
「やまださんは どなた ですか」 (asking identity) ≠
「やまださんは どんな 人 ですか」 (asking character description).
Don't present semantically-distinct forms as register equivalents.

D3 — **Formality vs elevation conflation.** だれ vs どなた is
referent-elevation (尊敬), not sentence-level formality. だれ is
the neutral default and is fine in polite/formal contexts.

D4 — **Out-of-Nx-scope item taught as canonical.** どなた is N4-N3
vocabulary. At N5 the canonical question word is だれ; どなた is
"shown for reference" with `scope_note` annotation.

D5 — **Kana form of whitelist kanji.** ひと in kana when 人 is in
the whitelist is JA-100 violation. Use kanji.

D6 — **Self-contradicting annotation.** ✗ line marked Incorrect AND
annotated with the register it's appropriate for ("(formal)",
"(polite)", "(in casual conversation)", etc.). Internally
contradictory — if it's appropriate to a register, it isn't wrong.

### F.32.2 The register_variant schema

```json
{
  "kind": "register_variant",
  "form_a": "わかってる。",
  "form_b": "わかります。",
  "label_a": "casual / spoken — contraction of わかっている",
  "label_b": "polite / formal — full polite form",
  "why": "...explanation of why both are grammatical, what governs the choice...",
  "category": "register",
  "scope_note": "[optional — flag if out-of-Nx-scope]",
  "provenance": "native_reviewed"
}
```

Lives in `common_mistakes` (not `wrong_corrected_pair`).

### F.32.3 CI invariant (paste into Nx content_integrity.py)

**JA-Nx (REG-001 D6 guard)** — no entry in `wrong_corrected_pair`
with `error_category == "register"` may have a wrong-field
parenthetical that names the register the form is appropriate for.
Trip phrases (the most common D6 markers):

  - "(formal)" / "(in formal context)" / "(in formal speech)"
  - "(polite)" / "(in polite contexts)"
  - "(casual)" / "(in casual conversation)"
  - "(among friends)" / "(with intimates)"
  - "(acceptable in X)"

Catches the most-egregious D6 violations. Subtler D1..D5 cases need
per-entry native-speaker triage.

### F.32.4 Sweep procedure (D1..D6 across the whole corpus)

The REG-001 bug specifies a 6-step sweep:

  1. **SWEEP-1** — All WRONG/RIGHT entries where `error_category`
     is `register` or `why` field references politeness/formality.
     Triage as A (migrate to register_variant), B (genuine error,
     keep), or C (pragmatic-mismatch, re-categorize).
  2. **SWEEP-2** — Semantically-distinct forms presented as
     register-equivalents (D2 class).
  3. **SWEEP-3** — Formality vs elevation conflations (D3 class).
  4. **SWEEP-4** — Out-of-Nx-scope items taught as canonical (D4).
  5. **SWEEP-5** — Kana-form of whitelist kanji (D5).
  6. **SWEEP-6** — Self-contradicting annotations (D6).

SWEEP-6 is the easiest to automate (CI invariant catches the marker
phrases). SWEEP-1 surfaces candidates but requires native-speaker
triage per entry. SWEEP-2..5 are deferred to native-speaker review
sessions (file as REG-NNN follow-up bugs).

### F.32.5 Bounded-coverage phrasing

  - "JA-Nx D6 invariant prevents *the marker-phrase set listed in
    F.32.3*" — not "prevents all D6 violations". A creatively
    phrased self-contradiction without these markers slips past.
  - "SWEEP-1 candidate report surfaces *entries with register
    keywords in the why-field*" — not "all register-variant
    candidates". A register-mismatch entry whose why-field uses
    Japanese terminology (尊敬 etc.) instead of English markers
    needs separate detection.
  - "REG-001 close-out covers *the N5 entries matching the trip-
    phrases*" — not "all register-conflations in N5". The deeper
    sweep (SWEEP-2..5) is scoped as native-speaker review work.

## F.33 Paper-question schema-discipline — three durable invariants (added 2026-05-18)

DOKKAI-001..003 (BUG-107..109) surfaced 3 schema-discipline classes
that apply to every paper-bank corpus across Nx levels. Each maps to
a CI invariant (N5: JA-128 / JA-129 / JA-130) and a generalizable
fix pattern.

### F.33.1 Class A — Single source of truth for passages

**Symptom:** A reading-comprehension paper stores its passage text
in two places: as `passages[]` at the paper top-level AND as
`questions[].passage_text` repeated on every question that references
the same passage. Over time, the two copies drift — most subtly via
markdown markers like a leading `> ` blockquote prefix that's on one
copy but not the other.

**Root cause:** Initial authoring tools convenience-denormalize the
text onto each question. Later edits (typo fix, prefix cleanup) hit
one copy but not both. Renderers reading from different sources show
inconsistent content.

**Fix:** Single source of truth — keep `passages[]` as canonical at
the paper top-level. Questions reference passages via
`passage_label` foreign key. Drop `passage_text` from question
objects entirely. Renderer joins at display time.

**Detection (CI invariant JA-128):** Substring-grep every paper file
for `passage_text` as a question-level key. Trip on any presence.

**Same drift-risk class as:** KANJI-001 / KANJI-004 (kanji.json
compound forms vs vocab.json form), VOCAB-002 (counter field shape),
LISTEN-001 (voice_planned vs audio_render_meta), INV-4 / JA-107
(version.json counts vs corpus). All share the "data in two places →
inevitable drift" anti-pattern.

**Horizontal-deployment note:** When a paper-bank already exists
WITHOUT a `passages[]` block (e.g., bunpou Mondai-3 paragraph
gap-fill questions that only have `passage_text` per question), the
fix is to CREATE the `passages[]` block from the unique passage_text
values + their `passage_label` foreign keys. This was the case for
bunpou/paper-7.json in the 2026-05-18 N5 close-out — 10 Mondai-3
questions referencing 2 distinct passages got their canonical
`passages[]` block created on first migration.

### F.33.2 Class B — English-fragment temporal markers in rationale_hi

**Symptom:** A learner-facing `rationale_hi` Hindi explanation
contains untranslated English temporal markers like " ago", " yet",
or " lot" — usually a carry-over from word-by-word translation
where the Hindi sentence-order pattern made the English word fall
through untranslated.

**Examples observed:**
  - `भूत-सकारात्मक रूप (आया एक महीना ago)।` → fix: `भूत-सकारात्मक: एक महीना पहले आया`
  - `यहाँ के लिए 1 वर्ष = आया 1 वर्ष ago।` → fix: `यहाँ एक साल से = एक साल पहले आया`

**Fix:** Rewrite with natural Hindi using the appropriate target-
language idiom (`पहले` for "ago / before", `अभी तक नहीं` for "not
yet", etc.). Set `rationale_hi_provenance = "native_reviewed_<DATE>"`.

**Detection (CI invariant JA-129):** Substring-grep for the trigger
set: ` ago ` / ` ago.` / ` ago,` / ` ago)`, ` yet ` / ` yet.` /
` yet,` / ` yet)`, ` lot ` / ` lot.` / ` lot,`. Conservatively skip
` before ` and ` then ` (legitimate in technical fragments).

**Same class as:** PAPER-004 (JA-122 apostrophe-s / contractions /
mojibake) — JA-129 is the extension catching temporal markers that
JA-122 doesn't cover.

### F.33.3 Class C — Schema-shape: explicit-null vs missing-key

**Symptom:** A field like `grammarPatternId` is present on some
questions and absent on others, with no documented convention.
Downstream code can't distinguish "not yet assigned" from
"intentionally absent — not applicable to this question type".

**Examples:**
  - dokkai questions: 78/102 had `grammarPatternId`, 24 absent.
  - goi (vocabulary) questions: 11 absent (vocab questions test
    word choice, not grammar pattern)
  - moji (kanji-reading) questions: 72 absent (orthography test,
    no grammar pattern)

**Fix:** Make the field always-present-as-a-key. When not
applicable, set value to `null` AND set the provenance field to a
typed `not_applicable_<reason>` value:

  - dokkai comprehension questions: `not_applicable_comprehension`
  - goi vocabulary questions: `not_applicable_vocab`
  - moji orthography questions: `not_applicable_orthography`

This matches the existing VOCAB-002 counter-field pattern (`counter
is always a key, sometimes null` after the BUG-015 fix).

**Detection (CI invariant JA-130):** For every paper question,
assert `grammarPatternId in question_keys`. When value is `null`,
assert provenance starts with `not_applicable`. Catches both the
missing-key case and the undocumented-null case.

**Same class as:** VOCAB-002 counter (always-a-key-sometimes-null),
LISTEN-005 (format vs format_type closed-enum), the original
PAPER-002 (bunpou-4.3 missing grammarPatternId).

### F.33.4 Build script template

The N5 close-out script `tools/fix_dokkai_bugs_2026_05_18.py` is
~150 lines of mechanical Python. Per-Nx fork:

```
1. Loop over data/papers/<category>/*.json
2. Drop questions[i].passage_text (Class A) + normalize passages[].text
3. Apply category-specific not_applicable_<reason> provenance
   for null grammarPatternId (Class C)
4. Per-question rationale_hi rewrites (Class B) — only the named Q-IDs
   from the bug report; do NOT mass-substitute "ago" → "पहले" globally
   (risks corrupting any legitimate English-glossing in technical
   notes)
```

After the per-paper fixes, run the LLM-surfaces regeneration script
(F.31) so `data/index.json` byte-sizes don't drift from the file
changes.

### F.33.5 Bounded-coverage phrasing

  - "JA-128 prevents *passage_text on paper questions*" — not "prevents
    all paper-data redundancy". A paper that stored other fields
    redundantly (e.g., choices duplicated into a top-level array)
    would still pass JA-128; needs separate invariant.
  - "JA-129 catches *the temporal-marker trigger set*" — not "all
    untranslated English in rationale_hi". A rationale that says
    "मैं learn जापानी" slips past. JA-122 covers apostrophe-s and
    mojibake; JA-129 adds temporal markers. The combined coverage
    is the rationale-hi guard set; neither is the universal solver.
  - "JA-130 enforces *grammarPatternId presence + documented null*" —
    not "enforces correct grammarPatternId value". A question tagged
    with the wrong pattern_id still passes JA-130 (JA-120 catches
    Mondai-1 particle alignment; broader correctness is per-entry
    judgment).

## F.34 Mobile-UI compliance — touch-target + iOS auto-zoom + route-resolution + locale parity (added 2026-05-19)

The MOB-001..019 (BUG-110..128) batch surfaced 5 durable classes of
mobile-UI defect that apply to every Nx SPA shipped to mobile users.
Each maps to a CI invariant (N5: JA-131..134; JA-132 is the
multi-class CSS-rule check). Same Selenium mobile-emulation pattern
applies across levels — fork with updated route table.

### F.34.1 Class A — Touch-target HIG compliance

**Symptom:** Interactive elements (buttons, anchor-links, navigation
items) render below the Apple HIG minimum touch-target size of 44×44
px on mobile viewports. Bug evidence from N5 audit:

  - `.btn-action` (home CTAs + feedback page actions): 281×36
  - `.study-order-link` (10 home cards): 328×34
  - `.back-link` / `.home-up-link a`: 125×20
  - `.brand-link` (header logo): 54×16
  - `.skip-link`: 187×41
  - `.toc-expand-all` / `.toc-collapse-all`: 99×36
  - Authentic-items page ref-chips: 12×17 to 48×15 (449 elements)
  - Examday / Weakareas inline "See full bank →": 139-167×15

**Fix:** Single consolidated CSS block at end of `css/main.css`
that sets `min-height: 44px` (with `padding-block: 10-12px` for
visual spacing) on every named class. Mirror to `css/main.min.css`.

**Detection (CI: JA-132):** Substring-grep `css/main.css` AND
`css/main.min.css` for marker comment `MOB-001..016 mobile UI
compliance batch` + every canonical touch-target class. Trips on
any removal during a CSS-cleanup pass.

**Anti-pattern:** Don't bump touch-target via `height: 44px`
explicitly — line-height conflicts and breaks visual density.
Use `min-height: 44px` + `padding-block` so existing typography
stays unchanged.

**Bounded coverage:** JA-132 catches *the specific class set named
in the marker*. New CSS classes added to the SPA after the marker
was written get no guard — extend the marker list on each
audit cycle.

### F.34.2 Class B — iOS Safari form-input auto-zoom

**Symptom:** Form inputs (`<input>`, `<textarea>`, `<select>`)
render at `font-size: 14px` or `0.875rem`. When focused on iOS
Safari, the browser auto-zooms the viewport (because a font under
16px would be "too small to read"). The page stays zoomed until
the user pinches back out. This is a jarring UX regression on
every form-bearing route.

**Fix:** Site-wide CSS rule:

```css
input, textarea, select {
  font-size: max(1rem, 16px);
}
```

The `max(1rem, 16px)` form satisfies HIG for users with non-
default `rem` sizing AND the 16px iOS-Safari threshold. Don't use
`maximum-scale=1` on viewport meta — worse for accessibility.

**Detection (CI: JA-133):** Search `css/main.css` for the
`max(1rem, 16px)` substring on a `input,textarea,select` selector.

**Bounded coverage:** N5 already had `#search-input` at 16px
(header search input). The missing 4 controls were inside
`#/feedback` (one form on one route). JA-133 catches future
forms that ship at <16px.

### F.34.3 Class C — Dead-end hash routes

**Symptom:** A hash route exists in href attributes (`<a href="#/X">`)
that the router does NOT have a handler for. parseRoute() silently
redirects to a default route (e.g., `#/home` or `#/diagnostic`).
Users / crawlers following the bookmarked URL land somewhere
unexpected.

**N5 examples:**
  - `#/listening/story` — referenced 4× in `js/listening-story.js`
    but router maps `listeningstory` (no slash). parseRoute parses
    `#/listening/story/cafe` as `{name: 'listening', params:
    'story/cafe'}` → renderListening (ignores params) → silent
    redirect to listening index.
  - `#/levels` — referenced in `js/home.js` home-up link. parseRoute
    catches it via `if (hash === '#/levels' || ...)` block and
    calls `location.replace('../')` → leaves SPA → if first-run,
    `if (!location.hash)` onboarding redirect kicks in → lands on
    `#/diagnostic`.

**Fix protocol:**
  1. Audit every hash-route reference: `grep -rn '#/[a-z]' js/*.js`.
  2. For each reference, confirm the route exists in `app.js`'s
     `routes` dict OR the path is a deliberate redirect (e.g.,
     `../` to a sibling page).
  3. Canonicalize: pick ONE form per route (no aliases) and update
     all hrefs to use it.
  4. For redirect routes (`#/levels` → `../`), change the link's
     `href` to the destination directly (skip the in-SPA redirect).

**Detection (CI: JA-134):** Substring-grep `js/home.js` for
`href="#/levels"` (must be `../` post-fix) and
`js/listening-story.js` for `"#/listening/story"` (must be
`#/listeningstory` post-fix).

**Bounded coverage:** JA-134 catches *these two specific dead-end
patterns*. A general "every hash href resolves to a router entry"
check would require parsing app.js's routes dict at CI time —
deferred. JA-134 is the targeted-pattern guard.

### F.34.4 Class D — Locale-parity for hard-coded UI strings

**Symptom:** A UI string is hard-coded in a JS template literal
instead of going through `t('key')` i18n lookup. The string is
correct in the default locale (en) but stays English when the user
switches to another locale (hi).

**N5 example:** `js/home.js` home-up-link literal `← All JLPT levels`
(line 357) was not i18n-wired. Hindi-locale users saw untranslated
English on the home page despite all other primary nav items
translating correctly.

**Fix:**
  1. Add the key to every supported locale (`locales/en.json` +
     `locales/hi.json` for N5).
  2. Update the JS to use `t('nav.all_levels')`.
  3. Run the minify step (e.g., `tools/build_min_js.py`) so the
     `js/min/home.js` bundle picks up the change.

**Detection (CI: JA-131):** Per-locale check that the `nav.all_levels`
key is present and non-empty.

**Same shape as JA-108:** broader locale-key-set parity guard.
JA-131 is the narrower invariant for this specific key because it
shipped to production once already.

**Bounded coverage:** JA-131 catches THIS specific key. A more
general invariant would scan all locale files for key drift; JA-108
already does that. JA-131 is the named-key guard so regressions
of this specific MOB-007 case surface explicitly.

### F.34.5 Class E — Test-infrastructure / scenario-design gaps

**Symptom:** Mobile-UI tests fail spuriously due to test-framework
limitations rather than app defects. The fix lives in the test
scenarios + test runner, not in app code.

**N5 examples:**
  - **MOB-018:** Selenium 4 + Chrome 148 with
    `Emulation.setDeviceMetricsOverride mobile=true` makes
    `window.scrollTo` a no-op. Footer-reachability scenarios can
    never reach the footer through scroll. Solution: split affected
    scenarios into "Auto (window-size emulation only, no
    touch-emulation)" + "Manual (Appium / real device)" variants.
  - **MOB-019:** Audio-UI scenarios target `#/listening`,
    `#/listening/story`, `#/reading` index pages — but audio loads
    only after tapping into a specific item (`#/listening/n5.listen.NNN`).
    Index pages return 0 audio elements. Fix: re-target scenarios to
    navigate INTO a representative item before asserting.

**Fix protocol:** these are scenario-content updates, not app-code
changes. Update the affected scenario rows in the xlsx Mobile UI
tab. Document in CHANGELOG as "scenario rewrites" (no behavioral
fix).

**No CI invariant** for this class — it's a test-authoring
discipline, not a runtime check. Document in the procedure manual
(this section) so future Nx builders avoid the same false-fail
trap.

### F.34.6 Build-script template (Nx-builder pattern)

The N5 close-out used:

  - `tools/build_min_js.py` — regenerate `js/min/` after JS changes
  - `tools/build_min_css.py` — regenerate `css/main.min.css` after
    CSS changes (if minifier exists; manual append if not)
  - `tools/build_llm_surfaces_2026_05_18.py` — regenerate
    `data/index.json` after any data mutation (so JA-125
    byte-size guard doesn't trip)

Re-run all 3 before committing any data or CSS/JS change. Same
8-stage architecture as F.31.3.

### F.34.7 Bounded-coverage phrasing

  - "JA-131..134 prevent re-introduction of *the specific bugs MOB-006/007/008/009 closed*" — not "all mobile-UI defects".
  - "JA-132 catches *the named touch-target class set in the marker comment*" — extension to additional classes requires explicit marker-list updates.
  - "Selenium mobile-emulation footer-reachability is *not Selenium-testable in current Chrome*" — Manual / Appium fallback documented.
  - "MOB-010 (sticky header top=16px) declined as P5 design-decision" — borderline by-design; not fixed.

## F.35 Rationale content-discipline — copy-paste mismatch + meta-content (added 2026-05-19)

The GOI-001..003 (BUG-130..132) batch surfaced 2 durable rationale-
content defect classes that complement F.30 (PAPER-001..004),
F.33 (DOKKAI-001..003), and F.34.4 (Class D locale-parity). These
apply to every paper-bank corpus across Nx levels.

### F.35.1 Class A — Copy-paste content-mismatch between rationale_hi
                    and stem (hard learner-facing breakage)

**Symptom:** A question's `rationale_hi` (Hindi explanation) is
byte-identical to a neighboring question's `rationale_hi` — copy-
pasted during authoring and the rewrite for the specific question's
topic was missed. The result is a Hindi-locale learner who answers
the question correctly and then reads an explanation about a
completely different topic.

**N5 example:** `goi-6.11` (phone-call paraphrase: 「電話を かけて +
一時間 話した」 = 「電話で 話した」) carried `rationale_hi` byte-
identical to `goi-6.12`'s (about age: 「いま 二十さいです」/はたち).
A Hindi-speaking learner sees age content on a phone-call question.

**Detection (CI: JA-136):** for each paper file, group questions by
their `rationale_hi` value; flag any value shared by 2+ questions
within the same paper. Threshold 30 chars — excludes legitimately-
short shared rationales (single-line "Hindi mirror of formula"
patterns).

**False-positive considered + rejected:** the bug spec proposed
"rationale_hi must share at least 1 Japanese token with stem_html
OR correctAnswer". Implementation showed ~100 false positives on
the existing N5 corpus — mostly dictionary-form ↔ polite-form
variation (`友だちと` in rationale_hi vs `ともだち` in stem;
`すき` vs `すきです`). The literal-substring overlap check is too
strict; semantic token equivalence requires per-language morphology
rules. **JA-136 falls back to the narrower-but-defensible cross-
question-equality check.** Token-overlap mismatch detection stays
in manual-review territory.

**Fix protocol:** for each flagged question, rewrite rationale_hi in
natural Hindi grounded in the actual question's stem + correct
answer. Update `rationale_hi_provenance` to
`native_reviewed_<DATE>`.

### F.35.2 Class B — Meta-content in learner-facing rationale

Extension of F.30.2 (Class B PAPER-003 meta-fix history). Same
underlying anti-pattern with new trigger phrases:

**N5 examples from goi-6:**
  - `goi-6.14` rationale ended with "Hence the rewording from a
    prior version" — commit-trail content (F.30.2 class).
  - `goi-6.12` rationale ended with "documented at vocabulary_n5.md
    but does not bear on the time-reference test point this question
    targets" — meta-documentation pointer + question-authoring
    framing, NOT pedagogy.

**Detection (CI: JA-121 extension):** added trigger substrings
`"Hence the rewording"`, `"rewording from a prior"`, `"from a prior
version"`, `"documented at vocabulary_n5.md"`, `"documented at"`,
`"does not bear on"`, `"test point this question"`.

**Fix protocol:**
  - Drop the meta sentence entirely if it adds no learner value.
  - OR rewrite as direct pedagogical content if the underlying
    information is useful (e.g., the goi-6.12 はたち special-reading
    note was rewritten as `"Note: 二十さい is read はたち, not
    にじゅっさい — a special on-yomi exception shared with 二十日
    (はつか)."`).

### F.35.3 Bounded-coverage phrasing

  - "JA-136 catches *byte-identical rationale_hi duplication within
    a paper file*" — not "all content-mismatch". A copy-paste that
    edited a few tokens to look different but still discussed the
    wrong topic slips past.
  - "JA-121 (extended) catches *the trigger phrase set*" — subtler
    meta-content phrasings still need per-entry review.
  - "Token-overlap check rejected for false-positive rate" — the
    literal-substring approach is too strict; a future invariant
    using morphological-stemming (kuromoji or similar) could
    revive the bug-spec's original recommendation with acceptable
    precision.

### F.35.4 Same drift-class lineage

JA-136 + JA-121-extension complete a 5-invariant family on paper-
question rationale fields:
  - JA-121 — no meta-fix history (PAPER-003 + GOI-002/003 extended)
  - JA-122 — no English-pattern fragments in Hindi (PAPER-004)
  - JA-129 — no untranslated temporal markers (DOKKAI-002/004)
  - JA-136 — no cross-question rationale_hi duplication (GOI-001)

Combined coverage: meta-content + foreign-fragment + copy-paste
defect classes. Subtler defects (wrong-but-coherent rationale,
misleading framing without trigger phrases) remain in manual-
review territory.

## F.36 Closing deferred items: 3 actionable + 1 genuinely-human-only (added 2026-05-21)

Documents the methodology for closing a batch of deferred items
where some are actionable (codify policy, ship advisory tool,
add CI workflow) and one is genuinely human-only (actual native-
speaker review). Pattern applies to any Nx after a long
LLM-curated audit session has accumulated deferred items.

### F.36.1 Class A — Codify implicit conventions into explicit policy docs

**When applies:** an audit flagged what it called a "violation"
but corpus-convention check shows the "violation" is actually
established practice.

**Example (N5 SWEEP-5):** REG-001 D5 claimed kana-form of
whitelist kanji (わたし / ともだち / じょうず) in honorific
examples was a defect. Convention check across grammar.json
examples showed kana-first is the established pattern for these
specific words (varies per-word; some words ARE kanji-first like
人 25× vs ひと 6×).

**Fix shape:** write a policy doc that:

  1. Documents the convention with measured counts
  2. Lists per-word preferences (not a global rule)
  3. Cites pedagogical rationale (Genki I / Minna I beginner-stage
     conventions; recognition-target vs production-target)
  4. Marks the audit finding as "closed-as-policy" rather than
     "declined-with-reason"

**Output:** `docs/ORTHOGRAPHY-POLICY-Nx.md` (or similar).
Pattern-template at `N5/docs/ORTHOGRAPHY-POLICY-N5.md`.

### F.36.2 Class B — Ship advisory audit tools where strict CI invariants would be too noisy

**When applies:** a bug spec proposes a strict invariant but
implementation produces too many false positives for CI use
(typically 5-20% false-positive rate from morphological /
semantic limitations of substring matching).

**Example (N5 GOI-001 follow-up JA-137 candidate):** bug spec
proposed "rationale_hi must share ≥1 Japanese token with
stem_html / correctAnswer". Lightweight stemmer (strip particles +
ます/ました/ません endings + です/だ + kana↔kanji normalization)
still produces ~21% false-positive rate on existing corpus,
primarily due to dictionary-form ↔ polite-form ↔ orthography
variation that requires kuromoji-class morphological analysis.

**Fix shape:** instead of strict CI invariant, ship as standalone
audit tool:

  1. Implement the stemmer + check as a CLI tool
     (`tools/audit_<class>_<date>.py`)
  2. Output advisory candidates (DON'T fail exit code on
     candidates; reserve non-zero exit for tool-internal errors)
  3. Document false-positive rate in the tool's docstring
  4. Note: "shipped as advisory; not CI-enforced due to
     morphology limitations. Each candidate needs human-reviewer
     judgment."

**Output:** `tools/audit_<class>_<date>.py`. Pattern-template at
`N5/tools/audit_rationale_overlap_2026_05_21.py`.

**Anti-pattern:** don't ship the strict check as CI if it would
block legitimate commits. False-positive noise erodes trust in
all CI invariants.

### F.36.3 Class C — Wire build-script integration into CI workflows

**When applies:** a tool exists but is run manually; the
maintainer can forget to run it after a data edit.

**Example (N5 LLM-005 build-script integration):**
`tools/build_llm_surfaces_2026_05_18.py` regenerates 1370+ static
mirrors + sitemap + data/index.json + llms.txt + 7 summary
pages. Without CI integration, maintainer forgetting to run it
after a data edit produces stale mirrors caught only by JA-125
(byte-size drift) post-fact.

**Fix shape:** create `.github/workflows/regen-<surface>.yml`
that:

  1. Triggers on push touching the relevant source paths
     (e.g., `paths: ['Nx/data/**', 'Nx/tools/build_*.py']`)
  2. Re-runs the regeneration script
  3. Asserts `git diff --quiet` post-run (no drift)
  4. Fails with clear error message + diff summary if drift

This catches drift PRE-merge instead of POST-merge, with a
clearer error message than the existing byte-size invariant.

**Output:** `.github/workflows/regen-<surface>.yml`.
Pattern-template at
`N5/.github/workflows/regen-llm-surfaces.yml`.

### F.36.4 Class D — Surface genuine-human-only items as path-forward docs

**When applies:** an LLM-curated audit reaches its limits
and the remaining work requires actual native-speaker /
domain-expert / paid-reviewer input.

**Example (N5 native-speaker re-verification of register_variant
entries):** 54 entries in grammar.json carry
`llm_curated_with_reference_*` provenance after Tier 1/2/3
audits. Genuine native-speaker review is required to upgrade to
`native_reviewed_*` provenance. An LLM cannot become a native
speaker by working harder.

**Fix shape:** write a path-forward doc that:

  1. Lists what needs human review (with counts)
  2. Acknowledges WHY this is human-only (specific limits of
     LLM judgment in the domain)
  3. Documents 2-3 options (community PR, commissioned review,
     status-quo with promote-on-finding)
  4. Picks a default
  5. Surfaces tracking signal — current state + expected post-review
     state ranges (best-case / realistic / worst-case)

**Output:** `docs/NATIVE-SPEAKER-RE-VERIFICATION.md` (or
`-HUMAN-EXPERT-REVIEW.md` for non-language domains).
Pattern-template at `N5/docs/NATIVE-SPEAKER-RE-VERIFICATION.md`.

**Anti-pattern:** don't pretend the LLM-curated work is "done"
just because the audits ran clean. Explicit provenance +
explicit path-forward = trust-preserving honest framing.

### F.36.5 Bounded-coverage phrasing

  - "Codify-policy class A closes *the specific finding that
    conflicted with established convention*" — not "all
    convention conflicts".
  - "Advisory-tool class B catches *candidates flagged by the
    substring-stemmer*" — not "all content-mismatches".
  - "CI-workflow class C catches *drift in the regenerated
    surfaces*" — not "all build-integration regressions".
  - "Path-forward class D documents *the LLM-curated entry set
    at this checkpoint*" — future audits may surface additional
    entries needing review.

### F.36.6 When to use this batch-closure pattern

Use at the end of a multi-day / multi-week audit session
where deferred items have accumulated. The pattern surfaces
each deferred item against one of 4 classes (A/B/C/D) and
closes via the appropriate output type. Avoids the
anti-pattern of letting deferred items pile up indefinitely
in `AUDIT-COVERAGE` "pending future work" sections.

## F.37 Mixed-script mojibake + off-by-one rationale_hi shift + fix-history strip (added 2026-05-21)

Three distinct content-drift classes surfaced in the same
sweep on `data/papers/goi/*.json` (GOI-004 / GOI-005 / GOI-006,
BUG-133 / 134 / 135). Each had a sibling instance elsewhere in
the corpus that the original single-fix sweep missed —
generalizing the lesson is what protects Nx.

### F.37.1 Class A — Mixed-script mojibake inside a JP-character word

**Anti-pattern.** A search-and-replace or transliteration
pass substitutes a kana character with the closest Devanagari
glyph, producing a token like 「あमारी ありません」 or
「一時間ぐらि」 — kana あ / ぐら + Devanagari ma + Devanagari ī
in a single word. The token reads as invalid Japanese
(mixed-script word) AND invalid Hindi (the Devanagari letters
don't form a recognizable Hindi word), and it garbles the
pedagogical point the rationale is trying to make.

**Detection.** Scan every rationale_hi (and any other field
that mixes languages) for the regex
`[ぁ-ゖァ-ヺ一-鿿][ऀ-ॣ०-ॿ]` — a Devanagari letter
immediately following a kana/CJK character with no separator.
**Exclusions:** Devanagari danda `।` (U+0964) and double-danda
`॥` (U+0965) are sentence-end punctuation; they appear
legitimately after a JP-character word. Hyphenated cross-script
terms like 「い-विशेषण」 are also legitimate (the hyphen is the
boundary). The clean ripgrep equivalent:

```
rg -nP '[ぁ-ゖァ-ヺ一-鿿][\x{0900}-\x{0963}\x{0966}-\x{097F}]' data/
```

**Fix.** Surface every hit. For each, restore the original JP
token (`あमारी` → `あまり` or `あまく`; `ぐらि` → `ぐらい`),
then rewrite the surrounding Hindi naturally so the rationale
reads cleanly. Stamp `rationale_hi_provenance: native_reviewed_YYYY_MM_DD`.

**CI invariant (JA-139 on N5).** Detector identical to the
ripgrep above, evaluated per-token across all rationale_hi
strings. The invariant is **honest** — it doesn't claim to
catch all mojibake, only the mixed-script class. Other
mojibake classes (full-line garbled text, encoding-double-pass
artifacts) need separate detectors.

**Horizontal-deployment proof point.** On N5, the original
GOI-006 bug listed exactly one hit (goi-7.4). The sharpened
JA-139 detector — applied to the entire `data/papers/` tree —
surfaced 2 more hits in `dokkai-2.11` and `dokkai-3.4` that
the original sweep missed. All 3 fixed in one batch. The
lesson: every per-bug fix must run a corpus-wide detector
**before** declaring the class closed; one-shot fixes leak.

### F.37.2 Class B — Off-by-one rationale_hi shift across consecutive questions

**Anti-pattern.** Two consecutive questions in a paper get
their `rationale_hi` cell content shifted by one: question N
carries question (N+1)'s rationale_hi, and (N+1) carries
(N+2)'s. The English `rationale` is correct; only the Hindi
side shifted. Looks plausible to a non-Japanese reader
because every Hindi cell is well-formed prose — but the
content describes a different question's grammar.

**Why the original sweep didn't catch it.** Token-overlap
detectors that compare `rationale_hi` ↔ `stem_html` produce
a 21% false-positive rate from polite-form ↔ dictionary-form
variation; running them as a strict CI gate is too noisy.
GOI-001's original fix (single-pair shift on goi-6.11) didn't
extend the corpus-wide sweep, so the same off-by-one pattern
in goi-7.6 ↔ goi-7.7 went undetected for one audit cycle.

**Sharpened detector (JA-137 on N5).** Instead of a strict
own-question overlap check, look for the **narrow signal of
an off-by-one shift**: a question's rationale_hi has **0**
content-token overlap with its OWN stem AND **≥2** overlap
with the NEXT question's stem. False-positive rate <1%; the
signal is the asymmetric overlap, not the absolute overlap.

**Fix.** For each detected shift pair, rewrite both Hindi
strings from scratch about their actual stems' content
(don't just shift them back — the (N+2) cell might have its
own issue). Provenance: `native_reviewed_YYYY_MM_DD`.

### F.37.3 Class C — Fix-history / version-references / replacement-history in rationale fields

**Anti-pattern.** A previous fix added meta-commentary to a
rationale, e.g., `"(replaces ので which leans N4)"`,
`"Strict-N5: drops the previous keyed form..."`,
`"per the same policy applied at Q97 in v1.12.13"`,
`"replaces the previous シャツ"`. The rationale becomes a
commit message instead of pedagogy. Learners read the fix
history; the actual N5 paraphrase point gets buried or lost.
Hindi mirrors carry the same bilingual drift.

**Detection.** Phrase-list scan over `rationale` +
`rationale_hi` for: `"replaces the prior"`,
`"replaces the previous"`, `"previous version"`,
`"prior version"`, `"Strict-N5:"`, `"in v1."`,
`"policy applied at"`, `"no longer appears"`, and the Hindi
equivalents `"पिछले संस्करण"`, `"पुराने"`, `"की जगह लेता"`.

**Fix.** Strip the fix-history sentence. Keep only the actual
paraphrase pedagogy (usually the first sentence of the
rationale, which states the N5 vocab triangle or grammatical
equivalence the question is testing).

**CI invariant (JA-121 extension on N5).** The existing
JA-121 detector (commit-message-style meta-fix history) grew
to cover the additional trigger phrases above. **No new
JA-NN number was minted** — JA-121's name and intent already
matched this class, so the extension stays inside JA-121.
Avoids invariant-number inflation when an existing detector
generalizes cleanly.

### F.37.4 Build script template (Nx-builder pattern)

```python
# tools/audit_mixed_script_mojibake.py
import re, json, glob, sys
DEVA = r"[ऀ-ॣ०-ॿ]"
JP   = r"[ぁ-ゖァ-ヺ一-鿿]"
HIT  = re.compile(f"{JP}{DEVA}")
for fp in glob.glob("data/papers/*/paper-*.json"):
    d = json.load(open(fp, encoding="utf-8"))
    for q in d.get("questions", []):
        for k in ("rationale_hi", "explanation_hi"):
            v = q.get(k, "")
            for m in HIT.finditer(v or ""):
                print(f"{fp}\t{q.get('id')}\t{k}\t{m.group()}")
```

For Class B (off-by-one shift):

```python
# tools/audit_off_by_one_rationale_hi_shift.py
import re, json, glob
JP_TOK = re.compile(r"[ぁ-ゖァ-ヺ一-鿿]+")
def tokens(s): return set(JP_TOK.findall(s or ""))
for fp in glob.glob("data/papers/*/paper-*.json"):
    qs = json.load(open(fp, encoding="utf-8")).get("questions", [])
    for i, q in enumerate(qs):
        own_stem = tokens(q.get("stem_html", "") + " " + q.get("correctAnswer", ""))
        if not own_stem: continue
        rh_toks = tokens(q.get("rationale_hi", ""))
        own_overlap = len(rh_toks & own_stem)
        if own_overlap > 0: continue
        if i + 1 >= len(qs): continue
        next_stem = tokens(qs[i+1].get("stem_html", "") + " " + qs[i+1].get("correctAnswer", ""))
        next_overlap = len(rh_toks & next_stem)
        if next_overlap >= 2:
            print(f"{fp}\t{q['id']}\town={own_overlap}\tnext={next_overlap}")
```

### F.37.5 Bounded-coverage phrasing

When closing this batch in an audit-coverage doc, use:

- "JA-139 prevents re-introduction of *mixed-script
  Devanagari-inside-kana mojibake in `rationale_hi`*"
  — NOT "JA-139 prevents all mojibake"
- "JA-137 catches the *narrow off-by-one shift signal
  (0 own + ≥2 next overlap)* — broader token-overlap
  divergence stays advisory in
  `tools/audit_rationale_overlap_YYYY_MM_DD.py`"
- "JA-121 trigger set extended with these 11 specific
  phrases; the underlying anti-pattern (fix-history in
  learner-facing rationale) is enforced *against this
  trigger set*, not against all possible meta-commentary
  phrasings"
- "Horizontal-deployment sweep on `data/papers/*` surfaced
  N additional same-class instances beyond the originally
  filed bug; all fixed in this batch"

### F.37.6 Same drift-class lineage (predicting Nx)

| Class | First seen | Next sighting | Lesson |
|-------|-----------|--------------|--------|
| Mixed-script mojibake | GOI-006 (goi-7.4, 2026-05-21) | DOKKAI horizontal sweep (dokkai-2.11, dokkai-3.4) same day | Always run corpus-wide before claim of closure |
| Off-by-one rationale_hi shift | GOI-001 (goi-6.11, 2026-05-19) | GOI-004 (goi-7.6 + goi-7.7, 2026-05-21) | First fix is the sample, not the close |
| Fix-history in rationale | GOI-002 (goi-6.14, 2026-05-19) → PAPER-003 | GOI-005 (7 fields across 5 papers, 2026-05-21) | Phrase-list detectors miss synonyms; extend trigger set each time a new phrasing surfaces |

**Operational rule for Nx:** any time a fix lands for one
of these three classes, schedule the corpus-wide sweep AS
PART OF THE SAME COMMIT. Don't let "horizontal deployment"
become a follow-up commit — it becomes a deferred item that
the user has to remember to nag about, and accumulates into
the batch-closure pattern of F.36.

## F.38 Moji-paper content discipline — 4 durable classes (added 2026-05-21)

The N5 moji-paper review (MOJI-001..007, 2026-05-21) produced four
new content-discipline classes that generalize cleanly to Nx
moji-equivalent subsections. Each got its own JA-NN invariant
(JA-140..143). The lessons extend the rationale-content family
documented in F.36 (PAPER-001..004) + F.37 (GOI-004..006).

### F.38.1 Class A — Per-mondai stem-emphasis convention split (Nx-relevant)

**Pattern.** A corpus uses two emphasis conventions (HTML
`<u>X</u>` and markdown `__X__`) split by sub-section
(typically Mondai 1 → HTML, Mondai 2 → markdown). Field name
implies one convention (e.g., `stem_html`); actual usage mixes
both within the same file at sub-section boundaries.

**Risk.** A renderer that only handles one rule-set silently
fails on half the corpus. An HTML-only renderer displays
`__X__` literally as underscores around text. A markdown-only
renderer leaves `<u>X</u>` as raw tags. Either way the
emphasis fails on whichever half doesn't match the renderer.

**N5 instance.** moji Mondai 1 (50 questions) used HTML; moji
Mondai 2 (50 questions) used markdown; paper-4 mixed both at
the Mondai 1→2 boundary within one file. The bug was filed
as MOJI-001.

**Nx pattern.** Any orthography-style sub-section where two
different emphasis-marking concepts (e.g., "underline the
kanji" vs "mark the kana") are author-conceptualized
differently. Authors of Mondai 2 may have intuited "mark
the kana" as needing a different visual treatment than
Mondai 1's "underline the kanji" — both legitimate UX intents
but ending up with two markup conventions in one corpus.

**Fix pattern.** Pick ONE convention based on the rendering
target. If `stem_html` is the field name and a web UI is the
render target, HTML `<u>X</u>` is the right choice. Convert
the other half in one atomic pass.

**Invariant pattern.** Substring scan: any moji-category
question with `__X__` in `stem_html` trips JA-140. Adapt for
Nx by changing the field-name + category match.

### F.38.2 Class B — auto_inferred grammarPatternId on orthography questions

**Pattern.** Auto-inference of `grammarPatternId` from stem-
content picks up surface-token similarity without semantic
understanding. Works on grammar tests (bunpou) where the
inferred pattern often matches the tested concept. **Fails
silently on orthography tests** (moji, where the question
tests kanji-reading / kana-to-kanji conversion). Particle
tokens (も, は, に) inside the stem trigger n5-013/n5-117/
n5-067 etc. inferences — but these tokens are NOT what the
question tests.

**Risk.** Spurious `grammarPatternId` values undermine
downstream consumers (drill suggesters, weak-area diagnostics,
cross-corpus pattern-difficulty reports). A learner who
struggles on moji-5.2 (testing 子ども kanji recognition) gets
counted as "weak on n5-013 も particle" — false signal.

**N5 instance.** 28 of 100 moji questions had spurious
auto-inferred IDs. Same anti-pattern class as the n5-013
over-misuse fixed at PAPER-001 in the bunpou paper sweep.
Filed as MOJI-002.

**Lineage with PAPER-001.** PAPER-001 was the first sighting
of auto-inferred grammarPatternId on a question type where
the inference was semantically wrong (bunpou where the
correctIndex-particle determines the right pattern, but
auto-inference matched on a surface particle elsewhere in
the stem). MOJI-002 is the corresponding sighting on
orthography questions where NO grammarPatternId belongs.
Pattern: **auto-inference works for grammar-tests where the
tested concept IS a grammar pattern; it fails on every other
test type**. For Nx, set the default to
`null + not_applicable_<test_type>` for non-grammar question
categories.

**Invariant pattern.** Per-category check: a question in a
non-grammar category with `grammarPatternId != null` AND
`provenance == "auto_inferred"` trips the invariant. JA-141
is the moji-category instance; JA-120 covers bunpou-particle
class. For Nx, mint one invariant per non-grammar category
(moji-equivalent, vocab-equivalent, listening, etc.).

### F.38.3 Class C — Word-by-word HI rendering of EN verb constructions

**Pattern.** Translation pass renders English verb
constructions word-by-word into Hindi when no direct cognate
exists. Same shape as F.36 Class D (PAPER-004 fragments)
and the older DOKKAI-002 / DOKKAI-004 instances:
- `'X has reading Y'` → `'X के पास है पढ़ते हुए Y'`
- `'one month ago'` → `'एक महीना ago'` (untranslated "ago")
- `'commute by train'` → `'आना-जाना by ट्रेन'` (untranslated "by")

Each English idiom whose Hindi version is a different syntactic
shape is at risk; every new instance needs both a fix (rewrite
to natural Hindi) AND a substring trigger added to the
corpus-wide JA-122-family scanner.

**N5 instance.** moji-2.1 + moji-2.2 (2 consecutive questions
with the same translation artifact). Filed as MOJI-005.

**Invariant pattern.** Substring scan: corpus-wide rationale_hi
for the trigger phrase trips the invariant. JA-142 is the
`के पास है पढ़ते हुए` instance; same shape as JA-122 (PAPER-004),
JA-129 (DOKKAI-002), JA-128 follow-ups. **Each fix adds one
trigger to the family**; the family grows monotonically.

### F.38.4 Class D — Cross-language content-coverage truncation

**Pattern.** Translation pass produces a HI rationale that
captures less content than the EN counterpart. Symptoms:
- EN ends with a definitive conclusion sentence ("for N5
  the 立 form is the only correct match")
- HI ends one sentence earlier (acknowledges alternatives
  exist but drops the "only correct match" verdict)

This is **content-coverage parity**, not translation-quality.
The HI reader is left ambiguous on the question's pedagogical
takeaway while the EN reader gets the definitive answer.

**Risk.** Hindi-medium learners receive systematically less
pedagogical depth than English-medium learners. Trust-
contract violation: if the docs claim "100% Hindi parity
across all content surfaces," a 250c HI vs 343c EN rationale
breaks the claim qualitatively even though the field is
populated.

**N5 instance.** moji-7.2 (250c HI / 343c EN, ratio 0.73 raw —
borderline pass on the raw ratio, but the truncation was on
the CONCLUSION sentence specifically). Filed as MOJI-006.
Plus 4 more pre-existing instances discovered when JA-143
first ran corpus-wide: goi-7.9 (0.59), moji-1.6 (0.60),
moji-4.10 (0.43), moji-6.3 (0.34).

**Fix pattern.** Extend the HI rationale to match the EN's
conclusion. Don't truncate the EN to match HI brevity —
the pedagogical content is what matters, not the field-
length parity.

**Invariant pattern.** Length-ratio scan: for any question
where EN ≥ 80c AND HI ≥ 40c, the HI/EN ratio must be within
[0.6, 2.0]. Accounts for HI's typical 1.3× expansion vs EN.
Below 0.6 = HI truncated. Above 2.0 = EN truncated. JA-143
is the instance.

**Caveat.** This is a STRUCTURAL heuristic, not a pedagogical-
coverage check. Within-band truncations (e.g., HI at 0.7×
of EN but the dropped 30% was the most pedagogically critical
sentence) still need manual review. The ratio bounds catch
the most-egregious cases.

### F.38.5 Same-class-discovery operational rule (extends F.37.6)

When wiring a new invariant from a single-instance bug filing
(like JA-143 from MOJI-006), **run the invariant corpus-wide
in the same close-out commit and fix all discovered
instances**. JA-143 first-run discovered 4 pre-existing same-
class instances beyond the original MOJI-006 single-instance
filing — fixing them in the MOJI batch saved a follow-up
commit and gave the user a clean "0 Open" close-out.

This generalizes the F.37.6 "horizontal-deployment sweep is
part of the fix commit" lesson to **newly-wired invariants
that detect a class the bug-report only described singly**.
Always corpus-scan first; fix the entire surfaced set together.

### F.38.6 Bounded-coverage phrasing for Nx audit docs

When documenting MOJI-class fixes in `AUDIT-COVERAGE-*.md`:
- "JA-140 catches *markdown `__X__` emphasis in moji
  stems*" — other emphasis wrappers (italic, bold, color)
  NOT covered.
- "JA-141 catches *moji-category with auto_inferred
  provenance*" — other categories may need their own minted
  invariants.
- "JA-142 catches *one specific Hindi translation-pattern
  leak*" — each over-literal English→Hindi cognate gets its
  own substring; full enumeration is open-ended.
- "JA-143 catches *the 0.6×–2.0× ratio band*" — within-
  band truncations still need manual review.

Per the writing-discipline rule (F.36.5 + the WRITING
DISCIPLINE FOR AUDIT DOCS section in
`N5/prompts/Japanese language Accuracy check.txt`), state
explicitly what the invariant catches and what it doesn't.

## F.39 Governance-doc + CI-hardening discipline — 8 durable classes (added 2026-05-21)

The N5 governance-doc audit + orphaned-workflow migration produced
eight durable classes that generalize to any Nx build. Documented
together because the orphaned-workflow class (Class F) is what
surfaced six of the others — a single architectural fix unblocked
visibility into 6 separate pre-existing drift patterns.

### F.39.1 Class A — Governance-doc stale-state class

**Pattern.** Hand-maintained README / governance docs claim
numerical state (counts, alignment ratios, deletion claims) that
drift from reality as the corpus moves through batch cleanups.
The docs were authored at a snapshot point (e.g., v1.12.8) but
the corpus has since moved (v1.15.5) without doc updates.

**N5 instances** (8 in one audit pass):
- DOCS-VOCAB-001: 1041→995 entry-count drift (46-entry stale)
- DOCS-VOCAB-002: lint-target enumeration incomplete
- DOCS-VOCAB-003: "deleted directory" still referenced in 28
  paper files
- DOCS-VOCAB-004: 1041-969=72 surplus enumerated to only 17;
  other 55 hand-waved
- DOCS-KANJI-001: false "canonically 103 per JLPT.jp" citation
- DOCS-KANJI-002: empty exception section with no template
- DOCS-KANJI-003: indefinite bootstrapping mode with no exit
  criteria
- DOCS-KANJI-004: REVIEW_DATE format unspecified

**Fix pattern.** Install a "Document status" header convention on
every governance doc:

```markdown
---
Document status:
- Last verified against corpus: 2026-05-21
- Corpus version at verification: v1.15.5
- Maintenance: hand-updated; CI does not regenerate this README
---
```

Stale drift becomes visible at a glance. Future readers + audit
reviewers immediately see when the doc was last reconciled.

**For Nx:** apply the same header convention to every governance
doc from day one. When a hand-maintained README is created,
include the Document status block. Audit each cycle.

### F.39.2 Class B — Broken cross-file ref class (extension of JA-117 / JA-82)

**Pattern.** README / spec claims a directory/file was deleted but
other artifacts still reference it (or vice versa). Same shape as
JA-117's `passage_id` + `pattern_id` cross-file resolution family.

**N5 instance:** DOCS-VOCAB-003 — README said KnowledgeBank/
deleted 2026-05-14 but 28 paper files still carried
`source_file: KnowledgeBank/<cat>_questions_n5.md`.

**Resolution options:**
- (a) Restore the missing target.
- (b) Update the broken refs to point elsewhere.
- (c) Downgrade to honest tombstones (`"(authored in-place; was X
  before Y date)"`) — N5 went with (c) since no consumer reads
  `source_file`.

**For Nx:** when deleting / merging governance content, grep for
references first. Don't leave broken refs as silent drift.

### F.39.3 Class C — False-authority citation class

**Pattern.** Governance doc cites an "official source" that
doesn't actually publish what's claimed. The cited number
circulates in third-party materials but the original cited
authority is silent / explicit-non-publication.

**N5 instance:** DOCS-KANJI-001 — "canonically 103 kanji per
JLPT.jp" but JLPT.jp's own FAQ says they don't publish kanji
lists post-2010 reform. The 103 figure traces to pre-2010 旧4級
+ third-party reconstructions.

**Fix pattern:** trace every "canonically per X" / "officially
per Y" citation to its primary source. If primary source doesn't
say what's cited, rewrite with honest provenance (consensus
reconstruction / textbook intersection / etc.).

**Hard to automate.** Treat as a per-audit manual check; flag any
"canonically per", "officially per", "per JLPT.jp" citations for
source-trace.

### F.39.4 Class D — Underspecified-format class (CI: regex-validation pattern)

**Pattern.** Governance doc says a field is "optional date for X"
or "format: see tooling" without specifying the canonical
representation. Downstream parsing fails inconsistently when
contributors enter free-form values ("Q3 2026", "next release",
"2026-08", "August 2026" all valid by the prose; none valid by
the parser).

**N5 instance:** DOCS-KANJI-004 — REVIEW_DATE field format
unspecified. Fixed by specifying ISO 8601 + wiring JA-144 regex
check.

**Pattern wiring:** `^- FIELD: \d{4}-\d{2}-\d{2}$` style match
against non-comment lines. Skip values inside HTML comment blocks
(`<!-- ... -->`) so template/example entries don't trigger.

**For Nx:** every optional / free-form field in a governance doc
gets a documented canonical format + CI regex check. Default to
ISO 8601 for dates, RFC 3987 for URIs, semver for version
strings.

### F.39.5 Class E — Indefinite-bootstrapping class

**Pattern.** Governance doc references a "bootstrapping mode" or
"pending state" without exit criteria. The invariant or feature
stays inactive indefinitely because no one knows when it should
activate.

**N5 instance:** DOCS-KANJI-003 — JA-25 in bootstrapping mode
pending `data/n5_official_kanji_scope.json`; no documented
target/owner/contents → stays inactive forever.

**Fix pattern:** every "bootstrapping" / "pending" state in a
governance doc must have an exit criteria block:

```markdown
## Bootstrapping exit criteria

The X invariant leaves bootstrapping mode when ALL of:

1. [What must be true to exit — concrete + measurable]
2. [Target version / date]
3. [Owner — named person]

Estimated effort: ~N hours.
```

**For Nx:** never leave a "pending" state without exit criteria.
The criteria don't have to be exact — even a rough target
("v1.16.0 or next major content review") is better than nothing.

### F.39.6 Class F — Orphaned-CI class (CI: workflow location verification)

**Pattern.** CI workflow files authored at the wrong directory
location are silently never executed. GitHub Actions only reads
`.github/workflows/` at REPO ROOT. Files at
`subproject/.github/workflows/` are silently inactive.

**N5 instance:** 5 workflow files (browserstack / content-integrity /
lighthouse / playwright / regen-llm-surfaces) at
`N5/.github/workflows/` had been defined-but-never-executed since
authoring. Verified via `gh api repos/.../actions/workflows`:
only Dependabot Updates + pages-build-deployment were registered
pre-fix.

**Symptoms (what indicates the orphan class):**
- `gh workflow list` shows fewer workflows than the local
  `.github/workflows` count.
- `gh api repos/.../actions/workflows` shows only the
  GitHub-managed defaults (Dependabot + Pages).
- Workflows-defined-locally never appear in recent run history.
- Recently-introduced check failures (CSS drift, data integrity,
  etc.) never surface — because the workflow that would catch them
  isn't actually running.

**Fix pattern:**
```bash
git mv subproject/.github/workflows/* .github/workflows/
```
+ add `defaults: run: working-directory: subproject` per job to
preserve the working-directory semantics +
update branch trigger to match the repo's default branch
(`master` vs `main`).

**Backlog expectation.** Once activated, expect the previously-
hidden backlog to materialize. The N5 instance surfaced:
- 37 CRLF-vs-LF size_bytes drift violations (Class H below)
- last_modified mtime drift on every push (Class G below)
- generated_at timestamp drift on every push (Class G)
- 1 reference to a deleted KB-era script (Class A class)
- 112 design-system violations across D-1..D-6 (pre-existing
  backlog)

These are normal "previously-inactive checks activate" outcomes,
not regressions. Plan for backlog payment.

**For Nx:** **verify CI registration as part of the build-out
checklist.** From the start, after authoring any workflow:
```bash
gh workflow list
gh api repos/<owner>/<repo>/actions/workflows --jq '.workflows[].name'
```
Confirm the workflow appears. If not, it's at the wrong path.

### F.39.7 Class G — CI-metadata ephemeral-fields class

**Pattern.** Build scripts that generate artifacts (manifests,
index files) record per-regen timestamps. CI regenerates →
records ITS timestamp → diff fails the "no drift" check even when
content didn't change. Result: every push spuriously fails
drift-guard workflows.

**N5 instance:** `data/index.json` recorded:
- per-entry `last_modified` (mtime from filesystem)
- top-level `_meta.generated_at` (UTC now at regen)

Both changed every regen → CI failed on every push regardless of
content changes.

**Fix pattern:** drop ephemeral fields from generated artifacts.
Build-tag belongs in version.json (single source of truth); not
in every derived artifact. Generator identity can stay
(`_meta.generator`) since the script path is stable.

**Detector:** a CI "regen produces no diff" check is itself the
detector. Any field that fails this check on every push is an
ephemeral-field candidate for removal.

**For Nx:** when authoring a build script that emits a JSON
artifact, ask: "would this field's value change on a no-op
regen?" If yes, exclude it or compute from git-stable inputs
(e.g., `version.json:version` instead of `datetime.now()`).

### F.39.8 Class H — Cross-platform line-ending class (CI: LF-normalize at compute time)

**Pattern.** Build scripts on Windows compute byte sizes via
`os.path.getsize()` which returns CRLF-bloated counts. CI on
Linux compares against LF-only file sizes. Mismatch ~1-3% per
file across the corpus.

**N5 instance:** `data/index.json.size_bytes` recorded CRLF
sizes on Windows-authored regens. Linux CI saw LF sizes. 37
violations on first real CI run.

**Fix pattern:** LF-normalize when computing canonical sizes:
```python
def _lf_normalized_size(path: str) -> int:
    with open(path, "rb") as f:
        return len(f.read().replace(b"\r\n", b"\n"))
```
Apply BOTH at the build script (recording the size) AND at the
CI check (computing the actual size). Both ends must agree on
canonical (LF) representation.

**Affected fields:** any size-tracking metadata. Could also affect
hash-based fields (SHA-256 of file content) if not LF-normalized.

**For Nx:** if the build runs cross-platform (Windows-authored
artifacts read by Linux CI or vice versa), enforce LF
normalization at every byte-counting / hashing site. Use a shared
helper function.

### F.39.9 Same-discovery-cascade operational rule (extends F.37.6 + F.38.5)

When activating a previously-orphaned CI check (Class F above),
**expect the same-class discovery cascade**: the check will
surface a backlog of pre-existing instances that were hidden by
the inactivity.

**Strategy:**
1. Activate the check (move workflow to correct path).
2. Run once + count the backlog.
3. If backlog is small (< 20 instances): fix in the same
   activation commit.
4. If backlog is large (> 20 instances, e.g., the 112 design-
   system violations): mark the step `continue-on-error: true`
   in the workflow + log the backlog as a separate close-out
   task. Don't block the activation commit.
5. Pay down the backlog in a focused cycle.
6. Once paid down, remove the `continue-on-error: true` flag.

Generalizes F.37.6's "horizontal-deployment sweep is part of the
fix commit" + F.38.5's "newly-wired invariant runs corpus-wide
in the same close-out commit" — to the case where the inactivity
window was years long and the backlog is too large to absorb in
one commit.

## F.42 Reactive→proactive CI-invariant authoring + type-confusion-in-string-field defect class (added 2026-05-22)

Two related learnings from a meta-audit conversation that surfaced
coverage gaps the existing 147 invariants weren't designed to catch.
Generalizes to Nx: CI suites built reactively (one invariant per
named pattern) leave systematic gaps that only surface when a human
or LLM-with-verification-discipline reads the actual data and
compares it against the field's intent.

### F.42.1 The reactive→proactive invariant-authoring pattern

**The anti-pattern.** Every CI invariant gets added AFTER a bug
surfaced the pattern it now catches. JA-121 exists because PAPER-003
had fix-history prose. JA-128 exists because DOKKAI-001 had
`passage_text`. JA-145 exists because DOCS-VOCAB-005 had
`KnowledgeBank/` prose. **No invariant has ever been written
proactively for a class of bug not yet seen.**

This means the CI suite catches re-introduction of *specific named
patterns*, but it does NOT catch first occurrence of an *unnamed*
pattern. The audit-doc writing discipline (bounded phrasing: "JA-NN
prevents re-introduction of *these specific patterns*") was set up
precisely to acknowledge this limit.

**The proactive complement (proposed for Nx).** For every metadata
field added to a data schema, write a *field-shape invariant in the
same commit as the schema addition*. Don't wait for a bug to surface
that the field accepts free text when it should be a path/sentinel/
enum/hash. Schema-shape invariants are cheap and prevent entire
classes of drift before the data accumulates.

**Operational rule.** When introducing a new field on Nx data files:
1. Document the expected value shape in the schema's `_meta` block
   (e.g., "source_file: a resolvable path OR literal sentinel '(authored
   in-place)'").
2. Add the corresponding JA-NN invariant in the same commit.
3. Run it on the seed data; it must pass before the schema lands.
4. Subsequent additions to the field must conform.

The cost is one CI invariant per metadata field per Nx (~30-50 fields
on N5). Pays for itself the first time someone types a date into a
hash column.

### F.42.2 The type-confusion-in-string-field defect class

**The pattern.** A spreadsheet column or JSON field is *typed* as
"string" in the schema but is *meant* to hold a specific shape (a
commit hash, a YYYY-MM-DD date, a file path, a URL, an enum value).
The schema accepts any string, so type-checkers don't fire. But the
actual value drifts from the intended shape — often via "muscle
memory" data entry, autocomplete suggestions, Excel auto-coercion,
or simple typos that look plausible.

**The N5 proof point.** A 2026-05-22 meta-audit of the bug-tracker
xlsx found:
- 99 of 155 Fixed rows had Excel-coerced `datetime.datetime` objects
  in the "Fix Commit" column (Excel saw a date-shaped value and auto-
  converted; the column-name says "Fix Commit" but the data type was
  "date").
- 51 of 155 had bare date strings (`"2026-05-21"`) in the same column.
- Only 4 of 155 had actual commit-hash-shaped values.

JA-118 (the existing "every Fixed row has a non-empty Fix Commit
cell" check) passed all 155 — empty isn't the failure mode. The
failure mode was *wrong-shape-with-non-empty-content*. JA-146 now
locks the shape (`hash` OR `<...>`-shaped sentinel).

**Detection patterns** (Nx-builder template):

| Field meant to hold | Detector regex template | Sentinel form when value unknown |
|---|---|---|
| Commit hash | `^[a-f0-9]{7,40}(\s+\(\+\s+submodule\s+[a-f0-9]{7,40}\))?$` | `<no-hash-archived; see X>` |
| File path | `os.path.exists(value)` + relative-to-repo-root check | `<no-path; see X>` or `(authored in-place)` |
| Date (ISO 8601) | `^\d{4}-\d{2}-\d{2}$` | `<date-unknown>` |
| Enum | `value in ALLOWED_SET` | `<not-applicable; see X>` |
| URL | `urlparse(value).scheme in {http, https}` + `.netloc != ""` | `<no-url-on-file>` |

**The canonical-sentinel pattern** (F.41.1) is the right complement:
when the value genuinely isn't known, store a `<...>`-shaped string
that the CI invariant accepts as a documented absence. Don't leave
the field empty (CI false-confidence) and don't fabricate a value
(audit-trail corruption).

### F.42.3 The doc-state-vs-code-state drift class

**The pattern.** Hand-curated documentation (TASKS.md, roadmap files,
README counts, feature checklists) drifts silently from the actual
codebase. No automation enforces the link. When a feature is shipped,
the maintainer must remember to flip the corresponding `[ ]` to `[x]`.

**The N5 proof point.** SVA-1.1 (footer privacy badge) and SVA-1.4
(Export Progress button) were both shipped weeks before being noticed
in a TASKS.md review on 2026-05-22 — they were still `[ ]` despite the
features being live in production.

**The advisory heuristic** (`tools/audit_tasks_md_against_codebase_*.py`
on N5; transferable pattern):
1. For each `- [ ]` item, extract distinctive keywords (backticked
   tokens, file paths, quoted phrases, CSS-class-shaped tokens).
2. Grep the codebase (js/, css/, locales/, index.html, README.md, etc.).
3. Score match strength: HIGH (≥5 hits across ≥2 code files), MEDIUM
   (≥2 hits with ≥1 code file), LOW (sparse), NONE.
4. Surface HIGH/MEDIUM candidates as advisory output. NOT a CI gate —
   false positives expected; human review required.

**Why advisory, not enforcing.** A strict CI rule would require an
LLM-grade matcher to verify "this feature description matches this
code surface." Beyond practical reach. The heuristic gets ~70% recall
at acceptable false-positive rate; the maintainer sweep covers the
gap. First-run on N5 surfaced 13 candidates from 60 `[ ]` items.

### F.42.4 The verification-discipline-before-fix rule

**Extends F.41.4.** When an autonomous audit pipeline files a bug
spec, the spec's textual claim must be verified against actual data
BEFORE applying the proposed fix. Two failure modes:

- **Spec premise is wrong**: actual data state doesn't match the
  claim (e.g., DOCS-VOCAB-005 claimed broken file-path refs; actual
  values were explicit prose annotations).
- **Spec premise is right but proposed fix degrades correctness**:
  e.g., DOCS-VOCAB-005's proposed `docs/X.md#anchor` pointer would
  have referenced anchors that don't exist in the methodology doc.

Both failure modes pattern-match on substring scans + naive template
expansion. Verification is: read the actual file content, compare to
the spec narrative, surface mismatches to the user with alternatives.

### F.42.5 Bounded-coverage phrasing for gap-closure batches

When closing a coverage gap (rather than a content bug), use:
- "JA-NN catches *the shape mismatch we surveyed*" — does NOT catch
  semantically-wrong-but-shape-correct values (a hash that points at
  the wrong commit, a path that resolves to the wrong file).
- "The cleanup pass *sentinelized historical drift as documented
  absence*; future entries lock to the canonical convention." — does
  NOT retroactively recover the original (lost) commit hashes.
- "Advisory heuristic surfaces *keyword matches between TASKS.md and
  named code surfaces*" — does NOT catch features shipped under
  different keywords or in surfaces not scanned (sw.js, data/*.json,
  third-party-vendored code, etc.).
- "Coverage *expanded by 1 invariant in this checkpoint*" — does NOT
  imply universal corpus correctness.

### F.42.6 Same defect-class lineage (Nx prediction)

| Class | First seen | Lesson |
|---|---|---|
| Type-confusion in string field | xlsx Fix Commit col (155 rows, 2026-05-22) | Schema-shape invariants must run on every string field where the *intended* shape is narrower than `Any string` |
| Reactive→proactive invariant authoring gap | Meta-audit, 2026-05-22 | Author field-shape invariants in the same commit as the schema addition, not after the bug |
| Doc-state vs code-state drift | TASKS.md SVA-1.1/1.4 (2026-05-22) | Advisory heuristic per `tools/audit_tasks_md_against_codebase_*.py`; supplement with maintainer discipline |

Generalizes F.37.6's "horizontal-deployment-as-part-of-fix-commit" +
F.41.4's "bug-spec-vs-reality verification" to the case where the
defect is a meta-property of the CI suite itself (coverage gap)
rather than a content-quality issue.

## F.41 Canonical-sentinel pattern + multi-case-bug close-out discipline (added 2026-05-22)

Two related learnings from the DOCS-VOCAB-003 → DOCS-VOCAB-005
close-out cycle on N5. Both generalize to Nx.

### F.41.1 Canonical-sentinel pattern for authored-in-place data-metadata fields

**The pattern.** When a JSON data-file carries a metadata field
that represents provenance ("where did this content come from") and
the content might be either externally sourced OR authored in-place,
define a literal canonical sentinel string for the in-place case
and a parallel resolvable-path branch for the external case. The
CI invariant accepts EITHER:
  (a) a path that resolves to an existing repo file, OR
  (b) the literal sentinel string (e.g. `"(authored in-place)"`).

Anything else fails. Specifically:
- Parenthesized prose other than the literal sentinel.
- Paths that don't resolve.
- Empty strings, nulls if the schema requires a string.

**Why this pattern.** When the upstream source file gets deleted
(a refactor, a merge, a DMCA takedown, a legal vetting batch), the
metadata field is left in three possible states:

  - Keep the prose breadcrumb: "(authored in-place; was X.md before
    Y/ merge on YYYY-MM-DD)". Readable but embeds the deleted
    directory name in 28+ files, leaking into search results,
    `git grep`, CI scans, and confusing future readers.
  - Replace with a "best-fit pointer": "docs/methodology.md#X" or
    "docs/<something>.md". Often factually wrong (the new doc
    doesn't actually contain the content), and silently degrades
    correctness while looking like a fix.
  - Replace with literal sentinel: `"(authored in-place)"`. Honest,
    minimal, machine-readable, future-source-aware (the field can
    still hold a real path the day a paper is genuinely externally
    sourced), and CI-verifiable.

**The CI invariant template** (Python, generic):

```python
def _check_ja_NNN_field_canonical_sentinel(
    glob_pattern: str,
    field_name: str,
    sentinel: str,
    repo_root: Path,
) -> list[str]:
    """Field must be literal sentinel OR resolvable path."""
    import json, glob
    failures = []
    for fp in sorted(glob.glob(glob_pattern)):
        d = json.load(open(fp, encoding="utf-8"))
        v = d.get(field_name)
        if not isinstance(v, str):
            failures.append(f"{field_name} missing or wrong type in {fp}")
            continue
        if v == sentinel:
            continue  # sentinel branch — pass
        if v.startswith("("):
            failures.append(
                f"{field_name} in {fp} is parenthesized prose other "
                f"than canonical sentinel {sentinel!r} — got {v!r}"
            )
            continue
        if not (repo_root / v).exists():
            failures.append(
                f"{field_name} path {v!r} in {fp} does not resolve"
            )
    return failures
```

**Bounded-coverage caveat.** The pattern catches *values that are
neither the literal sentinel nor a resolvable repo path*. It does
NOT catch a future case where the path resolves but is semantically
wrong (e.g. points at the wrong file in the right shape). For that,
a per-domain content-equivalence check is needed — out of scope of
the sentinel pattern.

### F.41.2 Multi-case-bug close-out discipline

**The anti-pattern.** A bug filing lists multiple resolution paths:

  > "Either (a) update the README, or (b) update the 28 paper files."

A subsequent fix takes only case (a) and marks the bug Fixed. The
unaddressed case (b) is silently buried. Months (or in the N5
case, hours) later, a separate audit surfaces case (b) as a "new"
bug — wasting filing-cycle and audit-cycle time.

**N5 proof point.** DOCS-VOCAB-003 (filed 2026-05-21) listed both
cases. Its fix updated the README (case (a)) without touching the
28 paper-file `source_file` fields (case (b)). Status flipped to
Fixed with empty Fix Date / empty Fix Notes / a date string in the
Fix Commit cell (instead of a hash). DOCS-VOCAB-005 (2026-05-22)
re-discovered the unaddressed case (b) less than a day later.

**The discipline (mandatory in close-out).** Every multi-case bug
close-out must explicitly state, in the Fix Notes:

  1. Which case(s) the close-out actually addressed.
  2. For each remaining case: either "resolved-in-this-batch by
     <X>" OR "filed-as-follow-up under <BUG-NNN>".
  3. If no follow-up is filed for a remaining case, the bug stays
     Open until all cases are resolved or explicitly declined-with-
     reason.

**Detector idea (not yet implemented).** A CI invariant could grep
bug-tracker Fix Notes for "case (a) or case (b)" / "case (a) and
case (b)" / "case ([a-z])" phrasing and verify that the Fix Notes
explicitly enumerate each lettered case. Not wired on N5 yet — the
volume of multi-case bugs is low enough to rely on close-out
discipline; if the pattern recurs, automate.

### F.41.3 Honest provenance during prose-cleanup

When trimming historical breadcrumb prose, the rule:
- Trimmed-to value must remain truthful for the current file
  (e.g., `"(authored in-place)"` is true; the bug-spec's proposed
  `"docs/X.md#anchor"` was not).
- Historical breadcrumb is preserved in the audit-trail artifacts
  (CHANGELOG, README, git history) — never silently destroyed.
- The CI invariant must accept BOTH the new sentinel AND any
  legitimate future path; not just the sentinel. Otherwise the
  field becomes vestigial.

### F.41.4 Bug-spec-vs-reality verification (mandatory pre-fix step)

Always reproduce the bug claim against actual data BEFORE applying
the proposed fix. The DOCS-VOCAB-005 spec claimed broken file-path
references on the 28 paper files; verification showed the values
were explicit parenthesized prose annotations. The proposed fix
would have replaced truthful prose with a non-existent pointer.

**The discipline (extends F.37.1 horizontal-deployment rule):**
- Read the actual file content of the claimed-defective fields.
- Don't trust the bug-spec's textual claim; verify with `grep` or
  `jq` or `git show`.
- If the spec's premise is wrong (the actual state doesn't match
  the claim), surface to the user with the actual content +
  alternative options. Don't silently degrade.
- If the spec's premise is right but the proposed fix is wrong
  (the right diagnosis, the wrong cure), surface similarly.

This rule applies *every time* a bug-spec is filed by an autonomous
audit pipeline. Pipelines pattern-match against substrings without
parsing semantics; humans (or LLMs with verification discipline)
have to confirm the match-to-defect mapping is real.

### F.41.5 Bounded-coverage phrasing for the canonical-sentinel pattern

When closing batches of this class in audit docs, use:

- "JA-NNN catches *values that are neither the literal sentinel
  nor a resolvable repo path*" — does not catch semantically-wrong
  resolvable paths.
- "Canonical-sentinel pattern at *this one field*" — generalising
  to other authored-in-place fields needs separate JA-NN with the
  sentinel string each field uses.
- "Historical breadcrumb preserved in CHANGELOG / README / git
  history; relocated from N files of data-metadata" — explicit
  that the information moved, not vanished.
- "Multi-case bug closed on cases (a) and (b)" / "Multi-case bug
  closed on case (a) only; case (b) filed-as-follow-up under
  BUG-NNN" — never silent partial closure.

Generalizes F.37.6's horizontal-deployment-as-part-of-fix-commit
rule + F.38.5's newly-wired-invariant-runs-corpus-wide rule to
the case where the defect class is a metadata-field convention
rather than a content-mismatch / content-quality class.

## F.40 CI-recovery triage — 6 durable classes from "what does a green-then-honest CI suite actually surface?" (added 2026-05-21)

The N5 CI-recovery triage produced six durable classes that
generalize to any Nx build. Documented together because they all
emerged from a single discovery cascade: fixing a CI timeout
(`workers: 1` → `workers: 2` + `video: off` on a 2-core ubuntu-
latest runner) let the Playwright smoke suite complete for the
first time since 2026-05-03, surfacing 65 pre-existing failures
the cancellation had been masking.

**Headline pattern.** When CI is consistently red but for an
*infrastructure* reason (timeout / OOM / disk-full / network
flake), every dependent failure mode is invisible until the
infrastructure issue is resolved. The first green-ish run after
the infra fix is the discovery moment, not the win moment.
Budget triage time accordingly: the actual product fix may be 1
commit but the discovery cascade can be 5-10.

### F.40.1 Class A — CI-timeout-masking-failures class

**Pattern.** A long-running CI suite hits the workflow timeout
cap (e.g., 15 min) and gets cancelled mid-run. The cancellation
prevents the test reporter from printing failure summaries, so
the CI badge says "cancelled" instead of showing the actual
failure breakdown. Repeated cancellations look like an
infrastructure problem (slow runner, flaky job) when they're
actually concealing 50+ assertion failures.

**N5 instance.** Playwright suite cancelled at 8m22s / 12m21s /
15m17s on three successive runs. Each bump-the-timeout cycle
produced more "cancelled" badges. The actual cost wasn't in
setup (cache-restored browsers took 25s) — it was a `workers: 1`
config that serialised 120 test instances. Parallelising to
`workers: 2` collapsed the run to 9m20s and immediately
surfaced 65 unique failures.

**Fix pattern.** When CI is consistently "cancelled" rather than
"failed":
1. Read the actual log via `gh run view <id> --log`. Note where
   the cancellation hit (which step, what was running).
2. Get the per-step timing breakdown via `gh run view <id> --json
   jobs`. Compare per-step elapsed times.
3. If the offending step is parallelisable (most test runners),
   try parallelisation BEFORE bumping the timeout. The timeout
   bump is a symptom-fix; parallelisation is a cause-fix.
4. After the suite completes (even if failure), accept the
   discovery cost: budget another N hours/days for triaging the
   exposed failures.

**For Nx:** every CI workflow should declare a `timeout-minutes`
that's at least 2× the expected runtime — but the EXPECTED
runtime must be measured, not guessed. When the suite hits the
cap, the diagnosis sequence above applies.

### F.40.2 Class B — Stale test assertions when UI evolves class

**Pattern.** When the UI is restructured (elements removed,
text changed, layout collapsed), tests against those affordances
become stale but typically don't fail loudly until the test
suite runs end-to-end. In the N5 cycle, ~10 tests asserted on
`.syllabus-title`, `.syllabus-trust-band`, `.locale-chip`,
"Start sitting" copy, `data-grammar-filter-group="tier"`, etc.
— elements / strings deliberately removed weeks earlier.

**N5 instances.**
- `.syllabus-title` + `.syllabus-subtitle` + `.syllabus-action-
  prompt` + `.btn-action-primary` removed when home was restructured.
- `.syllabus-trust-band` + `.trust-pill` removed in favor of in-
  card niche-N2 messaging + footer trust strip.
- 2-segment `.locale-chip` group → single `#locale-toggle`
  icon-btn (locale UI redesign 2026-05-09).
- Test-length picker: `button.length-btn` → `<select id="test-
  length">`.
- Grammar TOC tier chips: removed 2026-05-10 per user feedback
  (file header comment in `js/learn-grammar.js` line 190).
- "Start sitting" CTA copy → "Start full mock test →" (same
  date 2026-05-10).
- Hardcoded counts (177 grammar patterns; reading 30; listening
  30) that drifted to 178 / 54 / 50.

**Fix pattern.**
- Replace hardcoded counts with `fetch('data/version.json')`
  reads, OR with `data/<corpus>.json` length introspection at
  test runtime. The assertion then tracks the data without
  edits.
- For removed elements: either `test.skip` with a comment +
  git-history reference, OR rewrite the test to assert the
  replacement affordance (e.g., locale-chip → locale-toggle).
- For copy changes: prefer regex match (`/Start.*sitting|mock/`)
  over exact string match when the user-visible label is
  product-marketing-controlled rather than test-controlled.

**For Nx:** when removing or restructuring a UI affordance,
grep `tests/` for the class name + copy strings. Update or
remove the affected tests as part of the *same commit* that
ships the UI change. The horizontal-deployment-sweep rule
(F.37.6 / F.38.5) extends to test artifacts, not just code +
data + docs.

### F.40.3 Class C — First-run onboarding bypass for tests class

**Pattern.** When the app has a "first-run experience" gate
(redirect on no-history / no-streak / no-results), every CI run
hits it because Playwright's fresh-context browsers have empty
localStorage. The test navigates to `/`, the app redirects to
`#/diagnostic`, the test asserts against the home DOM that
isn't rendered.

**N5 instance.** IMP-044 (2026-05-11) added first-run onboarding:
hash-less visits with no history/results/streak redirect to
`#/diagnostic`. Every test loading `/` failed: page title shows
"JLPT N5 placement diagnostic" not the home title, the
`.syllabus-card` count is 0, etc. Affected ~12 tests across
3 spec files.

**Fix pattern.** Add a global `test.beforeEach` (or
`page.addInitScript`) that sets the "seen" sentinel before the
first navigation:

```js
test.beforeEach(async ({ page }) => {
  await page.addInitScript(() => {
    try { localStorage.setItem('app:onboardingSeen', '1'); } catch {}
  });
});
```

The sentinel must match the app's actual storage key (read
the app's first-run code to find it). Apply to every
`test.describe` block whose tests navigate to `/` (or any
hash-less route the app intercepts).

**For Nx:** any first-run flow MUST document its bypass
sentinel in the test fixtures README so future test authors
don't trip the same wall.

### F.40.4 Class D — Rule-order bugs in priority chains class

**Pattern.** When a recommender / decision engine has rules in a
priority chain and one rule has a too-permissive catch-all
condition, it dominates lower-priority specific rules that
should fire later in the chain.

**N5 instance.** The pedagogy recommender's R-13 ("catch-all
returning user gets Open Learn") had condition `if (signal.
isReturning)` — too broad. It dispatched BEFORE R-14 ("mock-
paper ready", grammar≥60% AND kanji≥50%) in the RULES array, so
R-14 NEVER fired for any returning user despite a sound product
intent. The bug was invisible because R-14 was only exercised
by a test that had never completed on CI.

**Fix pattern.**
- Audit every rule chain for catch-all conditions. Document
  explicitly which rule is "the catch-all" — there should only
  be ONE per chain.
- Place catch-alls at the END of the dispatch array, not
  according to rule-numbering.
- Add positive tests for EVERY priority rule, with explicit
  signal overrides that block higher-priority rules (e.g., null
  out `lastLearnId` to prevent R-06 dominance).
- Pair each positive test with a tie-break test (signal where a
  higher-priority rule should win).

**For Nx:** any recommender / decision-engine / SRS-scheduler
shipped should ship with the same positive-plus-tie-break
test discipline. The discovery cost is much lower in unit
tests than in CI-runtime failures masked by other issues.

### F.40.5 Class E — Color-contrast on branded headers class

**Pattern.** A design system ships a "muted text" color
calibrated for white / default-surface backgrounds. When that
muted color is used inside a branded header band (non-white,
non-surface bg), the contrast ratio fails WCAG AA.

**N5 instance.** `--color-text-muted: #6F6D66` was used in
`.primary-nav a`, `.app-header .icon-btn`, and elsewhere. On
white bg: 4.94 contrast (passes AA). On the tea-green
`--header-bg: #cfd8b5`: 3.48 contrast (fails AA). axe-core
flagged 408+ violation instances on the homepage alone (each
nav-link is one instance, but axe walks the DOM tree so
descendant elements compound).

A parallel case: `--color-text-faint: #9A968C` on the white
footer = 2.95 contrast (fails AA). axe-core caught
`.footer-disclaimer` rendering with the faint variant.

**Fix pattern.** Introduce a `--color-text-on-<surface>` token
per non-white branded surface:

```css
:root {
  --color-text:           #1F1F1C;
  --color-text-muted:     #6F6D66;  /* on white / surface */
  --color-text-on-header: #4A4A47;  /* on --header-bg #cfd8b5 */
}
@media (prefers-color-scheme: dark) {
  :root {
    --color-text-on-header: var(--color-text-muted);
    /* dark mode muted #A8A59C on dark header #2a3a2c = 5.76 ✓ */
  }
}
```

Wire the surface-specific token in every selector that lives on
the branded surface. Keep `--color-text-muted` for white/surface
contexts (a global darken would change the whole type rhythm).

For "faint" treatments on white: if the legal/design ask is
"faint but readable," the muted variant (4.94 contrast) is the
right floor. Don't ship `--color-text-faint` (#9A968C) where
WCAG AA matters; reserve it for non-functional decorative copy.

**For Nx:** audit each NEW non-white branded surface with axe-
core during the design stage, not during the CI-recovery
stage. The contrast pair (fg color × bg color) is part of the
token system, not an afterthought.

### F.40.6 Class F — Cross-platform snapshot baselines class

**Pattern.** Visual-regression tests with `playwright`-style
screenshot baselines tag each baseline with the OS (`-win32.png`,
`-linux.png`, `-darwin.png`). If the dev box that captures the
baselines runs Windows but CI runs Linux, the suite hits a 100%
miss rate on every CI run: it requests `-linux.png` files that
have never been generated, falls through to "snapshot doesn't
exist, writing actual," and reports each missing baseline as a
test failure.

**N5 instance.** 76 committed PNGs all named `-win32.png`. Every
CI run after the suite was wired (2026-05-03 DEFER-6 closure)
reported 38 unique "snapshot doesn't exist" failures. The 15-
min cancellation had been masking the count; once the suite ran
to completion, the failures became visible.

**Fix pattern.** Three options, in order of effort:

A. **Skip on CI temporarily.** `test.skip(!!process.env.CI,
   'baselines are -win32; Linux baselines need separate regen')`.
   Local dev still gets the diffing. Buys time for option B/C
   without leaving CI red.

B. **Workflow-dispatch regenerate.** Add a `workflow_dispatch`
   input `update-snapshots: true`. When triggered, the
   workflow runs `npx playwright test --update-snapshots` and
   uploads the new PNGs as an artifact. Download + commit
   manually.

C. **Per-OS baselines committed.** Run `--update-snapshots` on
   every supported platform; commit both `-win32.png` AND
   `-linux.png` (and `-darwin.png` if Mac dev exists). Larger
   repo but no migration friction.

**For Nx:** never commit visual-regression baselines from a dev
box whose OS differs from the CI runner. Either generate them
on the runner (option B/C) or skip on CI from day one (option
A) until you can.

### F.40.7 Operational rule — "the discovery cascade rule"

When an infrastructure fix unblocks visibility, treat the next
N hours as **observation time, not fix time**. The first
green-ish run after the unblock is the discovery moment.
Budget triage as a separate phase:

1. Capture the full failure list (`gh run view --log-failed`).
2. Bucket failures by class (test-side vs product-side; new
   regression vs pre-existing drift).
3. Stack-rank by fix cost AND blast radius. Cheap fixes first
   to thin the failure count; structural fixes second.
4. Commit in batches with explicit per-batch scopes ("4 stale
   assertions" / "a11y CSS fix" / "rule-order swap"). Each
   batch should be revertable without affecting the next.
5. After every batch, re-read the CI log. New failures may
   surface as old ones get out of the way.
6. The final batch is doc-propagation per Rule 4 + bug-sheet
   registration per Rule 5 — capturing the learnings before
   they fade.

This applies generally: every "fix unblocks visibility"
moment in a build pipeline (CI timeout fix, log-level fix,
infrastructure migration, sandbox upgrade) gets this discipline.

## F.13 What this appendix does NOT cover

- **Native-human review workflow** — what to hand to a native
  speaker, how to prioritize, what feedback structure to expect.
  Belongs in a future Appendix when funded.
- **Multi-level cross-corpus consistency** — when Nx ships, the
  same word may appear in N5/N4/Nx vocab with different attestation.
  Reconciliation policy TBD.
- **Audio re-render cost vs content change frequency** — N5's
  policy as of 2026-05-14 is "re-render the full surface on any
  renderer change" (validated cost: ~15 min CPU for 1782 grammar
  examples). For Nx, build a `--missing-only` + `--changed-only`
  selective re-render path so audio doesn't have to be a full sweep
  on every text fix. Track input-hash against manifest; re-render
  only when hash differs.
- **Hindi native-review process** — all Hindi content in N5 is
  LLM-curated. A native-Hindi reviewer round is queued (IMP-101)
  but not yet scheduled.

---

*Appendix F added 2026-05-15 capturing the audit-fix-iterate cycle
methodology from the N5 audit session (27 rounds, 2,061 fixes within
the categories defined that session, JA-81→JA-90).
Extended 2026-05-14 with F.12 documenting the TTS bunsetsu-space
particle-devoicing class caught on n5-008.8 (one user-reported audio
mismatch led to a corpus-wide 1782-file re-render).
Extended 2026-05-15 with F.14 capturing the writing-discipline
rewrite pass (banned-phrase list for audit docs, "saturated" always
qualified as "against current pattern set").
Extended 2026-05-16 with F.15 (verb-class particle disambiguation
from BUG-002), F.16 (static HTML mirrors for SPA hash routes from
BUG-001), F.17 (seven native-teacher bug classes from BUG-003
through BUG-009 — cross-pattern explanation contamination,
mora-count systematic error, pattern-instance contamination,
RIGHT/WRONG framing for valid alternatives, folk-linguistic grammar
terminology, pattern-particle mismatch in canonical examples), and
F.18 (full-surface generalization of the static-mirror pattern from
F.16, addressing BUG-010 — every SPA route surface gets a crawlable
static mirror with route-specific metadata, sitemap.xml, robots.txt,
and cross-surface linking; six-stage rollout sequence; meta-route
markdown-to-HTML pattern for README / CHANGELOG / PRIVACY / NOTICES;
documented gaps include per-page OG images, Hindi locale variants
for non-meta surfaces, Playwright snapshot CI, and a mirror-presence
CI invariant), and F.19 (schema-level fix for register-variant
common_mistakes from BUG-011 — `kind: "register_variant"` field
plus `label_a` / `label_b` register tags; UI + static-mirror
renderers split errors vs variants into separate sections;
backwards-compatible with legacy `wrong`/`right` field reads), and
F.20 (provenance labels must disambiguate human vs AI review at the
point of use, from BUG-012 — `native_reviewed` value renamed to
`ai_quality_reviewed` across 1758 entries; `review_status_provenance`
field added alongside; CI invariant + UI badge logic updated; the
real-human-review value `human_native_reviewed` reserved for a
future human review pass). F.19 extended on 2026-05-16 with §F.19.6
(BUG-013 follow-up: don't leave legacy keys in the data during a
schema migration — finish the rename in the same commit; data-surface
contradictions cost an extra round-trip in BUG-011 → BUG-013), and
F.21 (vocab-corpus data-quality bug classes from BUG-014 through
BUG-018 — template semantic-nonsense, inconsistent field schemas,
field-coverage gaps on core entries, OOS kanji in display fields,
cross-section duplicate entries; the three operational layers
content / schema / coverage all need explicit CI gates), and F.22
(kanji-corpus data-quality bug classes from BUG-020 through
BUG-022, 2026-05-17 — cross-file display drift after corpus-level
fixes, primary_reading misalignment with N5 standalone use,
field-name inconsistency from divergent authoring pipelines;
lesson: each corpus needs its own native-teacher audit pass).
F.22.1 extended 2026-05-17 with the BUG-023 lesson: the initial
narrow-scope JA-100 (OOS-kanji-only) missed 5 cases of the inverse
class — vocab.json kana-only forms where the kanji IS in scope.
Tightened to strict form-equality. Lesson: default to strict-
equality CI gates, not narrow-scope ones; the BUG-020 → BUG-023
round-trip cost an extra audit cycle.
F.22 also extended 2026-05-17 with F.22.5 — auto-derived data
inherits upstream dedup drift (BUG-024). The kanji.json
n5_compounds arrays were auto-derived from vocab.json BEFORE the
BUG-018/019 dedup landed; the dedup-cleaned source wasn't
re-propagated. JA-103 catches the residual subset-gloss
duplicates. Operational rule: every dedup pass on a source corpus
must trigger re-derivation of all consumer corpora.
Extended 2026-05-17 with F.23 — reading-corpus batch-drift
(BUG-041..046). A single class manifesting in six distinct
field divergences between the original 45-passage batch and the
later 9-passage batch: legacy enum with mixed semantics
(BUG-041), multi-language inline field (BUG-042), _meta
documentation drift (BUG-043), conceptual field duplication
(BUG-044), field-shape divergence (BUG-045), pronoun-form
inconsistency (BUG-046). Lesson: when a corpus grows in
phases, capture each field's convention as a strict-shape CI
invariant AT INTRODUCTION; permissive schemas absorb drift
silently. Sub-lesson (F.23.2): multi-locale string-parsing
must accept terminator punctuation from every locale in the
field, not just the "primary" one — Devanagari danda `।`
slipped past a `。`-only regex on first run. New CI invariants
JA-104 (difficulty enum), JA-105 (vocab_preview shape), JA-106
(format_type enum).
Extended 2026-05-17 with F.24 — listening-corpus migration
drift (BUG-047..053). Same meta-class as F.23, different
corpus and different migration trigger: a 2026-05-12 VOICEVOX
migration completed on `audio_render_meta` but left
`voice_planned` (BUG-047), audit-status fields on items 41-50
(BUG-048), the _meta.voice_variety_plan block (BUG-052), and
the voicevox_speaker_catalog (BUG-053) stale. Plus a separate
dual-field redundancy (BUG-051, format ↔ format_type) and an
operational deferral (BUG-049 pacing systematically too slow,
needs audio re-render). BUG-050 was already-fixed by the Rule-5
install commit cdef185. New CI invariants JA-110 (no
voice_planned) + JA-111 (no format; format_type closed enum).
Generalized operational rule (replaces F.23.7's batch-specific
phrasing): after any corpus-level migration or batch-mod pass,
run a same-shape audit not just on the data items but on every
field that references the migrated state — _meta blocks,
audit-status fields, sibling fields with overlapping semantics,
plan documents, and metadata catalogs.
Extended 2026-05-17 with F.25, F.26, F.27 capturing three
methodology learnings from the JA-91 / JA-94 final-unblock +
resolution + Audio Phase-2 close-out session: F.25
(baseline-allowlist pattern for reserved-invariant promotion —
the path from "reserved" to "wired with non-empty baseline" for
invariants whose detector mechanically surfaces legitimate
corpus structure mixed with genuine bugs), F.26 (empty-baseline
resolution methodology — Phase A example replacement + Phase B
explanation divergence rewrites to retire each baseline entry
without restructuring the corpus, leaving the baseline file as
a RESOLVED snapshot), and F.27 (from-source TTS re-render at
unified speed_scale supersedes stacked post-processing — when
to invoke a full re-render vs continued patching, plus the
provenance value of "one render, one filter" per item).
Extended further 2026-05-17 with F.28 (multi-role specialist-
review-by-tab methodology — bounded-honest stamping conventions
covering 11+ specialist roles; brutal-honesty re-audit pattern
for stricter ground-truth classification; NR-{ROLE}-NNN bug
naming convention; cross-artifact propagation per Rule 4/5)
and F.29 (Selenium UI test class — end-to-end E2E coverage of
every functional surface in spec §5 + the static-mirror
surfaces + sitemap + a11y + security headers + Service Worker +
audio + i18n + console-error-zero verification; critical
NR-UI-001 lesson that some defense-in-depth security headers
(frame-ancestors, X-Frame-Options) are HTTP-header-only and
IGNORED via <meta> — always verify runtime effectiveness, not
just source presence).
Extended 2026-05-21 with F.37 (mixed-script mojibake + off-by-one
rationale_hi shift + fix-history strip — BUG-133/134/135 closure).
Three drift classes surfaced in the same goi sweep, each with a
sibling instance the original single-fix pass missed; horizontal-
deployment-as-part-of-same-commit operational rule generalizes
the lesson; JA-137 (narrow off-by-one detector) + JA-139
(mixed-script mojibake detector) added to CI; JA-121 trigger set
extended in place (no new JA-NN number — preferred when an
existing detector's intent already matches the new class).
Extended 2026-05-22 with F.43 (5-bug DOCS-* close-out from
review-packet meta-audit — DOCS-VOCAB-006 / DOCS-CORE-001 /
DOCS-BRAND-001 / DOCS-Q-001 / DOCS-DKE-001). Captures five
durable governance-doc consistency defect classes + three new CI
invariants JA-147 / JA-148 / JA-149 + the bug-spec-vs-reality
verification reinforcement that rejected DOCS-VOCAB-005 as a
stale-snapshot artifact. Pairs with F.42's reactive→proactive
lesson: the meta-audit pipeline surfaces the unknown-unknown
classes; F.43's specific defect classes are named patterns that
JA-NN invariants now prevent re-introduction of.*

## F.43 Governance-doc consistency defect classes from review-packet meta-audit (added 2026-05-22)

Five durable defect classes generalized from the N5 DOCS-VOCAB-006 /
DOCS-CORE-001 / DOCS-BRAND-001 / DOCS-Q-001 / DOCS-DKE-001
close-out batch (BUG-156..160). All five surfaced from a
**review-packet meta-audit** — a separately-running audit
pipeline that consumes a sanitized snapshot of the project and
returns bug candidates. The pipeline catches classes that the
in-tree CI invariants don't, **but its bug claims must be
verified against current data** before any fix lands (per
F.41.4) because the snapshot timestamp may lag the working tree.

### F.43.1 Bug-spec-vs-reality verification — proof-point reinforcement

**N5 evidence (2026-05-22).** The review-packet meta-audit
filed DOCS-VOCAB-005 as "CARRY-OVER — fix not applied; all 28
paper files still hold `source_file: KnowledgeBank/<x>_questions_n5.md`."
Verification against the working tree showed all 28 already held
the literal sentinel `"(authored in-place)"` since the actual fix
landed (commit `b7f5787`, hours before the audit ran). The
review-packet snapshot pre-dated the fix.

Per F.41.4: **every bug-spec from an autonomous audit pipeline
must be verified against current data BEFORE applying any fix.**
This applied:
- 1 of 6 candidates rejected as stale-snapshot artifact;
- 5 of 6 verified real and shipped.

**Lesson for Nx-builders:** when the meta-audit pipeline files
N bugs, expect 1-2 of them to be stale-snapshot artifacts. The
verification step is the gate, not the bug filing.

### F.43.2 Class A — Known-mismatch enumeration drifts from computed set

**Anti-pattern.** A README documents "Known mismatches (N)"
between two related data files. The author maintains both sides
by hand. Over time, one side gains or loses entries while the
README is forgotten — the documented count and the actual
computed count diverge silently.

**N5 evidence (DOCS-VOCAB-006).** `n5_vocab_whitelist_README.md`
documented 3 known whitelist↔vocab.json mismatches (`倍`, `国籍`,
`週末`); the actual computed mismatch set had 4 entries — `では`
had been added to the whitelist but never authored as a
standalone vocab.json entry, and the README was never updated.

**Fix pattern.** Two parts:

1. **Author the missing case** in the README (or in the data
   it's tracking, if the missing piece is authoring work).
2. **Wire a CI invariant** that compares the README's
   enumeration to the actual computed set. The invariant must
   parse the README structure (section header count + bulleted
   tokens) and compare to the set computed at CI time.

**CI invariant template (Python, generic):**

```python
def _check_jaN_readme_known_mismatches_parity():
    actual = compute_actual_mismatches()  # set of tokens
    readme_text = (REPO / "docs" / "FILE_README.md").read_text(...)
    header_count_m = re.search(r"###\s+Known mismatches\s*\((\d+)\s*,", readme_text)
    declared_count = int(header_count_m.group(1))
    bullet_section = extract_section_after_header(readme_text)
    declared_tokens = set(re.findall(r"^\s*-\s+`([^`]+)`", bullet_section, re.M))
    failures = []
    if declared_count != len(actual):
        failures.append(f"...header count {declared_count} != actual {len(actual)}...")
    if declared_tokens != actual:
        failures.append(f"...bulleted set != actual set...")
    return failures
```

**N5 instance:** JA-147.

### F.43.3 Class B — Multi-source classification, one source updated

**Anti-pattern.** A taxonomy / classification lives in one
authoritative file (e.g., `n5_core_pattern_ids.json` classifies
patterns as core / late / deferred), but consumers read a
different file (e.g., `grammar.json` is the per-entry catalog).
When the authoritative file changes a classification but the
per-entry catalog doesn't reflect it, downstream consumers
(lint, paper-builder, live UI) can't distinguish the reclassified
entries from in-scope ones.

**N5 evidence (DOCS-CORE-001).** 5 patterns were classified
`deferred_to_n4` in `n5_core_pattern_ids.json` but had no
`scope` / `status` / `excluded` / `scope_note` field in
`grammar.json`. Consumers reading grammar.json couldn't filter
them out of N5 scope. Three operational consequences:

1. `version.json.counts.grammar` reported 178, but 5 were
   out-of-scope (effective N5 count = 173). Silent.
2. lint tools deriving N5 scope from grammar.json implicitly
   blessed `〜だろう` / `〜なくちゃ` etc. as N5-allowable.
3. The live UI surfaced deferred patterns to N5 learners.

**Fix pattern.** Mirror the classification into the per-entry
catalog with a dedicated field:

1. Add a `scope` (or `status` / `category`) field to each
   per-entry record reflecting the authoritative classification.
2. Add a sibling `<field>_note` (e.g., `scope_note`) field with
   prose justifying the classification + reference to the
   authoritative source.
3. Update consumer count fields (e.g., add `version.json.counts.
   grammar_n5` alongside `grammar`) so the in-scope count is
   first-class.
4. **Wire a CI invariant** that verifies per-entry classification
   matches authoritative classification. Both sides agreement is
   the test:

```python
def _check_jaN_classification_agreement():
    auth = load_authoritative_classification()  # dict: id -> category
    per_entry = load_per_entry_catalog()
    failures = []
    for entry in per_entry:
        eid = entry["id"]
        cat = auth.get(eid)
        if cat is None:
            failures.append(f"id {eid} not in authoritative classification")
            continue
        # Verify per-entry field reflects authoritative
        if cat == "deferred_to_n4" and entry.get("scope") != "n4":
            failures.append(f"id {eid} classified {cat} but scope={entry.get('scope')!r}")
        elif cat in ("core_n5", "late_n5") and entry.get("scope") not in (None, "n5"):
            failures.append(f"id {eid} classified {cat} but scope={entry.get('scope')!r}")
    return failures
```

**N5 instance:** JA-148. JA-107 extension recognized the new
`grammar_n5` scope-filtered count.

### F.43.4 Class C — Review-packet strip, undocumented in the packet's own README

**Anti-pattern.** A build script generates a sanitized export
of the project (review packet, anonymized data set, public
release bundle) by stripping certain fields. The strip protects
privacy / hides brand identity / removes CI noise. But the
packet's own README enumerates "What was stripped" without
listing all the strip categories. Reviewers see fields that
appear empty/wrong and reasonably conclude the live system has
a bug.

**N5 evidence (DOCS-BRAND-001).** `tools/build_review_packet.py`
zeros all string values in `branding.json` (privacy/anonymity
strip to protect brand-identifying content). The packet's own
README's "Stripped (review-noise)" section enumerated `_meta`,
timestamps, audio file paths, hash fields — but did NOT mention
the branding strip. Reviewers reading the empty `brand.name` /
`meta.title` / `og_*` fields would reasonably conclude the live
site has no SEO / no header / broken branding. (The live site
works fine; `index.html` hardcodes the brand strings.)

**Fix pattern.**

1. **Document every strip in the packet's own README.** Each
   strip rule needs an explicit bullet: what's stripped, why,
   and where the unstripped data actually lives.
2. **Embed the strip documentation in the builder script** (not
   just in a hand-edited README) so the documentation survives
   regeneration. The builder writes a templated README that
   already lists all strips.
3. **Distinguish "stripped for privacy" from "stripped because
   noise"** — reviewers need to know which fields are
   intentionally blank vs which would be a real defect.

**Operational rule:** the README that ships with a sanitized
packet must enumerate every category of stripping the builder
performs. The list lives in the builder source, not just in the
packet artifact (which gets regenerated).

### F.43.5 Class D — "Bank source" / "derived from" terminology overclaim

**Anti-pattern.** A README describes two independent data
corpora as if one were derived from the other. The terminology
("bank source", "derived from", "drawn from") implies a
many-to-one or one-to-one relationship that doesn't exist. New
contributors assume the relationship and try to "reconcile" the
two, wasting effort or introducing bugs.

**N5 evidence (DOCS-Q-001).** `n5_vocab_whitelist_README.md`'s
consumers section described `data/questions.json` (290 entries,
`q-NNNN` IDs, drill-bank schema) as a "bank source" for the
paper files (`data/papers/<cat>/paper-{1..7}.json`, 402
questions, `Q1..Q102` IDs, different schema). The actual ID
overlap = 0. Different ID schemes. Different schemas
(`correctAnswer` string vs `correctIndex` int; per-option
distractor explanations vs none; `category`/`mondai` fields vs
none). The two corpora are PARALLEL, not source-and-derived.

**Fix pattern.**

1. **Reserve "source of" / "derived from" / "bank source" for
   actual source-derived relationships.** When two corpora are
   independent, use independent-corpora language:
   - "Used in spaced-repetition flows"
   - "Used in mock-test simulations"
   - "Independent corpus from X with different schema and ID scheme"
   - "0 ID overlap with Y"
2. **If a reconciliation is planned**, document the migration
   path explicitly. If not planned, make the independence
   permanent in the README so contributors don't try to
   "fix" it.

### F.43.6 Class E — Placeholder boilerplate as "this'll get filled in later"

**Anti-pattern.** Pre-formalization authoring (the early phase
of a new field where rationale isn't recorded per-item) leaves
placeholder boilerplate in production data: "Pre-formalization
(initial dokkai authoring; rationale not individually recorded)."
The placeholder is honest about its emptiness but adds no
information. Later authoring batches add real per-item rationales
to NEW entries but never backfill the placeholders. Over time,
the placeholder ratio drifts — by the time someone audits, 28%
of entries are placeholders.

**N5 evidence (DOCS-DKE-001).** 25 of 90 (28%) entries in
`data/dokkai_kanji_exception.json` carried the placeholder
boilerplate. 65 of 90 (72%) had real per-item rationales
authored 2026-05-XX. The 25 placeholders all had
`addedAt: "<2026-05-02"` — the formalization deadline.

**Fix pattern.**

1. **Backfill placeholder entries.** For each placeholder, find
   the actual usage in the surrounding corpus and write a
   specific rationale. Format matches the real entries.
2. **Wire a CI invariant** that REJECTS placeholder phrasings.
   The placeholder text becomes a CI failure trigger:

```python
def _check_jaN_no_placeholder_boilerplate():
    PLACEHOLDER_PHRASES = [
        "Pre-formalization",
        "rationale not individually recorded",
        "TBD",
        "TODO: write rationale",
    ]
    failures = []
    for entry in load_target_corpus():
        text = entry.get("reason") or entry.get("rationale") or ""
        for phrase in PLACEHOLDER_PHRASES:
            if phrase in text:
                failures.append(f"{entry['id']}: reason contains placeholder {phrase!r}")
                break
    return failures
```

**N5 instance:** JA-149. The 25 backfilled rationales used the
surface-citation format from the 65 real entries (e.g., "京 →
東京 / 大阪 placenames in paper-3 Passage 24"), maintaining
consistency.

**Operational rule:** placeholder boilerplate has a half-life.
Mark it with a sentinel + author a CI gate that fires after a
chosen deadline (e.g., "any placeholder still present after
2026-12-01 fails CI"). Or backfill immediately. Don't ship
placeholders to long-term storage without a forcing function.

### F.43.7 Same-batch CI-invariant authoring discipline

All 5 fixes in this batch added or extended a CI invariant in
the SAME commit as the fix:

| Defect class | Fix | CI invariant |
|---|---|---|
| F.43.2 README-vs-computed | Document new mismatch in README | JA-147 (parity check) |
| F.43.3 Multi-source classification | Add scope field per entry | JA-148 (classification agreement) |
| F.43.4 Review-packet strip undocumented | Document strip in builder + README | (No CI; build-script templated) |
| F.43.5 "Bank source" overclaim | Rewrite README consumers section | (No CI; terminology, not data) |
| F.43.6 Placeholder boilerplate | Backfill 25 + reject phrasings | JA-149 (phrase rejection) |

3 of 5 classes shipped a CI invariant. 2 (Class C, Class D)
remain terminology / build-script discipline. This ratio is
expected: data-shape problems are CI-enforceable; terminology /
build-script-output problems live in conventions.

**Operational rule (Nx generalization):** for every batch
close-out, classify each defect by:
- "Data-shape, CI-enforceable" → mint or extend a JA-NN.
- "Terminology / convention / one-time edit" → document in
  procedure manual + README + build script.

The class determines the forcing function (CI for shape,
conventions for terminology).

### F.43.8 Bounded-coverage phrasing for the batch

When closing this class of batch in audit-coverage docs, use:

- "JA-NNN catches *the specific README-vs-computed mismatch-set
  divergence*" — does not catch other README-vs-data drift classes
  not specifically wired.
- "JA-NNN catches *the specific scope-field-vs-classification
  disagreement*" — does not catch broader multi-source consistency
  bugs beyond the named classification.
- "JA-NNN catches *the specific placeholder phrasings*" — does not
  catch all unspecific rationales (e.g., "see notes elsewhere",
  "TBD by editor", various other vague phrasings).
- "Bug-spec verification rejected N of M candidates as stale-
  snapshot artifacts" — names the verification step + reports
  honestly the fraction rejected.

### F.43.9 Same drift-class lineage table

| Class | First seen | Next sighting | Lesson |
|---|---|---|---|
| README-vs-computed drift | DOCS-VOCAB-006 (2026-05-22) | — | New JA-NN at parity-check time |
| Multi-source classification | DOCS-CORE-001 (2026-05-22) | — | Mirror classification into per-entry field + CI |
| Review-packet strip undocumented | DOCS-BRAND-001 (2026-05-22) | — | Embed strip docs in builder script |
| "Bank source" terminology overclaim | DOCS-Q-001 (2026-05-22) | — | Reserve source-derived terms; otherwise call out independence |
| Placeholder boilerplate at-rest | DOCS-DKE-001 (2026-05-22) | — | Phrase-rejection CI invariant |

For Nx, predict these classes as part of the batch close-out
template: the meta-audit will surface them, and the procedure
manual section names them so the fix is mechanical rather than
re-invented.

## F.45 SPA history-mode migration — 5 durable findings from the v1.16→v1.17 hash→pathname cutover (added 2026-05-24)

Captures the migration of the N5 SPA from hash routing (`#/learn/n5-001`)
to history-mode path routing (`/learn/n5-001/`). The migration was
triggered by external-tool inaccessibility: LLM web-fetchers,
link-previewers, and search-engine crawlers can't read content past
a `#` fragment, so every pattern's URL produced an empty app shell.
The dual-surface workaround (interactive SPA at hash route + static
mirror at `learn/grammar/n5-XXX/` that JS-redirected to the SPA)
worked for crawlers but produced **two URLs per page**, which is
architecturally wasteful and a sharing-experience footgun.

**Headline meta-lesson:** hash routing is the cheap default for an
SPA on GitHub Pages, but the dual-URL pattern it forces (one hash
URL for interactivity, one static-mirror URL for crawlers) compounds
into routing-shape, asset-resolution, cache, and audit-trail bugs
that all need to be solved in the same change. Plan the migration
in 10 atomic phases (see commit `85f8a01` + follow-ups
`52d8a9d` / `9cc58e2` for the actual N5 cutover); attempting fewer
phases produces "half-migrated" intermediate states that 404 in
production.

### F.45.1 Class A — Hash routing duplicates URLs; history mode unifies them

**Anti-pattern.** SPA reads `location.hash` for routing. Every page
has TWO URLs:
  - `#/learn/n5-001` (interactive SPA)
  - `learn/grammar/n5-001/` (static crawler mirror, with a 1.5 s
    setTimeout that redirects to the hash URL).
The static mirror was added later to fix crawler-readability of the
hash URL. The redundancy is invisible until you try to share a URL
in Slack/LinkedIn (no rich preview from the hash URL) or fetch one
with an LLM web tool (sees only the empty shell).

**Detection.** Any time the codebase carries both:
  - a route resolver that reads `location.hash`, AND
  - a separate static-mirror generator that emits HTML at distinct
    paths whose content overlaps with the SPA-rendered route,
the architecture is in dual-URL state. Look for `setTimeout(...goToSPA...)`
or `meta[http-equiv=refresh]` in the mirror — both signal "the
mirror exists to redirect to the real URL", which means the real
URL isn't crawler-resolvable.

**Fix pattern.**
1. Refactor `parseRoute()` to read `location.pathname` instead of
   `location.hash`. Keep a backward-compat branch that
   `history.replaceState`s any legacy `#/...` URL on boot.
2. Replace every `location.hash = '#/X'` site with
   `history.pushState(null, '', basePath + 'X/')` (or a
   `navigateTo()` helper in a router module imported across the
   codebase to avoid circular imports).
3. Replace the hashchange listener with a `popstate` listener.
   Keep the hashchange listener as a backward-compat wrapper that
   delegates to the same route() handler.
4. Move static mirrors to the canonical path the SPA route now
   uses. Remove the `setTimeout(redirect)` block — let the SPA
   boot in place by loading the SPA's `app.js` from the mirror
   and rendering into a `<main id="app">` wrapper. The mirror's
   static content is replaced by the SPA's dynamic render on
   hydration; crawlers without JS keep the static content.
5. Add a `404.html` at the site root with the rafgraph
   spa-github-pages snippet for any deep link to a route that has
   no static mirror (e.g. `/settings/`). Pair with a decoder in
   `index.html`'s `<head>` that unpacks the redirect query and
   `replaceState`s the URL back to the clean form before SPA boot.

**N5 instance:** BUG-024. Pre-migration commits: `85f8a01`
(routing) + `52d8a9d` (asset src + CSS) + `9cc58e2` (cache buster).

### F.45.2 Class B — Base-aware `fetch()` doesn't cover HTML attribute resolution

**Anti-pattern.** When the SPA boots from a deep mirror path like
`/learn/n5-001/`, every relative URL in the page is resolved against
the deep path. A `fetch()`-wrapper that prepends the base path
(`getBasePath() + 'data/grammar.json'`) fixes `fetch()` calls. But
HTML attribute resolution — `<audio src="audio/grammar/X.mp3">`,
`<img src>`, `<link>`, `<script>` — uses `document.baseURI` and is
NOT routed through the wrapper. Result: audio 404s on every deep
link.

**Detection.** Grep the codebase for HTML attribute injection
patterns: `<audio... src=`, `<img... src=`, `<source src=`,
`<link... href=`, plus dynamic `el.src = ...`. Any of these that
take a relative path needs to be base-aware separately from
`fetch()`.

**Fix pattern.** Export an `assetUrl(path)` helper from the router
module (sibling to the fetch wrapper). It returns
`getBasePath() + path` for document-relative URLs and passes
through absolute URLs. Wrap every HTML-attribute injection site
through `assetUrl()`:

```js
${audioPath ? `<audio src="${esc(assetUrl(audioPath))}"></audio>` : ''}
```

**N5 instance:** BUG-025. 4 modules touched (`learn-grammar.js`,
`listening.js`, `listening-story.js`, `reading.js`). Verification
needs both unit-level (fetch resolves to the right URL) AND
end-to-end (audio file `audio.load()` fires `loadedmetadata` with
a non-zero `duration` from a deep path).

### F.45.3 Class C — Cache-buster bump in TWO places after every shippable JS change

**Anti-pattern.** After fixing a JS bug, you bump the SW
`CACHE_VERSION` (good). But the `<script src="...app.js?v=N.N.N">`
tag in every HTML file still references the OLD `?v=` value. The
URL is what the browser uses as a cache key — same URL means same
cache entry, so the browser keeps serving the cached version even
though the server has the fix. SW eventually evicts on next visit
+ activate cycle, but users on the same tab as before the SW update
won't see the fix until they close + reopen.

**Detection.** After bumping SW CACHE_VERSION, grep every HTML
file for the old `?v=N.N.N` cache-buster value. Bump every site
that references the SPA's main JS bundle. For N5 this is the SPA
root `index.html` + all 178+ static mirrors.

**Fix pattern.** A one-shot tool that replaces `?v=<old>` with
`?v=<new>` across all relevant HTML files. Idempotent; re-running
is safe. Generic template:

```python
RE_APP_JS = re.compile(r'(src="[^"]*app\.js\?v=)[^"]+(")')
for f in target_html_files:
    text = f.read_text(encoding="utf-8")
    new_text = RE_APP_JS.sub(rf"\g<1>{NEW_VERSION}\g<2>", text)
    f.write_text(new_text, encoding="utf-8")
```

**N5 instance:** BUG-027. The fix landed in the same commit as the
SW version bump; should have been bundled with the SW bump from the
start, not deferred to a separate commit after a user-reported
"still doesn't work".

### F.45.4 Class D — Test-tooling false positive on schema-variant entries (FP-16)

**Anti-pattern.** A second schema for a data field exists alongside
the primary one. In N5's `common_mistakes` array, most entries are
`{wrong, right, why}` (the primary schema). Some entries are
`{kind: "register_variant", form_a, form_b, label_a, label_b, why}`
(a second schema where both forms are grammatically valid — the
entry teaches register *contrast*, not error correction). A naive
auto-check that scans `for empty wrong/right` flags every
register_variant entry as a data gap.

**Detection.** Before adding a new `for empty X/Y` style check,
look at the union of `kind` values (and equivalent type-discriminator
fields) on the same array. If ≥2 distinct schemas exist, every
type-naive check must short-circuit on the discriminator.

**Fix pattern.** Add an explicit early-return at the top of any
type-naive validator:

```python
for row in entries:
    if row.get("kind") == "register_variant":
        continue
    # ... main check ...
```

Catalog the false positive in the audit prompt's FP catalog (FP-NN)
so future cycle iterations don't re-discover it.

**N5 instance:** BUG-023 / FP-16. Initially produced 38
false-positive Fail flags during the v4 test-scenario run; fix
prevented an entire review cycle from chasing imaginary bugs.

### F.45.5 Class E — Windows CRLF inflates `os.stat().st_size` vs LF-normalised count

**Anti-pattern.** Cross-artifact integrity invariants that store
file sizes in JSON (e.g., `data/index.json` listing every shipped
data file with `size_bytes`) compare the stored value to a recomputed
value at CI time. On Linux the file has LF line endings; on Windows
checkouts get CRLF endings, inflating the byte count by 1 per line.
For a 77,000-line file (N5's grammar.json), `os.stat().st_size`
reports 77 KB more than `git diff` would, and the CI invariant
fails on every Windows write.

**Detection.** Run the integrity check on a Windows checkout
after a data write. If `size_bytes` mismatches by exactly N (where
N = number of lines in the file), CRLF inflation is the cause.

**Fix pattern.** Tools that write data files AND update the
`data/index.json` size_bytes entry must compute the **LF-normalised
size**, not the on-disk size:

```python
with open(path, "rb") as fh:
    lf_size = len(fh.read().replace(b"\r\n", b"\n"))
```

This matches git's storage representation and the size the CI
invariant recomputes from the same normalisation. Use this helper
in every data-mutation tool, not just one.

**N5 instance:** Surfaced during BUG-024 fix (JA-125 invariant
failed after grammar.json edit on Windows). Documented in
`N5/tools/fix_remaining_grammar_bugs_2026_05_24.py`.

---

## F.44 Native-teacher review of a "shippable" corpus — 7 durable findings (added 2026-05-22)

Captures the 13-bug close-out from the N5 v1.15.8 native-teacher
review (NTR-001..013 → BUG-161..173). The review opened with the
verdict "this is a strong N5 corpus — better than most commercial
N5 apps and competitive with Try!/So-matome on substance" and then
listed 4 Severity-1 + 4 Severity-2 + 5 Severity-3 items, total 13.

**Headline meta-lesson:** when a corpus is "shippable" by structural
CI gates (whitelist, schema, cross-ref resolution), the remaining
defects shift from systemic to **per-item content quality** — and a
native-teacher pass is the only way to surface them. The 13 items
broke into 7 durable classes that an Nx-builder should anticipate.

### F.44.1 Class A — Multi-artifact discipline that holds on M of N artifacts but slipped on the (N+1)th

**Anti-pattern.** The N5 corpus gated grammar examples / reading
passages / listening scripts / listening choices against the kanji
whitelist (∪ dokkai exception). Vocab examples were the outlier —
not gated. Result: 99 of 3,036 vocab examples leaked non-whitelist
kanji. The LLM-curation pass introduced ~3× the rate of the human
baseline (5.8% vs 2.1%) because the LLM didn't know about the
whitelist that the human authors respected.

**Detection.** For every cross-artifact predicate (whitelist /
schema / ID-resolution), enumerate the artifacts it should apply
to + diff against the artifacts it actually applies to. Outliers
are bugs in the gating, not in the content.

**Fix pattern.**
1. Authoring fix: re-write the violating items to comply with the
   predicate (mechanical kana-substitution of side-words was
   sufficient for 99/99 N5 vocab cases).
2. Gating fix: add a CI invariant that locks the predicate on the
   newly-conformant artifact. Generic template:

```python
def _check_jaNNN_artifact_X_whitelist():
    WL = load_canonical_whitelist()
    failures = []
    for item in load_artifact_X():
        for offending in offending_tokens(item, WL):
            failures.append(f"{item.id}: contains {offending}")
    return failures
```

3. **Provenance audit.** Did the human-curated baseline have a
   lower violation rate than later auto-generated batches? If yes,
   the auto-generation pass needs the same predicate-check the
   humans were doing implicitly. N5 evidence: LLM 5.8% violations
   vs human 2.1% = the LLM didn't know what the humans knew.

**N5 instance:** NTR-001 (vocab examples) + JA-150.

### F.44.2 Class B — Duplicate-pattern cleanup that wasn't finished

**Anti-pattern.** Two grammar patterns share the same headword.
One self-identifies as a duplicate via a `contrasts` block ("This
is a duplicate entry — see the canonical pattern.") but the
structural cleanup wasn't completed. Both still appear in the
canonical pattern list; both serve to learners.

**Detection.** Grep `contrasts[*].note` (and similar prose fields)
for "duplicate" / "canonical pattern" / "same as" / "alias of"
phrases. Each hit is a half-finished cleanup.

**Fix pattern (when external references prevent simple deletion).**
1. Mark the duplicate with `deprecated: true` + `deprecated_reason`.
2. Set `_alias_of: <canonical_id>` (one-way; canonical does NOT
   point back).
3. Keep the duplicate entry in the data file for ID-stability
   (external references in questions.json / audio_manifest / etc.
   still resolve).
4. Add a UI filter to hide deprecated entries from main listings
   (grammar TOC, etc.); deprecated entries remain reachable via
   direct ID for backward compatibility.

**N5 instance:** NTR-002 (n5-045 deprecated; n5-017 canonical).

### F.44.3 Class C — Gloss-primary inversion vs modern spoken usage

**Anti-pattern.** A dictionary-derived gloss orders senses by
classical/literary frequency. Modern spoken usage has inverted the
sense hierarchy — but the gloss still leads with the formal sense
and parenthesizes the modern one. Learners encountering the word
in conversation hear sense B; the gloss tells them sense A is
primary. They mis-parse.

**Detection.** Per-headword native-speaker spot-check: does the
gloss's leading sense match what a native speaker thinks when they
hear the word in isolation? If the leading gloss-sense is
parenthesized with "(modern)" / "(colloquial)" / "(more common)",
that's the cue to flip.

**Fix pattern.**
1. Re-order glosses so the modern-spoken primary is first.
2. Re-state the formal/literary sense as the secondary with an
   explicit register marker ("more formal/literary").
3. Sync gloss_hi (or other locales) in the same commit. Don't ship
   English-flipped + Hindi-not-flipped (semantic drift).
4. Provenance: native_reviewed_<date>.

**N5 instances:** NTR-003 (かれ/かのじょ) + NTR-009 (Hindi sync).

### F.44.4 Class D — Pronoun with no register caveat

**Anti-pattern.** A pronoun's gloss is bare ("you" / "he" / etc.)
when the actual register is restricted: formal-only, intimate-only,
or marked-only. Generic-pronoun usage produces L2-error patterns
(L1 maps to "you" → L2 produces あなた everywhere). The gloss
needs a usage warning.

**Detection.** For every pronoun in the corpus, ask: "would using
this pronoun freely in conversation flag the speaker as L2?" If
yes, the gloss needs a register caveat + sample examples in the
right contexts.

**Fix pattern.**
1. Add a `usage_note` field with the register restrictions.
2. Update the gloss with the caveat in parens.
3. Replace lead example with a context where the pronoun IS
   appropriate (form-filling, wedding vows, lyrics, etc.) or pivot
   to the L1-natural alternative (name + さん).
4. Sync usage_note_hi (or other locales). UI consumers should
   render the usage note prominently.

**N5 instance:** NTR-004 (あなた).

### F.44.5 Class E — Section / category mislabeling

**Anti-pattern.** A vocab item is filed in a section whose number
conflicts with another section's number, OR the section semantic
doesn't match the item (movie filed under furniture). Both surface
in section-grouped review lists as nonsense entries; both reduce
learner trust.

**Detection.** Enumerate section labels + cross-tabulate against
section numbers. Conflicts are duplicates (one section number used
for two semantic-distinct sections). Per-item semantic-check is
spot-check work.

**Fix pattern.** One-line section field edits, provenance-stamped.
A CI invariant could enforce "section number uniqueness across
labels" for the duplicate-number case, but the semantic-mislabel
case (movie under furniture) is harder to automate without an
ontology.

**N5 instances:** NTR-005 (おはし section 20 → 19) + NTR-006
(えいが section 26 → 37).

### F.44.6 Class F — Etymology-as-mnemonic conflation

**Anti-pattern.** A kanji mnemonic includes an etymological claim
that's false but cognitively convenient (e.g., "the on-yomi さん
of 三 is the source of the honorific -さん"). Most learners won't
notice; curious learners will look it up, find the false claim,
and lose trust.

**Detection.** Per-mnemonic native-speaker pass over etymology
claims, specifically. The mnemonic-as-memory-aid pattern is fine;
the mnemonic-as-history claim is the trap.

**Fix pattern.** Soften the etymology claim without losing the
mnemonic ("the sound *san* is everywhere in Japanese — so the
reading is easy to hold onto. (Note: the honorific さん comes
from a separate root [様 → さま → さん]; the shared sound is
coincidental.)"). Preserves the cognitive crutch; drops the
incorrect history.

**N5 instance:** NTR-007 (三 mnemonic).

### F.44.7 Class G — Defensible-but-deviant pitch-accent values

**Anti-pattern.** A pitch-accent lookup produces a primary drop
value that's defensible (an alternate exists in some dictionaries)
but doesn't match the canonical reference (NHK 2016 for Japanese).
The audio recording may use one value; the data lists another. A
native-pronunciation pass is the only resolution.

**Detection.** Sample-check N pitch-accent values per session
against NHK 2016 (or the canonical reference). Flag mismatches as
"native_review_pending" rather than silently shipping.

**Fix pattern.** Annotate, don't auto-correct. Add
`native_review_pending: '<YYYY_MM_DD>_<source>'` to each flagged
entry. The audio rendering pass is the source of truth for what
ships; the dictionary value is the truth for what learners should
hear in formal contexts. When the two disagree, the annotation
preserves the gap for the eventual native-speaker pass.

**N5 instance:** NTR-008 (4 pitch-accent flags: 3 annotated, 1
(これ) confirmed correct).

### F.44.8 Class H — Particle-nuance not flagged in question explanations

**Anti-pattern.** A mock-test question is technically correct
(the conjugation tested has only one right answer) but the
surrounding sentence carries a subtle particle-nuance that, in
natural speech, would imply a meaning the explanation doesn't
mention. Above-N5 learners notice and feel something's off; the
explanation doesn't help.

**Detection.** Native-speaker pass over question-bank questions
specifically for particle-nuance traps in the test sentence. This
is qualitative; no good CI proxy.

**Fix pattern.** Append a one-line nuance note to explanation_en
(or explanation_hi parallel). Preserves the question's correctness
for the conjugation tested; protects the learner who notices the
wrinkle.

**N5 instance:** NTR-010 (q-0226 は-contrast note).

### F.44.9 Class I — Field-name overclaim ("collocations" for templates)

**Anti-pattern.** A data field is named with a corpus-linguistics
term (e.g., "collocations") but the content is actually
mechanically-generated template substitutions. Honest-but-narrower
naming would be "particle_examples" / "case_marker_examples" / etc.

**Detection.** Per-field semantic audit: does the field name match
the content? If a field claims to be "collocations" and contains
the same 6 particle templates substituted with each headword, it's
not collocations.

**Fix pattern.** Rename the field to reflect the actual content.
Update UI consumers + grep for old name. Provenance-stamp the
rename. Real corpus collocations can override the field where they
exist; the rename doesn't preclude future enrichment.

**N5 instance:** NTR-011 (`collocations` → `particle_examples`
on 12 pronoun entries).

### F.44.10 Class J — Prescriptive primary reading vs colloquial reality

**Anti-pattern.** A kanji entry's `primary_reading` is the
prescriptive answer (e.g., 七 = しち) but the colloquial usage
distribution is split (七つ = ななつ, NHK uses なな for numerals).
The single primary value hides the split. Learners who studied the
primary then encounter なな in listening and don't connect them.

**Detection.** Per-kanji reading-distribution audit against actual
usage in dokkai/listening passages + NHK conventions. Where the
distribution is split, the primary is misleading.

**Fix pattern.** Keep the prescriptive primary (preserves
predictability). Append a usage note to `reading_rule` documenting
the split: "X is prescriptive primary; Y is heard in <contexts>."
Documents the reality without breaking the primary-reading API.

**N5 instance:** NTR-012 (七 reading_rule + なな-usage note).

### F.44.11 Class K — Counter applied indiscriminately + sub-typo

**Anti-pattern.** A counter field is applied to all members of a
class (e.g., all pronouns) without checking whether the counter
makes semantic sense per-item. Collective pronouns (私たち / みなさん)
don't count themselves; the counter applies to the noun-of-reference.
Plus: cross-entry typos in the counter values that go unnoticed
because no CI invariant locks the field shape.

**Detection.** Per-counter semantic check: does counting "1 X, 2 X,
3 X" produce meaningful output? If not, the counter doesn't apply
to X itself. Also: enumerate counter.reading values across the class
and look for outliers (kanji in a kana field, etc.).

**Fix pattern.** For semantically-inappropriate counters: drop the
field, OR add `applies_to: noun_of_reference` annotation so UI can
suppress. For typos: fix them; consider a CI invariant locking the
field shape (counter.reading must be kana-only). Provenance bumped.

**N5 instance:** NTR-013 (collective-pronoun counter annotations +
みなさん.counter.reading typo).

### F.44.12 Operational rule — when a native-teacher review surfaces N findings, batch the close-out

For Nx-builders running an external native-teacher / JLPT-expert
review:

1. **Verify every claim against current data** before filing bugs
   (per F.41.4). A typical review will have 0-15% stale-snapshot
   artifacts if the data has moved since the snapshot was packaged.
2. **File all bugs in a single batch** under a prefix that groups
   them (NTR-NNN / NR-NNN / etc.). This survives future audits as
   "the 2026-05-22 native-teacher pass."
3. **Triage by severity (1/2/3) + assign priority (P1..P4).**
   Ship Severity-1 first; Severity-3 polish can land in a follow-up.
4. **Bundle related fixes into single commits.** Glosses + Hindi
   sync (NTR-003 + NTR-009) belong together because the Hindi gloss
   was downstream of the English. Section retags + same-file edits
   (NTR-005 + NTR-006) belong together.
5. **Add CI invariants for the data-shape findings, document the
   rest as conventions.** Of N findings, M will be data-shape
   (gateable) and N-M will be terminology / convention. Per F.43.7
   ratio.
6. **At the end of the batch, do a single Rule 4/5 propagation
   commit** covering procedure manual + accuracy prompt + N5Improvement
   + AUDIT-COVERAGE. Saves N-1 propagation cycles vs per-fix doc
   updates.
7. **Stamp every fix with provenance: native_reviewed_<date>.**
   Future audits can roll back the batch by provenance if needed.

### F.44.13 Bounded-coverage phrasing for native-teacher batches

When closing this class of batch in audit-coverage docs, use:

- "13 of 13 findings closed for the corpus snapshot scanned;
  6 of 13 added a JA-NN CI invariant locking the named pattern."
  — NOT "all native-teacher findings resolved."
- "JA-150 prevents re-introduction of *the specific vocab-example-
  kanji-whitelist violation pattern*" — does not catch register
  drift, unidiomatic phrasing, or other LLM-curation regressions
  the review didn't have bandwidth to audit.
- "Pitch-accent entries flagged native_review_pending pending
  actual native-speaker pass" — does not assert the dictionary
  values are correct; defers to NATIVE-SPEAKER-RE-VERIFICATION.md
  path-forward.
- "Bug-spec verification rejected 0 of 13 candidates this batch"
  — the review came from a human-curated checklist, not an
  autonomous audit pipeline, so stale-snapshot artifacts were 0%.

### F.44.14 Same drift-class lineage table for Nx prediction

| Class | First seen | Lesson |
|---|---|---|
| Multi-artifact discipline gap (F.44.1) | NTR-001 vocab examples (2026-05-22) | Enumerate all artifacts the predicate should cover; outliers are gating bugs |
| Half-finished duplicate cleanup (F.44.2) | NTR-002 n5-045 (2026-05-22) | Grep contrast-prose for "duplicate"/"canonical"; complete the cleanup with deprecated flag |
| Gloss-primary inversion (F.44.3) | NTR-003 かれ/かのじょ (2026-05-22) | Native-speaker check that leading gloss matches modern spoken sense |
| Pronoun missing register caveat (F.44.4) | NTR-004 あなた (2026-05-22) | Pronouns need usage_note with register restrictions |
| Section / category mislabel (F.44.5) | NTR-005/006 (2026-05-22) | Cross-tabulate section numbers; spot-check semantic match per item |
| Etymology-as-mnemonic conflation (F.44.6) | NTR-007 三 (2026-05-22) | Native-speaker pass over kanji mnemonic etymology claims |
| Defensible-but-deviant pitch-accent (F.44.7) | NTR-008 (2026-05-22) | Annotate native_review_pending, don't auto-correct |
| Particle-nuance not flagged in Q&A (F.44.8) | NTR-010 q-0226 (2026-05-22) | One-line nuance note in explanation_en |
| Field-name overclaim (F.44.9) | NTR-011 collocations (2026-05-22) | Rename to reflect actual content |
| Prescriptive vs colloquial reading (F.44.10) | NTR-012 七 (2026-05-22) | Keep primary; append reading_rule usage note |
| Counter applied indiscriminately + typo (F.44.11) | NTR-013 (2026-05-22) | Per-item semantic check + typo audit |

For Nx, the meta-audit will surface these classes again with
different content. The procedure-manual section catalogs the
patterns so the next round is mechanical rather than reinvented.

### F.44.15 Deferred-item batch closure — cohort sweeps, annotation-only fixes, and sample audits (added 2026-05-23)

F.44.12 step 3 says "ship Severity-1 first; Severity-3 polish can
land in a follow-up." Empirically, **every native-teacher batch
leaves 1-3 items deferred at first-pass close** because they
require methodology decisions, not data edits. The 2026-05-22
NTR batch closed 13 of 13 surfaced items but explicitly deferred
three follow-ups: (5) cohort sweep over OTHER kanji mnemonics
after the 三 finding (NTR-007), (6) NHK 2016 verification of
the 4 pitch-accent flags (NTR-008), and (7) spot-check OTHER
LLM-curated vocab examples for regressions beyond the
kanji-whitelist breach (NTR-001). These three close-out shapes
generalize to Nx-builders.

**Three deferred-item close-out shapes.**

**Shape 1 — Cohort sweep when one finding implies a class.**
When a single defect (e.g., 三 mnemonic claims false shared
etymology with -さん honorific) is fixed in the primary batch,
the question "are there OTHER items in the same class?" remains
open. Resolve by mechanical sweep over the cohort with a
text-pattern audit tool. N5 instance: `audit_kanji_mnemonic_
etymology_2026_05_22.py` scanned all 106 kanji mnemonic fields
for the regex `r"(borrowed everywhere|borrowed from|comes from|
same root|honorific|particle|-さん|-さま)"`. Found 1 hit
(八 mnemonic conflated 蜂 "bee" pronunciation with 八 itself).
Softened to "shared sound is a useful memory hook, not a
derivation." Result: 104 of 106 mnemonics clean (the original
三 finding + 八 cohort hit). Pattern-set is bounded; the audit
is NOT a guarantee of "no etymology errors in the corpus" —
it's a guarantee of "no instances matching these N patterns
in the corpus snapshot scanned."

**Shape 2 — Annotation-only when the source-of-truth conflict
is unresolvable autonomously.** When a defect is "data value
disagrees with canonical reference X" AND the Nx-builder can
not authoritatively verify against X without a native-speaker
pass, **do not auto-correct**. Annotate. N5 instance: NTR-008
listed 4 pitch-accent flags. The review cited NHK 2016 drop
values. But the reviewer is the same author as the audit
pipeline that produced the data; elevating the review's NHK
claims to authoritative would be circular. Resolution:
`fix_pitch_accent_nhk_refinement_2026_05_22.py` added per-entry
`nhk_2016_claim_drop` / `nhk_2016_claim_drops_by_sense`
metadata + `audio_uses_drop` (source of truth for rendered
material) + `nhk_2016_claim_provenance: "review-cited, pending
actual NHK source verification"`. The primary drop values were
NOT changed. The final native-speaker pass (per
NATIVE-SPEAKER-RE-VERIFICATION.md) remains the gating step.
Pattern: when the only verifier is the author, prefer
annotation that preserves the gap over auto-correction that
masks it.

**Shape 3 — Deterministic-stratified sample audit with named
dimensions and bounded-honesty result.** When a finding implies
"there may be MORE of this class hiding elsewhere in the
corpus" (e.g., the LLM-curation pass that introduced 99
kanji-whitelist violations may have introduced OTHER classes
of LLM regression), a full corpus audit is too expensive but
random spot-checks produce false positives (per N5Improvement
"Anti-pattern A"). Resolution: deterministic stratified
sample with SHA256 seeding for reproducibility, named
dimensions (D1 over-formal, D2 unidiomatic, D3 headword-absent,
D5 template-cluster) with explicit regex/heuristic patterns,
result bounded to those dimensions. N5 instance:
`audit_llm_curated_vocab_sample_2026_05_22.py` sampled 99 of
914 llm_curated examples (10.8% rate, stratified by section,
SHA256-seeded by `f"{vocab_id}|{ex_idx}"`). Result: 0 real
findings across all 4 dimensions. The 3 D3 (headword-absent)
hits were ALL false positives caused by rendaku and する-verb
conjugation. Bounded-honesty phrasing: "0 findings against the
named D1/D2/D3/D5 dimensions on the sample scanned" — does
NOT assert the LLM layer is regression-free; the audit did
not sample at 100%, did not name every possible LLM-regression
class, and rendaku-style false positives suggest tighter
matching primitives would be needed for confident closure.

**Operational rule (F.44.15 extension to F.44.12 step 6).**
Batch the three deferred-item close-out commits as a single
`audit(...) / fix(...) / fix(...)` triple, then ONE Rule 4/5
propagation commit covering all three (this sub-section).
Don't do per-item propagation for cohort/annotation/sample
audits — they share the methodology pattern and a single
propagation commit captures it.

**Bounded-coverage phrasing for deferred-item batches.**

- "Cohort sweep over 106 kanji mnemonics — 1 of 106 hit;
  pattern-set covers N regex patterns" — does NOT claim
  "no etymology errors remain in the corpus." Pattern-set is
  the bound.
- "3 of 4 pitch-accent entries annotated with NHK-claim
  metadata; 1 confirmed match; primary drop values
  UNCHANGED" — does NOT claim "pitch-accent verified against
  NHK 2016." Annotation preserves the gap.
- "0 findings against named D1/D2/D3/D5 dimensions on 99/914
  llm_curated examples (10.8% stratified sample, SHA256-seeded)"
  — does NOT claim "LLM-curated layer is regression-free."
  Sample rate + named dimensions are the bound.

### F.44.16 Same drift-class lineage table extension for deferred items

| Class | First seen | Lesson |
|---|---|---|
| Cohort sweep methodology (F.44.15 Shape 1) | NTR-007 cohort (2026-05-23) | When one finding implies a class, sweep the cohort with regex-pattern audit; result bounded to pattern-set |
| Annotation-only when verifier == author (F.44.15 Shape 2) | NTR-008 NHK refinement (2026-05-23) | When the only verifier is the author of the audit, annotate to preserve the gap; don't auto-correct (circular authority) |
| Deterministic-stratified sample audit (F.44.15 Shape 3) | NTR-001 cohort spot-check (2026-05-23) | Named dimensions + SHA256 seeding + bounded-honesty result; rendaku/conjugation false positives need tighter primitives |

### F.44.17 Stale-snapshot re-paste of a previously-closed review (added 2026-05-23)

**Anti-pattern.** A native-teacher or external review document gets
re-pasted into the project after a batch has already closed against
the earlier version. Without verify-before-fix discipline (F.41.4),
the temptation is to re-file all N items as new bugs — polluting
the tracker with N redundant entries, several of which fail re-
verification within minutes because the data has already moved.

**N5 instance (2026-05-23 NTR re-paste).** The 2026-05-22 NTR-001..013
review document was re-pasted as "Pending bugs (13 items)" on
2026-05-23. Verify-against-current-data pass found:
  - 9 of 13 already closed within this session (NTR-001..013 batch:
    99 vocab kanji breaches → JA-150 + 99 rewrites; n5-045
    deprecated; section retags; gloss flips; usage_note added;
    mnemonic softened; pitch-accent NHK-claim metadata; q-0226
    contrast note) — verified-stale-snapshot, rejected as filings.
  - 3 of 13 genuinely-new or broader-scope: whitelist reverse-
    direction asymmetry (11 vocab forms ungated); listening pacing
    multi-band exposure (38/50 below JEES-strict but all tagged
    in_range); collocations templated corpus-wide (983 entries
    beyond NTR-011's 12 pronouns).
  - 1 of 13 broader-scope claim rejected with rationale: singular
    pronouns counting people with 人 IS semantically correct
    (「あなたは何人いますか」). NTR-013 close for collective pronouns
    only was bounded-correct.

**Detection.** Before filing ANY bug from a re-pasted review, run
verification scripts that load current data and check each claim's
state. Each claim falls into one of three buckets:
  1. STALE — current data already shows the fix; the claim was real
     against an earlier snapshot but is now closed. Reject as a
     filing; document in commit message + AUDIT-COVERAGE that the
     re-verification ran.
  2. REAL — current data confirms the claim; file new bug.
  3. PARTIAL / BROADER-SCOPE — original close was bounded to a
     subset; re-paste implies the broader scope. Decide whether
     broader scope is correct: if yes, file as a follow-up bug
     (NTR-FU-NNN naming) that extends the original; if no, reject
     with explicit rationale.

**Fix pattern.**
1. Run claim-by-claim verification BEFORE filing anything (F.41.4).
2. Categorize into STALE / REAL / PARTIAL / REJECT-with-rationale.
3. File only REAL + PARTIAL as new bugs.
4. Annotate STALE in the commit message + audit-coverage entry —
   preserves the audit trail without polluting the tracker.
5. Reject REJECT-with-rationale items in the commit message + audit
   doc; do NOT silently drop them (a future reviewer needs the
   rationale).
6. Provenance-stamp the follow-up bugs with their lineage to the
   original (`NTR-FU-NNN extends NTR-NNN`).

**Bounded-coverage phrasing for re-paste close-out.**
  - "M of N items from re-paste verified as stale-snapshot
    (already closed in batch X); K of N filed as new bugs; J of N
    rejected with rationale" — never "N items closed."
  - "Re-verification found 9 of 13 already closed within this
    session against the working tree at HEAD; the remaining 4 split
    into 3 new follow-up bugs + 1 explicit-rejection" — preserves
    the categorization for future audit-doc consumers.

**N5 instances:** F.44.17 first surfaced 2026-05-23. Future review
re-pastes will fall into the same pattern; document the
re-verification commit in audit-coverage to short-circuit
re-litigation.

### F.44.18 Same drift-class lineage table extension for re-paste & broader-scope follow-ups

| Class | First seen | Lesson |
|---|---|---|
| Stale-snapshot re-paste verification (F.44.17) | 2026-05-23 NTR re-paste | Run verify-before-fix on every claim; STALE/REAL/PARTIAL/REJECT triage; file only REAL+PARTIAL |
| Reverse-direction CI gate asymmetry (F.44.18 + NTR-FU-001) | n5_vocab_whitelist 2026-05-23 | A CI invariant gates one direction; the reverse direction silently drifts. Detection: enumerate all directional predicates + check both. Fix: add JA-NN for the reverse. |
| Multi-band metric with single-tier classification (F.44.18 + NTR-FU-002) | listening pacing 2026-05-23 | A continuous metric (pacing mpm) is classified into a single tier ("in_range") when consumers want multiple bands. Fix: expose ideal / strict / lenient bands as parallel fields; keep the single-tier for backward compat; document the methodology decision in _meta. |
| Field-name overclaim broadened beyond bounded close (F.44.18 + NTR-FU-003) | collocations 2026-05-23 | A field-name fix (NTR-011 rename 12 pronouns) leaves the broader corpus drift. Detection: count entries with the legacy name; if >>fix scope, the close was bounded. Fix: expand the rename to all entries + add JA-NN locking the new name. UI consumers must update in same commit (the NTR-011 close had a silent UI regression for the 12 renamed pronouns). |

### F.44.19 Re-paste triage verification MUST run actual data-inspection (amendment to F.44.17, added 2026-05-23)

**Anti-pattern surfaced by the 2026-05-23 re-re-review.** When
classifying a re-paste claim as STALE (per F.44.17), the
verification script's correctness matters as much as the
classification itself. A bug in the verification script that
returns empty output ≠ "data already shows the fix"; it ≠
verification at all.

**N5 instance.** Item #2 of the 2026-05-23 NTR re-paste was
classified STALE in Part 42 based on:
  - A python script that loaded `grammar.json` and looked up
    `n5-045` to check deprecation flags.
  - The script used `g.get('grammar', g.get('entries', []))` —
    but the actual top-level key is `patterns`. The lookup
    returned an empty iteration.
  - I concluded "STALE — already closed" because the script
    produced no failure output. Actual failure cause: the loop
    never ran.
  - Reviewer's 2026-05-23 re-re-pass against the regenerated
    review packet caught the issue (n5-045 still in core_n5 list +
    contrasts.note still self-identifying).

**The discipline tightening.** STALE classifications MUST satisfy
both conditions:
  1. **Verification script PRINTS non-empty per-claim output**
     showing the field state observed. ("found id=n5-045 with
     deprecated=True, _alias_of=n5-017" — not silence).
  2. **The output is parseable and matches the expected closure
     state.** If the script can't find the entry at all, that's
     a VERIFICATION-FAILED state, not a STALE-CONFIRMED state.

**Fix pattern (mandatory).** Every STALE classification in
audit-coverage must cite the per-claim verification line from
the script's output. If the line says "found N=0 matches", that's
a failed verification — re-write the script. If the line says
"found id=X with field=Y", THAT is the verification.

**N5 cost of the discipline failure.** One bug (NTR-FU-004)
filed a session later that should have been caught in Part 42's
triage. Time cost: ~30 minutes of re-verification. Trust cost:
the audit-doc's "9 of 13 STALE" claim from Part 42 had one
false-positive STALE (which we now know was actually PARTIAL —
the data fix landed but the cleanup discipline didn't propagate
to n5_core_pattern_ids).

**Operational rule.** When implementing verify-before-fix per
F.41.4 / F.44.17, the verification script's first dry-run on a
KNOWN-PRESENT field (sanity check: load grammar.json and find
n5-001) is mandatory before classifying any claim as STALE.

### F.44.20 Four new follow-up defect sub-classes (added 2026-05-23)

The 2026-05-23 re-re-review surfaced four sub-classes that
extend Classes B (half-finished cleanup), D (pronoun missing
register caveat), K (counter applied indiscriminately), and a
new Class P (ID-immutability vs section-retag divergence):

**Class B sub-class — deprecation lattice complete on entry,
incomplete on canonical-pattern catalog (NTR-FU-004).**
NTR-002 set `deprecated: true` + `_alias_of` + `deprecated_reason`
on n5-045 in grammar.json. Cleanup leaked: n5-045 was still in
`core_n5` in n5_core_pattern_ids.json + the entry's
`contrasts[0].note` still self-identified as duplicate (now
redundant with the deprecation field). Fix: introduce `deprecated`
bucket in the canonical pattern catalog + JA-153 lock + update
the entry's contrasts.note to reference the deprecation field
instead. Extend JA-148 to accept the new bucket. Extend tier-
checking invariants (JA-34) to exclude deprecated entries from
the actual-vs-listed comparison.

**Class D sub-class — pronoun-usage-note added; cohort-of-examples
sweep incomplete (NTR-FU-005).**
NTR-004 added usage_note to あなた + rewrote example [0] to a
name+さん alternative. Examples [1] and [2] kept using あなた in
ways the new usage_note tells learners not to (`あなたは
がくせいですか。` + `あなたは 何さいですか。`). Fix pattern: when
authoring a usage_note, sweep ALL examples in the entry; rewrite
each to either parallel the alternative OR demonstrate the
narrow legitimate use case the usage_note allows. One example
showing the legitimate use is pedagogically valuable.

**Class K sub-class — reflexive vs singular pronoun counter
distinction (NTR-FU-006).**
NTR-013 added `applies_to: 'noun_of_reference'` to collective
pronouns (私たち / みなさん). Singular pronouns (私, あなた, etc.)
kept plain counter (defensible: counting people with 人 is
valid). But じぶん is REFLEXIVE — not a singular pronoun in the
same sense; counting "ones-self" isn't meaningful. Fix:
reflexive pronouns get the same applies_to annotation. Pattern
for Nx-builders: distinguish reflexive from singular in pronoun
classification before per-class counter discipline.

**Class P — ID-immutability vs section-retag divergence
(NTR-FU-007).**
When NTR-005/006 retagged vocab entries' `section` field, the
entry IDs (which embed the original section slug — e.g.,
`n5.vocab.20-tableware-and-cooking.はし-chopsticks` for section
"19. Tableware") were kept immutable to preserve external
references (audio_manifest / questions.json / user localStorage).
The slug-encoded section then diverges from the field-encoded
section. Without an explicit flag, future audits parse the ID
for section info and surface a false bug. Fix: add
`legacy_section_in_id: true` flag + note + provenance to every
entry where the divergence is intentional; add JA-154 to surface
any future drift without the flag. ID-immutability + section-
field-authoritative is the documented policy. Horizontal sweep
found 1 additional entry (にこにこ) beyond the 2 the reviewer
flagged — sweep tool surfaced what eyeball-review missed.

### F.44.21 Native-speaker-verification audit-block schema for LLM-circular-authority claims (added 2026-05-23)

**Anti-pattern.** A reviewer asks the LLM to perform native-speaker
verification of claims (NHK 2016 lookups, audio pitch verification,
native-intuition register judgments). LLM training-data knowledge
is defensible but not authoritative — and if the LLM is the same
author as the original audit pipeline, doing this work becomes
circular authority (F.44.15 Shape 2).

**The temptation.** "Do my best with training data; mark it
acknowledged-circular and ship." This sets a precedent that
LLM-authored verification becomes acceptable, eroding the trust
contract for verification claims across the corpus.

**The honest alternative.** Scaffold the audit-block schema with
explicit `verifier_pending: true` so a real human native speaker
can fill in the verification fields. Build a queue file for the
broader corpus pass. Lock the discipline with a CI invariant
that catches any future LLM-authored promotion that bypasses the
human pass. Document the protocol so the human knows what to do.

**N5 instance (2026-05-23).** Reviewer asked Claude to verify 3
pitch-accent entries (みなさん / あなた / きのう) against NHK 2016
dictionary + audio recordings. Claude declined and instead:
  1. Added the `audit` block schema to the 3 entries with
     `verifier_pending: true`, blank result_schema fields, and
     per-entry review questions lifted verbatim from the task.
  2. Built `docs/PITCH-ACCENT-VERIFICATION-QUEUE-2026-05-23.md` —
     587 remaining `match_kind: "by-reading"` entries sorted by
     N5 vocab frequency proxy (section number).
  3. Added CI invariant JA-155: any entry with
     `match_kind: "exact"` AND an audit block must have the
     audit block completed (verifier_pending: false +
     result_schema populated). Pre-existing 354 exact entries
     without audit blocks are grandfathered (legacy kanjium-
     exact-form provenance).
  4. Extended NATIVE-SPEAKER-RE-VERIFICATION.md with the
     pitch-accent-specific protocol (5 steps: NHK lookup, audio
     location, audio-vs-dictionary reconciliation, match_kind
     promotion, vocab.json cross-update).
  5. Documented the grandfather rule via _meta.discipline_note
     in n5_pitch_accent_reference.json.

**Discipline anchors (binding for Nx-builders).**
  - **No LLM-authored verification of native-intuition claims.**
    If the verification requires a real human native speaker, do
    not let the LLM fill in the verifier_credential field with
    its own identity.
  - **Scaffold-don't-fake.** Add the schema, leave the values
    blank, let the human fill in.
  - **CI invariant locks the discipline.** If the schema has
    fields the LLM might be tempted to fill in incorrectly, CI
    catches the incomplete or wrong-credential entries.
  - **Document the grandfather.** Pre-discipline legacy entries
    are explicit; the bar for new entries is clearly higher.

**Audit-block schema (canonical for pitch-accent; generalizable):**

```json
"audit": {
  "verifier_pending": true,
  "pending_since": "<ISO date>",
  "pending_wave": "<wave-name-YYYY-MM-DD>",
  "current_state_at_audit_request": { ... },
  "review_question": "<specific question for the human>",
  "verification_protocol_link": "<path to protocol doc>",
  "verification_required_against": [<reference sources>],
  "verifier_credential_required": "<who is qualified>",
  "result_schema": {
    "verified_against": null,
    "verified_at": null,
    "verifier_credential": null,
    "<domain-specific fields>": null,
    "decision_note": null
  }
}
```

**Bounded-coverage phrasing for this pattern.**
  - "Audit-block scaffolded on N entries with `verifier_pending:
    true`; M pre-existing entries grandfathered as legacy
    provenance" — bounds the discipline clearly.
  - "CI invariant locks completeness on audit-bearing entries"
    — does not assert grandfathered entries are native-speaker-
    verified; their authority bar is the original automated match.
  - "Broader-corpus queue file ranks the N remaining entries by
    frequency proxy" — bounds the pass scope without
    overpromising completion.

### F.44.22 Same drift-class lineage table extension for native-speaker-deferral discipline

| Class | First seen | Lesson |
|---|---|---|
| LLM-circular-authority on native-intuition claims (F.44.21) | pitch-accent 2026-05-23 | When asked to verify what only a native speaker can verify, scaffold the audit block + decline the verification; CI lock + queue file + protocol doc make the human's work mechanical |

### F.44.23 CI-invariant re-paste discipline — verify-before-add (added 2026-05-23)

**Anti-pattern.** A reviewer or audit-pipeline re-paste asks for a CI
invariant to be "added" to prevent some regression. Without
verification, the temptation is to add the invariant. But the
invariant may already exist (possibly under a different ID or
distributed across multiple existing JA-NNs). Adding the
redundant invariant violates "Reuse Over Recreate," adds
maintenance surface, and slows CI for zero detection value.

**The mistake to avoid.** "Just add it; codified is better than
not-codified." This sets a precedent where every re-paste of
the same finding produces a new invariant, eventually creating
N invariants that all enforce the same predicate. CI gets
slower; nothing more is caught.

**The honest pattern.** Before adding any CI invariant:

  1. **Run the EXACT predicate against the current corpus.**
     Print non-empty per-corpus output showing the violation
     count (mandatory per F.44.19 verify-before-classify
     discipline). If the corpus is clean against the predicate,
     either an invariant already enforces it OR the corpus is
     incidentally clean (no enforcement).
  2. **Search check_content_integrity.py (or equivalent) for
     existing invariants** that name the same predicate. Use
     grep against `whitelist`, `kanji`, the relevant field
     names, etc.
  3. **Read the existing invariants' implementations** to
     confirm the predicate is enforced — not just named.
  4. **Triage per F.44.17:**
     - **STALE** — predicate already enforced under existing
       JA-NN(s). Document the existing coverage + decline the
       redundant add. Do NOT add a "pointer" or "consolidation"
       invariant just for symbolic value; it adds CI surface
       without detection value.
     - **REAL** — predicate is not enforced; add the new
       invariant.
     - **PARTIAL** — predicate is enforced for some scope but
       not others; either extend the existing invariant or
       add a complementary one with explicit scope boundaries.

**N5 instance (2026-05-23).** Reviewer asked to "add a CI
invariant that prevents future vocab examples from re-introducing
the kanji-whitelist regression that v1.16.2 just cleaned up"
plus extend to grammar / reading / listening. Verification
showed:
  - **JA-150** (added 2026-05-22 NTR-001 close) already enforces
    the EXACT predicate (whitelist ∪ exception) on vocab.json
    examples.
  - **JA-13** enforces a STRICTER predicate (whitelist only)
    across grammar/questions/reading/listening — same coverage
    the task asks for, with a tighter rule.
  - **JA-28** enforces the union for dokkai-paper context
    specifically.
  - Live state: 0 violations across all 4 corpora.

Triaged as STALE. No new invariant added. This F.44.23 entry
documents the decision so future sessions don't re-litigate
the same pattern.

**The "symbolic consolidation invariant" temptation.** When a
reviewer wants ONE named invariant they can point at, a
maintainer may be tempted to add a redundant JA-NN whose
purpose is documentary, not detective. Resist this:
  - The documentation belongs in the procedure manual or audit
    log, not in CI.
  - CI surface is a maintenance liability; every invariant adds
    test runtime + drift risk.
  - Future maintainers reading the redundant invariant may
    "improve" it independently from its parent, creating
    silent divergence.

If a future reviewer asks "what's the load-bearing invariant
for X?", the answer goes in the audit log + procedure manual,
not as a redundant CI check.

**Bounded-coverage phrasing for STALE-classified invariant requests.**
  - "Predicate already enforced by JA-X (added YYYY-MM-DD,
    BUG-NNN close); live state 0 violations" — does NOT assert
    the predicate is bulletproof; only that it's gated.
  - "Distributed across N existing invariants" — does NOT
    consolidate them into one; the distribution is intentional
    (different scopes / different sources of truth).
  - "Adding a consolidation pointer would be redundant; the
    documentation belongs in the audit log" — bounds the
    decision rationale.

### F.44.24 Same drift-class lineage table extension for CI-invariant-re-paste discipline

| Class | First seen | Lesson |
|---|---|---|
| CI-invariant re-paste of existing-but-distributed predicate (F.44.23) | BUG-1 vocab-whitelist 2026-05-23 | When asked to "add" an invariant for a regression already locked by JA-NN, verify the existing coverage + decline the redundant add + document the existing coverage in the audit log |

### F.44.25 Review-packet staleness — regen-after-data-change discipline (added 2026-05-23)

**Anti-pattern.** A project ships a "review packet" — a compact
content snapshot for external review (e.g., uploaded to a Claude
Project Knowledge or one-shot chat). The packet is typically
gitignored (generated locally, not committed) because (a) it's
derived data, (b) it may contain stripped-or-anonymized variants
of the canonical files. When the author bumps the data version
and commits changes BUT forgets to regenerate the packet before
sharing, the reviewer reviews against stale content and surfaces
"bugs" that are already fixed in the working tree.

**The failure mode is self-replicating.** When the reviewer's
stale-snapshot finding gets re-pasted into a new session, the
new session has to:
  1. Run F.44.17 STALE/REAL/PARTIAL/REJECT triage
  2. Discover that ~half the findings are already-closed
  3. Either re-litigate (waste of context) or document the
     stale-snapshot rejection (overhead in audit logs)

The cleanest fix is preventing the stale share in the first
place. **The CI invariant (JA-156) is the load-bearing lock;
the discipline doc below is the soft procedural reminder.**

**N5 instance (2026-05-23).** Session shipped v1.16.0 → v1.16.4
across 4 minor version bumps + 18+ commits. The author explicitly
regenerated the packet exactly ONCE (at v1.16.2, after the user
asked "can I pass it for review?"). Between v1.16.2 and v1.16.4,
two version-bumping data commits happened with no packet regen:
v1.16.3 (4 follow-up bug fixes + JA-153/154) and v1.16.4 (3
pitch-accent audit blocks). Reviewer asked "have you updated
review packet? because the review is based on it" — verification
confirmed the packet was happen-to-be-current via a side-effect
of one of the build tools, but the author had NOT explicitly
regenerated it. Codification: JA-156 + this F.44.25 entry.

**Discipline (binding):**

1. **JA-156 CI invariant** (`tools/check_content_integrity.py`):
   when the gitignored `data/_review_packet/` directory exists
   locally, its `version.json.version` field must match
   `data/version.json.version`. Skip-on-absent — the check is
   local-only (catches the pre-share author mistake).

2. **Commit-time checklist extension.** After every commit that
   bumps `data/version.json.version` (or touches any
   `data/*.json` file at all), the author MUST run:
   ```
   python tools/build_review_packet.py
   ```
   before sharing the packet with any external reviewer. The
   regen takes <2 seconds; the cost of skipping it is one full
   re-paste-triage cycle in the next session.

3. **Pre-share verification.** Before answering "is the review
   packet ready to share?" with "yes," the maintainer MUST run
   the full CI check or explicitly invoke JA-156:
   ```
   python tools/check_content_integrity.py 2>&1 | grep JA-156
   ```
   If it FAILs, regenerate before answering.

4. **Gitignored-artifact discipline pattern (generalizable).**
   Any gitignored generated artifact that's shared externally
   needs a freshness CI invariant of this shape:
     - Compare a version/timestamp field in the artifact to the
       canonical source.
     - Skip-on-absent so remote CI doesn't break.
     - Failure message names the regen command + the discipline
       doc.

**Bounded-coverage phrasing.**
  - "JA-156 catches *packet-version-vs-live-data-version
    mismatch when the packet exists locally*" — does NOT catch
    content drift inside the packet (would require deep diff);
    only catches the version-stamp mismatch.
  - "Skip-on-absent guarantees remote CI doesn't break" — does
    NOT mean remote CI is enforcing the freshness; only local CI
    enforces.

### F.44.26 Same drift-class lineage table extension for gitignored-artifact freshness

| Class | First seen | Lesson |
|---|---|---|
| Gitignored-shared-artifact freshness (F.44.25) | review packet 2026-05-23 | When a gitignored generated artifact is shared externally (review packet, generated docs, exports), add a CI invariant comparing the artifact's version field to the canonical source. Skip-on-absent for remote CI; load-bearing locally. The artifact-vs-source version mismatch is the failure mode; CI is the lock. |

### F.44.27 RECALL-NOT-READ — correct-version-cite + stale-content-quote (added 2026-05-24)

**The failure mode.** A reviewer (or LLM acting as one) opens the
review packet, faithfully copies `version.json.version` into the
report header (correct value, no drift), then writes findings that
quote field values that **do not exist in the packet** at that
version — they exist in an earlier version that has since been
fixed. The version cite checks out; the content cite does not.

This is **not** the same as the F.44.17 stale-snapshot pattern
(reviewer cites an old version + content from that old version —
internally consistent, just out-of-date). RECALL-NOT-READ is
internally inconsistent: the version says vN but the content is
from vN-1. Three plausible mechanisms:

1. **Project-Knowledge cache effect** — reviewer uploaded a fresh
   `version.json` (top of the packet, small file) but the larger
   paper files in the Project Knowledge are still from a prior
   upload. The reviewer sees vN in version.json but the paper
   files are vN-1.
2. **Conversation-history recall** — reviewer participated in a
   prior session against vN-1 and the conversation turn-history
   contains the broken strings. When asked to review vN, the
   model surfaces remembered strings instead of re-reading.
3. **Training-data leakage** — for strings that were public for
   a non-trivial window before being fixed, the model may surface
   them from pretraining instead of from the upload.

The maintainer's defense against ALL three is identical: force
the reviewer to **re-read the packet** at review time, and provide
upstream signals that catch a stale read.

**The 3-block BINDING preflight defense pattern.** When designing
the reviewer-facing prompt for an Nx-level packet:

1. **Preflight 1 — version-field echo.** Reviewer pastes
   `version.json.version` + `cacheVersion` + `builtAt` verbatim
   at the top of the report. Standard anchor.
2. **Preflight 2 — content-fingerprint echo with explicit
   STALE-MARKERS.** For each known-fixed-from-prior-version
   string, list the string in the prompt with a "STOP + re-pull"
   instruction if it appears in the reviewer's quote. Example:
       > 3. `papers/dokkai.json`, question id `dokkai-2.5`,
       > `rationale_hi` first 60 chars = `<paste>`
       > - **STALE-MARKER:** if your quote contains
       >   `माता काम करता है में अस्पताल`, the dokkai paper file
       >   in your upload is v1.16.8. **STOP. Re-pull. Do not
       >   write findings.**
   The stale-marker self-tests the upload: if the reviewer can
   echo back the FIXED string, the upload is current; if they
   echo a marker, the upload is stale and the report self-
   terminates before findings.
3. **Preflight 3 — read-not-recalled attestation.** Reviewer
   pastes a verbatim statement that every quoted string was
   read at review time, not recalled from prior sessions /
   training / memory. Pasting an attestation is a low-cost
   gate against high-cost downstream noise.

**Per-finding amplification.** Even with the 3-block preflight,
the reviewer might pass preflight then write 10 findings from
memory. Defense: per-finding `Read-not-recalled: [x]` checkbox
+ `Observed:` field must be verbatim copy-paste (no paraphrase,
no translation-from-memory). Re-read per finding.

**CI invariant lock.** Add a `JA-NN` substring-presence check on
the reviewer prompt: the preflight section headers + the
STALE-MARKER strings + the read-not-recalled checkbox + the
no-paraphrase / no-translation-from-memory rules + the
`RECALL-NOT-READ` triage label must all be present. This locks
the prompt against accidental future edits that drop the
defenses. (For N5 this is JA-161, added 2026-05-24.)

**Stale-marker maintenance discipline.** Each time the maintainer
fixes a stale-marker-class defect (rationale text correction,
field-rename, etc.), append the OLD value as a new STALE-MARKER
entry in the prompt. Over time the STALE-MARKER list grows; that's
intentional — every entry catches one more class of stale upload.
Prune entries only when (a) the old text is so far in the past
that no live cache could still contain it AND (b) keeping it
would meaningfully increase prompt size. The break-even point is
empirical; default to keeping markers.

**Why this is distinct from F.44.17.** F.44.17 was about
"the reviewer is internally consistent but out-of-date — verify
findings against current state per F.44.19". F.44.27 is about
"the reviewer is internally INconsistent — the version cite is
fine but the content quotes are from a prior state". F.44.17's
verify-before-fix still catches RECALL-NOT-READ artifacts
(content checked against current data shows the strings as
already-fixed), but F.44.17 is a downstream defense. F.44.27
adds upstream defenses (the 3-block preflight) so the reviewer
self-terminates before producing noise.

**Bounded coverage.**

- "The 3-block preflight catches RECALL-NOT-READ" — does NOT
  guarantee it catches every future stale-anchor variant. New
  mechanisms will surface; extend the defense.
- "STALE-MARKER list grows over time" — does NOT mean every
  past defect must have a marker. Use judgment: only strings
  that are uniquely identifying + likely to leak via cache /
  recall warrant a marker.
- "Per-finding read-not-recalled checkbox is BINDING" —
  enforcement is by maintainer-triage convention (reports
  without the checkbox are rejected). CI cannot verify the
  reviewer actually re-read; the checkbox is a discipline
  signal, not a proof.

### F.44.28 Same drift-class lineage table extension for RECALL-NOT-READ

| Class | First seen | Lesson |
|---|---|---|
| Correct-version-cite + stale-content-quote (RECALL-NOT-READ, F.44.27) | reviewer v4 pass 2026-05-24 against N5 v1.16.9 (4 Hindi rationale strings from v1.16.8) | When a reviewer-facing prompt asks for content verification, "echo the version field" is necessary but not sufficient — the version field can be fresh while the rest of the upload is stale (Project-Knowledge cache effect), and even with a fully fresh upload the model may recall content from training or prior conversations. Defense: 3-block preflight (version echo + content-fingerprint echo with STALE-MARKERs + read-not-recalled attestation) + per-finding verbatim-quote + CI invariant locking the prompt's defense markers. The downstream verify-before-fix (F.44.19) still applies as a secondary catch; F.44.27's upstream preflight is the primary catch. |

### F.44.29 REAL-pattern + STALE-entries — F.44.27 sub-pattern refinement (added 2026-05-24)

**The failure mode.** A reviewer (or LLM acting as one) cites
specific entries that are STALE-against-current (the search
strings the reviewer names don't exist in live data — they were
fixed in a prior version), BUT supplies a real underlying
pattern that the cited entries instantiate. The cited entries
are no-action; the pattern is real.

This is a refinement of F.44.27, not a replacement. F.44.27
codified the case where reviewer cites stale + has nothing else
("ignore-with-rationale"). F.44.29 codifies the case where the
reviewer cites stale + the pattern is real ("ignore-the-stale-
entries-but-sweep-the-pattern").

**Worked example (N5 v5 reviewer batch, 2026-05-24).** Reviewer
shipped a "developer bug-fix instruction prompt":

  - Items 1-4: REPLACE rules for 4 entries with the v1.16.8 broken
    Hindi rationale strings. **All 4 SEARCH strings were 0-hit
    in live data** (fixed in v1.16.9 BUG-192..195). STALE per
    F.44.27.
  - Item 5: General NORMALIZATION RULE — "Convert `भूखा + चाहना
    को खाना` shape to natural Hindi SOV." The reviewer named 2
    entry shapes (`भूखा + चाहना को खाना` / `भूखा → चाहना को खाना`).
    Horizontal sweep on the distinguishing substring `चाहना को`
    against live data found **3 hits** (the 2 named entries PLUS
    `चाहना को आराम` in a 3rd entry the reviewer didn't name).
    Sweep on a related shape `का क्रिया` found a 4th muddled
    entry.

  Total: reviewer named n=2 → swept-found n+k=4. Same multiplier
  pattern as v4 listening cycle (n=1 → 18).

**The discipline (codified):**

1. **Triage each cited entry individually per F.44.19** (verify-
   before-fix with PRINT non-empty per-claim output). Classify
   STALE / REAL / PARTIAL / REJECT.
2. **If ANY cited entry is REAL, the pattern is suspect.** Even
   if only 1 of N cited entries is real, the underlying pattern
   may exist elsewhere.
3. **Horizontal sweep the pattern.** Identify the distinguishing
   substring(s); grep across live data; collect all hits.
4. **Fix all hits with consistent style.** Use the surrounding
   project's established rationale_hi (or analogous) convention.
5. **Lock the marker via CI invariant extension.** Add the
   distinguishing substring to the relevant JA-NN word-salad /
   content-discipline invariant's marker set. Tight marker
   (avoid false positives on legitimate constructions).
6. **Document the cited-but-stale entries explicitly as STALE**
   in the close-out doc. The reviewer's report deserves full
   triage even when most items are STALE.

**Defense layering rule:**

- Upstream defense: 3-block BINDING preflight from F.44.27
  (version-echo + content-fingerprint with STALE-MARKERs +
  read-not-recalled attestation). Catches pure-recall reviewers
  before findings.
- Downstream defense: F.44.19 verify-before-fix with PRINT
  non-empty per-claim output. Catches stale entries that pass
  preflight (e.g., reviewer cites a stale entry inside a real-
  pattern claim).
- Lock defense: JA-NN substring extension (or new JA-NN if
  pattern doesn't fit an existing invariant). Locks the surfaced
  pattern against re-introduction.

Both upstream AND downstream defenses are required. Single-layer
defenses always have escape valves. F.44.27 alone misses v5-shape
patterns (reviewer passes preflight then writes findings against
stale entries inside real-pattern claims); F.44.19 alone misses
v4-shape patterns (reviewer writes pure-recall findings the
maintainer must reverse-engineer to triage). The combination
catches both shapes.

**Marker-extension policy (sub-rule).** When extending an
existing JA-NN word-salad marker set:

- Choose the **shortest distinguishing substring** that uniquely
  identifies the broken shape. Longer substrings (full broken
  phrases) miss minor variations; shorter substrings risk false
  positives.
- Sanity-check against the entire current corpus: the new marker
  must catch the broken entries AND zero legitimate constructions.
- Document the marker's first-seen entry-id in the JA-NN function
  docstring (for future archaeology).
- Update the matching A-NN audit prompt entry to mention the
  extension.

**Bounded coverage.**

- "Horizontal sweep multiplier n → n+k" — empirically observed
  in 2 cycles (v4 listening n=1→18; v5 word-salad n=2→4). Does
  NOT guarantee the multiplier holds on every future cycle.
- "Marker extension catches re-introduction" — locks the
  documented shapes; does NOT catch novel shapes that don't
  match any existing marker.
- "REAL-pattern + STALE-entries sub-pattern documented" —
  captures one observed variant; future RECALL-NOT-READ
  variants will surface new sub-classes.

### F.44.30 Same drift-class lineage table extension for REAL-pattern + STALE-entries

| Class | First seen | Lesson |
|---|---|---|
| REAL-pattern + STALE-entries (F.44.29, F.44.27 sub-pattern) | reviewer v5 pass 2026-05-24 against N5 v1.16.10 (4 stale REPLACE rules + 1 real NORMALIZATION RULE → 4 fixed entries via 2 named + 2 swept) | When a reviewer cites stale entries inside a real-pattern claim, the cited-stale entries are no-action (F.44.27 STALE classification) BUT the underlying pattern is real and requires horizontal sweep. Triage each cited entry individually via F.44.19; if any are REAL, sweep the pattern; lock the surfaced markers via JA-NN extension. Defense layering: upstream preflight (F.44.27) + downstream verify-before-fix (F.44.19) + marker lock (JA-NN extension) — all 3 required, single-layer defenses have escape valves. Horizontal-sweep multiplier n → n+k empirically holds across cycles. |

### F.44.31 Audit-cluster fix pass — norm-definition + category-whitelist + dedup-with-backfill discipline (added 2026-05-24)

**Context.** N5 received an audit (Claude_audit_2026-05-24) surfacing 8 bug clusters (BUG-A..H) — duplicate common_mistakes rows by aggressive norm, dup-example rows, wrong==right (under strip-only) rows, contradictions between common_mistakes and wrong_corrected_pair, short why fields, oversized meaning_ja fields, a category rename, and an xlsx process change. Fixing the 8 clusters surfaced 3 generalizable discipline gaps.

**The 3 discipline gaps and their codifications:**

**1. Norm-definition awareness per audit class.** The same audit dataset can produce different counts depending on the norm function chosen. The N5 audit-cluster norm `re.sub(r'[、。「」？！\s]', '', s or '')` strips spaces AND Japanese punctuation; a BUG-H-shape audit using `.strip()`-only equality counts fewer rows. When the dedup-norm is stricter than the wrong-vs-right norm, rewriting a row to differ only by spacing/punctuation will pass the wrong-vs-right check but still fail dedup. Lesson: pick rewrite content that differs in SUBSTANTIVE ways (different particle, different conjugation, different lexeme) — not just spacing or punctuation — so the rewritten row survives BOTH norms.

   - **Audit-class norm table** (document this explicitly per-cluster in the next audit pass):
     - `dedup_norm(s) = re.sub(r'[、。「」？！\s]', '', s or '')` — strips internal punctuation; used for "is this row a duplicate of another row".
     - `strip_norm(s) = s.strip()` — leading/trailing whitespace only; used for "does wrong actually differ from right".
     - When the two diverge, choose rewrite content where dedup_norm(wrong) ≠ dedup_norm(right) AND strip_norm(wrong) ≠ strip_norm(right).
   - **Discipline check:** when authoring rewrites for one class, sanity-check the rewrites against the OTHER classes' norms before saving. The fix pass should not introduce new violations under stricter classifiers.

**2. Category-whitelist propagation across array boundaries.** When code paths add cm entries via cross-array promotion (e.g., promoting a wrong_corrected_pair entry up into the common_mistakes array as a JA-51 backfill), the source array's vocabulary for category fields may NOT match the destination array's whitelist. N5's wrong_corrected_pair uses `error_category` with values like `lexicon`, `pragmatic`, `word_order`, `morphology` — none of which are in the JA-51 valid set `{particle, verb_class, conjugation, register}`. Naive promotion produces 24+ invariant violations.

   - **The discipline (codified):**
     1. Whenever a promotion / backfill / cross-array copy path is introduced, audit ALL fields whose validity is governed by a CI invariant.
     2. Implement a CATEGORY_MAP (or analogous mapper) at the promotion boundary. Map source vocabulary → destination whitelist. Default unknowns to the broadest valid category (typically `register` for "miscellaneous learner errors").
     3. Add a JA-NN invariant that catches the SHAPE of this gap: e.g., "every cm row whose source field is `promoted from wrong_corrected_pair` has category in JA-51 whitelist". (Optional but recommended.)
   - **N5 reference mapping** (for reuse on subsequent levels):
     - `lexicon → register` (vocabulary / word choice — broadest miscellaneous)
     - `word_order → register` (sentence structure convention)
     - `pragmatic → register` (speech-act convention)
     - `morphology → conjugation` (word-form construction)
     - `punctuation → register` (writing convention)
     - `counter → particle` (counters group with particle behavior)
     - everything else → register

**3. Dedup-with-backfill discipline (preserve high-floor invariants).** When a dedup pass drops rows from a column with a "≥N entries per row" CI invariant (N5 has JA-51 requiring ≥3 categorized common_mistakes), the dedup pass MUST be paired with a backfill pass that promotes non-duplicate entries from an adjacent array (e.g., wrong_corrected_pair → common_mistakes) to restore the floor. Naive dedup-only drops 41 patterns below the JA-51 floor.

   - **The discipline (codified):**
     1. Before authoring a dedup pass, enumerate every CI invariant of the form "≥N per row" on the column being deduped.
     2. Identify the SOURCE for backfill: which adjacent array can supply non-duplicate entries? For N5's common_mistakes, wrong_corrected_pair is the natural source.
     3. Implement dedup + backfill as a single atomic pass. Order: dedup first → identify deficit → promote candidates (filtered against existing keys to avoid re-introducing duplicates) → write back.
     4. Tag all backfilled rows with `provenance="auto_fix_YYYY_MM_DD"` + `audit_wave="..."` + `source="promoted from <source-array>"` for forensic traceability.
     5. If the backfill source is also exhausted, fall back to a hand-authored template (N5 uses a punctuation-omission template that works for most patterns).
   - **Sidecar logging requirement:** every drop AND every backfill MUST be logged to `data/<corpus>.fix_log.json` with the dropped/added row content, the kept/source reference, and the reason. Sidecar files are forensic — git diff is insufficient because it doesn't show INTENT.

**Cross-cutting discipline (applies to all 3 gaps):**

- **Provenance + audit_wave fields on every mutated row.** N5's audit-cluster fix tags every mutated row with `provenance="auto_fix_2026_05_24"` + `audit_wave="claude_audit_2026_05_24"`. This makes the fix pass auditable downstream — a future native-teacher pass can filter to just claude-authored rows.
- **Side-by-side fix-log sidecar.** A `data/<corpus>.fix_log.json` sidecar with `_meta` + per-bug-cluster sections (drops, changes, backfills) — keyed by cluster id (BUG-A..H). Re-runnable; idempotent; gitted.

**Bounded coverage.**

- "CATEGORY_MAP catches all whitelist mismatches" — locks the documented mismatch classes; does NOT catch novel category values introduced in future arrays. Re-audit the source array's category vocabulary before each cross-array promotion path.
- "Dedup-with-backfill preserves JA-51" — empirically verified for N5's JA-51 floor of ≥3 categorized cm; does NOT generalize automatically to higher floors (e.g., ≥5) without adjusting the backfill quota.
- "wcp → cm promotion preserves teaching quality" — N5's wcp entries are already curated learner errors, so promotion is safe; other corpora may have wcp entries with placeholder content that should be filtered out before promotion.

### F.44.32 Same drift-class lineage table extension for audit-cluster discipline

| Class | First seen | Lesson |
|---|---|---|
| audit-cluster fix (F.44.31, norm + whitelist + dedup-backfill) | Claude_audit_2026-05-24 cluster sweep against N5 v1.16.12 (8 clusters BUG-A..H — 52 dedup drops, 47 backfills, 14 example drops, 7 rewrites, 4 category renames, 4 meaning_ja splits, 2 contradictions resolved, 3 short-why expansions, +3 xlsx columns) | When fixing a batch of audit-surfaced bugs that involves dedup + rewrite + backfill, lock 3 disciplines: (1) audit-class norm awareness — rewrite content must survive BOTH the stricter dedup-norm AND the lenient wrong-vs-right strip-norm, requiring substantive differences not just spacing/punctuation; (2) category-whitelist propagation — when promoting entries across arrays (wcp → cm), map source-array category vocabulary through a CATEGORY_MAP to the destination's CI-invariant whitelist; (3) dedup-with-backfill atomicity — when dedup drops rows from a column with a "≥N per row" invariant, pair with an in-pass backfill from an adjacent array (filter against existing keys), with hand-authored template fallback. All mutated rows carry provenance + audit_wave tags; all drops/changes/backfills log to a fix_log.json sidecar. |

### F.44.33 Metric-gaming anti-pattern in audit-driven fix passes (added 2026-05-24)

**Context.** Post-BUG-A..H, a second-round reviewer audit (independent
re-audit against N5 v1.16.12) called out that the BUG-K wcp.why
expansion was metric-gaming: a fix-pass added boilerplate suffixes to
25 crisp one-liner rationales to satisfy a ≥6 whitespace-token floor in
the audit predicate, damaging pedagogical quality. The originals were
complete; the expansions added tautology + empty generality + broken
self-reference.

**The anti-pattern (codified):**

When an audit predicate enforces a quantitative floor (token count,
char length, item count) on a quality dimension, a fix-pass optimizing
the metric instead of the quality can DAMAGE the corpus while
satisfying the predicate. Concrete shapes:

| Anti-pattern | Symptom | Why it slipped past review |
|---|---|---|
| Token-count floor on `why` rationales | Crisp 5-token explanations padded to 12 tokens with filler | Audit metric green; pedagogical quality red. The author optimized for the visible metric. |
| Length floor on `meaning_ja` | Short clean meanings padded with repetition | Same shape; different field. |
| Item-count floor on examples / cm | Filler examples added to satisfy "≥10 examples" | Volume up, value down. |
| Coverage floor on slot-tokens | Slot tokens (Verb-, counter) inserted in fields that don't need them | Visible coverage up; readability down. |

**The discipline (codified):**

1. **Quality dimensions need content checks, not size floors.**
   Replace "rationale ≥ 6 tokens" with "rationale contains both a
   rule-statement and a correction-statement" — even if the content
   check is hard to automate (NLP-level), the spec for it is
   tighter and resists gaming.
2. **If a quality-dimension content check is too hard for static
   analysis, drop the metric.** A non-emptiness check is enough; rely
   on human review for the rest. Don't substitute a gameable proxy.
3. **When metrics change, document the WHY of the change.** "Dropped
   ≥6 token floor because reviewer flagged metric-gaming on BUG-K"
   tells the next maintainer not to re-introduce it.
4. **Distinguish 'Fail' from 'NA-heuristic-limit' in audit verdicts.**
   A static check that can't handle a legitimate case (e.g.,
   conjugation-aware pattern matching) should emit a 'NA-heuristic-
   limit' label, not a 'Fail'. The tracker accepts NA-heuristic-limit
   as not-a-failure.

**Slot-token whitelist sub-rule:**

Pedagogical slot notation (`Verb-`, `Verb-stem`, `counter`, `Adj`,
`Noun`, `A`, `B`, `X`, `Y`, `NP`) is LEGITIMATE Latin content in
meaning_ja. Maintain a SHARED whitelist between authoring conventions
and audit predicates. When a new slot-token is introduced in
authoring, extend the audit whitelist in the same commit (Rule 5).
Otherwise the audit will flag legitimate slot notation as
out-of-spec Latin.

**Bounded coverage:**
- "Token-count floor anti-pattern documented" — covers the specific
  ≥6 token shape that was gamed; future similarly-shaped floors on
  other quality dimensions are the maintainer's call (apply this
  pattern there too).
- "NA-heuristic-limit verdict label" — locks the specific verdict
  vocabulary; tracker readers need to know it means not-a-failure.

### F.44.34 Same drift-class lineage table extension for metric-gaming anti-pattern

| Class | First seen | Lesson |
|---|---|---|
| metric-gaming in audit-fix passes (F.44.33) | BUG-K wcp.why expansion 2026-05-24 — independent reviewer flagged 25 rationales boilerplate-expanded to satisfy ≥6 token floor; revert applied; predicate dropped | Quality-dimension audit predicates must use content checks (does the text name a rule AND a correction) not size floors (token count, char length). If content checks are too hard for static analysis, fall back to non-emptiness — don't substitute a gameable size proxy. Distinguish 'Fail' (real defect) from 'NA-heuristic-limit' (predicate can't cleanly handle this case) in verdict labels. Maintain a shared slot-token whitelist between authoring and audit; extend on each new convention introduction. When reverting a metric-gaming fix-pass, log the revert + diff in fix_log; preserve the lesson in the procedure manual so the next maintainer doesn't re-introduce the same gameable predicate. |

## F.46 Single source of truth for the spec — retire generators that emit a parallel prose copy (added 2026-05-29)

A spec generator that renders its own prose into a second document is a
drift engine. The next-level builder should never create one.

### F.46.1 The anti-pattern

A build script (N5's `tools/build_spec.py`) generated a distributable
`.docx` "functional spec" from its OWN inline prose plus a supplement
file. That produced a SECOND, parallel prose copy of the specification
alongside the canonical living-Markdown spec. Symptoms:

- No reader could tell which copy was authoritative.
- Edits to the canonical `.md` did not propagate to the generated
  `.docx`, and vice versa.
- A design-system section diverged between the copies; an implementer
  followed the stale copy and shipped a styling defect that cost ~1 day
  to unwind.

### F.46.2 The rule

Keep exactly ONE authoritative spec — the living `.md`. Do not build or
keep a generator that maintains a parallel prose rendering. If a
distributable format is genuinely needed, generate it at release time as
a throwaway artifact: never commit it, never hand-edit it, regenerate on
demand. Otherwise skip it. When you inherit an existing parallel-copy
generator, archive it (preserve provenance — do not delete) and fold any
unique content back into the canonical doc in the same pass.

### F.46.3 Non-blocking CI checks must be labeled "non-blocking" everywhere

When a CI step runs `continue-on-error: true` (a visibility check, not a
gate), every doc that references it must say so — "non-blocking",
"visibility", "reports but does not fail the build". Never describe it as
"enforced" / "locked by CI" / "blocks deploy". A non-blocking check that
the docs call "enforced" is a false-enforcement drift: the next
maintainer trusts a gate that is not there. (N5's design-system checker
ran non-blocking with a ~116-violation backlog while several docs claimed
it was "enforced" / "locked by CI"; reconciled 2026-05-29.)

### F.46.4 Renaming a code/CI-referenced doc — target the name the refs already expect

When a doc is referenced by FILENAME from code or CI (a CSS
source-of-truth comment, a checker docstring, a workflow `# Source:`
comment), a rename must target the exact name those references already
use. grep the whole tree for the filename BEFORE renaming; a well-chosen
rename heals dangling references instead of creating new ones. (N5's
design-system-file rename healed three pre-existing dangling references in
a single move.)

### F.46.5 Bounded coverage

- "Retire parallel-copy spec generators" — covers the specific
  generate-a-second-prose-doc anti-pattern. Release-time throwaway
  renderers (never committed, never edited) remain acceptable.
- "Non-blocking checks labeled non-blocking" — applies to every
  `continue-on-error: true` step and the docs that cite it; it does not
  decide whether a given check should block (that is the maintainer's
  call per the violation backlog).

### F.46.6 A derived count is a fact with one home — prose points to it, never copies it (added 2026-05-29)

**Same drift-engine class as F.46.1, narrower trigger.** F.46.1 is about a
*generator* emitting a parallel prose copy of a whole document. F.46.6 is
about a single *number* — the count of CI invariants, the corpus sizes
(vocab / kanji / reading / listening / papers), the audio-file total — that
some script already derives from the live source on every run. The moment
that number is typed as a literal into a second document, that document is a
stale copy waiting to happen. Nobody re-greps every doc when invariant #N+1
lands, so the literal rots silently while the deriving script stays correct.

**How it manifested at N5:** the live checker reported **171** invariants,
but the literal count was hardcoded-and-stale across ~12 living surfaces —
`21` (governance working-note), `48` (self-host + native-audio + front-door
README + Hindi mirror), `83` (improvement prompt × 3 + accuracy-audit
pre-flight), `104` (cross-artifact sync-map), and — worst — the spec
contradicted *itself*: §19 said "91 rules" while §25 (the authoritative
reference) was headed "JA-1 through JA-145" yet its own body documented rows
through JA-161. Five different wrong numbers, all once-correct, none updated
when the suite grew. The deriving script (`check_content_integrity.py`) was
right the entire time; only the prose copies drifted.

**The rule for an Nx builder:**
1. **Identify the deriving artifact.** Whatever script computes the number
   and prints it (the integrity checker prints its own invariant count on
   every run; a `version.json` builder derives corpus counts from the data
   files) is the single home for that fact.
2. **In living prose, do not state the number — point to the deriving
   artifact.** "see `tools/check_content_integrity.py` (it reports the live
   count)" never rots. The N5 front-door README modelled this correctly and
   never drifted: *"Counts drift over time — when in doubt, run the checker,
   which derives them from the live data files."* Copy that pattern.
3. **When a number genuinely aids the reader** (a spec reference section, a
   "current state" table), state it **with a date-stamp AND a pointer**:
   "171 at the 2026-05-29 checkpoint; the script is the source of truth."
   The date-stamp converts a silent lie into an honest, self-dating snapshot
   (bounded-phrasing discipline, F.44 / Rule 4).
4. **Distinguish living claims from point-in-time records — only fix the
   former.** CHANGELOG entries, dated audit reports, completed-task stamps,
   and version-stamped baselines ("v1.x.y · N invariants") are *correct*
   historical snapshots; rewriting them destroys provenance. The fix targets
   present-tense claims a reader takes as "the count right now."
5. **Generated mirrors fix themselves — fix the source, never the output.**
   If a static/SEO mirror carries the stale number, it is a stale *build* of
   a now-corrected source; regenerate the mirror (as its own verified step),
   do not hand-edit generated HTML.
6. **A CI guard is usually the wrong tool here.** A "doc count must equal
   live count" invariant fights every legitimate date-stamped snapshot and
   point-in-time record (high false-positive rate). The durable fix is
   structural: remove the literals so there is nothing left to drift. Prefer
   the pointer pattern over minting a guard invariant.

**Bounded coverage:** F.46.6 covers derived *scalar facts* duplicated into
prose. It does not mandate de-duplicating prose *descriptions* of invariants
(a human-readable reference section like spec §25 is legitimately a second
representation — just keep its header honest and pointer-stamped per rule 3).

### F.46.7 A generated artifact with a manual post-step is a regression trap; and a hand-evolved artifact can outgrow its generator (added 2026-05-29)

**Two related failure modes around generated artifacts, both observed at
N5 in one sitting, both costing rework.**

**Mode 1 - the un-integrated post-step.** When the final committed artifact
is produced by a GENERATOR (step 1) PLUS a manual POST-STEP (step 2) that
shapes the same output, running step 1 alone silently reverts step 2's
work. At N5 the static SEO mirrors are built by `build_static_mirrors.py`
(emits a bare template) and then a second script injects the global
app-header (brand + nav). The builder's own docstring said "run
`build_static_mirrors.py`" with no mention of the injector. Running the
builder alone therefore stripped the header from every mirror it wrote -
shipping the exact "deep-link page looks broken, no nav" bug the injector
existed to fix. It regressed twice before the pattern was understood.

  Rules for an Nx builder:
  1. Prefer a SINGLE-COMMAND generator: fold the post-step into the
     generator (call it as a final stage) so one run yields the FINAL
     artifact and cannot half-produce it. If you genuinely cannot
     integrate, document the required sequence loudly in BOTH tools'
     docstrings ("you MUST also run X afterwards").
  2. CI-GUARD the post-step's contribution, not just the generator's.
     A "every mirror contains the app-header" invariant turns "ran step 1
     alone" from a silent ship into a red build. This is the safety net an
     integration alone cannot give you for already-committed snapshots
     (someone can still hand-edit or run an old tool). At N5 this is the
     mirror-app-header-presence invariant; write the negative test too
     (break one file, confirm the guard fails, restore).

**Mode 2 - the artifact that outgrew its generator.** Over time, committed
artifacts get hand-patched (post-steps, hotfixes, format migrations applied
by one-shot scripts) while the generator is NOT kept in lockstep. Eventually
the generator emits a MATERIALLY DIFFERENT artifact than what is committed,
and "just regenerate it" is no longer a refresh - it is a migration. At N5
the committed content mirrors were still in the pre-history-mode hash-routing
format (redirect-to-`#/route` script + old banner), hand-patched with the
injected header and a later nav merge, while the generator had moved to the
history-mode template. A wholesale regen would have rewritten ~1372 pages'
routing / canonical-URL / redirect markup (~42k lines) - an SEO-affecting
migration, not maintenance.

  Rules for an Nx builder:
  3. Treat "generator output != committed artifact (beyond trivial
     refresh)" as DRIFT that needs a deliberate, separately-reviewed
     MIGRATION with its own verification (here: canonical URLs, redirect
     behavior, render checks), never a casual rebuild. Get explicit
     sign-off before regenerating hand-evolved artifacts en masse.
  4. VERIFY-BEFORE-BULK-ACTING. Before committing a 1000+-file regen, diff
     a representative sample and confirm the delta is ONLY what you
     intended. At N5 the expected delta was a one-line cache-buster bump;
     the actual delta was a full routing-format migration. Inspecting the
     diff (not trusting the "rebuild = refresh" mental model) caught it
     before it shipped. A clean per-file diff is the proof; the build
     succeeding is not.

**Meta-lesson:** when an assumption about a generated subsystem is wrong
TWICE in a row (here: "the header is stale" - it was intentional; then
"the rebuild is a version bump" - it was a routing migration), STOP
bulk-operating and surface for a decision. Two misreads means the mental
model is wrong, not the artifacts.

### F.46.8 Item-metadata labels drift from content via copy-paste leakage; guard the checkable subset only (added 2026-05-29)

**The bug class.** Example / item records often carry a short metadata LABEL
that is rendered to the learner - a category chip, a scenario tag, a `form`
field ("water-request", "restaurant-order"). When an example is duplicated to
seed a new one and the label is NOT updated, the label silently contradicts the
content. At N5 a user caught a grammar example "ペンを ください / Please give me a
pen" rendering the chip "WATER-REQUEST" (`form: "water-request"` copy-pasted
from a sibling water example). The JA + EN were correct; only the label lied.

**Why a naive label↔content CI guard backfires.** The obvious check - "the
label's head word must appear in the content/translation" - over-flags massively
(at N5: 336 of 558 hyphenated `form` labels) because MOST labels are
GRAMMATICAL or SCENARIO descriptors (topic-introduction, list-fruit,
existence-new, negative-request, speed-request) whose head legitimately is NOT
in the sentence. They describe the grammar function or the request's
manner/context, not a content noun. Flagging those is wrong.

**The rule for an Nx builder:**
1. **Separate content-attribute labels from descriptor labels.** Only a subset
   of labels name a concrete content attribute that MUST appear in the content
   (here: `<physical-object>-request/-order`, where the object - water, tea,
   coffee, menu, pen, ... - is the requested item). The rest (grammatical /
   register / scenario heads) are descriptors and are NOT content-checkable.
2. **Guard the checkable subset with a CURATED allowlist, not a blanket rule.**
   The CI guard keys on a curated set of content-attribute heads (e.g. the
   physical request-objects) and asserts the head appears in the translation.
   Heads outside the set are not checked -> zero false positives. Correctly
   labelled items always pass (a correct "menu-request" has "menu" in its
   translation); only copy-paste leaks fail. This sidesteps the F.46.6-rule-6
   "guard fights legitimate states" trap by scoping the guard to the class where
   the assertion is actually invariant.
3. **Record the false-positive class explicitly** in the audit prompt
   (descriptor-head labels are NOT mismatches) so a future reviewer/LLM does not
   "fix" legitimate labels.
4. **Detection scope is bounded; say so.** The guard catches the curated
   object set; general semantic label↔content verification stays manual /
   LLM-audit. A new content-attribute scenario adds one entry to the allowlist.

### F.46.9 Brand the machine/SEO surfaces too - they are part of the site (added 2026-05-30)

**The bug class.** A site's crawler / SEO surfaces - the static `*.html`
syllabus-summary pages, `sitemap.xml`, machine-readable indexes - are easy to
ship "naked": correct content, but bare default styling with no header/footer.
A human who lands on one (via a footer link, a search result, or a shared URL)
sees what looks like a *different* website. At N5 a user hit `/N5/home.html` and
`/N5/sitemap.xml` and reported both as off-brand.

**Two specific traps:**
1. **The header-injection step usually globs `index.html` only.** If brand chrome
   is added to mirrors by a post-build injector that walks `index.html` files
   (the common pattern), the `*.html` summary pages are silently skipped and stay
   header-less. Fix: bake the header into the summary-page GENERATOR template
   rather than relying on the injector - this also keeps the regen drift-check
   consistent (cf. F.46.7: generated artifact + manual post-step = regression
   trap). Reuse the SAME header markup + stylesheet link the mirrors use.
2. **`sitemap.xml` renders as raw XML in browsers.** Add an `<?xml-stylesheet?>`
   processing instruction + ship a small XSL stylesheet that renders it as a
   branded table. Crawlers ignore the PI and parse the raw `<urlset>`, so SEO is
   unaffected; only humans get the styled view.

**Related placement rule.** Keep crawler-only links (raw `llms.txt`, the raw
sitemap, machine indexes) OFF the human landing / level-picker page - they read
as belonging to another site. Surface only human-relevant overview links, and
put any level-specific link (e.g. "Nx syllabus overview") in THAT level's
footer, not on the multi-level root. Crawlers still discover the machine files
via `robots.txt`.

### F.46.10 Brand the surfaces COMPLETELY (footer too), and never leak dev jargon to learners (added 2026-05-30)

Two follow-ups to F.46.9, both from a user reviewing the now-branded surfaces:

1. **Header is not enough - inject the footer too.** A user noticed the static
   pages still had NO footer menu, unlike the SPA. "Brand chrome" means header
   AND footer. Extend the same injector to add the site footer (footer-nav +
   trademark, absolute static-mirror URLs, no JS) before the closing body tag on
   every mirror, idempotently. Gotchas: the injector that previously SKIPPED
   files already having the header must stop skipping them (they still need the
   footer - inject each element independently); a mirror may keep its own small
   per-page footer (breadcrumb/license) - the site app-footer is a separate,
   additional element. Guard footer-presence with its own CI invariant (here
   JA-172), symmetric to the header guard (JA-170), so a builder-run-alone
   cannot strip it.

2. **Do not show developer jargon to a language learner.** Once a crawler/SEO
   page becomes user-facing (linked from the footer, branded), audit its COPY
   for terms only a developer understands: "static index", "SPA route", "JSON
   corpus", "server-rendered HTML / no JS required", "crawler-readable". Reword
   into plain language ("Open the grammar list", "Open the app") or remove. The
   audience changed from crawlers to learners; the words must follow. This is the
   counterpart to F.46.9's "machine links off the landing page": once a page IS
   user-facing, its remaining copy must read for the actual human audience.

### F.46.11 Changing an already-baked header across all mirrors: migrate, don't re-inject; and bump the mirror CSS key (added 2026-05-30)

When you need to CHANGE (not just add) the shared header/footer that's already
baked into thousands of static mirrors - e.g. a user asks to split the brand
lockup into two links (mark -> level picker, level wordmark -> level home) - two
traps:

1. **The header-injector skips files that already have the header**, so editing
   its template and re-running does NOT update existing mirrors. To push a header
   change you must either (a) regenerate every mirror header-less then re-inject
   (heavy; and remember two generators own different mirror sets), or (b) run a
   one-off find-replace MIGRATION over the baked files. (b) is the surgical
   choice: a whitespace-tolerant regex (`<svg.*?</svg>` with DOTALL captures the
   mark regardless of formatting) that matches the old lockup and rewrites it,
   handling both the absolute-URL form (mirrors/summary/sitemap) and the
   relative-URL form (SPA shell + SPA-clone mirrors). ALSO edit the generator
   templates so future builds emit the new form. Dry-run on one file per form
   first; the regex is idempotent (post-split it no longer matches).

2. **A CSS change that affects mirrors needs the mirror CSS cache key bumped.**
   Mirrors often link `main.min.css?v=<old>` with a stale, inconsistent query
   (different mirrors carry different old versions). If your change touches CSS
   (e.g. a new flex rule for the split lockup), returning visitors keep the old
   CSS until the HTTP cache TTL expires -> transient broken layout. Normalize the
   key to the current release across ALL mirrors in the same migration. Keep the
   SPA shell's css `?v=` == js `?v=` == SW CACHE_VERSION (the version-sync
   invariant); the mirror key is separate and only needs to change, not match.

(Aside: a split lockup needs the container - not each link - to be the flex row,
or the two `display:flex` links stack vertically.)

## F.47 Bug-to-test-coverage traceability audit - recording gap vs testing gap (added 2026-05-31)

When a stakeholder asks "are all the fixed bugs covered by tests/scenarios?",
the naive answer (read one coverage column, count blanks) almost always
OVERSTATES the gap. Run a layered determination instead.

### F.47.1 Layered coverage determination

For each Fixed bug, accept the strongest available signal:
1. Recorded - a coverage column is already populated.
2. Inferable - the fix-note cites an invariant id / "regression" / "verified".
3. Literal-ID - the bug audit-id appears verbatim in an invariant description.
4. Class-level - the invariant names a SIBLING bug-id of the same structural
   class, or a range covering this bug (e.g. "MOB-001..016 batch").

Separately bucket bugs a regression test does NOT apply to: test-scenario-
quality / schema / triage / process fixes (the scenario IS the artifact), and
non-product items (deploy-config such as HTTP headers / CSP, native-review-
queue items, tooling/access).

### F.47.2 The recording gap is the usual finding

Expect a small fraction of fixed bugs to have a POPULATED coverage column
while a large fraction are actually guarded. Columns get back-filled only for
recent bugs; older ones are covered by an invariant whose id was never written
into the row. Report this as a TRACEABILITY gap, distinct from a TESTING gap -
they have different fixes (back-fill vs new invariant).

### F.47.3 Read the invariant CHECK before declaring a gap

An invariant description cites the FIRST bug of a class, not every sibling, so
a string-search for the bug-id under-reports coverage. Before flagging a fixed
bug as "needs a new guard", read the actual check logic: the failure mode is
frequently ALREADY locked by an existing invariant under a sibling name (a
"(form,reading) tuple unique" check guards a later duplicate-row bug; a
"format_type closed enum" check guards any later undocumented-value bug; a
"deprecate legacy field X" check guards any later contradiction-on-X bug).
Adding a parallel invariant would duplicate the guard - reuse over recreate.

### F.47.4 Authoritative back-fill discipline

Back-fill the coverage column ONLY where the linkage is verifiable, and tag
each entry as a cross-reference back-fill - never reconstruct a fix narrative
you did not witness (no invented tool names / dates / steps). Two tiers are
safe: (a) the invariant description NAMES the bug-id (author-declared); (b) you
READ the invariant check and it covers the bug exact failure class. A count-
lock invariant that merely encodes a bug numeric side-effect ("corpus size
locked at N, adjusted -k by BUG-x") is a PARTIAL count-effect lock - label it
as such; do not imply the full fix is locked.

### F.47.5 Bounded-coverage phrasing

State counts as "covered as determined by the matching method, against this
snapshot", not "all covered". Distinguish "demonstrable link" from "fully locks
the fix". Send the genuine residue (human-judgment correctness: grammar facts,
translation accuracy, distractor validity; plus content-freshness / unmet-
target items) to the deferred native-human-review track (F.36.4 / F.44.21)
rather than chasing it with CI invariants.

## Appendix F.48 — Static-mirror render-path parity (added 2026-05-31)

Triggered by BUG-243: a user screenshot showed the n5-017 "HOW TO USE / 使い方"
section as empty space under the header. Investigation found the SPA rendered
the section correctly, but the static SEO mirror at the same route emitted
only `<h2>Attaches to</h2><p>question_word</p>` — a single token where the SPA
renders a 4-row conjugation table. Under any noscript / slow-boot / SW-update
condition, the user sees the lean mirror.

This is the THIRD repetition of the same pattern class:

- 2026-05-29 (Part 60): `build_static_mirrors.py` ran alone, the post-build
  app-header injector did not re-run, mirrors lost their header → JA-170.
- 2026-05-30: same trap for the app-footer → JA-172.
- 2026-05-31 (Part 62): the builder's HOW TO USE rendering was anemic
  compared to the SPA → JA-173.

### F.48.1 The render-path-set is bigger than the SPA

Today's render-path-set for a content route (e.g. `learn/<pid>/`) has at
least three members:

1. The **SPA renderer** (`js/learn-grammar.js renderGrammarPatternDetail`)
   produces the rich, hydrated DOM after JS boot.
2. The **static SEO mirror** (`tools/build_static_mirrors.py`) is the
   pre-rendered HTML served before the SPA hydrates. Under noscript,
   slow-boot, or SW-update conditions, this is what the user sees.
3. The **post-build injectors** (e.g.
   `tools/inject_app_header_into_mirrors_2026_05_27.py`) add features
   the builder did not emit (app-header, app-footer at this checkpoint).
   Running the builder alone strips whatever the injectors had added.

When a user reports "section X looks empty", probe all three render paths.
Stopping at "the SPA looks fine on my Playwright probe" misses the bug —
the user's browser was likely painting one of the OTHER two paths.

### F.48.2 The fix is parity, not just a cache bump

The temptation when the SPA renders correctly is to attribute the user's
report to a stale cache and bump CACHE_VERSION. That is a defensive
secondary, not the fix. The actual fix is to bring the mirror to parity
with the SPA — the builder must emit the same shape the SPA renders, and
a JA-NN parity invariant must lock it.

Every parity bug close-out must have all three elements:
1. The builder enhanced to emit the rich shape.
2. A JA-NN invariant referencing verbatim content markers that disappear
   under the bug-class (JA-173 references each `form_rules.conjugations[].
   example` string).
3. CACHE_VERSION bumped as a defensive secondary.

### F.48.3 Surgical refresh side-steps the wholesale-rebuild trap

`build_static_mirrors.py` carries a documented warning: a wholesale run
re-migrates ~1,372 hand-patched content mirrors (routing-format + app-
header injection state). For BUG-243 we instead wrote a surgical script,
`tools/refresh_grammar_howto_in_mirrors.py`, which opens each
`learn/<id>/index.html`, locates the body region between `</h1>` and the
first `<footer>`, and regenerates only that body using the updated
renderer. Header, footer, SPA boot script, canonical URLs, and breadcrumb
markup pass through untouched. 178 mirrors rewritten, 0 unparseable.

This is the right shape for any future "the builder produces the right
content but the wholesale rebuild has side effects" situation: write a
narrow body-replace script that imports the rich rendering function
directly and substitutes only the affected region.

### F.48.4 Long-term path: fold injectors back into the builder

Until the post-build injectors are folded back into `build_static_mirrors.py`,
every post-build injection target needs its own JA-NN parity invariant.
The pattern is now well-understood: each injected feature (header,
footer, HOW TO USE) needs (a) builder-side emission of the feature, (b)
a JA-NN that fails the build when the feature is absent, (c) a surgical
refresh script for the next time the feature's content shape changes.

Long-term, fold the injectors back into the builder so a wholesale
rebuild produces a true superset of the current mirrors. The builder
becomes the single source; the injectors retire. This is tracked as a
separate refactor, not part of any single BUG-NNN fix.

### F.48.5 Bounded coverage

JA-173 prevents re-introduction of *the specific bare-token mirror shape*
(an `<h2>Attaches to</h2>` block with no `class="pattern-usage"` section)
AND *missing-conjugation-example drift* on patterns with
`form_rules.conjugations ≥ 2`. It does NOT constrain SPA-renderer
regressions; those need their own invariants if they become a class. The
"three render paths" framing locks today's known set; a future pipeline
change (e.g. a new injection target) must extend the Phase-0 check in
`N5/prompts/N5Improvement.txt` accordingly.


## F.48 Native-review-prep content cleanup - 9 reviewer issue-classes, detector-driven (added 2026-05-31)



Before sending an Nx grammar corpus to a native reviewer, run a first-pass cleanup of mechanical / surface issue-classes so the native focuses on genuine language nuance, not obvious noise. Calibrate the fix on ONE entry, show the maintainer, then horizontal-deploy with a detector per class.



### F.48.1 The 9 classes (from the N5 grammar review)
1. Fragmented English / jargon-token explanations (e.g. "X CLAUSE"); also broken "vs ?:" contrast placeholders (template target never substituted).
2. Inconsistent English translation of the same pattern across examples.
3. Overstated register superlatives ("most-used", "Don't overuse").
4. False wrong/correct contrasts (a grammatical sentence struck through; the "correct" field is a note, not a sentence) -> reclassify to register_variant.
5. Near-identical duplicate example sentences.
6. Inconsistent bilingual section labels (some sections chipped, some not).
7. Force-fit politeness ladder on items that do not inflect for register (tell: humble == respectful).
8. Raw internal pattern ids (n5-NNN) leaked into learner-facing prose.
9. Duplicate content across two fields (same text in essay.cultural_context AND cultural_callout.note), rendered twice.



### F.48.2 Detector-driven, not blanket
Write a data-agnostic detector per class and fix only genuine instances. Verify class membership before "fixing" - several flags are FALSE POSITIVES that must be LEFT ALONE: "never use X / always Y" are correct hard grammar rules, not register overstatements; comparison-pattern examples naturally share an end-clause (inherent, not a duplicate); formation formulas ("Noun + を + ください") are clear notation, not fragmented English; audio-path ids (audio/grammar/n5-NNN.N.mp3) and _alias_of/_homonym_of ref fields legitimately carry ids and must not be stripped.



### F.48.3 Render-level vs data-level de-dup
When a duplication is systemic (class 9 hit 174/178 patterns - the cultural note stored verbatim in two fields), fix it at the RENDER level (stop rendering one copy in BOTH the SPA renderer and the doc generator) rather than editing N data entries. One render change, reversible, no data churn.



### F.48.4 ID-strip keeps the human-readable name
Class 8: strip "(n5-NNN)" parentheticals (the named target usually precedes them) and replace bare "n5-NNN" with the target pattern's display name (lookup). Never leave a dangling "see ." Same principle as resolving alias/homonym labels to names in the renderer.



### F.48.5 Gotchas that cost CI cycles
- index.json size_bytes is LF-normalized (JA-125 computes len(read().replace(CRLF,LF))). Windows text-mode writes produce CRLF; record the LF size, or write data files with newline='\n'.
- Stripping ID/parenthetical text can drop an essay under a min-char richness bar (JA-54 >=500); enrich with genuine content, not id-padding.
- Bug-tracker Fix Commit cells must be a SINGLE hash or a <...> sentinel (JA-146) - "hashA + hashB" fails. Cite one commit per row.



### F.48.6 CI guards added
JA-174 (no raw n5-NNN in learner-facing grammar prose), JA-175 (no unfilled "vs ?:" placeholder), JA-176 (no identical-ja duplicate examples within a pattern). These lock classes 8/1/5 against re-introduction of THESE specific patterns.



### F.48.7 Bounded-coverage phrasing
Fixes authored by the maintainer (rewrites, new examples, trimmed ladders) are PROVISIONAL and tagged for native confirmation - the native reviewer reviews; the maintainer implements. State counts as "addressed against the detector's pattern set, this snapshot", not "all fixed".

## F.49 Native-review false-negatives - 'correct sentence marked wrong' (added 2026-05-31)

After the first-pass cleanup (F.48), a native pass over EVERY wrong/correct (✗/✓)
pair surfaced a distinct, higher-severity class: FALSE NEGATIVES - the struck (wrong)
sentence is itself correct, natural Japanese. Marking it wrong teaches learners to
AVOID correct forms.

### F.49.1 Sub-classes
1. Register/politeness swap (CRITICAL): plain vs polite of the SAME meaning struck as
   wrong (だろう/でしょう; から/ので). Both correct.
2. Sentence-final-particle intent swap: ね/よ/よね marked wrong vs each other - they
   differ in INTENT (agreement / informing / shared-agreement), not grammaticality.
   'よ, not both' is a linguistic error: よ and ね co-occur as よね.
3. Pragmatic/cultural mislabeled as grammar (じょうず about oneself = boastful but
   grammatical) - that is a culture note, not an error.
4. Data-pairing error: a correct sentence paired against an unrelated correction
   (past-affirmative vs past-negative).
5. MALFORMED (structurally detectable): the 'correct' field literally admits the
   'wrong' is correct ('already correct', 'IS valid', '(correct)').
6. Focus-particle が vs は: が is correct under a focus/'who?' reading; only 'less
   natural' for a neutral statement - not ungrammatical.

### F.49.2 Auto-detectable vs native-only
Only the MALFORMED sub-class (#5) is deterministically guardable - regex the
correct/right field for self-admission text (CI: JA-177 on N5). The rest need native
grammaticality judgment on the struck sentence IN ISOLATION; no scanner decides 'is
this valid Japanese'. Plan a human native pass; do not claim a content-CI closes it.

### F.49.3 Fix shapes
- Register/intent swaps -> register_variant (both forms neutral; why explains nuance).
  Never keep a ✗/✓ between two valid forms.
- Pragmatic/cultural -> culture/usage note (or variant), not ✗.
- Data-pairing / malformed -> reframe the ✗ to a GENUINE, confident error (reading slips
  よじ/しちじ/ろっぷん, い-adj past たかかった vs x たかいでした, final-particle placement, お/ご,
  space-before-か). Keep the entry count; do not delete.
- が/は -> append a focus-reading note; keep, do not flat-mark wrong.
Tag every authored reframe needs_native_review for the next native pass.

### F.49.4 Bounded coverage
'Reframed N flagged false negatives from the native pass against this snapshot'; the
malformed sub-class is locked by JA-NN; the judgment sub-classes remain a standing
native-review item, not a closed enum.

## F.50 Deploying a committed content fix - the version-bump derived-artifact cascade (added 2026-06-04)

A content fix committed to `data/*.json` and passing content-CI is NOT live to
users, and is NOT fully propagated, until a separate release step runs. Treat
"deploy the fix" as a distinct procedure from "author the fix." On the N5
v1.17.x cutover the grammar.json fixes had landed in earlier commits, yet
cache-first kept serving the old JSON and the static mirrors still rendered the
pre-fix content - committed, but neither deployed nor propagated.

### F.50.1 Two-phase reality: authoring != deploying
- Authoring commit edits `data/*.json` and goes green on content-CI. The fix
  exists in the repo only.
- Users do not see it until the cache version bumps (cache-first SW + `?v=`
  assets keep serving the old JSON for days otherwise). No-JS / SEO crawlers do
  not see it until the static mirrors regenerate.
- The tell: "I fixed and committed it - why does the live site still show the
  old text?" You authored; you did not deploy.

### F.50.2 The derived-artifact cascade (run all in the same release commit)
Bumping the build/cache version (vMM.mm.pp) and/or editing CHANGELOG makes a
fixed set of derived artifacts stale at once. Regenerate every one in the same
commit (N5 names; mirror on Nx):
1. Cache version, 3 places that MUST match (CI: JA-68) - version.json
   (version + cacheVersion), sw.js CACHE_VERSION, index.html `?v=` on css + js.
   (Extends bumper-sticker #18 / Sec 3.2.21.)
2. Static mirrors - the per-entity SEO/no-JS pages are RENDERED from the data
   JSON; a content fix to the JSON does not touch them. Re-run the mirror
   builder for the affected stage(s), then re-inject header/footer (CI:
   JA-170/172). The builder is content-addressed: the number of real git diffs
   it produces tells you how many mirrors were genuinely stale (proof the regen
   was necessary, not churn). N5 example: 67 grammar mirrors differed.
3. Corpus index size (CI: JA-125) - index.json records each data file's
   LF-normalized byte size; bumping version.json changes its size, so update
   that entry's `size_bytes` (and `_meta.version`).
4. Review packet (CI: JA-156, local-only / skip-on-absent) - the gitignored
   reviewer snapshot must match the live version; regenerate it.
5. Meta-mirrors (CI: JA-113) - the changelog static mirror must contain the
   latest CHANGELOG heading; re-run the meta stage AFTER editing CHANGELOG.
6. CHANGELOG entry + spec closed-bug lineage (INV-9 lineage table).

### F.50.3 Verify the deploy, not just the commit
- A green CI proves the repo is internally consistent; it does NOT prove users
  see the fix.
- After push, fetch the LIVE version file (curl with a cache-bust query) and
  confirm the new version string; spot-check one regenerated mirror for the
  fixed content AND absence of the defect. (Reinforces the existing "fetch the
  live data file and re-audit" gate.)

### F.50.4 Anti-pattern: editing JSON by string-append (the quote-escape trap)
Appending free text to a JSON string value via raw string-replace breaks the
file the instant the text contains a double-quote (e.g. a note reading
malformed 'already correct' rows, written with inner double-quotes, closes the
JSON string early). It surfaces as several UNRELATED invariants failing at
once, all reporting "Expecting ',' delimiter" on the same line - the signature
of one malformed JSON file, not N real defects (every invariant that PARSES
that file fails together).
- Fix shape: edit JSON by parse -> mutate dict -> `json.dump` (auto-escapes),
  never string concatenation. If you must string-edit, escape embedded quotes
  or use single quotes inside the value.
- Always `json.load` the file to confirm it parses BEFORE running the suite.

### F.50.5 Bounded coverage
The cascade enumerated here covers the derived artifacts wired at this
checkpoint (JA-68 / 113 / 125 / 156 / 170 / 172); any derived surface added
later must be appended to this list. The deploy-verification step confirms the
live state at fetch time, not a standing guarantee.

## F.51 Nx-build-readiness gap closures - BUG-254..260 (added 2026-06-04)

Closes the seven Nx-build-readiness gaps registered as BUG-254..260 (surfaced by a
build-readiness rating of this manual). Each closes a "the manual specifies the
procedure" gap; the procedures execute at the next Nx build. Ordered by priority
(P1 first). Where an existing section already covers part of a gap, this section
completes + cross-references it rather than duplicating.

### F.51.1 (P1, BUG-254) Authoritative Nx content inventory - manifest + verify gate
Appendix B.12 already gives FETCH-not-INVENT extraction recipes; the missing piece
is a committed, count-verified inventory the authoring passes treat as the source
of truth. Procedure, run BEFORE any content authoring (build layer 3):
1. For each corpus (kanji / vocab / grammar) produce `feedback/n<L>-<corpus>-inventory.md`
   by running the B.12 recipe against the §A.7 source-authorities (JLPT-official
   where published; else the documented curated lists, per B.11). Never hand-type
   the list - fetch it.
2. Each inventory row carries: surface form, reading, gloss, source tag, and a
   `tier` (new-at-<L> vs prerequisite). One row = one intended entry = one future ID.
3. Count-reconciliation gate (NEW): assert each inventory's row count sits inside the
   §0 scope-table band for <L> (e.g. N4 kanji ~280 cumulative / ~170 new; vocab
   ~1500; grammar ~210). A count outside the band HALTS authoring with an "inventory
   vs scope-table mismatch" message - it means the fetch under- or over-collected.
   Wire it as a build-data preflight, not a post-hoc audit.
4. Authoring consumes inventory IDs only; an authored entry whose ID is absent from
   the inventory is a defect (add a JA-NN cross-ref check on Nx: every data/*.json id
   resolves to an inventory row).
Bounded: the inventory is authoritative against the source snapshot fetched; the JLPT
publishes no official post-2010 lists, so curated sources carry a documented
confidence note (B.11). This closes the Pass-20 finding restated at Appendix E
(content lists sized but not identified).

### F.51.2 (P1, BUG-255) Native-accuracy validation - sampling protocol + two-gate ship
F.49/F.50 establish that "is this valid Japanese?" is not auto-guardable. This is the
corpus-scaled human-in-the-loop protocol (the §19 native-teacher playbook is
per-item; this sizes it):
- Two-gate ship: v1 ships LLM-only (`auto:false, review_status:"llm_only"`), every
  authored entry tagged `needs_native_review`; v2 promotes `review_status ->
  "native_verified"` after a native pass. Any "verified" badge stays gated at v2
  (F.20.5).
- Stratified sample when a full native pass is infeasible: review a random sample per
  corpus sized for ~95% confidence / ~+-5% margin (the usual ~370-of-large-N rule),
  AND 100% of CRITICAL surfaces (wrong/correct pairs, cultural callouts, politeness
  ladders - the F.49 false-negative classes live here). Record sample size + found
  error-rate in `feedback/native-review-<corpus>.md`.
- Acceptance threshold: suggest <2% error on examples and 0% on wrong/correct pairs.
  Above threshold -> full pass on that corpus, not just the sample. Below -> ship v1
  with the rate disclosed in bounded phrasing ("native-reviewed sample of N;
  estimated error rate X% +- margin").
- Reviewer brief: hand the native reviewer the §19 brief + the F.49 sub-class
  checklist so the pass targets the known classes (register vs error, pragmatic vs
  grammar, false negatives).
Bounded: a sample bounds the error rate; it does not certify every entry. Only a full
native pass closes `native_verified` for a corpus.

### F.51.3 (P2, BUG-256) Multi-pass authoring schedule with per-corpus quotas
Mode B yields scaffold + ~20% content in one run; the rest lands over numbered passes
with explicit quotas + per-pass definition-of-done. Default schedule (scale absolute
counts by the §0 band for <L>):

| Pass | Target (cumulative) | Per-corpus done-when |
|---|---|---|
| 1 (one-shot) | MVS per §A.4: ~20% of each corpus + ALL critical paths | builds green; all CI invariants pass; UI renders one of each entity |
| 2 | 100% kanji whitelist; 50% grammar + vocab | every kanji entry present (whitelist is finite + gates JA-13); grammar/vocab half |
| 3 | 100% grammar; 80% vocab; full reading set | all patterns authored; reading covers each format type |
| 4 | 100% vocab + listening + mock papers | full corpus present; papers per §A.9 timing |
| 5 | native review (F.51.2) + audit cadence (F.5) | review_status promoted; bounded-coverage doc written |

Stop condition per pass: counts reach quota AND CI green AND no open P1/P2 bug. Kanji
leads (finite, bounded, gating). Bounded: quotas are targets against the §0 band, not
guarantees; a pass that reaches CI-green below quota logs the shortfall in TASKS.md
rather than padding content to hit a number.

### F.51.4 (P2, BUG-257) Per-level effort + tooling scaling (extends the §0 table)
The §0 scope table quantifies COUNTS; the gap was the EFFORT + TOOLING those counts
imply. Add:

| Level | Content vs N5 | Native-review load | Tooling change beyond N5 ports |
|---|---|---|---|
| N4 | ~1.5x | full pass still feasible | none; one-time tier-taxonomy + kanji-policy decisions |
| N3 | ~3-4x vocab | sampling becomes mandatory (F.51.2) | batch the LLM audit; shard large data/*.json reads |
| N2 | ~6x vocab | sample-only feasible; full pass = months | paginate static-mirror builds; memory-aware loaders |
| N1 | ~10x vocab, ~2000 kanji | sample-only; expert reviewer (academic register) | incremental/only-changed builds; watch CI runtime budget |

Effort: N5 = 17-25 wks (§13). Scale ~linearly with vocab for N3/N2; super-linearly
for N1 (register complexity + reviewer scarcity dominate). Re-estimate per level; do
NOT assume the N5 timeline. Bounded: multipliers are planning estimates derived from
the §0 counts, not measured build data.

### F.51.5 (P2, BUG-258) Audio decision - synthetic default (ship-acceptable), native path documented
Default (§0.A.2) is synthetic TTS (VOICEVOX per D.1), tagged `voice:"synthetic"`,
and this IS acceptable-for-ship at the v1 bar for N4..N1. v1 quality bar: pitch-accent
correct on headwords (spot-check vs OJAD); no dropped particles (the F.12 bunsetsu-space
trap); single speaker per role; pace per the §0 listening row; unified speed_scale
(F.27). Native-audio path (optional, v2+): record per the audio_manifest schema (B.2),
keep `audio_render_meta.voice_provider`, budget a native VA only for listening drills
where synthetic prosody actively misleads comprehension. Decision: synthetic is the
documented ship default; native voice is an explicit v2 upgrade, not a build blocker.
Bounded: synthetic-acceptable applies to the stated v1 bar; high-stakes listening
realism remains a v2 native item.

### F.51.6 (P3, BUG-259) Pass-20 / Pass-22 residual status - CORRECTED
The Mode-A/B preamble line "Remaining open: F-22.4 / F-22.5 code-side changes" is STALE
as of 2026-06-04 (verified against live code):
- F-22.4 (JA-25 whitelist-exceptions invariant): DONE - wired in
  `tools/check_content_integrity.py` (registry entry "JA-25 Whitelist exceptions
  documented (Pass-22 F-22.4)").
- F-22.5 (llm_audit SYSTEM_PROMPT extraction): DONE - `tools/llm_audit.py` loads
  SYSTEM_PROMPT from `tools/prompts/llm_audit.prompt.md` via `---SYSTEM_PROMPT---` /
  `---END---` delimiters.
So both code-side items the preamble flagged are shipped; all Pass-22 polish items are
now closed in code. Pass-20: the Appendix B post-amble records 38/40 closed; the remaining open
items (F-20.12 / F-20.13 / F-20.14) are the Nx content-inventory / authoring
fetches (Tanos / Bunpro), now addressed PROCEDURALLY by F.51.1 / BUG-254 and
executed at the Nx build (Pass-21) - not a manual-readiness gap. (The older
preamble snapshot '36/40, F-22.4/F-22.5 open' is superseded; Pass-22 is 10/10.) Lesson (the F.39.1 governance-stale class): this note went stale
because the code shipped in a parallel session and the preamble was not updated. On
every build, re-verify "remaining open" claims against the LIVE code before trusting
them; supersede this preamble note in favour of this subsection.

### F.51.7 (P3, BUG-260) Source-repo pin + snapshot delineation
Both operating modes require the live source (N5) repo; "copy from N5 / port verbatim"
breaks if the source moves or drifts. Closure:
- Source pin: this manual is validated against `gauravaccentureproducts/JLPTSuccess`
  at commit `92690ae8` (N5 source, 2026-06-04). Re-record this pin on every
  manual-validation pass; when building N<L>, prefer the pinned commit as the
  "copy from N5" reference so instructions resolve to the files they were written
  against.
- Snapshot vs live delineation: Appendix B already SNAPSHOTS the drift-sensitive
  structure - JSON schemas (B.3), vocab-ID slug rule (B.1), audio-manifest schema
  (B.2), invariant specs (B.8). Rule: if a "copy from N5" target is STRUCTURAL
  (schema / rule / invariant / id-format) it must be snapshot in Appendix B; if it is
  BULK content or code, it stays a LIVE reference read at the pinned commit.
Bounded: the pin fixes a known-good reference point; it does not vendor the source -
a build still needs the source repo present (the Mode-A/B precondition stands).

## F.52 Template-generated content artifacts - conjugation + semantic-frame nonsense (added 2026-06-04)

A native-reviewer specific-bug audit (BUG-266) cited 12 concrete JP-content errors in
the vocab corpus. Reproduction confirmed all 12 AND revealed they were instances of a
SYSTEMATIC template-generation defect: an auto-builder filled headwords into fixed
frames without conjugating or checking sense. The cited 12 were the visible tip of
~142 affected entries. This is the durable lesson for any Nx corpus that was
bulk-seeded by frame templates.

### F.52.1 The two sub-classes
1. MALFORMED CONJUGATION (objective). A field built as "<headword> + ます" / "<headword>
   + ました" appends the polite ending to the DICTIONARY form: べんきょうするます,
   かすました, あるます, すむます. Never valid - you conjugate the stem. In N5 vocab this
   hit ALL 110 verbs (the particle_examples template emitted form+ます and form+ました
   for every verb regardless of class).
2. SEMANTIC-NONSENSE FRAME (needs judgment). A fixed example/collocation frame applied
   to a headword it can't pair with: 「今日は とても <adj>です」 for non-weather adjectives
   (今日は 白い / まるい / ぬるい = a day isn't white/round/lukewarm), 「えいがは <adj>でした」
   for color/taste/size adjectives ("the movie was yellow") - which ALSO carries an
   い-adjective past-form grammar error (でした, not かったです), 「この <noun>は <adj>です」
   mismatches (この りんごは うるさいです = an apple isn't noisy), and noun-as-buyable-object
   frames (あたらしい / たかい カタカナ - a writing system isn't new/expensive).

### F.52.2 Sub-class 1 is deterministic - fix + lock
A malformed conjugation is wrong at any JLPT level, so fix it programmatically with a
verb-class-aware conjugator (read pos / verb_class per entry):
- godan (verb-1): final う-row kana -> い-row + ます (す->し, く->き, む->み, る->り, つ->ち,
  ぐ->ぎ, ぶ->び, ぬ->に, う->い). ある->あります.
- ichidan (verb-2): drop final る + ます.
- irregular (verb-3): する->します; 来る->来ます; <X>する->Xします.
Per-entry pos is what disambiguates a homonym: きる(verb-1, cut)->きります vs きる(verb-2,
wear)->きます. Then ADD a JA-NN regression guard that compares each example against the
entry's OWN form+ます / form+ました - a PRECISE comparison never false-positives on a
correctly conjugated form (かします != かす+ます). JA-178 is the N5 instance.

### F.52.3 Sub-class 2 needs sense judgment - allowlist-remove, never fabricate
A semantic frame is valid for SOME headwords and nonsense for others. Do not blanket-
delete (many 「この本は おもしろいです」-style sentences are fine) and do not blanket-keep.
Use a conservative allowlist for the frame's valid semantic class (e.g. 「今日は とても X」
-> weather/day-quality adjectives only: すずしい / あたたかい / いい) and REMOVE the rest.
Removal is safe and non-fabricating; rewriting needs a native speaker. GUARD: never
reduce an entry below 1 example - if a removal would empty the field, skip it and log
for native attention. The few salvageable-by-grammar-fix cases (えいがは 長いでした ->
長かったです is sensible) are not worth the per-item risk of an LLM deciding which; leave
them for the native pass.

### F.52.4 The meta-lesson: audit the whole field, never just the citation
When a reviewer cites N instances of a defect in a TEMPLATE-GENERATED field, the real
scope is "every entry the template touched", not N. Reproduce each citation against the
live data first (confirm it exists - do not trust the extracted report's row numbers,
which may be docx page positions not entry IDs), then scope the systematic class with
one query before fixing. BUG-266: cited 12 -> actual 110 conjugations + ~32 nonsense
sentences. Split the fix: deterministic sub-class fixed + CI-locked this pass; sense-
judgment sub-class either allowlist-removed (clear nonsense) or deferred to the native
queue (residual naturalness, e.g. まいにち すむ adverb collocations -> the OPEN-003/004
particle-example class).

### F.52.5 Bounded coverage
JA-178 prevents re-introduction of *the specific form+ます / form+ました malformation* in
verb particle_examples. It does NOT validate that a particle_example is a good particle
example (the field is template-seeded and its naturalness is native-judgment work), nor
does it catch malformed conjugations in OTHER fields (examples[].ja, glossaries). The
semantic-frame removals are "addressed against the cited frames + the conservative
allowlist, this snapshot" - a native pass still owns the residual.

## Appendix F.53 — Reviewer deliverables: auto-stamp + keep-exactly-one (stale-copy prevention) (added 2026-06-06)

A human-review deliverable (e.g. the vocab review .docx emitted by
build_vocab_review_docx.py) is uploaded to an external store (SharePoint / Drive) by
hand. That uploaded copy does NOT auto-refresh from the repo build. Two failure modes
recurred on the N5 native-review cycle and cost several review round-trips:

### F.53.1 The two stale-copy failure modes
1. STALE COPY - after a fix lands in the repo build, the reviewer re-checks the SAME
   previously-uploaded file. The fix is in the repo but not in their copy, so they
   re-report an already-fixed item as "still pending". Nothing is wrong with the data.
2. WRONG DATED COPY - once several timestamped builds pile up in the output folder, the
   older (pre-fix) one gets uploaded by mistake instead of the newest. Same symptom: a
   "pending" report against a bug already fixed in the latest build.

### F.53.2 The builder rule (keep exactly one dated file)
The builder that emits a reviewer deliverable MUST, on every full build:
  - stamp the output filename with build date+time (YYYY-MM-DD_HHMM), AND
  - delete any prior stamped copies first, so the folder holds exactly ONE dated file
    = the current build.
Reference implementation (build_vocab_review_docx.py, arg=='all'):
    stem = os.path.splitext(out_path)[0]
    for prev in glob.glob(stem + "_*.docx"): os.remove(prev)
    shutil.copy2(out_path, stem + "_<stamp>.docx")
The canonical un-stamped file stays as the tracked / diff-able artifact; the single
stamped copy is the upload target. The date in the name is the unambiguous "this is the
latest" signal - reviewers are told to grade ONLY the file with the newest stamp.

### F.53.3 Diagnostic before re-fixing a re-reported item
When a reviewer re-reports an item you believe is fixed, do NOT re-edit data first.
Compare the offending string's count across three places: (a) the source data, (b) the
canonical repo build, (c) the uploaded copy. If (a) and (b) are 0 but the report
persists, it is a STALE / WRONG upload, not a code defect - the fix is to re-upload the
freshly-stamped file, not to touch data. This three-way count check turns "the reviewer
keeps reporting it" from a mystery into a one-command diagnosis.

### F.53.4 Bounded coverage
Auto-stamping guarantees the repo always offers exactly one current dated file; it does
NOT control what a human ultimately uploads to the external store. The operator step
(re-upload the newest stamp after every fix) remains a manual hand-off and is the
residual failure surface.

### F.53.5 The auto-stamp must tolerate a locked old copy
The "keep exactly one dated file" rule deletes the previous stamp on every rebuild. But the
reviewer is often reading that previous file in Word when you regenerate, and Windows holds
an exclusive lock on an open .docx - so `os.remove(prev)` raises PermissionError [WinError 32]
and the WHOLE build aborts before it writes the new stamp. A deliverable builder must never
fail to produce output because of a cleanup side-effect: wrap the old-copy removal in
try/except, skip the locked file with a one-line warning, and continue. The repo then carries
two dated copies for one cycle (harmless - the operator uploads the newest), and the stale one
is cleaned up on the next rebuild once the reviewer has closed it. General rule: cleanup of a
prior artifact is best-effort; producing the new artifact is mandatory - never let the former
block the latter.

## Appendix F.54 — Auto-generated heuristic field encodes a generic default that is WRONG for a sub-class (kanji reading_rule / on-dominance) (added 2026-06-07)

A native review of the N5 kanji pages found the `reading_rule` field — auto-generated on
~60 kanji from a generic template ("standalone kanji -> kun-yomi; compounds -> on-yomi. For
X: standalone use of kun (K); compounds use on (O).") — was BACKWARDS for on-dominant kanji.
It is the correct DEFAULT for content kanji (山 standalone = やま) but wrong for the numbers
(二 standalone = に, not ふた) and on-loan kanji (語 = ご, 分 = ふん, 半 = はん, 天 = てん). The
reviewer cited 11; the real class was larger.

### F.54.1 Detection signal (do not fix per-citation)
The reliable signal for "is the generic standalone=kun rule wrong here?" is: **primary_reading
in on'yomi (script-normalised) AND not in kun'yomi**. on'yomi is stored in katakana (イチ) and
primary_reading in hiragana (いち), so convert katakana -> hiragana (subtract 0x60 in the
katakana block) before comparing. That query returned 17 candidates; native judgment removed 4
false-positives where the kun standalone IS valid (年 とし, 先 さき, 会 会う, 新 新しい) —
primary_reading was simply the chosen primary for a common on-compound. Net: 14 corrected.

### F.54.2 The general lesson
A template that bakes a "typical" linguistic rule into a per-item field is confidently WRONG
for the minority sub-class it does not cover. When a heuristic field (reading_rule, register,
default-reading, part-of-speech) is auto-stamped corpus-wide, audit the WHOLE field against an
INDEPENDENT per-item signal — not just the reviewer's cited examples. Same shape as the vocab
particle_examples template-artifact class (F.52): the generator pasted a frame without checking
it against the entry's own data.

### F.54.3 Render-faithful review packets surface the rest
The same packet (build_kanji_review_docx.py — the kanji sibling of the vocab/grammar review
builders; see F.53 for the auto-stamp/keep-one behaviour they share) surfaced one-off issues
because it renders the data verbatim: an on-reading example that did not demonstrate the on-yomi
(父親 ちちおや for 父's ふ -> 父母 ふぼ), malformed kanji+kana (手つだって -> てつだって),
counter-before-core-meaning (本 -> "book"), surname-only example sentences that do not teach the
kanji (田中 in 中 / 田 -> 箱の中に… / 田んぼに…), and fill-in-the-blank cloze items leaking into the
example-sentence field (外, 私). Authoring rules: example SENTENCES must be complete (no cloze
blanks); example WORDS lead with the kanji's core meaning; an "on-reading example" must actually
contain that on-reading.

### F.54.4 Bounded coverage
The reading-rule correction covers "every on-dominant kanji detected by the primary_reading-in-
on'yomi signal in this snapshot." No CI invariant locks reading-rule correctness — it is
native-judgment prose, and the signal is a detection aid, not a guard.

## Appendix F.55 — Per-entry image assets (kanji mnemonic illustration) + the min-rebuild trap (added 2026-06-07)

A proof-of-concept added a per-kanji mnemonic illustration (`img/kanji/<glyph>.png`) to the
kanji detail's "Radical & mnemonic" section. Three reusable lessons:

### F.55.1 Source edits are INVISIBLE until you rebuild the mins
The SPA serves `js/min/*.js` and `css/main.min.css` (index.html links the minified files; the
ES-module entry is `js/min/app.js`). Editing `js/<x>.js` or `css/main.css` alone changes NOTHING
the running app sees. After ANY UI/source change you MUST run BOTH:
  `python tools/build_min_css.py`   (css/main.css -> css/main.min.css)
  `python tools/build_min_js.py`    (js/*.js -> js/min/*.js)
Symptom when forgotten: the page renders the OLD behaviour with no error, and a local preview
shows your change "missing." This cost a full debug cycle here. Make the two min-rebuilds a
reflex deploy step, right next to the cache bump.

### F.55.2 Pattern for a per-entry image asset
Mirror the existing `stroke_order_svg` pattern (a relative-path field on the data entry):
- data: `mnemonic_image: "img/kanji/<glyph>.png"` + REQUIRED sibling `mnemonic_image_alt`
  (screen-reader text — the card bakes its own Japanese text into pixels, invisible to assistive
  tech) + `mnemonic_image_provenance`.
- render: a lazy-loaded `<figure><img loading="lazy" decoding="async" alt=...></figure>` inside
  the section; the image is SUPPLEMENTARY — authoritative readings/meaning stay as live HTML,
  never only in the picture.
- CI guard: one invariant (file-resolves-on-disk + non-empty alt; here JA-179) scales to every
  entry that later gains an image.
- weight: source cards were 1024x1024 / ~2.3 MB each. Lazy-load keeps a single page cheap, but a
  FULL set must be optimised first (downscale + WebP, target ~100-150 KB) or repo + page weight
  balloon. Image production is the gating cost, not the code.
- licensing: AI-generated art needs a provenance/licence note in NOTICES (commercial-use right
  confirmed) — same discipline as the KanjiVG CC BY-SA attribution.

### F.55.3 Local preview needs the production base path
The SPA boots only under its production base (`…/JLPTSuccess/N5/`). Served from a localhost root
(`http://localhost:PORT/`) the static shell loads but the router never populates `#app` (stuck on
the skeleton) — a base-path assumption, not a code defect. To render-verify a UI change locally,
either serve under the same path prefix, or verify the component with a static HTML harness (real
`main.min.css` + the real asset + the exact emitted markup) and confirm the visual on the live
deploy. Do NOT conclude "the app is broken" from a localhost-root skeleton.

## Appendix F.56 — Review-provenance is internal; never a learner-facing tag (added 2026-06-08)

A round of audits built a `review_status` field (`{native_reviewed, llm_curated, auto_generated}`)
on every content item AND a learner-facing badge that displayed it ("AI quality-reviewed" next to
kanji meanings / vocab glosses, an "auto / pending native review" tag on mnemonics, a
"native-teacher-reviewed" footnote on the papers page, a "native_reviewed" claim in the README).
The product owner directed (2026-06-08): **who or what reviewed an item is the owner's concern, not
a learner-facing signal — the learner must see only the content; the owner takes final
responsibility for correctness.** General rule for any Nx build:

- **Keep the data, kill the display.** A provenance / review-status field is useful internal
  metadata (audit tracking, CI completeness like JA-35) — retain it. But it must NEVER render to
  the end user, as a badge, banner, tooltip, footnote, or README claim.
- **A misnamed quality tag is worse than none.** Here the value was machine-assigned (LLM acting as
  a reviewer persona), so "native-reviewed" / "AI quality-reviewed" overclaimed trust. Showing it
  invited a credibility hit the moment a learner found an error. Don't ship trust signals you can't
  stand behind.
- **Disable at the source, not just the flag.** The badge was gated behind a settings flag that had
  silently defaulted ON (comment said "default false"; code said `true`). Belt-and-suspenders:
  hard-disable the render function (return '') AND set the flag false — a flag alone is one toggle
  away from regressing.
- **Lock it.** Add a Phase-0 / grep check that the rendered-label strings are absent from served JS
  + learner-facing HTML/README (internal data fields, audit docs, and NOTICES disclaimers excluded).

## Appendix F.57 — Live UI-review fix cycle: learner-facing hygiene + verification discipline (added 2026-06-08)

A rapid live-site review by the product owner produced a batch of small UI fixes. These are the
generalizable patterns + the verification discipline every Nx level should reuse. The shape of the
cycle: owner reviews the live SPA → fires terse findings → fix the reported item + horizontally
deploy → ship per batch (one cache bump each) → register every finding in the bug sheet with status.

### F.57.1 Collapse overlapping render sections; a "words containing this kanji" list must exclude kana-only homophones
Two detail-page sections that present the same data under different headings ("Example usage" vs
"Words containing this kanji") read as duplicates - merge into ONE. Build the merged list from the
union of the candidate arrays (e.g. `examples[]` for the richer compound set + the vocab-linked
`n5_compounds[]`), dedup by surface form, and make a row clickable through to its vocab entry when one
exists. CRITICAL filter: a "words/compounds containing this kanji" list must include ONLY forms that
literally contain the target glyph (`glyph in form`). Kana-only homophones (e.g. あめ "candy" shares
the reading of 雨 but contains no kanji) must be excluded - listing them under "contains this kanji"
is simply wrong. Keep the homophone data if it has teaching value; just don't render it in that list.

### F.57.2 Scroll to top on every route change
A hash-routed SPA retains the window scroll position across route changes, so opening a list item
(e.g. a kanji card) can land the user mid-page with the item's header (the large glyph) off-screen.
Add `window.scrollTo(0, 0)` after the route handler renders, in the central router. Hash routing
carries no in-page anchors, so this is always safe and is the expected behaviour.

### F.57.3 Em-dash / smart-punctuation sweep: scope it, prove it's safe, defer the dense prose
Owners often want em-dashes (—) and other smart punctuation removed as an "AI-tell." At scale this is
NOT a hand-edit. Method that worked:
- **Measure first.** Count occurrences per surface. The split is usually lopsided: a few hundred in
  UI chrome (render strings + locale files + index.html) vs tens of thousands buried in the dense
  bilingual EXPLANATION prose in `data/*.json`. Scope the first pass to UI chrome; DEFER the prose to
  a separate reviewed pass (a per-sentence context-aware rewrite + native-script clause-break review)
  and log it in the task backlog so it isn't lost.
- **Prove no logic dependency before a scripted replace.** Grep the code for the character inside
  regex / string-comparison / RegExp contexts. If there are none (the usual case - em-dashes live in
  display strings + comments only), a uniform scripted replace is safe: spaced " — " → ", " (clause
  break reads naturally as a comma for short labels); tight "—" → "-".
- **Don't over-engineer string-vs-comment isolation.** A hand-rolled JS tokenizer drifts on regex
  literals. Since there's no logic dependency, replacing inside comments too is harmless (comments are
  stripped from the minified bundle and never render) - accept the wider diff rather than risk a
  fragile parser.
- **Verify by absence.** After rebuilding the mins, grep the SERVED bundles (`js/min/*` + the minified
  CSS) for the character → expect 0. `node --check` every js file to confirm no replacement broke a
  regex.

### F.57.4 Verification + test maintenance for UI removals
- **Source edits are invisible until the mins rebuild** (see F.55.1). After ANY UI/source change run
  the min-CSS and min-JS builders before the cache bump - this is the single most repeated trip-up.
- **Removing a feature means updating its test to assert ABSENCE, not deleting the test.** When a
  filter card / badge / section is removed, rewrite the spec to assert the elements are gone
  (`toHaveCount(0)`) and the surrounding view still renders (e.g. the full unfiltered grid). A stale
  test that still asserts the removed element EXISTS will go red in CI.
- **Local SPA route-content may not render under a bare static server.** Serving the app at a plain
  `localhost:PORT/` (or a sandbox preview) can leave the router stuck on the loading skeleton (base-
  path / data-fetch / SW timing), even though production is fine. Use the project's dedicated test
  server (the Playwright `webServer`) for UI tests, and do NOT conclude "the app is broken" from a
  local skeleton. As a deploy-safety gate that does NOT need a browser, `node --check` the MINIFIED
  bundles (the minifier can in theory mangle output a source-only check would miss) and rely on CI's
  browser run for render assertions.
- **Beware over-broad test selectors.** A selector like `.brand-link` that matched one element can
  silently start matching two after a header/levels change, tripping the test runner's strict mode.
  Prefer a selector scoped to the specific element. (Flag pre-existing fragility to the owner rather
  than silently rewriting tests outside the current change's scope.)
- **Register every review finding in the bug sheet with status + a real fix commit** (hash, or a
  `<deferred-...>` sentinel for deferred items, per the Fix-Commit-shape invariant). Group a session's
  findings under a clear prefix; the changelog carries the narrative, the bug sheet carries the
  canonical status.

### F.57.5 Static SEO/no-JS mirrors lag the SPA - flush them deliberately
A cache-bump deploys the SPA data path immediately, but the pre-rendered static mirror pages keep
serving OLD content until regenerated. After a batch of data/UI corrections, regenerate the affected
mirror stage (pure-Python generator; runs reliably even where the SPA won't boot locally) + re-inject
the app header/footer, and verify a corrected value flushed through. Note that the mirror generator
may render a DIFFERENT (often simpler) subset than the SPA - confirm which fields it emits before
assuming an SPA-only issue (e.g. a candy/homophone row) even exists on the mirror.

## Appendix F.58 - Deriving a learner-facing reference from a SEED corpus: verify completeness, label provenance, expect native passes to iterate (added 2026-06-09)

A request to produce a learner-facing grammar reference (Pattern / Meaning / Usage / 3 examples
per item) "from the existing corpus" exposed a chain of traps that apply to ANY Nx deliverable
built on a level's data files. The corpus LOOKED authored; it was a seed.

### F.58.1 "Exists" is not "authored" - verify field-level completeness before trusting a corpus
A level's `data/*.json` can be a SEED: the catalogue (id, pattern, one gloss) is populated while
the pedagogical fields (examples, form_rules, common_mistakes, explanation) are empty placeholders.
The grammar seed in this case carried 128 patterns with `meaning_en` on all of them, but
`examples: []` and empty `form_rules` on all 128, plus a SINGLE curated example per pattern living
in a separate `KnowledgeBank/grammar_examples_*.md`. The `_meta.history` literally said "examples +
form_rules to be authored." Before treating any corpus as a source for a deliverable, COUNT
populated-vs-total per field (not file existence) and grep for placeholder markers ("(to be
authored)", empty arrays); report the completeness matrix up front. Do not call a seed "audited" -
if it never went through the Section 19 native pass, say so. (Related signal class: the file/field
exists but is a template default - see F.52 / F.54.)

### F.58.2 Fill gaps with model-generated content only under explicit provenance; keep the raw extract pristine
When the deliverable needs fields the seed lacks, generating them is legitimate FOR A DRAFT, but:
(a) provenance-tag every field at the line level - `[corpus]` (verbatim), `[corpus-fixed]` (corpus
content corrected this pass), `[AI-gen]` (model-authored, not native-reviewed); (b) carry a
disclaimer that AI-generated Japanese is machine-checked only and is not a substitute for native
review; (c) apply corrections through an OVERRIDE layer in the builder, leaving the extracted corpus
data unmodified, so the raw-vs-rendered distinction stays auditable. IMPORTANT boundary with F.56:
provenance tags belong ONLY on an internal review/draft artifact whose audience is the owner/author.
They must NEVER appear on the learner-facing product.

### F.58.3 The seed's OWN content needs the same audit as new content
A native pass found defects in the seed itself, not only in the generated fill: an example that did
not demonstrate its pattern (the `くする` i-adjective pattern illustrated with `へやを きれいに します`,
which is actually `na-adj + にする`); loose or wrong glosses (`または` glossed "both"; `つづける`
glossed "keen on"); and an awkward grammar combination modeled as canonical (`ようだ` shown as
`ふりそうな ようです`, stacking `そう` + `よう`). Treat a seed's curated examples as UNREVIEWED until a
native pass clears them, and audit them with the Section 19 playbook exactly like freshly authored
content - the same defect classes F.54.3 lists for kanji example words apply to grammar examples.

### F.58.4 Native passes iterate - state bounded coverage, never "done"
Two native review passes each surfaced a NEW item the previous automated checks had not (pass 1: a
batch; pass 2: one more malformed hybrid the pass-1 token list had not anticipated - see F.59.3).
Automated scans can cover the MECHANICAL classes (kanji-scope, malformed-hybrid); naturalness,
pedagogy, and gloss accuracy need human judgment and tend to reveal a fresh item per pass. Per the
Rule-4 writing discipline, report "all KNOWN issues fixed; class X clean against the snapshot
scanned," not "done." The fastest path to true closure is ONE full native sweep of every item, not
iterative spot-checks - offer that explicitly rather than implying a spot-checked draft is final.

## Appendix F.59 - Kanji-scope bounding creates malformed kanji+kana hybrids that a character-whitelist scan cannot catch (added 2026-06-09)

This promotes the one-off already noted in F.54.3 (`手つだって` -> `てつだって`) into a STANDING gate,
because the same defect recurred across a 128-pattern x 3-example deliverable and a per-character
kanji-whitelist scan reported it clean.

### F.59.1 The anti-pattern and the rule
To keep a word inside the level's kanji whitelist, the temptation is to replace ONLY the out-of-scope
kanji of a multi-kanji word with its kana reading, leaving a kanji+kana hybrid: `問題`->`問だい`,
`京都`->`京と`, `会議`->`会ぎ`, `試合`->`試あ`, `間違い`->`間ちがい`, `手伝う`->`手つだう`,
`一度`->`一ど`, `何度`->`何ど`, `週末`->`週まつ`, `富士山`->`ふじ山`. These read as a broken /
half-finished kanji conversion and a native reviewer flags each one. RULE: a word whose canonical
form needs an out-of-whitelist kanji is written WHOLE in kana (`もんだい`, `きょうと`, `かいぎ`,
`まちがい`) - never split mid-word. (If the deliverable is NOT whitelist-bound - e.g. a standalone
reference rather than the site corpus - prefer the full correct kanji, optionally with furigana;
decide the orthography policy per deliverable and apply it uniformly.)

### F.59.2 Why a character-level whitelist scan passes the hybrid
The retained kanji (問, 京, 会 ...) IS in the whitelist, so a scan that checks each kanji character
against the allow-list reports 0 violations. The malformation lives at the WORD / orthography level,
not the character level. A scope check and an orthography check are DIFFERENT checks; passing the
first says nothing about the second.

### F.59.3 Detect with a GENERAL boundary scan, not a curated bad-token list
A curated list of known-bad hybrids only catches the cases you already enumerated. In this session a
pass-1 list (`問だい`, `京と`, ...) cleared the doc, yet a native pass-2 found `間ちがい`, a hybrid the
list had not anticipated. The reliable method: extract EVERY `(kanji-run)(immediately-following
hiragana-run)` token from the RENDERED artifact, dedup, and review the full set - legitimate
okurigana (`行きます`, `始める`, `高い`) sits alongside the malformed forms, and a human or a
dictionary / morphological check separates them. Because the extractor surfaces ALL kanji->kana
boundaries, an un-anticipated hybrid is surfaced for review rather than missed. Run it on every
authored or generated Japanese surface (example sentences, usage notes, glosses, pattern names), not
only the cited items - the same horizontal-deployment discipline as any fix batch.

### F.59.4 Wiring + bounded claim
Candidate CI invariant (JA-NN) for any level that authors Japanese: flag tokens of the form
kanji-then-hiragana whose combined span is not in a maintained allow-list of legitimate okurigana
verbs/adjectives; everything else is surfaced for review. Until that is wired, the general scan is a
detection AID, not a guard - state coverage as "no malformed hybrid in the N tokens scanned for this
snapshot," not "none exist." Pair it with the kanji-scope scan; the two are complementary (F.59.2),
and neither alone is sufficient.

## Appendix F.60 - The English gloss must cover every example shown; usage must license each example (added 2026-06-09)

Multi-pass native review of the same 128-pattern x 3-example deliverable (see F.58, F.59) surfaced a third
recurring class, distinct from the mechanical kana/kanji defects: SEMANTIC gloss-coverage drift. It recurred
in opposite directions across consecutive rounds (an over-listing gloss in one pass, a too-narrow gloss in
the next), so it is promoted to a standing review pass, not a one-off.

### F.60.1 The anti-pattern and the rule
A pattern entry carries one short English meaning plus 2-3 example sentences. The gloss tends to get written
to fit example #1 (commonly the seed-corpus example), while examples #2-3 - often model-generated to add
variety - exercise OTHER senses or functions of the same form. Two failure directions:
- TOO NARROW: gloss `named; called ~` for casual `って`, while example #3 (`あした 雨が ふるって。`) used the
  casual hearsay-quote sense ("I hear it'll rain tomorrow"). The learner cannot map example #3 to the meaning.
- OVERREACH: a gloss lists senses (`reason for ...`) that none of the shown examples demonstrate (the
  cleft-focus `のは～だ` case). The learner is told a sense the entry never illustrates.
The rule: the gloss must be the UNION of exactly the senses the displayed examples exercise - no narrower
(every example must be reachable from some clause of the gloss) and no broader (every gloss clause must be
earned by at least one example). The usage line must likewise name the attachment + sense for each example,
so each example is licensed - e.g. `N + って (= という/とは: called; as for) / plain form + って (= casual quote)`.

### F.60.2 Detection: a meaning<->example reconciliation pass
For each entry, map every example sentence to the gloss/usage clause that licenses it:
- example with NO licensing clause  -> gloss is too narrow (extend it, OR swap the example for an on-sense one).
- gloss clause with NO supporting example -> clause is unsupported (add an example, OR trim the clause).
This is the semantic analogue of the seed-completeness pass (F.58) and the hybrid scan (F.59), but it is NOT
mechanizable by character- or count-level gates: a kanji-scope scan and a "exactly 3 examples each" count
both PASS a semantically-miscovered entry. It needs human (or sense-tagged) judgement per entry.

### F.60.3 High-risk set, bounded claim, candidate invariant
Highest risk: forms that are particles or sentence-enders with several grammatical FUNCTIONS, where one
surface form spans naming / topic / quote / hearsay / cause / contrast - e.g. `って`, `と`, `し`, `から`,
`のに`, `ば`/`たら`. Audit their gloss-coverage explicitly; single-function content words rarely drift.
Report bounded: "gloss covers the senses exercised by the examples shown, for the M patterns reviewed,"
never "gloss complete." Candidate review-time invariant (not fully automatable without sense tags): flag any
entry whose gloss is a single short sense while one of its examples contains a quotation / hearsay / topic /
contrast-marker variant of the form, and surface it for native review. Pair with F.58/F.59 - mechanical
scans catch kana/kanji/count; this pass catches the meaning<->example mismatch; neither substitutes for the
other.


## Appendix F.61 - A kanji card can be dictionary-correct and still teach nothing: attribution, orthographic convention, and the checks that catch each (added 2026-08-28)

**Context.** A native-teacher pass over a finished N4 kanji book (170 cards / 633 examples / 245
practice items) returned 11 findings AFTER the corpus already passed a JMdict POS+priority gate and a
MeCab okurigana/temporal gate with zero findings. Every example word was a real word with a real
reading. The defects were in the relationship between a card and its own examples, and in
orthographic convention - neither of which a dictionary-validity check can see.

**The check classes worth adding at any Nx level.**

1. **READING ATTRIBUTION.** For each example on kanji X's card, does its reading actually use one of
   the readings THAT CARD teaches (allowing rendaku / handakuon / gemination)? A word can be perfectly
   attested and still be underivable for the learner: 支度(したく) reads 度 as タク on a card teaching
   only ド and たび. The book already had a `special` flag ("learn it as a whole word") on 11 such
   examples; the gate is that the flag be applied CONSISTENTLY, not that irregulars be banned.
2. **READING COVERAGE, weighted by frequency.** Which listed readings does no example demonstrate?
   Raw, this over-reports: 87 of the corpus's readings were unexemplified and most were legitimately
   rare. Two cuts make it actionable: (a) is the card's PRIMARY reading exemplified (0 failures here,
   because the design already enforced it), and (b) is an unexemplified reading a CORE word one level
   down? 夜=よる, 家=いえ and 習う were all N5/N4 basics absent from their own cards while every example
   was an on-reading compound.
3. **ORTHOGRAPHIC CONVENTION.** JMdict's `uk` (usually written in kana) tag against words printed in
   kanji. Needs human triage - 犬, 目, 会う, 味噌 carry `uk` on a minor sense and are properly written
   in kanji - but it found a card whose 3 of 4 examples (無い/無し/無くなる) are normally kana, which
   drills a spelling the learner will rarely meet.
4. **GLOSS-vs-TARGET on answer keys.** Answer keys that print `word (reading) . meaning` are a
   copy-paste hazard: two entries carried a neighbouring item's gloss (屋上 . "typhoon" from the 台風
   item; 借りました . "debt; loan" from 借金). Both CONTRADICTED their own explanation one line below,
   so a cheap high-signal invariant is: the gloss field must share a content word with a dictionary
   sense of its own target word.
5. **REGISTER CONSISTENCY WITHIN AN ITEM TYPE.** 22 of 62 orthography carriers ended plain while 40
   ended polite. Fix WITHOUT touching the underlined target or the options by embedding the plain
   verb in a polite frame the corpus already uses (`~のが すきです`, `~ことに しました`, `~そうです`).
   Write the added frame in KANA ONLY so no new kanji enters a per-chapter cumulative scope pool -
   otherwise the scope validator fails and the "fix" costs a second round.
6. **WAKACHI-GAKI PARTICLE FLOATING.** In a spaced-for-young-readers corpus, a particle must attach to
   the word it marks. `e wo kaku` written with the particle free of its noun mis-teaches phrase
   boundaries. One regex over every sentence and option finds it.
7. **SCRIPT MISMATCH IN A FIELD USED FOR EQUALITY.** 7 cards printed no bold primary reading because
   `primary_reading` was stored in hiragana while the `on` list was katakana, so the renderer's
   `reading == primary` test silently never matched. Any field whose ONLY job is to match another
   field by equality needs an invariant asserting membership, not just non-emptiness. Generalises
   F.54: a derived field can be well-formed and still never fire.

**False-positive classes to pre-empt (these cost the most review time).**

- **Kana-headword collision.** Looking up a kana surface in a dictionary returns every homograph:
  おおい -> "hey!", ことり -> "clink", あく -> "a spring wind". Always look up the KANJI form, or
  constrain by the reading, before flagging a gloss.
- **English stemming mismatch read as a gloss error.** "sells" vs "sell", "characters" vs
  "character", "uneasy" vs "uneasiness" are not defects. Compare stems or accept substring matches
  in either direction.
- **Line-filtered greps that hide the source of a value.** A card appeared to gloss the verb as
  "debt; loan" until the filtered-out neighbouring line showed the gloss belonged to a different
  example on the same card. Read the whole block before reporting.
- **Positional line diffs after an insertion.** A change-guard style line diff reports every line
  after an inserted line as CHANGED. Diff the line MULTISETS instead to see only content that truly
  entered or left; trust ADDED/REMOVED over CHANGED.

**Reporting discipline.** State the finding count against the surface actually scanned ("11 findings
over 170 cards and 245 items in this build"), name the discarded false positives and why, and keep
judgement calls (register, coverage-by-frequency) separate from outright errors (a wrong gloss). Of
11 findings here, 4 were flatly wrong Japanese, 3 were convention, 3 were internal consistency and 1
was a rendering bug - a single "11 errors" headline would have overstated all but four.


## Appendix F.62 - Page furniture that ignores the chapter variable, and decoration that silently joins the layout flow (added 2026-08-29)

**Context.** Two reader complaints on a finished Nx workbook - "the review pages are too loud" and
"the opener hero sits low" - both turned out to be single-line CSS defects rather than taste, and
both were invisible to every automated gate the project runs (pagination, font embedding, content
integrity, balance). They are worth checking for by construction at any level.

### 1. Themed furniture that hard-codes one theme's colour

A per-chapter book carries a colour variable per chapter (accent + page tint). If any shared
component hard-codes the FIRST chapter's accent instead of reading the variable, it looks correct
for chapter 1 and wrong for every other chapter, and nobody notices because chapter 1 is what gets
reviewed. Here `.mhead`, the example-box border and its label all used the world-1 green, so **12 of
14 chapters printed green section bars on a non-green page**: four competing hue families on a single
spread. The fix is to set a CSS custom property on the page section from the chapter's own accent
and have every component read `var(--acc, <fallback>)`; keep the fallback so standalone previews
still render.

**Check to add:** render one page from a NON-FIRST chapter and diff its fill colours against the
chapter's declared accent. Any component still emitting chapter 1's accent is the bug. A one-page
colour census (collect every `fill` in the page's drawing list, group by hex) makes this a
five-second check, and it is how the defect above was found.

### 2. `position:relative` on decoration keeps it in the layout flow

Ornaments positioned by explicit coordinates are absolute by intent. If a later rule re-declares
them `position:relative` - a very common way to "make z-index work", which absolute positioning
already permits - they stay in the flow and OCCUPY LAYOUT SPACE while their `top:` offsets move them
somewhere else visually. The symptom is a centred block that is not centred, with no obviously
wrong number anywhere in the CSS.

Measured here: four ornaments occupied **97.5mm of a 176.6mm flex column (56%)**, leaving 2.4mm of
free space, so `justify-content:center` had nothing to distribute and the hero sat 2.2:1 low. Note
the second-order trap: an SVG with `width:20px` and no height resolves to the **150px default
height**, so a 20px star was contributing 39.7mm of column. Sizing decoration by width alone is
therefore doubly dangerous inside a flow.

Note also the compensating hack that had accumulated on top: a `padding-bottom` had been added to
drag the hero up out of the packed column. Once the real cause is fixed, that compensation
over-corrects in the opposite direction and must be removed in the same change - and any ornament
coordinates tuned against the broken layout must be re-tuned, because they were calibrated to the
bug.

**Check to add:** for any page template that centres content, assert in the browser that the set of
in-flow children is exactly the set you intend. `getComputedStyle(el).position` on every child of the
centring container, with decoration expected to report `absolute`, catches this class immediately.
Static CSS reading cannot settle it when two rules contradict each other.

### 3. A fill that separates by hue but not by value is noise, not hierarchy

The "loud" page also carried tinted meta boxes at **luma 238 against a page tint of luma 239**. They
read as an extra colour family while doing no hierarchy work whatsoever. Two lessons: (a) judge a
tint by its VALUE distance from what it sits on, not by whether it "looks subtle"; (b) the surface a
block sits on is the one that matters - these boxes sat on a 253 panel, so the meaningful step was
253 vs 238, and the near-identical page tint was a red herring because the two never touch.

Deriving the wash from the chapter accent (about 10% into the panel colour) gives an identical value
step in every chapter while the hue always belongs to that chapter. Verify the mixed result in the
PRINT engine, not just the dev browser, and confirm the computed hex - `color-mix()` silently
falling back would leave the block unstyled.

**Anti-pattern to avoid:** removing the fill entirely. That was tried here and merged the worked
example into the numbered questions it was meant to be distinguished from. Reach for a smaller step,
not no step.

### 4. Do not read a threshold gate flipping green as a fix

A balance gate that had failed for three builds went green in this pass. It was NOT fixed: the
page's empty-band measurement was unchanged (116 -> 117 rows against a 103 limit) and only the ink
fraction drifted 0.353 -> 0.332 across a 0.350 cut, because an unrelated padding change reflowed the
page. Any gate combining two thresholds with AND will flip on incidental reflow. When a long-standing
failure disappears in a change that did not target it, measure the underlying quantities before
recording it as resolved, and say so explicitly in the register.


## Appendix F.63 - Sweeping a book for vertical-balance defects: scoping the population, and choosing the extent you measure (added 2026-08-29)

**Context.** A reader reported one page whose content group "sits 20-30px low". Sweeping all 388
pages instead of fixing that page found the same defect class on 17 further pages across three more
templates, and two of the three causes were the SAME recurring anti-pattern. Fixing only the reported
page would have left the rest.

### Scope the population before measuring

Not every page can be asked "is the content group centred". Split templates in two:

- **Display templates** - a discrete content group floating in a field (title pages, section
  dividers, colophons, credits, openers). Centring is meaningful; measure them.
- **Panel-filling templates** - a card or panel that spans the page by construction (lesson pages,
  exercise pages, answer keys). Their content is SUPPOSED to reach both edges. Measuring them for
  "balance" produces confident nonsense.

Here that was 33 display pages out of 386. Reporting the other 353 as defects would have buried the
real finding.

### The extent you measure decides the answer

Two natural choices, and BOTH mislead on their own:

- **Box-inclusive extent** (text plus drawn rectangles) counts decoration as content. Ornaments and
  tape are as wide as real panels, so no size filter separates them: this reported the already-fixed
  world openers as 17mm out.
- **Text-only extent** ignores empty structural boxes. On a panel-filling template whose writing
  cells are empty, it sees only the top of the page and reports a huge false imbalance.

Use text-only extent, restricted to display templates. That combination matches what a reader
perceives, because on those templates every real panel contains text while decoration does not.
Always exclude page furniture (running head, folio, author line) from the extent - it is fixed by
design and including it flattens the very difference you are looking for.

### Two causes, one of them recurring

1. **Leftover compensation padding.** A `padding-bottom` added to drag a group out of a layout it no
   longer sits in. Seen twice in one book (42mm on the world divider, 20mm on the answer-key divider)
   and once as asymmetric container padding (4mm top / 8mm bottom) that quietly biased a
   `space-evenly` group upward. Whenever you fix a layout cause, grep the template family for
   padding values that existed only to compensate for it - they now push the opposite way.

2. **Optical versus geometric centring.** One page measured PERFECTLY centred (group centre 114.25mm
   against a container centre of 114.3mm) and still read low, because the group was top-light and
   bottom-heavy: a weightless decorative icon and plain text on top, a bordered card and a filled
   pill at the bottom. This is a real typographic phenomenon, not a bug, and the fix is a deliberate
   optical offset. Two rules: derive the offset from a measurement (here, balancing the TEXT mass
   needed 10.5mm) rather than nudging by eye, and COMMENT it in the CSS as an intentional optical
   correction, or a later tidy-up will "restore symmetry" and reintroduce the complaint.

**Report shape.** Give the before/after delta per template with the page count, and state explicitly
which templates were examined and found correct, and which were excluded as out of scope and why. A
sweep that only lists what changed cannot be distinguished from a sweep that missed things.

## Appendix F.64 - A generator whose parser has drifted from its source destroys the data it claims to build (added 2026-09-29)

**The shape.** A project designates a markdown KnowledgeBank as the source of truth and a script
that parses it into JSON. Over months the markdown is edited by hand and its conventions evolve;
the JSON is edited by hand too, through review cycles. Nobody runs the generator, because
everything already works. The generator's parser silently stops matching the markdown. It now
returns EMPTY records for every entry - not an error, empty - and because a merge step writes
whatever keys it is handed, one run overwrites every field it owns with nothing.

On N4 this emptied on/kun/meanings across all 170 kanji, emptied the primary reading of 167 of 252
entries, cut a 249-glyph whitelist to 170, and took the content-integrity checker from 27
violations to 160. The markdown had moved from `- On:` / `- Kun:` / `- Meaning:` (capitalised,
ASCII-comma) to `- on:` / `- kun:` / `- meanings:` (ideographic comma, katakana on-yomi preserved,
okurigana preserved, `(none)` for empty, an explicit `- primary: R  (kind: on|kun)` line, and
`secondary_on:` / `secondary_kun:` sub-bullets). Not one of those matched.

**Rules, in the order they matter.**

1. **Never run a regenerator against live data to find out what it does.** Copy the source tree and
   the outputs into a scratch directory, run it there, and diff every output against the real file
   before it is allowed anywhere near the repo. The diff is the specification of what the tool
   currently believes.
2. **An empty parse is a failure, not a result.** If a parser produces a record with no readings,
   no meanings and no primary, raise. The single line `if all-fields-empty: raise` is the whole
   difference between a loud failure and a silent wipe. Assert on the aggregate too: parsing N
   entries and finding N of them empty is a dialect change, not a data problem.
3. **A generator must never delete.** An entity present in the output with no entry in the source
   is an ERROR to surface, not a row to drop. Dropping it takes every hand-authored field with it -
   examples, notes, review status, stroke data - none of which the generator could regenerate.
4. **Scope the generator to what it can actually own.** The N4 script wrote five files; it had a
   merge-preserving path for one of them. The other four were naive overwrites that discarded
   hand-authored fields, refilled a deliberately-empty file, and rebuilt a UNION whitelist from a
   catalogue that holds only half the union. Quarantine the paths a tool cannot do safely, and
   record the measurement that condemned each one in the file, next to the dead code.
5. **Check which side is actually stale before choosing a direction.** The instinct is source ->
   derived, because that is what the header says. Here 21 of 143 markdown entries were BEHIND the
   JSON, which had been corrected through review and corroborated against KANJIDIC2. Regenerating
   would have reverted verified content. The reconciliation ran derived -> source once, then the
   normal direction became a no-op.
6. **The no-op is the proof.** After reconciling, `build --report` must print zero changes and
   re-running the sync must report zero edits. Two tools that are each idempotent against the
   other is what "this file is the source of truth" actually means. Assert it in CI: a glyph-set
   equality check (does the source list the same entities?) says nothing about whether any ENTRY
   is in step, and the entry contents are where this drifts.
7. **Run the release-blocking checker, not just the domain verifier.** The domain verifier
   (readings exist in KANJIDIC2, stroke counts match) passed throughout. The cross-file invariants
   are what caught both the original wipe and, later, a subtle regression the rewrite introduced.
8. **Two files can use the same field name for different questions.** A catalogue's `primary`
   reading is the headline reading in catalogue form (katakana on-yomi, okurigana attached); a
   furigana file's `primary` is what you would write as ruby over the bare glyph (kana, bare).
   They coincided for 167 of 170 entries, which is exactly enough agreement to make mirroring one
   onto the other look correct. An override table that looks like legacy cruft may be the only
   thing encoding the distinction: find out what fails when you remove it before removing it.
9. **Mutation-test a new invariant.** A guard that has only ever passed proves nothing. Inject each
   regression it claims to catch, confirm each fails, and restore from bytes held in memory with a
   sha256 equality check. Assert the mutation actually applied - a string anchor that silently
   misses makes the test report a pass it never earned.
10. **Line-based change guards mislead on structured files.** Inserting a nested object shifts
    every following line; a text-mode guard then reports thousands of CHANGED rows and buries the
    real edit. Reconstruct the pre-edit file from the snapshot and diff it key by key.
