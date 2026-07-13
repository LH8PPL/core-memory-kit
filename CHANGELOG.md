# Changelog

All notable changes to claude-memory-kit are documented in this file.

The format is based on [Keep a Changelog](https://keepachangelog.com/en/1.1.0/) and this project adheres to [Semantic Versioning](https://semver.org/spec/v2.0.0.html).

## [Unreleased]

<!-- New user-facing capabilities land here in the same PR that ships them (CLAUDE.md "Document user-facing capabilities" rule). -->

### Added

- **Codex support** — `cmk install --ide codex` wires OpenAI's Codex end-to-end: hooks in `.codex/hooks.json` (SessionStart recall-inject, prompt + turn capture — the turn read from the session's rollout file, edit observation, and the PreToolUse delete-guardrail), MCP registered through Codex's own `codex mcp add` (your `config.toml` is never hand-edited), a managed `AGENTS.md` block, and the automatic memory engine running through `codex exec` (read-only sandbox, your existing ChatGPT/Codex login — no API key). `--backend codex` routes split-brain background memory through Codex from any install. One-time step: run `/hooks` inside Codex once to trust the kit's hooks. Docs: `docs/CODEX.md`. (Task 196 tail, [#284](https://github.com/LH8PPL/claude-memory-kit/pull/284))

### Fixed

- **Live MCP recall freshness (CLI parity)** — a running `cmk mcp serve` now picks up facts written by another process mid-session (a Stop-hook auto-extract, a `cmk remember` in another terminal, a second editor window) immediately, instead of only seeing them after a restart. Every MCP read tool now refreshes the index before reading, exactly as every CLI read already did. (Task 218, D-329)

### Added

- **CLI↔MCP parity params** — the MCP tools gained three options their CLI counterparts already had: `mk_search` now takes `include_expired` (surface facts past their declared expiry, hidden by default), `mk_lessons_promote` takes `section` (override the landing section), and `mk_forget` takes `deleted_by` (audit provenance). (Task 218, D-329)

## [0.5.1] — 2026-07-12

### Security

- **Every path into your committed memory is now screened for secrets — not just the direct write
  commands** — Poison_Guard previously screened `cmk remember`/auto-extract writes, but LLM-summarized
  content and promotions skipped it: a secret pasted in conversation could survive the nightly
  summary **verbatim** into git-committed `recent.md`/`archive.md`, a pasted API key rode transcript
  promotion (the PII judge only knows names/emails), the persona-review queue took classifier output
  unscreened, and `cmk trust <id> high` would bless old content past patterns added since it was
  written. All of these now screen through one shared gate: summaries are checked before AND after
  the model call (a poisoned source day costs a regex pass, not a nightly model bill), a poisoned
  transcript batch is withheld with a content-free marker (the raw text stays in your local buffer),
  and a trust increase re-screens the content against the current pattern catalog first. Every
  rejection is logged redacted — the secret itself never lands in any log. (Task 216, D-320;
  design §6.7.1.)

### Fixed

- **`cmk install` no longer nags about running MCP servers** — when kit MCP servers were running, a
  plain project install used to print a multi-line warning (a PID list + a DLL-lock caveat) and ask
  `[y/N]` whether to stop them. But a project install never touches the locked global files — only an
  `npm install -g` upgrade can — so the whole thing was noise on the common path, and the answer was
  always "no". The install is now silent about running servers and just reports what it did; if a
  global *upgrade* ever half-breaks on a locked file, the recovery message already tells you exactly
  how to fix it. (Task 222.)

- **A duplicated CLAUDE.md / instruction-file block is now folded on install and fully removed on
  uninstall** — if your CLAUDE.md (or a Kiro steering / Cursor rules file) ever ended up with two
  kit-managed blocks (a copy-paste, or a merge conflict resolved by keeping both sides), re-running
  `cmk install` refreshed only the first block and left the stale duplicate behind forever, and
  `cmk uninstall` also removed only the first — contradicting the clean-removal promise. Install now
  folds all managed blocks into one (your own content around and between them is preserved),
  uninstall removes every block, and `cmk doctor` (HC-9) flags a duplicate with the fix. (Task 220.)

- **The nightly memory-distill no longer pops a black console window on Windows** — the 23:00
  scheduled task launched `node.exe` directly, so Windows opened a visible console window over
  your screen for the run's duration. `cmk register-crons` now registers the task to run through
  a tiny windowless launcher, so the nightly distill (and weekly curate) run invisibly. (Task 215;
  re-run `cmk register-crons` to apply.)

- **Hook payloads are now parsed BOM-tolerantly across every hook bin** — a leading UTF-8 byte-order
  mark on a hook's stdin (some agents/platforms prepend one) made the bin's JSON parse throw and
  silently no-op. For the delete-guard bin this was a fail-open: a BOM-prefixed destructive command
  slipped past unblocked. All 11 hook bins now share one BOM-tolerant parser (a regression is caught
  at test time, not in a live session). Latent on Claude Code (it doesn't emit a BOM); this closes the
  class before any agent triggers it. (Task 207.)

- **The session-start commit offer can no longer sweep in the un-screened turn buffer** —
  the kit's "N memory files are uncommitted — commit them?" proposal offered all of
  `context/`, including `sessions/now.md`, the one file the privacy screen hasn't fully
  processed yet (names are masked at its roll, not at write). Accepting the offer before
  the roll could commit a raw personal name. The proposal now excludes the pre-roll buffer
  from both the count and the offer; its content lands (screened) in the daily summary the
  next offer covers. (Task 206.)

- **A half-broken upgrade is now self-diagnosing instead of a cryptic crash** — on Windows,
  upgrading the global package (`npm install -g`) while a kit MCP server was running could
  half-break the install (locked DLLs), after which every `cmk` command died with a raw
  module-not-found stack. Now `cmk` detects the half-install and prints the exact 2-step
  recovery (stop the servers → reinstall). (Task 205; the running-server heads-up that
  originally shipped with this was refined by Task 222 — see above — so a plain `cmk install`
  stays quiet.)

- **Daily distill no longer silently starves on a busy repo** — the nightly rolling-summary
  (`recent.md`) could go days stale on a large/busy project without any warning: the scheduled
  job was killed mid-run (a sleeping laptop at 23:00), the health check falsely reported it
  healthy, and the session-start fallback was shadowed by the more-frequent session roll. Now:
  the distill is **resumable** (it processes one day at a time and banks each, so a killed run
  keeps its progress and the next run continues); `cmk doctor`'s scheduled-compaction check
  now **verifies the actual output freshness** instead of just that the job fired (no more
  false "healthy"); the session-start fallback **also runs the daily distill** when it's due;
  and `cmk register-crons` now registers the nightly job with **WakeToRun** so the machine
  wakes to finish it. (Tasks 203/204, ADR-0020.)

## [0.5.0] — 2026-07-10

### Added

- **AUTO-JUDGED PRIVACY: sensitive content is screened out of your committed memory automatically (Task 148, ADR-0019).** Your project memory is committed to git and may be public — so the kit now screens for personal/sensitive content at every write, on two boundaries, with no command to run. (1) **Transcripts**: each turn is buffered to a gitignored `*.live.md`, and a deterministic pattern pass masks emails / phone numbers / your OS username BEFORE anything touches disk; the buffered turns are then batch-screened by an async Haiku judge (adapted from Anthropic's PII-purifier prompt — it also catches names, addresses, and health details in prose) and only the screened text is appended to the committed `{date}.md`. If the judge is unavailable the turns stay in the gitignored buffer and retry next session — never an unscreened commit (an honest degrade to native-Claude-Code behavior). (2) **Facts**: the auto-extract classifier now tags each candidate `commit` (default) / `local-only` / `drop` — `local-only` (useful but sensitive) routes to a gitignored `context.local/private.md` instead of the committed tier, and `drop` isn't saved at all. A kill-switch (`privacy.screen: off` in settings) turns the screen off; a machine-local `context/.locks/redactions.log` records every redaction so a false positive is locally recoverable. The explicit `cmk remember` path keeps the deterministic mask; the `<private>…</private>` tag remains the surgical override.
- **learn-loop: THE STOP-HOOK JUDGE (Task 192, ADR-0017 Phase 1c)** - the loop CLOSES: four deterministic outcome detectors now ride the existing hooks (no LLM, no ritual): a failing tool call dampens the facts the model just searched (attributed via the recall-log); a user correction dampens the prior turn's ids and resolves pending expectations MISS (REVERSAL on revert-phrasing - the strongest oracle-free signal); a search that only re-fetched already-injected ids registers a recall-miss dampen (re-surfacing is never reinforcement); an expectation that survives the turn window with nothing fired resolves WEAK-POSITIVE. Every delta routes through the feedback-screen (rate-limited, burst-held, audited).
- **learn-loop: EXPECTATION PRE-REGISTRATION + JUDGMENT FILES (Task 191, ADR-0017 Phase 1b)** - the earned-judgment wedge: a `PREDICTION: <specific outcome>` line in any assistant turn is captured automatically by the Stop hook as a pending expectation; resolutions (HIT/MISS/REVERSAL) append to `judgment_<slug>.md` records - method-preferences that carry their baseline, replication count, and an append-only evidence log. Misses lock, hits only nudge, preference cycles surface as `contested`, and a judgment expires (`decays_after` rides the expiry machinery). Judgments are loop-born: `cmk remember` cannot write them.
- **learn-loop: FEEDBACK-SCREEN (Task 193, ADR-0017 Phase 1d)** - every trust-score mutation now routes through a screen inside `applyTrustSignal`: per-fact daily rate limit, burst-hold quarantine (a same-day storm of negative signals holds further dampens instead of applying them - a systemically-wrong judge can no longer mass-dampen good memories), and every delta is audit-logged. Decisions + refusals are visible at `context/.locks/trust-signals.log`. Fail-open: a broken screen never blocks the primary write.
- **learn-loop: RECALL-LOG (Task 190, ADR-0017 Phase 1a)** — the kit now records which memory IDs surfaced each turn (`context/.locks/recall.log`, NDJSON, gitignored local diagnostic): the SessionStart inject logs the snapshot's surviving citation ids, and `cmk search`/`mk_search` log each query's returned ids. IDs + query only, never content; best-effort (can never break injection or search). This is the attribution primitive the v0.5 learn-loop's outcome signals resolve against.

### Fixed

- **Cursor on Windows now captures your session automatically — it was silently doing nothing before.** Two Windows-only defects, both found by driving a real Cursor 3.5.17 session in the v0.5.0 cut-gate: (1) Cursor prepends a UTF-8 byte-order-mark to the JSON it pipes to its hooks, which made the kit's parser throw and treat *every* hook as an unknown event — so capture/recall/observe fired but did nothing, and `context/sessions/now.md` stayed empty though the hooks ran; (2) Cursor passes the project root as `/c:/Your/Project` (a leading slash before the drive letter), which resolved to a dead path. Both are fixed, so automatic capture/recall/observe now land in your real project on Windows. macOS/Linux were unaffected (no BOM, normal paths).
- **Kiro IDE now captures what you *say*, not just what the assistant does — so automatic memory works there like it does in Claude Code.** On the Kiro IDE, the kit relied on Kiro's `USER_PROMPT` hook variable to capture your prompt, but on Kiro IDE 1.0 that variable arrives empty (a Kiro-side regression — their open issues #9619/#6188). The result: your turns weren't captured, so the automatic fact-extraction never saw your stated preferences and silently saved nothing (explicit `cmk remember`, recall, and the cross-project cold-open still worked). The turn-end capture now recovers your prompt directly from Kiro's own session transcript — which is reliable — so a preference you state casually ("I always use httpx, never requests") gets captured and extracted automatically, no command needed. Claude Code and kiro-cli were unaffected.
- **The screened transcript no longer stalls on a slow-model day.** The async privacy judge (the L3 pass that promotes screened turns into the committed transcript) had a 20-second timeout — too tight when the model backend was slow, so the promote deferred every run and the committed transcript could lag indefinitely (content stayed safely in the gitignored buffer — never leaked — but never surfaced). The detached per-turn judge now gets a generous ceiling-free budget (120s, matching the other background LLM passes); the SessionEnd top-up keeps a tight budget so it stays inside the hook window. A deferred promote now also reports *why* (timeout vs. rejected output) instead of failing silently.
- **`mk_search` no longer falsely claims your semantic search is broken on a keyword-only scope.** Searching `--scope decisions` (the decision-history journal, which is keyword-only by design) made the MCP `mk_search` tool print *"the embedder is unavailable — run `cmk install --with-semantic`"* even when semantic search was working perfectly. The note now fires only for a genuine embedder failure; a by-design keyword-only scope degrades silently. (The `cmk search` CLI was already correct — this brings the MCP tool to parity.)
- **semantic-mode memory leak that could exhaust RAM (P-5VJJUEES)** — on a semantic/hybrid project (`cmk install --with-semantic`), the per-session temporal sweep re-synced the WHOLE semantic index once per new fact, and each sync batch-embedded every uncached fact body in a single ONNX forward pass. On a large corpus with a long fact this allocated gigabytes of off-heap native memory (observed: a runaway process reaching ~9 GB during a session). Fixed two ways: the sweep now syncs the index ONCE and only embeds the per-fact query against it (a `syncIndex` seam), and the embed pass is split into batches bounded by both item-count (`EMBED_BATCH_SIZE=16`) and character budget (`EMBED_BATCH_CHARS=8000`, with a hard per-body truncation) so no single forward pass can blow up. A count-mismatch now fails closed (falls back to keyword search) rather than caching desynced vectors, and empty bodies are skipped. Keyword-only projects were never affected. Live-verified: worst-case embedding peaks at ~440 MB, flat.

## [0.4.5] — 2026-07-06

### Added

- **Run your automatic memory through a DIFFERENT agent than you code in** (Task 201, the "split-brain" backend). Building on Task 200, you can now decouple *which agent you code in* from *which agent runs the background memory chore* (compression / extraction / persona). The background "janitor" LLM is cheap, frequent, and unattended — so route it to whatever CLI is cheapest while keeping your premium subscription for actual coding. E.g. code in Claude, but `cmk install --backend kiro` runs the automatic memory on `kiro-cli`'s Haiku (your Google login). Set it at install (`--backend <claude|kiro|cursor>`) or after (`cmk config set backend.agent <agent>`) — both write the same key. New **`cmk config show`** gives a one-glance readout of your setup (installed-for agent, active backend agent + whether it's an override, backend CLI presence, semantic mode) — informational, distinct from `cmk doctor`'s health checks. This is what makes the override legible. (No other memory tool lets you *choose* a non-primary agent for the background call.)
- **The automatic memory engine now runs on WHATEVER agent you installed for — no Claude Code required** (Task 200). The kit's automatic features (compression, auto-extract, the cross-project persona/wedge, the temporal sweep, daily/weekly distillation) call an LLM in the background — and until now that call always shelled out to the `claude` binary. So a **Cursor-only or Kiro-only** user got file capture/search/recall but every automatic LLM step silently did nothing. Now the background call routes through **your** agent's own CLI, using the login you already have: Kiro → `kiro-cli` (your Google/Kiro login), Cursor → `cursor-agent` (your Cursor subscription — no API key), Claude Code → `claude` (unchanged). If your agent's CLI isn't on your PATH, `cmk install` and `cmk doctor` (new **HC-11**) now tell you clearly — the file-only features keep working, and only the automatic LLM steps wait until you install the CLI (an honest heads-up, never a silent no-op). Live-verified end-to-end on real `cursor-agent` and `kiro-cli`.
- **Cursor is now a first-class agent** (Task 196). `cmk install --ide cursor` wires the full automatic memory loop into [Cursor](https://cursor.com) in one step: recalled memory injects at session start (`sessionStart` → `additional_context`), every turn is captured (`beforeSubmitPrompt` + `afterAgentResponse`), file edits are observed (`afterFileEdit`), the session compresses at `sessionEnd`, and the memory delete-guardrail screens shell commands (`beforeShellExecution` → `permission: deny`). All hooks drive one dispatcher (`cmk cursor-hook`) wired into `.cursor/hooks.json` — your own hooks and MCP servers are never touched (touch-only-our-keys, refuse-to-clobber on a corrupt file) — plus the `claude-memory-kit` MCP server in `.cursor/mcp.json` and an always-applied rule at `.cursor/rules/claude-memory-kit.mdc`. `cmk uninstall --ide cursor` removes exactly that surface; `cmk doctor` is Cursor-aware. Timely: Cursor removed its native Memories feature in 2.1.x — the kit restores the automatic capture loop Cursor users lost, and a project's `context/` is shared with Claude Code and Kiro.
- **Stale "current state" facts now self-correct EVERY session, not just weekly** (Task 198). The temporal contradiction-catch (v0.4.4's headline — when a newer fact supersedes an older state, the old one's validity window closes so recall answers with the *current* state) used to run only in the weekly curation pass, so a stale fact could mislead a new session for up to a week. It now runs at **every** memory-maintenance moment — the end of each session, the start of the next, and weekly as a backstop — so a state change captured this session is resolved by the next session boundary. Idle sessions cost nothing (the sweep skips instantly when no new facts landed), and on projects with semantic search enabled it finds the same-subject pairs by meaning (embedding similarity) instead of keyword overlap. No new command, no user action — it's part of the automatic loop.

### Fixed

- **Kiro sessions now actually receive the memory snapshot** (D-269, found by the Task-196 live-test). Since v0.4.0, the `cmk hook agentSpawn`/`promptSubmit` inject leg read a non-existent field of the injector's result and printed an **empty string** — Kiro ran without the recalled-memory snapshot while capture kept working (memory accumulated but never came back at session start). Fixed for Kiro and the new Cursor adapter together, and locked with integration tests that run the real injector end-to-end. Claude Code was never affected (its SessionStart uses a different bin).

## [0.4.4] — 2026-07-03

### Added

- **Facts now carry a temporal `shape`** (Task 66.1, the first slice of the v0.4.4 temporal-validity engine). Every captured fact is classified by what KIND of truth it asserts — `State` / `Event` / `Plan` / `Relationship` / `Preference` / `Absence` / `Timeless` — so the kit can start telling "we deploy to Cloud Run" (an ongoing condition that can go stale) apart from "we migrated on May 3" (a one-time event that stays true) and "user does NOT want emoji" (a negative fact search can't otherwise see). Auto-extract classifies automatically; existing facts read as `State` untouched. Explicit capture: `cmk remember --shape` / `mk_remember shape`.
- **Stale "current state" facts now resolve themselves — the contradiction-catch** (Tasks 66.2 + 66.4, the v0.4.4 headline). The class this kills, measured in the kit's own memory: 18 facts about one release marching "scope locked" → "cut-gate in progress" → "published", all still live, any of which could mislead a new session (the "you said Postgres, now SQLite — which is current?" problem). Each week the kit finds same-subject facts with its own search, has one batched Haiku call judge each pair (validated 10/10 on real memory, ~$0.004 per batch), and when a newer fact supersedes an older state, the older one's **validity window closes** — annotated with when it stopped being true, archived, never deleted, point-in-time history intact. Judged restatements feed the recurrence signal instead. Your next session opens with a one-line note of what was resolved ("2 stale state facts auto-superseded…"), so memory answers with the CURRENT state and keeps the trail.
- **Facts with a shelf life now expire on their own** (Task 66.3). Declare a validity end at capture — `cmk remember "demo Friday" --expires 2026-07-04` (or the `mk_remember expires` param) — and after that date the fact **hides from search automatically** and the weekly curation sweep **tombstones it** (audited and recoverable via `--include-expired` / `cmk get --include-tombstoned`; nothing is ever hard-deleted). Auto-extract can also suggest an expiry, but ONLY when your conversation states a concrete date — it is instructed to never guess one. Permanent facts are untouched: no `--expires`, no expiry.
- **Claude now offers to commit your memory when it piles up** (Task 150, ADR-0018). Committed-tier memory (`context/`) is the kit's whole point — it travels with `git clone` — but nothing ever committed it for you. Now, when a session starts with uncommitted memory files accrued, Claude gets a heads-up and offers a one-tap commit at a natural moment; you say yes, Claude runs an ordinary `git add context/` + commit through the normal permission flow. The kit itself never touches git — you keep the gate, you lose the remembering burden. Non-git projects and clean trees see nothing.

### Fixed

- **A brand-new user's first cross-project rule now bootstraps the persona — the wedge fills from empty** (D-263, found live by this release's cut-gate). Before: if `~/.claude-memory-kit/` didn't exist yet — every fresh machine — the Stop-hook auto-extract and `cmk lessons promote` silently dropped your first "from now on, in every project…" rule (the promote path required the user tier to already exist, so the cross-project persona could never create itself). Now the tier is scaffolded automatically on the first promotion that clears the confidence/recurrence gate — created exactly when a real durable rule is landing in it, never speculatively.
- **The memory-commit proposal now appears on a fresh user's very first session** (D-264, found live by this release's cut-gate). The new "offer to commit your memory" heads-up was being dropped whenever the injected memory snapshot was still empty — which is exactly a brand-new user's first session, the moment their first uncommitted `context/` files pile up. The proposal (and the temporal-supersede heads-up) now ride even an empty snapshot, so the offer reaches the people who need it first.

## [0.4.3] — 2026-07-01

### Changed

- **Persona promotion now earns its way in by RECURRENCE, not just phrasing** (Task 151). A cross-project trait you keep *demonstrating* — but never explicitly declare as an "always/never" rule — now graduates into your persona once it has recurred enough, instead of being stranded by a wording gate. The classifier cites the facts it synthesized a trait from and the kit sums their real recurrence to decide; the LLM groups, code counts. (Closes the cold-open regression where a demonstrated-but-undeclared philosophy never reached the user tier.)
- **Your persona survives a full cold-open even when it's large.** When a user-tier scratchpad (`USER.md`/`HABITS.md`/`LESSONS.md`) outgrows its inject budget, the kit now **condenses it in place** rather than moving your highest-trust traits to an un-injected archive — so a freshly promoted trait can't silently vanish from the next session's snapshot. Under pressure, the lowest-trust, least-recently-touched bullets yield first; a high-trust trait is never the one dropped.

### Added

- **An evolving per-fact trust score.** Each fact carries a `trust_score` in the rebuildable index (never in your committed files, so it adds no git noise), seeded higher for things you stated yourself than for things inferred automatically — and it rises and falls from passive outcomes (a contradiction or supersession lowers it, a restatement raises it) with no command to run.
- **Explicit `cmk lessons promote` now spreads a promotion across your persona by topic** instead of always landing in one section — an identity/preference goes to `USER.md`, a working-style rule to `HABITS.md`, a cross-project lesson to `LESSONS.md` (offline, no LLM call; `--to`/`--section` still override).

### Security

- **Poison_Guard now blocks invisible / zero-width / bidi Unicode in captured memory** (Task 70.4). A hidden-instruction vector matters more for this kit than for any database-backed one: memory is committed to git, so a poisoned fact travels with `git clone` to every teammate. The write-time screen now rejects zero-width characters (U+200B/C/D, U+2060, U+FEFF), bidi overrides and isolates (the "Trojan Source" class — U+202A–E, U+2066–9), and the soft hyphen / Arabic letter mark / Mongolian vowel separator — while leaving ordinary text (whitespace, accents, CJK, emoji) untouched.

### Fixed

- **`cmk search` now finds your promoted persona** (Task 182). Your cross-project rules live in `HABITS.md` / `USER.md` / `LESSONS.md` (and a project's `SOUL.md`) — but the search index only ever walked `MEMORY.md`, so a rule you promoted with `cmk lessons promote` was **unsearchable**, even in the same session. The index now walks every canonical scratchpad, so a promoted trait is findable (via search) as well as injected. Surfaced live by the v0.4.3 cold-open.
- **A fresh install's `cmk search` no longer returns the scaffold's `(example)` placeholders** (Task 183). The seed bullets that ship in a new install (all carrying a template sentinel) are now excluded from the index, so a real query in a brand-new project returns nothing misleading instead of "decide whether to deprecate /api/v1."

## [0.4.2] — 2026-06-28

### Security

- **Resolved 3 CodeQL code-scanning alerts** (Task 173). Hardened the `cmk config set` key walker against prototype pollution (`__proto__`/`constructor`/`prototype` segments are refused at the utility itself, not only at the public entry points), and made the release-notes extractor escape **every** regex metacharacter in the version string (not just `.`) before matching. Neither was live-exploitable (the public config API already guarded; the version is semver-validated), but both are now correct in isolation and the alerts are cleared. No behavior change for users.

## [0.4.1] — 2026-06-27

### Fixed

- **Bounded memory now self-heals reliably even with a dead scheduled cron** (Task 167) — the session-buffer roll (`now.md` → daily summary) no longer gets suppressed by a registered-but-never-firing cron (e.g. a laptop asleep at the scheduled time). Memory compaction runs on every session start and never compounds. The cron-liveness check keys off whether a run *actually happened* (an anacron-style heartbeat), not whether a scheduler is merely registered.
- **A stray `~/context/` no longer hijacks project discovery** (Task 168) — `cmk mcp serve` and the session-start memory injection now stop at your home directory when walking up to find the project, so an unrelated `context/` folder in your home can't be served as the wrong project. Windows 8.3 short-name paths are canonicalized before comparison.
- **Memory tools stay prompt-free on Claude Code 2.1.x — the real fix is an auto-approve hook** (Task 172). Claude Code 2.1.x tightened permission matching so that neither the kit's allow-list rules nor a skill's `allowed-tools` reliably suppress the "Use skill?" / "proceed with mcp__cmk__…?" approval prompts (a known Claude Code limitation — see anthropics/claude-code#17499 + #14956). `cmk install` now wires a `PermissionRequest` hook that auto-approves **only the kit's own** memory tools (`mcp__cmk__*`) and skills (`memory-write`/`memory-search`), so when the model saves or recalls a memory mid-conversation the prompt is answered for you and capture stays invisible. It also pre-approves the kit's MCP **server** (`enabledMcpjsonServers: ["cmk"]`) so the server connects without the per-project "approve this MCP server?" prompt. Nothing else is auto-approved — your other tools and servers prompt as usual. (The automatic background capture was already prompt-free; this fixes the in-conversation path.)
- **Memory-tool allow-list, kept as belt-and-suspenders** (Tasks 169 + 171) — the kit also writes the `Skill(<name>:*)` wildcard form and each specific MCP tool name (`mcp__cmk__mk_remember`, …) into `permissions.allow`. On current Claude Code these sit behind the auto-approve hook above; they become the primary mechanism again if/when Claude Code restores wildcard / `allowed-tools` matching.
- **`cmk install --with-semantic` no longer falsely reports failure on Windows** (Task 170) — the install checked `npm`'s exit code, but on Windows a harmless cleanup warning (a leftover temp DLL still locked by a running process) makes `npm` exit non-zero *after* the embedder installed fine. The kit now checks whether the embedder actually imports — if it does, semantic recall is enabled regardless of npm's noisy exit. No manual step needed.

### Added

- **`cmk doctor` HC-10 — scheduled-compaction liveness** (Task 167) — an informational check that flags a registered cron that has stopped firing. Memory self-heals each session regardless, so it never prescribes a manual command; it SKIPs when no cron is registered (the default).
- **Windows Task Scheduler catch-up** (Task 167) — `cmk register-crons` now sets `StartWhenAvailable` so a missed nightly run (machine off/asleep) runs on wake instead of being silently dropped.

## [0.4.0] — 2026-06-21

### Added

- **Cross-agent install — `cmk install --ide <agent>`** (Task 50; the v0.4.0 differentiator). The kit can now install into agents beyond Claude Code. `--ide kiro` wires Kiro's surfaces in one step, covering **both** the IDE (GUI) and the `kiro-cli` terminal: MCP registration (`.kiro/settings/mcp.json`), steering (`.kiro/steering/cmk.md`, `inclusion: always`), the memory skills (`.kiro/skills/memory-search` + `memory-write`), **automatic IDE hooks** (`.kiro/hooks/cmk-capture.kiro.hook` on `agentStop` → deterministic `cmk hook stop` capture; `cmk-inject.kiro.hook` on `promptSubmit` → recall), and a **CLI agent-config** (`~/.kiro/agents/cmk.json` + a `chat.defaultAgent` pointer in `~/.kiro/settings/cli.json`) carrying `agentSpawn`→inject and `stop`→capture hooks. (These fire live — verified against a real `kiro-cli` session.) The hook command is platform-correct (`cmd.exe /c cmk hook …` on Windows, where Kiro routes hooks through WSL). The CLI agent is registered as the **default agent** so its hooks auto-fire — but **guarded**: if you already have a default agent, the kit installs a named `cmk` agent instead and leaves your default untouched (the install notice tells you how to opt in). Both hook surfaces drive the **same** `cmk hook` dispatcher and the same capture/inject core. Restart Kiro to activate the hooks; steering/skills/MCP are immediate. A `--ide kiro` install also drops a managed **`AGENTS.md`** block at the project root — Kiro's always-loaded instruction file (per kiro.dev), which the CLI agent-config's `prompt` points at. It does **not** write Claude-Code-only files (`CLAUDE.md`, `.claude/skills/`) on a Kiro install — Kiro can't read them. `--ide agents-md` emits the same managed `AGENTS.md` block standalone — a portable memory-awareness rung for the many tools that read `AGENTS.md`. The memory core (store / search / compression / CLI) is identical across agents; only the per-agent wiring differs. Default remains `claude-code` (unchanged). Built on a shared, tested config-write primitive (`mutateAgentConfig` — touch-only-our-keys, refuses to clobber a corrupt config) so each future agent stays thin.
- **Dual-agent projects — Claude Code and Kiro can share one repo.** The installs are additive **overlays**: each `cmk install [--ide <agent>]` writes only its own agent's wiring and never clobbers the other's, and the shared memory brain (`context/`) is written once and reused. So a project used by both (two teammates, or one person switching tools) just runs both installs; `--with-semantic` set by either install is preserved by the other (it lives in the shared `context/`, not per-agent).
- **`cmk uninstall --ide kiro`** — uninstall is now agent-scoped for Claude Code + Kiro. `cmk uninstall` removes the Claude Code managed surface; `cmk uninstall --ide kiro` removes the Kiro surface (its `.kiro/` managed blocks, skills, IDE hooks, the `AGENTS.md` block, and the guarded `~/.aws` CLI agent). Both stay conservative — they **never** touch `context/` (the shared brain) or any content outside the kit's markers.
- **A memory delete-guardrail — the kit now blocks a command that would delete your memory before it runs.** `cmk install` wires a `PreToolUse` hook (`cmk-guard-memory`) that inspects every shell command the agent is about to run and **blocks it** if it's a destructive command (`rm`, `Remove-Item`, `git clean`, `git reset --hard`, …) aimed at a memory path (`context/`, your `~/.claude-memory-kit` persona tier, `MEMORY.md`/`DECISIONS.md`). A safe command, or a delete of anything else, runs normally — only a memory delete is stopped (with a clear reason). Wired for **Claude Code** (`PreToolUse`, `Bash`/`PowerShell`) — where it fires reliably. On **Kiro**, coverage depends on the surface: Kiro IDE and **Kiro CLI V3 (2.9+)** both rely on Kiro's *own* native "this is destructive, proceed?" confirmation (Kiro's IDE hooks can't be installed from a file, and Kiro CLI V3 redesigned its hook system — embedded `preToolUse` blocking was replaced by a `permissions.yaml` model; first-class V3 guardrail support is a planned follow-up). Fail-open by design: a broken guardrail never wedges your session, it just stops guarding. This came from a real data-loss incident — an accidental `rm` after a directory change deleted a repo's session/transcript memory; the guardrail makes that unrunnable.
- **Kiro hooks auto-run — no more "Run / Reject" prompt every turn.** A `--ide kiro` install now pre-trusts the kit's OWN hook commands so Kiro runs them silently instead of asking you to approve each one. On the IDE side it writes `kiroAgent.trustedCommands` into the workspace `.vscode/settings.json`; on the `kiro-cli` side it sets the agent-config's `toolsSettings.shell.allowedCommands` — both scoped to the kit's commands only (`cmk hook *`, `cmk-guard-memory`, plus `cmk remember`/`cmk search` for the kiro-cli explicit path), never a blanket wildcard. Without this, the inject/capture/guard hooks prompted on every fire and "automatic memory" wasn't automatic (found by the v0.4.0 Kiro live-test gate).
- **Kiro IDE — MCP tools auto-approve so `mk_remember` and friends run prompt-free in chat.** The IDE gates MCP *tool* calls through a different trust system than shell *hooks*, so the kit's memory tools (`mk_remember`, `mk_search`, …) used to pop a "Reject / Trust / Run" prompt every call. A `--ide kiro` install pre-approves the kit's 11 MCP tools via `autoApprove` in `.kiro/settings/mcp.json`. (`mk_forget` is safe to auto-approve: it previews and waits for a confirm token before deleting anything.)
- **`kiro-cli` (the terminal client) — fully working, and no `cmd.exe` console-window popup.** The terminal client differs from the IDE under the hood: the kit's `kiro-cli` agent (`~/.kiro/agents/cmk.json`) enables the shell tool (`tools: ['*']` — without a `tools` capability set a custom agent can't run *any* command) and uses the kit's **`cmk remember` / `cmk search`** commands for explicit recall/capture (pre-trusted, so they run prompt-free), while the `agentSpawn`/`stop` hooks do automatic capture+inject every turn. **Automatic capture reads kiro-cli's own session transcript** (`~/.kiro/sessions/cli/`, a different location + format than the Kiro IDE) and runs the same extract→promote pipeline as Claude Code — so a cross-project rule you state in a kiro-cli chat ("always use uv, in every project") promotes to your persona automatically, with no command. The agent does **not** load an MCP server (`includeMcpJson: false`) — kiro-cli launches every stdio MCP server in a *visible* console window on Windows, so turning MCP off for the terminal agent removes that popup entirely (the terminal uses the shell commands instead of MCP tools). The memory core and behaviour are identical to the IDE/Claude Code; only the in-chat surface differs. All verified end-to-end against a real `kiro-cli` session (the cross-project rule landed in the persona tier live).
- **Kiro now captures your prompts too — with the same privacy strip as Claude Code.** On both Kiro surfaces, each prompt you send is now recorded to the session transcript (the searchable history tier) on the prompt-submit hook — matching Claude Code's behaviour — and anything inside `<private>…</private>` is stripped *before* it's written, so a secret you paste into a prompt never lands on disk. Previously the prompt-submit hook on Kiro only did recall (injected memory); it now does recall **and** capture.
- **Kiro `kiro-cli` now records large file edits, like Claude Code.** The `kiro-cli` agent wires a `postToolUse` hook (scoped to the `fs_write` file-write tool) that appends a one-line edit summary (`file=… lines=…`) to the session buffer when you make a substantial edit (>50 lines) — the same observation Claude Code records on `PostToolUse`. It feeds the same memory pipeline, so the kit notices what you're actively working on.
- **Kiro IDE 1.0 — the kit's skills, hooks, and MCP tools run prompt-free, no per-tool approval.** Kiro IDE 1.0 introduced a per-workspace trust store (`~/.kiro/workspace-roots/<hash>/permissions.yaml`). `cmk install --ide kiro` now pre-trusts the kit's own surfaces there — its shell hook commands, its 11 MCP tools, and its two skills (`memory-write`/`memory-search`) — so the agent never stops to ask "Load skill: memory-write — Allow?" or to approve a memory tool. Only the kit's own surfaces are added; your existing rules are preserved, and `cmk uninstall --ide kiro` removes only the kit's. (Verified live: the kit's full memory loop — inject, capture, observe, `mk_remember`, and the cross-project promotion — runs end-to-end on Kiro IDE 1.0 with no approval prompts.)
- **Kiro IDE 1.0 support — new hook format + a memory delete-guard and edit-observation in the IDE.** Kiro IDE 1.0 replaced the old `.kiro.hook` format with clean per-hook `.kiro/hooks/*.json` files (v1). `cmk install --ide kiro` now writes **both** — the v1 files `cmk-{capture,inject,guard,observe}.json` (for Kiro IDE 1.0+) and the legacy `.kiro.hook` files (so older Kiro keeps working; on 1.0 they sit inert as "legacy", no double-fire). The v1 format unlocks the full hook set in the IDE — recall, capture, **a delete-guardrail (`PreToolUse`, which can block a destructive command)**, and **large-edit observation (`PostToolUse`)** — so the IDE now reaches parity with Claude Code and `kiro-cli`. The v1 schema + the capture `Stop` trigger are confirmed against Kiro IDE 1.0's own hook-migration output; the remaining firing details are verified in a live Kiro IDE 1.0 session at the cut-gate.

### Fixed

- **The Kiro CLI default-agent guard now tolerates a UTF-8 BOM in `settings.json` — it no longer clobbers your existing default agent.** A `~/.kiro/settings/cli.json` written by a Windows editor (or PowerShell `Set-Content -Encoding utf8`) carries a byte-order mark that broke the guard's JSON read, so it missed an existing `chat.defaultAgent` and overwrote the default with the kit's agent. Config reads are now BOM-tolerant kit-wide (a shared `read-json` helper, also applied to the `mutate-agent-config` path), so an existing default is correctly detected and preserved (the kit installs a named `cmk` agent instead).
- **`cmk doctor` is now agent-aware — HC-1 no longer false-FAILs on a Kiro install.** Before this, `cmk doctor` only knew about Claude Code: HC-1 hard-checked `.claude/settings.json`, so on a `--ide kiro` project it reported a scary **FAIL** with a wrong `cmk repair --hooks` hint — on the very feature this release ships. HC-1 now detects the install kind and treats Kiro's capture/inject as a **capability** check: it PASSes if **either** the IDE hooks (`.kiro/hooks/cmk-capture` + `cmk-inject`) **or** a cmk-owned CLI agent (`~/.kiro/agents/`) is present — so both a Kiro-IDE user and a `kiro-cli`-only user get a correct PASS — and FAILs (pointing at `cmk install --ide kiro`) only when neither surface exists. Claude Code installs are unchanged. (Found by the v0.4.0 Kiro live-test gate; the kiro-cli-only case caught by the two-pass code review.)
- **The memory skills' YAML frontmatter is now valid, so Kiro accepts them.** The `memory-write` skill's `description` contained an unquoted `: ` (in the phrase "update memory: X is now Y"), which is invalid YAML — a strict parser reads it as a new key. Claude Code reads skill frontmatter leniently and never noticed, but Kiro strict-parses it and rejected the skill outright (*"Invalid SKILL.md frontmatter"*). Both memory skills' descriptions are now YAML block scalars (`>-`), immune to embedded colons/quotes/apostrophes, and a build-time validator strict-parses every skill's frontmatter so this can't recur. (Found by the v0.4.0 Kiro live-test gate.)

### Fixed

- **Background memory compression no longer fails needlessly when Claude is slow, so `recent.md` / the archive stay fresh.** The lifecycle compression jobs that run with no time limit (daily distill, weekly curate, the session-start catch-up roll) were using the same 50-second budget as the in-session compressor, and retried too quickly — so a slow `claude --print` window could time them out and leave consolidated memory stale (a real case left `recent.md` 4 days behind). They now get a 120-second budget and wait between retries, matching the no-deadline nature of those background jobs. ([#209](https://github.com/LH8PPL/claude-memory-kit/pull/209))

## [0.3.4] — 2026-06-19

### Added

- **A documented update path + drift detection.** New "Updating to a new version" guide for both install routes (README + QUICKSTART §9) — the npm two-step (`npm i -g @latest` → `cmk install` per project) and the plugin flow (`/plugin update` → `/reload-plugins` → re-`bootstrap`), with the Windows EBUSY "close Claude Code first" note. A new `cmk doctor` check (**HC-9**) flags a project whose scaffold is behind your installed `cmk` after an update, so the easily-forgotten per-project re-install never goes unnoticed.

### Fixed

- **Compression now recovers from a transient Haiku failure instead of leaving the session buffer stuck.** The lifecycle compression passes (daily distill, weekly curate, the lazy session-start roll) retry once with backoff on a transient timeout / overload, so an intermittent `claude --print` slowdown no longer strands `now.md` until the next session. Failures are also now logged with their exit code + reason for diagnosis. ([#206](https://github.com/LH8PPL/claude-memory-kit/pull/206))

## [0.3.3] — 2026-06-18

### Fixed

- **search(156): `cmk search --scope decisions` no longer shows a scary "unknown-scope" warning when semantic search is on.** The decision-journal scope is keyword-only by design (the journal is a plain markdown file, not embedded), but with the hybrid default (after `cmk install --with-semantic`) it would print `semantic default unavailable (unknown-scope:decisions)` — or, with an explicit `--mode`, fail outright. It now recognizes the scope is keyword-only and just returns results, silently. The recall itself always worked; the alarming message is gone.
- **reindex(157): `cmk reindex --full` no longer crashes on a dual-written fact.** A fact captured via `cmk remember` lives in both the working scratchpad and its archive file with the same id; a full reindex hit a `UNIQUE constraint failed` and aborted. The index now replaces by id with deterministic precedence (the archive copy wins), so reindex is robust and search results de-duplicate cleanly. Affects anyone who ran a manual `cmk reindex --full`; automatic indexing was unaffected.

### Added

- **Tombstone recovery (155): `cmk get <id> --include-tombstoned` un-forgets a fact — for you, never for the AI.** A `cmk forget` removes a fact from all recall, but its body is kept in the archive. You can now recover it: `cmk get <id> --include-tombstoned` reads the archive and returns the forgotten fact's body + when/why it was deleted. This is a **human-only** flag — the AI's `mk_get` tool stays tombstone-blind, so a fact you forgot never resurfaces in Claude's recall (a deleted fact staying deleted is the whole point). A live fact always takes precedence; recovery is a fallback only when the id isn't live.
- **Decision-journal recall (156): ask the AI how a decision evolved, not just what it is.** The `context/DECISIONS.md` journal (added in 0.3.2) records every decision append-only — including the ones you later superseded or retracted. It's now **recallable**: `cmk search "<topic>" --scope decisions` (or `mk_search` with `scope: "decisions"`) searches the journal for decision **history** — "what did we reject", "did X change", "why did we move away from Y" — and returns the superseded/retracted entries the live fact store no longer carries. The memory-search skill and the injected recall directive now point Claude at it for evolution/"what did we reject" questions, so you can just *ask* ("weren't we using Postgres? what changed?") and the AI consults the journal. This completes the decision-journal feature: it's no longer write-only.
- **Decision journal stays current automatically (159): no `cmk digest` needed.** The `context/DECISIONS.md` journal now updates itself — every decision you capture is rendered into it at session end (and at the next session start for sessions that didn't close cleanly), so the journal is always current without you running any command. Previously it only existed if you ran `cmk digest` by hand; now it's automatic, like the rest of the kit's memory. (`cmk digest` still works as a manual refresh.)

## [0.3.2] — 2026-06-16

### Fixed

- **search(153): natural queries with dots, hyphens, or version strings no longer crash.** `cmk search "v0.3"` (or asking Claude to recall something via `mk_search`) used to fail with an `FTS5 parse error` because characters like `.`, `-`, and `:` have special meaning in the search engine's grammar. Queries are now auto-sanitized — each word that needs it is quoted for you — so `v0.3`, `user-explicit`, and `section:search` all just find results. Multi-word queries keep their "match all words" behavior, and an explicit `"quoted phrase"` you type yourself is still honored as a phrase search.

## [0.3.1] — 2026-06-14

### Added

- **install: `cmk install` now scaffolds a `.gitattributes` that pins committed memory to LF line endings.** Default Windows git (`autocrlf=true`) rewrites line endings at clone, which could make committed facts unreadable on a Windows checkout. The reader already self-heals (v0.3.0); this prevents the mangling at the source so your memory travels intact across platforms. Idempotent managed block (refreshed in place; everything else in your `.gitattributes` is preserved).

- **config(129): `cmk config get` / `set` / `--show-origin` — settings without hand-editing JSON.** Now that `--with-semantic` writes a real user-facing setting (`search.default_mode`), you can read and change kit settings by dotted key instead of editing `context/settings.json` by hand: `cmk config get search.default_mode` resolves across tiers (local > project > user), `cmk config set search.default_mode hybrid` writes the project tier (or `--local` for the gitignored per-machine tier, preserving sibling keys), and `cmk config --show-origin <key>` shows every tier that defines it — which value wins and which are shadowed.

- **security(134): Poison_Guard screens more secret types.** The secret catalog gained fixed-prefix provider tokens — GitHub OAuth/app/refresh + fine-grained PATs, Stripe live keys, Google API keys, GitLab PATs, npm tokens, and Hugging Face tokens — so a captured fact carrying one is rejected before it lands on disk. Pure additions (literal prefixes + length floors, no entropy heuristics); each ships a benign-near-miss test so ordinary prose is never falsely blocked.

- **memory(143): semantic near-duplicate detection at write time — memory rot dies at the door.** With semantic recall enabled (`cmk install --with-semantic`), explicit captures (`cmk remember` / `mk_remember`) now compare the incoming fact against existing memory **by meaning**: "use uv not pip" vs "always install with uv, never pip" is caught even with zero keyword overlap, and routed to the conflict queue as a reviewable proposal — never silently dropped, never silently duplicated (`cmk queue conflicts` to resolve). Fully local (one embedding per capture, no API calls); degrades gracefully to the existing literal dedup when the embedder is absent. The detection threshold was measured against the real model, not assumed.

- **doctor(144): a memory-HEALTH section — content quality, not just plumbing.** `cmk doctor` now ends with an informational read-only summary of what's IN your memory: total facts with the trust distribution, old-and-untouched facts worth a skim, possible duplicate pairs (literal token-overlap candidates — surfaced for review, never auto-removed), and pending conflict/review queue items. A healthy memory earns one quiet line; concerns appear only when non-zero, and the section never affects the doctor exit code.

- **ux(145): a session-start status line — the kit finally tells you it's working.** Every session now opens with one user-visible line (e.g. `claude-memory-kit: 23 fact(s) in context, 2 captured in the last 24h, 1 conflict(s) pending — cmk queue`), shown via the hook's user-display channel: the model never sees it and it costs zero context tokens. An empty project says so honestly (`memory is empty — capture starts this session`) instead of staying silent.

- **install(141a): npm 12 readiness — the kit survives July 2026's install-scripts flip.** npm 12 turns dependency install scripts off by default, which silently blocks the native build `better-sqlite3` needs (the package then looks installed but search crashes at first use). Now: `cmk install` probes the binding up front and **offers to fix it inline** (one `[Y/n]`, runs the documented `--allow-scripts` reinstall for you); `cmk install --with-semantic` passes `--allow-scripts=onnxruntime-node` itself on npm ≥ 11.16; a new doctor check (HC-8) backstops with the exact remediation command; the README documents the prepared-install one-liner.

- **import(142): `cmk import-claude-md` — onboard from the rules file you already own.** New installs no longer start empty: one command parses an existing `CLAUDE.md` (default), `.cursorrules`, `AGENTS.md`, or any rules file into typed granular facts (`user`/`feedback`/`project`/`reference`, inferred from headings) through the kit's safe write path — Poison_Guard secret screening, home-path sanitization, dedup against existing memory — with `write_source: imported`, `trust: medium`, and real `source_file`/`source_line` provenance. Code fences and the kit's own managed block are never imported. `--dry-run` previews; apply requires explicit `--yes`.

### Fixed

- **privacy: `<private>` content is now stripped on every write path, not just the prompt hook.** Previously `<private>…</private>` was redacted only by the prompt-capture hook, so a fact written via `cmk remember`, `mk_remember`, or an import could carry the secret verbatim into committed memory. It's now stripped at the shared write boundary (terse bullets and rich fact files, all tiers) before anything touches disk — and the content-addressed id is computed from the redacted text, so dedup keys on what actually lands.

- **privacy: a `<private>` secret could survive in a fact's *title* when an 80-character title trim severed the closing tag.** A fact's title is derived from the captured text and trimmed to 80 characters; if that trim landed inside a `<private>…</private>` span it broke the closing tag, the redaction regex no longer matched, and the secret leaked into the frontmatter title + the index. The strip now runs before the title is derived, so a trimmed title can never carry private content (verified end-to-end: title, filename, and index all redacted).

- **`cmk repair --index` now actually rebuilds the index.** The repair path invoked the full reindex without the database handle it needs, so `cmk repair --index` / `--all` silently did nothing — masked because every test mocked the reindexer. It now opens the db and runs the real rebuild on the real path.

- **a failed index rebuild after a capture is no longer silent.** `cmk` keeps `context/memory/INDEX.md` current on every write (best-effort). If that rebuild ever failed (e.g. an auto-extract hook killed mid-rebuild), the committed index could quietly fall behind the actual facts with no trace. The failure now records an audit entry, and `cmk doctor` (HC-4) already flags the drift with `cmk reindex` as the one-command fix — the fact itself is always safely on disk.

- **persona: cross-project traits you demonstrated (not just ones you declared as rules) now reach your persona — no stranded review queue.** When the kit synthesized your cross-project style, traits stated as universal rules ("always use uv") were auto-promoted, but traits it merely *inferred* from how you worked (e.g. a layered-architecture preference you described but didn't declare as a rule) were routed to a review queue surfaced nowhere with no resolve command — so they silently stranded and never reached the persona that injects into new projects. The maintenance passes (daily-distill / weekly-curate) now auto-drain that queue: inferred persona candidates promote automatically (reversible with `cmk forget` if wrong), so your working style transfers to new projects more completely. (A deeper redesign — promoting by cross-project recurrence rather than phrasing — is planned.)

- **recall: questions about your project now reach memory instead of re-reading the code — however you phrase them.** The `memory-search` recall skill used to fire reliably only on precise phrasings like *"what did we decide about X"*, and crawled the code for structure/architecture/"where does X live" questions (its skip-clause wrongly treated those as live-code questions). It now triggers on the **intent** — "the answer might be something the project already established" — so oblique, roundabout asks recall correctly too (*"why is everything so spread out across these folders?"*, *"remind me what we settled on for X"*, *"how come the route files are so thin?"* all reach memory). The skill also fires on the per-prompt "memory available" hint, the skip-clause is narrowed to genuinely-live code, and the CLAUDE.md preamble + hint reinforce it. Verified live across precise, oblique, and vague phrasings — and confirmed it correctly stays out of the way for live-code actions and this-conversation questions.

### Changed

- **internal: content fingerprints migrated from SHA-1 to SHA-256.** The non-cryptographic content hashes used for dedup, change-detection, and provenance (`source_sha1`, the reindex diff key) now use SHA-256, consolidated into one shared helper. No user action needed; existing memory re-indexes itself once on first use after upgrade. (On-disk field names are unchanged for back-compat.)

## [0.3.0] — 2026-06-11

### Fixed

- **portability(139): cloned projects recall their memory on Windows.** Default git settings (`autocrlf`) rewrite the committed memory files' line endings on clone, which made every fact invisible to search until now — reads are line-ending tolerant and self-heal on the next write.

- **import(138): `cmk import-anthropic-memory` no longer breaks search.** Imported bullets carried a non-standard provenance comment that failed the next index rebuild (search fell back to the stale index with a warning). Imports now write the canonical provenance shape.

- **memory(136): a long extraction can no longer write a corrupted fact.** When a knowledge-dense turn produced more rich facts than the output budget, the last fact was silently truncated mid-word and stored as a stub. Clipped facts are now dropped (and counted in the diagnostic log) instead of written, and the budget is 4x larger so clipping is rare.

- **install(133): the `memory-search` skill is permission-allow-listed, so recall fires prompt-free** (the skill shipped in this release without its allow entry — first invocation would have asked "Use skill?").

- **memory(132): organic auto-capture works again — the extractor no longer suppresses itself.** Since v0.2.0, the fact extractor was shown the just-captured turn as "already saved" context (a write-then-read ordering bug), so it answered "nothing durable" for most organic conversation — explicit `cmk remember` captures and persona promotion were unaffected. The dedup snapshot is now taken before the turn is buffered. Found by the v0.3.0 release gate; if your `context/MEMORY.md` stayed suspiciously empty, this was why.

### Removed

- **`cmk view` (a never-implemented stub).** The command answered "not yet implemented" since v0.1.0 — removed rather than left promising vapor; a real memory viewer (for non-developer users) is parked as a designed v0.4 candidate. Read memory directly (`context/MEMORY.md`, `context/memory/`) or through `cmk search`.

### Fixed

- **memory(124): `cmk forget` and fact merges keep `INDEX.md` current.** Tombstoning or merging a granular fact now refreshes the markdown index in-band — previously the removed fact stayed listed (a dangling link) and `cmk doctor`'s INDEX-accuracy check failed until a manual `cmk reindex`. Found by dogfooding the kit on its own repo.

### Added

- **search(104.2 + 126): the session record is searchable — the last-resort recall tier.** `cmk search "<query>" --scope transcripts` (and `mk_search` with `scope`) searches the session record — verbatim transcripts AND the compressed daily/weekly summaries — by keyword or meaning — the exact error message from three weeks ago, the command that fixed something, how a discussion actually went. Kept deliberately separate: normal searches never surface raw history; the `memory-search` skill reaches for it only when curated memory has no answer. Transcripts keep full history (unlike Claude Code's ~30-day session files), with growth bounded per turn at capture time.
- **transcripts(104.1): the kit's transcript now records what Claude DID, not just what it said.** Each assistant turn's entry gains a compact **Tools** block — the commands run, files edited, searches made, with truncated results — extracted at capture time from Claude Code's live session record (which itself expires after ~30 days and never leaves your machine). Your committed `context/transcripts/` becomes a durable, portable record of the actual work, ready to serve as the last-resort recall tier. Capped per turn so transcripts stay lean; privacy tags are honored everywhere.
- **hooks(75.2): a per-prompt "memory available" nudge keeps recall alive mid-session.** Substantive prompts in a project with a memory archive now carry a one-line model-facing hint (via the existing UserPromptSubmit hook — no new hook, no extra process) reminding Claude that recorded memory exists beyond the session snapshot and naming the `memory-search` skill. Short prompts ("ok", "go") never pay it. With this, the recall trigger is complete: authority instruction at session start, an auto-invoked recall skill, and mid-session awareness.
- **skills(75.1): the `memory-search` recall skill — Claude now knows WHEN to search its memory.** `cmk install` (and the plugin) ships a second skill alongside `memory-write`: an auto-invoked, read-only recall skill that fires on "what did we decide about X" / "have we seen this error before" / before re-deriving recorded project knowledge from code. It runs forked (raw archive expansions never bloat your conversation — only a curated, citation-backed summary returns) and teaches the filter-before-fetch ladder over the kit's existing `search → timeline → get` tools. The session-start snapshot is the hot index; this skill reaches everything behind it.
- **mcp(125): degraded recall is never silent.** When a project's configured hybrid default can't run (embedder unavailable), `mk_search` now tells Claude the results are keyword-only and to suggest `cmk install --with-semantic` — so the degradation reaches the user instead of hiding. (The CLI already printed a stderr note; this brings the MCP surface to parity.)
- **install(46): one-flag semantic enablement — `cmk install --with-semantic`.** Installs the local embedder, pre-warms the model (the one-time download happens during install, not on your first search), and flips the project's default search to **hybrid** — from then on, plain `cmk search` and Claude's `mk_search` recall by meaning with no flags. `--no-semantic` pins keyword-only; if the embedder is ever unavailable, a configured hybrid default degrades gracefully to keyword instead of failing.
- **search(65): semantic + hybrid recall are REAL — ask in your own words, get the right memory.** `cmk search --mode=semantic|hybrid` (and the `mk_search` MCP tool Claude drives) now run an embedded vector backend: sqlite-vec inside the kit's existing index + a local ONNX embedder (`Xenova/bge-base-en-v1.5`), chosen by a measured bake-off — **R@5 0.941, paraphrase recall 1.000** on the kit's recall benchmark (vs 0.176 for keyword-only). Paraphrase queries that keyword search structurally misses ("where do credentials go" → the 1Password fact) now hit. The embedder is **optional** (~260 MB once, model downloads on first use): without it, semantic/hybrid degrade to a clear install hint and keyword search is unchanged; `CMK_DISABLE_SEMANTIC=1` opts out entirely. Zero API calls — everything runs locally.
- **inject(75.0): the session-start memory snapshot now opens with an authoritative-memory instruction.** Every non-empty injected snapshot leads with a fixed preamble telling the agent the injected memory + `cmk search` are the ground truth for documented knowledge and prior decisions — "when injected memory contradicts your assumptions, injected memory wins; never treat a question as novel when the answer is already in your prompt" (adapted from memory-os Layer 07). Fixes the cold-open failure where the agent re-derives from code what its memory already answers. The scaffolded `CLAUDE.md` gains a matching one-line Authority rule. Existing installs pick the preamble up automatically on upgrade — it is generated by the hook, not scaffolded.

## [0.2.4] — 2026-06-09

### Removed

- **Dropped the stale `memsearch` + Milvus scaffolding (Task 120).** The kit ships keyword-only and never actually used `memsearch`, but `cmk doctor` had two memsearch checks (HC-1 "installed" + HC-7 "reachable") and the install shipped a `milvus-deploy` Docker stack + a nightly-index cron + "install memsearch" setup docs — confusing users into thinking a semantic backend was required. All of it is gone: `cmk doctor` now runs **7 checks (HC-1..HC-7)** instead of 9, and `--mode=semantic`/`--mode=hybrid` report the Layer-5b backend is "not yet shipped" (the choice is deferred — design §9.3.1; the `semanticBackend` extension seam is kept).

## [0.2.3] — 2026-06-09

### Added

- `cmk remember --from-file <fact.json>` and `cmk remember --json` (stdin): capture a rich fact as a JSON object read from a file or piped in, so backtick / `$()` / quote-heavy `Why`/`How` content never rides the shell command line. Fixes the silent corruption where bash command-substitution ate backtick spans in `--why`/`--how` arguments (D-81). _(Task 108a)_
- **Claude can now do every memory operation through conversation — the MCP tools reach parity with the CLI (Task 108b).** The MCP surface (the tools Claude drives on your behalf, so you never type a command) gained:
  - **Rich capture** — `mk_remember` now writes a structured **Why/How fact file** (not just a one-line bullet) when given `why`/`how`/`title`/`type`, matching `cmk remember --why/--how`.
  - **`mk_trust`** — change a fact's trust level (low/medium/high).
  - **`mk_lessons_promote`** — carry a project-tier fact to your cross-project user tier so it applies in every project.
  - **`mk_forget`** — tombstone a fact (audit trail preserved). Destructive, so it's **two-step**: the first call previews exactly what would be removed and returns a confirm token; Claude must call again with that token to delete — nothing vanishes without you seeing it first.

  Plus the **review/conflict queues** are now MCP-drivable too — `mk_queue_list` shows what's pending and `mk_queue_resolve` clears it (`promote`/`discard` a review item; `keep-old`/`keep-new` a conflict) — so Claude can resolve a queued capture in conversation instead of you running `cmk queue`.

  And the CLI gained the read verbs the MCP tools already had, so the surfaces match both ways: **`cmk get <id…>`** (full fact bodies + provenance), **`cmk timeline <id>`** (what was captured around an observation), **`cmk cite <id>`** (a canonical citation link), and **`cmk recent-activity`** (recent changes in a time window). Both surfaces run the same shared core, so they always return the same thing — and a build-time guard fails CI if a memory op ever exists on only one side.

- **`cmk install` now registers the MCP server, so Claude can use those tools with zero friction (Task 108b).** Install writes `.mcp.json` (the `cmk` stdio server) and allow-lists `mcp__cmk__*` in `.claude/settings.json`, so the moment you open Claude Code it can capture/recall/forget through the tools above **without a per-call approval prompt**. This sidesteps a real Claude Code permission edge where a `cd … && cmk …` compound command always re-prompts — running the same op as an allow-listed MCP tool is prompt-free. The `memory-write` skill now prefers those tools too (falling back to the `cmk` CLI when the server isn't connected). `--no-hooks` skips this wiring.
- **Steer your memory in plain language — "forget that" and "trust this / that's not important" now work in conversation (Task 117).** The `memory-write` skill recognizes these as triggers and routes them to the safe path: "forget about X" → tombstone it (`mk_forget`, with a preview-then-confirm step); "trust this" / "that's important" → raise its trust; "that's not important / I'm not sure" → lower it (`mk_trust`). Trust drives what gets loaded first and what ages out, so you can curate your own memory without ever touching a file or typing a command.

### Fixed

- **`cmk persona generate` no longer times out on a real project (Task 111).** On a project with substantial memory, generating your cross-project persona failed with `claude --print did not return within 50000ms` — the classifier was fed your *entire* project memory as one unbounded prompt, and the timeout was sized for the 60-second session-end hook even though the command you run by hand has no such limit. Now the corpus is byte-capped (whole facts only) so the prompt can't balloon, and the explicit command (and the weekly curate pass) get a generous timeout since nothing is waiting on them. If it ever does time out (a transient API slowdown), the error now says so and tells you to re-run.
- **`cmk forget` (and any removal) now disappears from search automatically — no manual `cmk reindex` (Task 110).** A forgotten fact was tombstoned correctly, but its search-index entry lingered, so it kept showing up in `cmk search` (and could resurface in context) until you manually ran `cmk reindex`. A memory you told the assistant to forget reappearing is a trust failure, not cosmetic. Now the index self-heals: the boot reindex (which every read path runs) prunes entries for any source file that no longer exists, and `forget` reindexes in-band so the fact is gone the instant it returns — whether you forget via the CLI or by telling Claude in conversation (the `mk_forget` tool). In-place changes like `cmk trust` and adds like `cmk lessons promote` already propagated; this closes the deletion gap.
- **`cmk register-crons` now works on Windows and macOS — it had been broken since v0.1 (Task 109).** Registering the daily-distill + weekly-curate background jobs failed on Windows (even `--dry-run`, exit 2) because the kit built the scheduler command as a **pre-quoted string** and then **rejected its own inner quotes** — so the cron jobs could *never* register. It now hands the arguments to `schtasks` directly as an args array (no shell re-parsing), so the quoted absolute paths survive intact; macOS got the sibling fix (the `launchd` job no longer bakes literal `"` into the program path). Linux was already fine. _(Skipping cron remains fully supported — the kit falls back to compressing at session start.)_
- **Stale pre-1.0 messaging cleaned up across the unified MCP + CLI memory surface (Task 121, D-102).** After the CLI and MCP cores were merged (108b), a live run surfaced a hardcoded `mk_remember in v0.1.0 only writes to tier P` error plus other drifted `v0.1.0`/`v0.1.x` strings, and the MCP server reported a hardcoded version. Now: requesting a non-project tier (U/L) on a capture returns a clear note that it was saved to the project tier (and how to promote it cross-project) **instead of erroring**; the MCP server reports its real package version; and the user-facing tier/citation messages are version-agnostic.
- **Every memory capture now leaves an audit-log entry (Task 123).** Rich fact writes (both your explicit `remember` and automatic auto-extract) were silently skipping the operational audit trail on the create path — only duplicate-skips were logged. Now each create is recorded in `.locks/audit.log` with its tier, provenance, and trust, so the audit trail the kit promises is actually complete. Also: orphaned auto-extract temp files are now swept instead of accumulating.

### Security

- **Vulnerability reporting now goes through GitHub private Security Advisories (Task 123).** `SECURITY.md` routes reports through the repo's **Security** tab (private, with coordinated disclosure + reporter credit) instead of a direct email.

## [0.2.2] — 2026-06-07

### Added

- **Automatic memory now writes rich Why/How fact files, not just one-line bullets (Task 103).** The per-turn auto-extract pass — the one that runs in the background on every assistant turn and is immune to which memory tool the model happens to reach for — now synthesizes **structured fact files** (a titled record with a breakdown body + **Why** + **How to apply**) for durable project knowledge: your setup/config, project conventions, completed workflows, and tool quirks. Lighter signals (corrections, preferences) still land as terse `MEMORY.md` bullets. Before this, only the explicit `cmk remember --why/--how` produced rich files — so if the model saved to Claude Code's built-in memory instead, you lost the rich tier. Now rich capture rides the automatic path, at `trust: medium` (a later explicit `cmk remember` still supersedes), screened by the same secret-guard + home-path sanitization as every other write, and searchable via `cmk search`.

### Fixed

- **The scaffolded `CLAUDE.md` reads clean — no stale version or dead links (Task 107).** A fresh `cmk install` was dropping a `CLAUDE.md` block that still said *"v0.1.0 is under active development"*, undercounted the health checks (*"HC-1..HC-8"* — there are 9), and carried relative links to `docs/adr/` and `specs/…` that resolve **inside your repo** (where they don't exist). It now reads as a clean runtime contract with external doc links. Also: the managed `.gitignore` block's version marker tracked the install version instead of a hardcoded `v0.1.0`, and a stray internal `Task 92` reference was removed from the gitignore comment.
- **A session-buffer rollup can no longer drop a turn it races with (Task 106).** When the kit compresses your live session buffer (`now.md`) it takes ~5–10s (a background Haiku call) and then clears the buffer. If your session wrote a new turn *during* that window, the old behavior could clear it away with the rest. The kit now **claims** the buffer with an atomic file-rename before compressing, so anything written meanwhile lands on a fresh buffer and is never touched. (This mattered more after Task 105 started rolling at session start, when a new session is actively writing.) Verified with a concurrent-write test + a live end-to-end run.
- **Session memory self-heals at the start of a new session, not only on a clean exit (Task 105).** The kit compresses your live session buffer (`now.md`) into a dated daily file at session end — but Claude Code only fires the session-end hook when you cleanly close the window, **not** when you start a new chat in the same window. So if you live in one long-running window, `now.md` could grow without bound and the rolling daily/weekly summaries never built. Now, at **session start**, the kit notices a `now.md` left over from a prior session and rolls it forward in the background (detached, so it never slows your session start). The compression no longer depends on a clean exit. (Both paths run and are idempotent.)
- **Hook bins no longer hang when run manually without piped input (Task 101).** v0.2.0 fixed this for the SessionEnd bin (`cmk-compress-session`, Task 100), but every other lifecycle hook bin — `cmk-capture-prompt`, `cmk-capture-turn`, `cmk-inject-context`, `cmk-observe-edit`, and the plugin's `cmk-version-check` — shared the same blocking stdin drain: run one by hand (e.g. to debug) without redirecting input and it would hang forever waiting for an end-of-input the terminal never sends. They now detect an interactive terminal and skip the blocking read, so a manual run finishes instead of stalling. No change as a real hook — Claude Code still pipes the payload exactly as before.

## [0.2.1] — 2026-06-06

### Docs

- **README refresh for v0.2.0.** The root README status line still said "v0.1.2 live / v0.2 in progress" (now wrong), and the **npm landing page** (`packages/cli/README.md`) didn't lead with the cross-project persona **wedge** — the headline v0.2.0 capability — and was missing `cmk lessons promote` / `cmk disable-native-memory` / `cmk persona generate` from the command table. Both READMEs now describe the wedge (a fresh project cold-opens knowing how you work) and the full v0.2.0 command surface. _(The v0.2.0 tarball shipped with the older README; this lands on the npm page with the 0.2.1 publish.)_

## [0.2.0] — 2026-06-06

**The wedge** — your cross-project coding persona + project memory, committed to git and portable, so a brand-new project cold-opens already knowing how you work. Plus automatic capture, self-curating memory, and "Claude stays consistent."

### Added

- **`cmk install` now scaffolds the `memory-write` skill into your project (Task 69).** Both delivery routes — the npm `cmk install` and the Claude Code plugin — now ship the same Claude Code skill at `.claude/skills/memory-write/`, so it travels with `git clone`. The skill is what makes explicit capture work: when you say "remember this", "from now on…", "I prefer…", or "we decided…", Claude saves it through `cmk remember` (the safe path — Poison_Guard secret-screen, home-path sanitization, dedup, audit). A drift guard (`validate-skill-sources.mjs`, run on every test) keeps the two routes byte-identical.
- **`cmk lessons promote <id>` — carry a lesson across all your projects, the safe way (Task 76).** This is the explicit half of the wedge: take a fact you captured in one project and promote it into your user tier (`~/.claude-memory-kit/`) so it applies on **every** project. Defaults to `LESSONS.md`; `--to HABITS.md`/`USER.md` and `--section` route it where you want. The promotion runs through the same safe path as auto-capture — home-path sanitization, Poison_Guard secret-screen, dedup, and an audit entry — so you never have to (and never should) hand-edit the user-tier files. Before this the command was a stub, which is exactly what tempted an unsafe manual edit.
- **Cross-project memory now fills in real time, not weekly (Task 61).** Auto-persona used to promote your cross-project doctrine to the user tier only on the *weekly* maintenance pass — so "Claude knows how I work in every project" could lag up to 7 days, invisible in a short trial. Now the same per-turn auto-extract pass that captures project facts **also promotes cross-project doctrine to the user tier the moment you state it** — no extra LLM call, no waiting. The weekly pass stays on as a dedup/catch-miss janitor. (A turn that is *only* cross-project doctrine — "from now on, in every project, …" — still lands the promotion that turn.)
- **Auto-persona — The user tier fills itself (Task 45).** The weekly maintenance pass now synthesizes your **cross-project doctrine** ("how I work everywhere" — tooling habits, architecture preferences) from a project's captured facts and **auto-promotes it into the user tier** (`~/.claude-memory-kit/`) at `trust: medium` — no manual step. It auto-supersedes a stale persona fact when an updated one arrives, and never overwrites a `trust: high` hand-curated entry (those stage in the conflict queue). Fixes the self-test gap where cross-project preferences were captured but stranded in the project tier, leaving the cross-project memory empty.
- **`cmk disable-native-memory` / `cmk enable-native-memory` — coexist with Claude Code's native Auto Memory, your choice (Task 60, ADR-0011).** Claude Code ships its own Auto Memory (ON by default) that writes the same kind of files the kit does, so with both running you get two memory layers injected at session start (context bloat). The kit now **coexists by default and never touches your setting** — but `cmk disable-native-memory` is a one-command opt-out that writes `autoMemoryEnabled: false` into the project's `.claude/settings.json` (**committable — it travels with `git clone`**), so the kit is the sole lean layer. `cmk install` mentions the coexistence + the opt-out, and `cmk doctor` (HC-8) shows the current state. Reverse anytime with `cmk enable-native-memory`.
- **`cmk persona generate` + durable persona review queue (Task 45 follow-up).** A new command to **run persona synthesis on demand** — promote high-confidence cross-project doctrine to the user tier now, instead of waiting for the weekly pass. And lower-confidence candidates are no longer dropped: they're written to **`<user-tier>/queues/persona-review.md`** (deduped) so nothing the synthesis surfaced gets lost between runs.
- **The review + conflict queues now drain themselves.** The daily-distill and weekly-curate maintenance passes automatically resolve the queues — medium-trust auto-extractions are **promoted** into `MEMORY.md`, and a lower-trust write that conflicts with an existing higher-trust fact is **auto-resolved in favor of the higher-trust fact** — so you no longer have to run `cmk queue review` / `cmk queue conflicts` by hand (those still work if you want manual control). Mistakes self-correct: a later, better fact auto-supersedes, and stale medium-trust entries age out.
- **`cmk persona export` / `cmk persona import` — carry your cross-project persona across your own machines (Task 72).** Your project memory already travels with `git clone`, but your *persona* (the user tier — how you work everywhere) is deliberately machine-local and kept out of the repo, so it never leaks to teammates. These two commands give it a portability button without breaking that: `cmk persona export persona-bundle.json` packs the user tier (scratchpads + fact store + settings) into one OS-agnostic file you carry via your own private channel (USB / a private git repo / Dropbox); `cmk persona import persona-bundle.json` applies it on the other machine. Import overwrites but backs up anything it replaces and is **transactional** — a mid-import failure rolls back fully — then rebuilds the search index. The bundle is already home-path-sanitized + secret-screened (no machine paths or usernames travel). A seamless auto-syncing variant (`cmk persona sync`) is planned.

### Changed

- **The scaffolded `memory-write` skill is now safe, and the scaffolded `CLAUDE.md` is leaner (Task 69, security).** The old skill granted itself `Edit`/`Write` and told Claude to **hand-edit** `MEMORY.md`/`USER.md` directly — bypassing the secret-screen and home-path sanitization (the same class as the v0.1.2 username-leak). The rewritten skill grants only `Bash(cmk remember *)` / `Bash(cmk forget *)` / `Read`, routes every write through `cmk`, and carries a hard "NEVER hand-edit memory files" gate. The memory-write *procedure* moved out of the appended `CLAUDE.md` block (now 4 invariant facts + a pointer to the skill) and into the skill itself, where it loads only when needed — your `CLAUDE.md` stays shorter and the kit stops competing with your own instructions.
- **Explicit capture is seamless again — no "Use skill?" prompt (Task 90).** Task 69 moved capture into the `memory-write` skill, which Claude Code gates with its own approval prompt — so the first explicit capture popped a *"Use skill /memory-write?"* dialog even though Task 79 had already silenced the `cmk` command prompt. `cmk install` now also allow-lists `Skill(memory-write)` in `.claude/settings.json`, so a model-invoked capture runs without prompting — the explicit half of the wedge is friction-free on a fresh install. (Surfaced by the v0.2.0 cut-gate manual run.)
- **The wedge promotes reliably and session summaries stay grounded (Tasks 86 / 87 / 84b).** Cross-project rules stated across a busy build turn now promote to your persona (not only single-rule turns) — a dedicated persona pass runs at session end over the actual conversation. The end-of-session summary is built from the **dialogue** rather than file-write logs (no more invented frameworks in your memory). And all three compression layers keep only the **latest** version when a fact changes, so stale memory self-supersedes instead of accumulating contradictions.
- **The kit's hooks now run on Node alone — no bash, on any OS (Task 62).** Both install routes now invoke the lifecycle hooks directly with `node` (the plugin route via `node "${CLAUDE_PLUGIN_ROOT}/bin/<hook>.mjs"`; the npm route already used PATH-resolved node bins). Previously the plugin route shipped bash wrapper scripts, which required a POSIX shell (Git Bash or WSL) on Windows — a hidden dependency that could fail on a machine without a real bash. Node is the only runtime requirement now, exactly like Claude Code itself. No action needed; install and hooks work the same on Windows, macOS, and Linux.
- **`cmk doctor` no longer reports a healthy fresh install as broken.** On a brand-new project, three checks were marked **FAIL** when they were really "nothing's happened yet" or "optional": distill freshness (HC-3) and transcript firing (HC-4) before you've had a session, and cron registration (HC-6) — which is optional, since the kit falls back to lazy-on-read compression. These are now **SKIP** on a fresh project (matching how the README already describes cron), so a clean install reads `6 pass · 0 fail · 3 skip` and `cmk doctor` exits `0` instead of `1`. The genuine failure cases still FAIL: a *stale* distill, and transcripts that exist but stopped firing.
- **Discarded low-value extractions now leave an auditable trace (Task 92).** When the per-turn capture pass judges something too trivial to keep (LOW trust), it used to vanish with no record of *what* it dropped — so a fact the grader got wrong was unrecoverable. Now each drop logs a short excerpt + reason to the session's diagnostic `extract.log`, so you can see what was discarded without it polluting active memory or the review queue. That log carries raw, un-screened text, so `cmk install` now also gitignores it (`context/sessions/*.extract.log`) — it stays local, never committed.
- **The cold-open now keeps your highest-value memory, not whatever happens to be first in the file (Task 93).** When a memory tier is too big to inject whole at session start, the kit used to drop whole sections from the *end* of the file — so a high-trust rule in a late section could be cut while lower-value earlier content survived, purely by position. Now it drops the **lowest-value section first** (by trust, then recency), so your most important and most recent rules are the ones that reach a fresh session. Behavior is unchanged when memory fits or carries no trust metadata; the overflow that doesn't get injected stays searchable on disk.
- **Memory now self-trims at the end of every session, not just when you write (Task 94.3).** Graduation — moving a scratchpad's overflow into the searchable fact store so the injected slice stays under its load-cap — used to fire only when a new capture pushed a file over the cap. Now a proactive sweep runs at session end across all your fact-bearing scratchpads (project `MEMORY.md`/`SOUL.md` + the user-tier persona `USER.md`/`HABITS.md`/`LESSONS.md`), so a file that drifts over cap between sessions, or whose bullets simply aged past the staleness window, gets trimmed before the next session starts. Overflow is **graduated** (high-trust → fact store, recoverable + searchable) or **archived** (stale low/medium → `memory/archive/`), never silently dropped — the never-lose invariant. The machine-local config tier is left untouched.

### Fixed

- **`cmk lessons promote` / `cmk forget` now explain the "scratchpad bullet vs fact" id mix-up (Task 102).** `cmk search` lists ids for both graduated facts and scratchpad bullets, but these two commands act on facts only — so pasting a bullet id used to return a flat "no matching fact." They now detect that the id is a live bullet and say so: *"'…' is a scratchpad bullet in MEMORY.md, not a fact"* with guidance on which id to use (for promote, pick a result whose location is a `context/memory/*.md` file). A genuinely-unknown id still gets the plain not-found.
- **The session-end hook no longer hangs when run by hand (Task 100).** The `cmk-compress-session` handler drains its stdin like every Claude Code hook. Run from a real session-end it gets the hook payload and an immediate EOF, so it returns at once — but run **manually** in a terminal without piping anything in (e.g. while testing your install), the stdin read had nothing to wait for and blocked until the 60s hook ceiling killed it. It now detects an interactive terminal and skips the wait, so a manual run finishes normally. The real-hook path is unchanged.

## [0.1.2] — 2026-05-30

First real-world self-test (build a small app across two sessions) surfaced that the kit **captured** facts but couldn't **recall** them, plus a cluster of write-path and Windows issues. This release fixes the whole loop end-to-end and adds the code-quality gate.

### Fixed

- **Session-start recall (the headline).** The injected memory snapshot was ~70% template-comment noise + placeholder seed bullets, with the real captured facts buried mid-payload — so a fresh session reported "no real facts populated yet" and re-derived everything from the codebase. `inject-context` now strips format-comment headers + placeholder seed bullets, drops the reference `INDEX.md` (which self-declares "NOT auto-loaded"), and excludes scaffolding-only tiers. A real project's snapshot dropped from ~11 KB of noise to a few hundred bytes of just-the-facts.
- **`cmk search` returned "no results" on a fresh install** even for facts sitting in `MEMORY.md` — the FTS5 index was never built (nothing reindexed for a one-shot CLI call). `cmk search` (and the MCP `mk_search`) now reindex before querying; `reindexBoot` gained an mtime fast-path so the per-search cost stays flat as memory grows.
- **Durable-fact writes could leak your username + ship the wrong schema.** Hand-written fact files used a frontmatter schema the index couldn't read, and an absolute interpreter path (`C:\Users\<you>\…`) landed in the **committed** project tier. Fact-file + scratchpad writes now run through home-path abstraction (`C:\Users\you\…` → `~`, case-insensitive, all OSes) **and** Poison_Guard (fact files previously bypassed the secret screen).
- **Windows: compression/auto-extract silently failed for usernames with a space.** `spawn(..., {shell:true})` with an args array (a) emitted Node's DEP0190 and (b) concatenated argv unescaped, so a temp path under `C:\Users\First Last\…` broke cmd.exe tokenization. New `spawn-bin` helper never pairs `shell:true` with an args array (POSIX argv-style; Windows single pre-quoted command string).

### Added

- **`cmk remember "<fact>"`** — explicit, safe durable capture (Poison_Guard + home-path abstraction + dedup + correct schema). The agent uses this instead of hand-writing files under `context/memory/`. `--trust`, `--section`; `cmk remember --help` for details.
- **Coverage gate (Task 54):** `npm run test:coverage` (vitest v8) with 70% ratchet thresholds enforced in CI; **SonarQube Cloud** CI-based analysis (maintainability / reliability / security-hotspots + coverage) on every PR.
- **`cmk install --verbose`** for the full per-tier file breakdown.

### Changed

- **`cmk install` output is outcome-first** — "`<project> ready — context/ scaffolded, hooks wired`" instead of a confusing file tally ("skipped 4 existing" read like a problem; those were the cross-project user-tier files *outside* the folder). The breakdown moved to `--verbose`.
- The scaffolded `CLAUDE.md` capture guidance now routes durable writes through `cmk remember` and never tells the agent to hand-write fact files.

## [0.1.1] — 2026-05-29

Unify install (Task 49): a tester now needs a **single** complete entry point — `npm install -g @lh8ppl/claude-memory-kit && cmk install` — with no separate `/plugin install` step. Both install routes are now complete on their own; pick one.

### Added

- **`cmk install` now wires the lifecycle hooks** into `<repo>/.claude/settings.json` (PATH-resolved bare bin names, cross-OS shell form), making the npm route a complete entry point. `--no-hooks` opts out for scaffold-only installs.
- **5 hook bins shipped in the npm package** (`cmk-inject-context`, `cmk-capture-prompt`, `cmk-observe-edit`, `cmk-capture-turn`, `cmk-compress-session`) plus the spawned `cmk-auto-extract.mjs` — de-plugin-ified twins of the `plugin/bin/` handlers (Task 33/36 pattern), so the hooks resolve after `npm install -g` without `${CLAUDE_PLUGIN_ROOT}`.
- **`.claude-plugin/marketplace.json`** at the repo root makes the plugin route registerable via `/plugin marketplace add LH8PPL/claude-memory-kit` — a complete parallel entry point to `cmk install`.
- **Shared `settings-hooks.mjs`** boundary (`writeKitHooks`) used by both `cmk install` and `cmk repair --hooks`, so the two never drift.

### Changed

- **`cmk repair --hooks` now writes the npm-route hook form** (PATH-resolved bare bin names, 5 functional events) instead of the plugin form (`bash "${CLAUDE_PLUGIN_ROOT}/bin/..."`, 6 events incl. the `Setup`/`cmk-version-check` stub) — so repaired hooks work with no plugin loaded. The plugin form still lives in `plugin/hooks/hooks.json` for the plugin route.
- **README + QUICKSTART** reframed to present the two install routes as "pick one, each complete" (was: "you need both").

### Fixed

- **`cmk doctor` HC-2** now traverses the canonical nested hooks shape (`{hooks:[{command}]}`) that `cmk install` / `cmk repair` actually write — previously it only inspected a flat top-level `command`, so `cmk install` followed by `cmk doctor` reported HC-2 fail on hooks the kit itself had just written (a latent install→doctor composition gap surfaced while shipping Task 49).

### Security (Task 53)

- **CI security scanning** on every push + PR: `gitleaks` (secrets), `osv-scanner` + `npm audit --audit-level=high` (CVEs/supply-chain, hard gate on high/critical), `CodeQL` (SAST, JavaScript), and weekly **Dependabot** PRs. Same SCA/SAST/secrets shape as Artifactory Xray + SonarQube, built from the free GitHub-native/OSS stack.
- **CI publish with signed provenance** (`.github/workflows/publish.yml`): releases now publish on a `v*` tag from GitHub Actions via OIDC + `npm publish --provenance`, with the npm credential stored only as the encrypted `NPM_TOKEN` secret — replacing the local-publish flow whose on-disk token was the v0.1.0 leak vector.
- **`SECURITY.md`** threat model + responsible-disclosure policy; `bugs` URL added to both packages.

## [0.1.0] — 2026-05-28

The first public release of claude-memory-kit — a per-project, in-repo memory system for Claude Code that fixes per-session amnesia by storing durable facts as markdown inside `<repo>/context/` (committed) + `<repo>/context.local/` (gitignored) + `~/.claude-memory-kit/` (user-tier). Architecture-first first release: ~55 dev days, 42 tasks shipped (45-task ledger; 3 deferred to v0.1.1).

### Added

#### Foundation (Layers 1–3)

- **3-tier memory model** (P/L/U): project tier in `<repo>/context/` (committed), local tier in `<repo>/context.local/` (gitignored), user tier in `~/.claude-memory-kit/` (cross-project per-user)
- **`cmk install`** scaffolds the 3-tier layout into a project, drops a managed CLAUDE.md block, and adds `.gitignore` entries for regenerable + machine-local state
- **Granular fact archive** with content-addressed 8-char base32 IDs (Node ⇔ Python parity package `@lh8ppl/cmk-canonicalize`); INDEX.md pointer file walked at session start
- **Bounded scratchpads** (MEMORY.md / USER.md / SOUL.md) with character caps + consolidation discipline
- **Frontmatter-everything provenance**: every observation carries `created_at`, `source_file`, `source_sha1`, `write_source`, `trust` fields enforced by `writeFact()` boundary

#### Auto-extract + Hook chain (Layer 4)

- **`cmk-inject-context`** SessionStart hook composes a Frozen snapshot ≤ 13KB (NFR-1) across the 3 tiers with cross-tier ID dedup and budget-driven truncation
- **`cmk-capture-turn`** Stop hook detached-spawns the auto-extract subagent against the bi-turn temp file (user + assistant exchanges)
- **`cmk-capture-prompt`** UserPromptSubmit + **`cmk-observe-edit`** PostToolUse(Write/Edit) hooks capture intent + structural-edit signals
- **`cmk-compress-session`** SessionEnd hook compresses `now.md` → `today-{date}.md` via Haiku with 50s timeout + 120s shared cooldown
- **`memory-write` skill** for explicit user phrases ("remember this", "from now on", "we decided", "forget about X")
- **Trust hierarchy** (high/medium/low) with auto-extract routing: high → MEMORY.md, medium → `queues/review.md`, low → discarded with audit
- **Poison guard** regex catalog (PG-001…PG-013) gates auto-extract writes against secrets + prompt-injection patterns
- **Conflict queue** when an extracted fact contradicts an existing trust:high observation; resolved via `cmk queue conflicts`
- **Review queue** for medium-trust auto-extracts; resolved via `cmk queue review`

#### Search (Layer 5a)

- **SQLite + FTS5 keyword index** at `context/.index/memory.db` (regenerable; never source of truth)
- **chokidar runtime watcher** keeps the index in sync with markdown edits
- **`cmk reindex` + `cmk reindex --full`** boot + drop-and-rebuild paths
- **`cmk search "<query>"`** with BM25 + RRF hybrid mode (semantic backend deferred to v0.1.x)
- **MCP server** (`cmk mcp serve`) exposes 6 tools to Claude Code: `mk_search`, `mk_get`, `mk_timeline`, `mk_cite`, `mk_remember`, `mk_recent_activity`

#### Cron compression (Layer 6)

- **`cmk daily-distill`** rolls up the last 7 days of `today-*.md` into `recent.md`
- **`cmk weekly-curate`** archives `today-*.md` > 7 days into `archive.md` with cross-day bullet dedup via canonicalize primitive
- **`cmk register-crons`** registers both jobs with the host scheduler (Linux crontab pipe-pattern, macOS launchd `~/Library/LaunchAgents/`, Windows Task Scheduler) — emits absolute paths to dodge cron's restricted PATH
- **`cmk compress --lazy`** fallback for no-cron environments; SessionStart hook detached-spawns it on staleness detection
- **Cron-detection sentinel** (`context/.locks/cron-registered`) coordinates lazy-fallback with cron-active mode

#### Cross-cutting

- **`cmk doctor`** runs HC-1..HC-9 with structured report + repair commands (exit 0 all-pass, 1 some-fail, 2 error)
- **`cmk repair --hooks` / `--locks` / `--index` / `--all`** idempotent self-repair surfaces
- **`cmk roll --scope now|today|recent`** manually trigger any compression pipeline
- **`cmk import-anthropic-memory`** merges bullets from `~/.claude/projects/<slug>/memory/MEMORY.md` into project MEMORY.md
- **`cmk transcripts extract`** filters Claude Code session jsonls into clean markdown corpora
- **`cmk forget <id>`** tombstones a fact (audit-preserved, not deleted)
- **`cmk lessons promote <id>`** copies a project-tier fact to the user tier
- **Cross-OS install CI matrix** (`.github/workflows/install-matrix.yml`) validates `cmk install` produces byte-identical scaffolds on Windows / macOS / Linux

#### Quality + Discipline

- **1100+ tests** across 57 test files spanning unit, integration, and live-Haiku spawn-smoke layers
- **8 structural validators** running as `npm test` prerun: test-ids alphabet, template scaffold cap-coordination, exit-doors headers, internal references, spawn discipline, numbering gaps, composition addressing, platform-commands cross-OS
- **Two-pass code-review discipline** (self + code-review-excellence skill) on every PR — empirically every PR in the autopilot run had at least one skill-review-only catch
- **Composition verification** rule with 7 documented instances of the cross-module gap class
- **Stress-test gate** (5x full suite) before any PR touching spawn boundaries, hook handlers, or detached children
- **Decision-trail preservation** rule: documented plans are appended-to, not substituted (the Task 33 Python → Node pivot is the canonical precedent)

### Deferred to v0.1.1

- **Task 45 — Auto-persona generation**: persona candidate surfacing + `cmk persona accept/reject` subcommands + auto-apply mode + conflict-with-hand-curated handling. Originally tail-appended as a v0.1.0 release blocker on 2026-05-24; re-prioritized to v0.1.1 on 2026-05-28 per the autopilot sequencing. Forward-compat seams (Task 12 scratchpad + Task 22 compression + Task 23 auto-extract) are all in place.
- **Layer 5b — Semantic search**: memsearch + ONNX BGE-M3 backend. Surface seam in place via the `CompressorBackend` interface (ADR-0008) + `SEMANTIC_UNAVAILABLE` error category. Install via `pip install memsearch[onnx]` post-v0.1.0 unlocks `cmk search --mode=semantic` and `--mode=hybrid`.
- **Tasks 46-48** (added 2026-05-28 after research into other products' install-time consent patterns): `cmk install --with-semantic` opt-in semantic-backend bootstrap, `cmk doctor --repair` prompt-then-install, NFR promotion for the ask-before-install rule.
- **Live end-to-end acceptance test on a real project**: gate moved from Task 42 (pre-release) to Task 44 (post-release verification) per the autopilot sequencing.

### Known limitations (documented in design §15 trade-offs)

- Provenance frontmatter adds ~150 bytes per bullet (acceptable; preserves full audit trail)
- Token budget at session start is ~20-35 KB (higher than ideal but well inside Claude's 200K context)
- Cross-project facts require explicit `cmk lessons promote` (cross-project search is v0.2)
- Markdown-as-source / SQLite-as-cache requires regeneration on schema changes (simpler than DB-as-source)
- 8 v0.1.x candidates documented inline in design.md §16

### Acknowledgements

- Pattern source: Simon Scrapes' [Master Claude Memory](https://www.youtube.com/watch?v=rFWxRZ5D-lM)
- Closest production reference: [Hermes Agent](https://github.com/NousResearch/hermes-agent) (verified character-cap parity)
- Architectural inspiration: [claude-mem](https://github.com/thedotmack/claude-mem), [claude-remember](https://github.com/Digital-Process-Tools/claude-remember), [GBrain](https://github.com/garrytan/gbrain)
- Convergence with Anthropic's native auto-memory (Claude Code v2.1.59+) on the `<type>_<slug>.md` granular pattern
- Test discipline (five exit doors) from [Yoni Goldberg's nodejs-testing-best-practices](https://github.com/goldbergyoni/nodejs-testing-best-practices)

[0.1.0]: https://github.com/LH8PPL/claude-memory-kit/releases/tag/v0.1.0
