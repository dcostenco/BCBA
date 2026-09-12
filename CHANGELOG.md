# Changelog

All notable changes to this project will be documented in this file.

## 20.18.1 — 2026-09-12

### Task-skill continuity across compaction and manifest updates

- Restores the three most recently active prompt-routed task skills together
  with the protected-floor digest after `SessionStart(source=compact)`.
- Detects a newly materialized managed-skill generation and re-injects current,
  re-authorized task bodies on the next prompt, including short `continue`
  turns. A prompt that matches another skill retains the prior active rules.
- Prevents stale managed paid skills from using the user-owned local-skill
  entitlement exception during interrupted syncs or downgrades.
- Injects the actual body of a prompt-matched user-owned local skill even when
  signed out, while an entitled platform body wins any same-name collision.
- Anchors injected context to the user's preceding request for Codex's trailing
  developer-message placement and includes the anchor inside the host budget.
- Bounds and validates hook state before forming CLI arguments, keeps the two
  worst-case CLI waits below the host timeout, and makes the v5 script reject
  stale v4 command invocations so rewritten code never inherits old trust.
- Upgrade procedure: `prism connect --refresh --no-models`, then trust both v5
  entries in Codex `/hooks`. Restart only when the running host has not reloaded
  the new definitions; subsequent skill-content generations refresh in place.

## 20.18.0 — 2026-09-01

### Protected-floor digest in the bootstrap + post-compaction re-injection

- **Added: `session_bootstrap` inlines a protected-floor digest** (paid tiers,
  standard/deep). One inert line per rule from each skill's first paragraph or
  pinned `digest:`, plus a section map; per-skill cap 360 chars, whole block
  ≤6,000 chars, source read capped at 64K. The digest budget is additive on
  top of `NATIVE_STARTUP_MAX_CHARS` on every bootstrap path (projects,
  first-run, no-projects), so the project/session share is unchanged at every
  depth (pinned by a with/without byte-identity test). Quick depth stays
  names-only. A floor skill whose body yields no digest (front matter only,
  fenced blocks only) is listed as `digest unavailable; read the full skill`
  so an absent rule is never mistaken for a silent one; the block is dropped
  only when the budget cannot carry every digestible name at ≥80 chars.
- **Added: `prism floor-digest`** and a `SessionStart` hook matched on
  `compact` (Claude Code `~/.claude/settings.json`, Codex `~/.codex/hooks.json`,
  hook version 4). The hook resolves tier and depth through the same manifest
  snapshot as the bootstrap — a free-tier machine with paid names left in its
  manifest gets nothing (adversarial-review finding, pinned). The script reads
  the event as `hook_event_name`, `hookEventName`, `event_name`, `eventName`
  or `event` (any casing or separators) and the trigger as `source`,
  `trigger` or `reason` with any value beginning `compact`; every other
  SessionStart (startup, resume, clear) emits nothing. **The Codex half is
  UNVERIFIED against a live compaction**: the entry is registered and its
  trust state reported, and the script accepts every documented spelling of
  the payload, but no Codex compaction has been observed end-to-end. Its
  failure mode on an unrecognised payload is *no* re-injection, never a wrong
  one. Claude Code's payload shape is pinned by test; the live check on this
  machine is part of the release procedure. If the digest was rendered from a
  generation whose files never finished reaching the skill roots, the hook
  payload carries the same `Skill files are STALE` warning the bootstrap
  shows — after a compaction the bootstrap's copy is no longer on screen.
- **Fixed: Codex trust voided on hook rewrite.** `ensurePromptRouteHook` now
  reports `pending-or-unknown` whenever it changed `hooks.json`, regardless of
  `[hooks.state]`, and "detected" requires the current *versioned* command
  (`--v4`) to appear at least twice in `config.toml` — trust recorded for an
  older hook version, or an unversioned entry, reads as pending, never as
  detected; connect's ✓ line now names both hooks.
- **Fixed: an unparseable host config was replaced.** A `settings.json` or
  `hooks.json` that exists but is not valid JSON (a hand-edit with a trailing
  comma, say) is now left byte-identical, nothing is registered there, and
  connect prints `⚠ <host>: <path> is not valid JSON — prism-route hooks NOT
  registered`. Before, the parse failure was treated as "no file" and the
  operator's model/env/permissions were overwritten with a minimal hooks file.
  The npm postinstall notice says the same thing for Codex instead of
  "installed but NOT yet trusted — press t", which sent the operator to
  `/hooks` to trust an entry that was never written.
- **Fixed: frontmatter-only symptom skill inlined its YAML** when the closing
  fence was the file's last line (inline path had its own fence parser).
- Hardening from review: every `<` and `>` in digest text becomes a guillemet
  (`‹`/`›`) — per bracket, not per tag-shaped span, so a tag split across two
  units cannot re-form when the assembler joins them, and the assembled digest
  is made inert as a whole; wiki-link stripping is linear (256KB of `[`
  digests in milliseconds, was 54s). A digest unit that opens a new section
  carries its heading in front (`Do NOT delegate: Tasks requiring…`), so a
  skill whose sections are "Delegate to" / "Do NOT delegate" cannot flip
  polarity when the assembler joins a unit from each — including when the
  section is opened by a mid-document H1, an empty heading, or a setext
  underline, each of which previously reset the section to the intro. The
  on-disk `SKILL.md` is used only when it *digests*: an empty file, a file
  cut off inside its frontmatter (which rendered `prompt_triggers: …` YAML as
  the rule), or a frontmatter-only file falls back to the DB copy. A Codex
  approval whose Windows path is TOML-escaped (`C:\\Users\\…`) now matches
  the registered command. `check-publish-clean` refuses a publish whose
  CHANGELOG.md, README.md, or translated README leads with a version *ahead*
  of package.json, so release notes cannot announce a version npm does not
  carry; notes that lag the bump (the repo's convention) still pass. The
  guard reads the whole heading line and compares its *newest* version token
  (a `v20.17.3 – v20.18.0` range on a 20.17.3 package is ahead), matches a
  typographic apostrophe in `What’s New`, and strips a leading BOM — each of
  which had silently disabled a half of the check. An inert free-tier filter
  in the floor-digest name resolution was removed in favour of a pinned
  invariant that the free bundle and the protected floor stay disjoint.

## 20.15.0 — 2026-08-24

### Security — dashboard DNS-rebinding fix (GHSA-9cvx-7x8q-3g6m)

- **Fixed: the Mind Palace dashboard validates `Host`/`Origin` before serving
  any `/api/*`, `/sse`, or `/messages` request.** The dashboard auto-starts on
  every MCP boot, binds loopback, and ran with auth disabled by default — but
  loopback binding does not stop DNS rebinding. A page the developer merely
  visited could rebind its own hostname to `127.0.0.1`, reach the dashboard as
  "same-origin" with an attacker `Host`/`Origin`, and read or export the whole
  cross-project session-memory store with zero credentials. Requests whose
  `Host`/`Origin` is not loopback (or the operator-configured
  `PRISM_DASHBOARD_ORIGIN`) now get `403`, independent of whether auth is
  configured. Route scoping uses the same WHATWG-normalized pathname the router
  resolves, so a dot-segment target like `/x/../api/settings` cannot slip past
  it (a live bypass caught in adversarial review).
- **Added: the data API is gated by a per-startup token by default** (the
  advisory's second remediation). With no auth configured, the dashboard mints a
  random token and prints a tokenized URL to the startup log; opening it once
  stores a `SameSite` cookie so the SPA authenticates transparently. Pin it with
  `PRISM_DASHBOARD_TOKEN`, or disable it with `PRISM_DASHBOARD_NO_TOKEN=1` (the
  `Host`/`Origin` guard still runs). Configuring Basic Auth or JWKS replaces the
  token with that stronger gate. **Operator-visible change:** open the tokenized
  URL from the log, not a bare `http://localhost:3000`.
- 73 new security regression tests (`tests/dashboard/host-guard.test.ts`,
  `tests/dashboard/dashboard-token.test.ts`); docs updated (README, IDE_SETUP,
  WEB_SCHOLAR, examples).

## 20.14.0 — 2026-08-18

### Model convergence — `prism connect` now updates your models

- **Added: `prism connect` converges local models against the registry, and
  `prism update-models` does it standalone.** connect already self-updated
  the npm package and reconverged configuration; models were the missing
  half — a machine kept vision-less models for four days after the registry
  carried the fix, and every image request refused with
  `layer1_classifier_no_vision`. Convergence pulls each *installed*
  `prism-coder` tier (it never decides a 16 GB model belongs on your
  laptop) and then repairs the local alias: `ollama cp` aliases are
  snapshots that silently detach from their source on every re-pull, so
  `prism-coder:<tier>` is re-aliased whenever its bytes differ from
  `dcostenco/prism-coder:<tier>`. Freshness is delegated to `ollama pull`
  itself — cheap when current, and never a reimplementation of the
  registry protocol. Model failures never fail connect: each tier reports
  and the rest continue. Opt out with `--no-models`; preview with
  `--dry-run`.
- **Expect a large download the first time if you keep the 27b.** The
  registry's 27b was updated this week, so the first converge on a machine
  holding it pulls ~16 GB. The plan (which tiers, and the `--no-models`
  escape hatch) is printed before any transfer starts.
- **Caveat: convergence treats `prism-coder:<tier>` names as prism's.** If
  you maintain a deliberately custom local model under one of those exact
  names, convergence will re-point it at the registry bytes — keep custom
  builds under your own names, or use `--no-models`.
- **Fixed before release (adversarial review): the spawned `ollama` CLI now
  targets the same daemon tags are read from.** `PRISM_LOCAL_LLM_URL`
  configured a remote Ollama for reads while `ollama pull`/`cp` acted on
  the shell's ambient `OLLAMA_HOST` — convergence could read one daemon
  and mutate another. The spawn env pins `OLLAMA_HOST` to the tags URL.

## 20.13.1 — 2026-08-18

### Local inference

- **Changed: image requests are processed locally — never refused for content,
  never escalated.** 20.13.0 refused any image whose Layer 1 verdict was raised
  by the picture. That conflated two properties: leak-prevention (images never
  reach cloud — architectural, unchanged) and refusal. On-device inference is
  exactly where sensitive material is safe, and the refusal broke screenshot
  and document verification hardest on the paid tiers where cloud escalation
  was permitted. Every image-carrying request now serves locally with cloud
  pinned off for the whole call — including the route guard and the grounding
  verifier, which could previously carry a prompt or a draft derived from the
  pixels off-device. The verdict stays in `attempts` as an audit marker. An
  image-carrying request is now strictly more private than the same words
  without one. A prompt whose *words* match a reserved rule keeps its existing
  text-path behavior.

### Session memory (portal-backed installs)

- **Fixed: `session_export_memory` and project listing were dead on
  portal-backed installs.** Both portal endpoints existed; the client never
  called them and fell through to a storage path those installs don't
  configure. Exports and project inventory now route through the portal.
- **Fixed: exports no longer include erased entries.** On direct/local
  backends, rows deleted with `session_forget_memory` still shipped in every
  export. All backends now exclude them, matching the portal path.
- **Hardened: an export refuses rather than writing an empty or silently
  truncated backup** when the server response doesn't match the expected
  contract. A backup that reports success must be complete.

### Tooling

- **Fixed: the test suite parses on Windows again.** A release-staging import
  broke suite-level parsing on windows-latest (runtime code unaffected);
  extracted via subprocess with a Windows-safe file URL.

## 20.13.0 — 2026-08-17

- **Added: `prism_infer` accepts screenshots.** Image inputs route through the
  tier ladder with vision-aware tier selection, so a caller can hand a
  screenshot to local inference. The Layer 1 and latency work below builds on
  this capability.

### Layer 1 safety gate

- **Added: attached images are screened for content, not just the request text.**
  Layer 1 classifies a *request*, and images had been passed to it since the fix
  noting that "a screenshot of clinical material would otherwise pass a gate that
  only ever read the text prompt" — the plumbing landed, the instruction never
  did. Holding one clinical incident report constant and varying only the
  wording, the gate escalated 6 of 28 times: a question answered with a timestamp
  left nothing firing at either layer. Each attached image now gets its own
  focused screen before classification, one image per call, and only a clean
  "no" permits local processing — a timeout, a non-2xx, or a reply with no
  yes/no token all escalate. Bounded by consecutive failure rather than a clock,
  so a stalled Ollama costs the same at one image or eight while slow-but-
  answering work is never cut off. Screens *clinical* content only; widening the
  question to the other reserved categories was tried and reverted on
  measurement. Defence in depth, not a guarantee.

- **Fixed: a paid caller could be handed an answer about an image the cloud never
  saw.** The Layer 1 cloud escalation called an inference path with no image
  channel, so an image request was answered from the text alone — "how many
  lines are in this image?" returned "The image contains 42 lines." with
  `used_cloud=true` and nothing to distinguish it from a real answer. It now
  refuses.

- **Fixed: the non-operational artifact exemption was unreachable.** The
  deterministic classifier checked the reserved rules first, so "add auth_bypass
  as a test fixture label in the middleware test" was refused by regex in 0ms.
  The exemption now runs first, but only over the *operational* rules — clinical
  intents fail closed before anything can exempt them.

- **Added: a reserved refusal now names its category.** A refusal that only said
  "reserved content refused" told the caller nothing actionable; it now reports
  which of the reserved rules fired.

### Local inference

- **Fixed: oversized screenshots cost far more than they were worth.**
  Screenshots are now downscaled to a 2000px long edge before inference: seven
  non-Latin scripts drop from 47.0s to 13.8s and a native Retina screenshot from
  ~16–28s to roughly ~10–18s depending on its content, all with identical
  answers. 2000 rather than 1600 because 1600 was measured
  returning a *confidently wrong* number on a dense table, and because it leaves
  a 1920-wide desktop capture untouched. `PRISM_MAX_IMAGE_EDGE` overrides the
  cap; `0`, `off`, or `none` disables downscaling. Shrinking happens only when an
  image genuinely exceeds the cap.

- **Fixed: the context gate undercounted dense payloads and served a truncated
  answer.** The token estimate chose its divisor by code-punctuation density,
  which is blind to base64, dense JSON, and TSV — an 84,953-char payload cleared
  the 32,768 gate, Ollama silently discarded ~70% of it, and the model answered
  confidently from the fragment. The estimate now keys on whitespace density, and
  a truncation detector abandons any tier whose evaluated token count collapses
  to `num_ctx/2` (Ollama's context-shift signature) rather than serving a partial
  answer. The chat-template overhead is now measured per model (~1,111 tokens on
  4b/2b, not the literal 64 it was budgeted) instead of guessed.

- **Fixed: the RAM gate uses the sizes Ollama actually serves.** The vision
  builds grew every tier (2b 2.3→3.3 GB, 9b 5.8→6.7 GB, 27b 16→17 GB) while the
  size table lagged, so the picker could admit a model that then ran out of
  memory. The table now matches the published weights, so a low-RAM machine is
  gated to a tier that fits rather than one that OOMs.

- **Fixed: `num_ctx` is read from the model rather than a table that goes stale.**

- **Fixed: thinking is a tier capability, not a mode** — image requests take
  thinking from the tier, and the screenshot vision path no longer pays for
  reasoning a tier does not need.

### Security & tooling

- **Fixed: ingest no longer reads a provider key from the environment.**
  Q&A generation POSTed directly to the Anthropic API with a key from
  `ANTHROPIC_API_KEY` or `~/.anthropic_key`. An ambient credential means any
  process with the variable set bills the owner — the vector by which a local
  test run once burned roughly $500 against a key in a shell profile. Ingest now
  routes through `prism_infer`, so it is local-first and any cloud use is
  entitlement-gated; PHI redaction still runs before the model sees anything.

- **Fixed: `shell_run` no longer goes through a shell (CodeQL critical
  command-injection).** The tool passed its command to a shell, so caller-
  controlled input could be interpreted as shell syntax. It now executes without
  a shell.

- **Fixed: the entitlement plan gate must fail closed on an unknown tier.** An
  unrecognised plan value fell through to a permissive default rather than the
  lowest tier, so paid-plan gating could evaporate on a malformed entitlement.

- **Fixed: the private-content leak guard reported clean on a repo full of
  leaks.** It handed JavaScript regex source to POSIX `git grep -E`, matching
  none of it, and a `git grep` that finds nothing exits 1 — indistinguishable
  from a clean scan. Four of five content rules were dead on arrival. Patterns
  now run under PCRE, every rule carries a sample it must match, and the guard is
  wired into `prepublishOnly`.

- **Fixed: MCP annotations are declared so non-interactive hosts can call
  `prism_infer`**, and a crashed browser run no longer locks every later run out
  of the profile.

## 20.12.1 — 2026-08-14

- **Fixed: `prism connect --refresh` converged only one registration per host.**
  Claude Code keeps additional directory-scoped entries under
  `projects["<dir>"].mcpServers`, and the scoped one wins for sessions started
  in that directory. A machine could therefore keep launching an old build in
  some directories forever, with `connect` reporting success. Refresh now
  converges every Prism-managed entry in the files it owns, in one atomic
  write, preserving per-entry settings and credentials, and never touching a
  hand-rolled entry. A plugin-owned `.mcp.json` remains outside its reach.
- **Fixed: `prism update` compared the wrong version.** It checked the version
  of the CLI making the call rather than the globally installed package it
  updates, so it could report "current" while the installed package was a
  release behind. It now reads the installed version from the npm global
  prefix.
- **Fixed: the opt-in scheduled updater could not start.** launchd gives an
  agent a minimal PATH that omits `/usr/local/bin` and `/opt/homebrew/bin`,
  where node and npm live on a standard install, so the agent died before
  running anything. The generated LaunchAgent now carries a working PATH;
  `prism autoupdate status` flags an older PATH-less agent as needing repair
  instead of reporting a clean "enabled".

## 20.12.0 — 2026-08-14

- **New: Prism tells you when a newer release exists.** Session startup now
  carries a one-line notice ("Update available: Prism X.Y.Z — run
  `prism connect`") whenever the installed version is behind npm. The check
  is cache-only on the prompt-critical path — a background refresh pings the
  registry at most once a day, 30 seconds after startup, and offline machines
  stay silent. Checkout registrations are told `prism connect --refresh`.
  Opt out with `PRISM_NO_UPDATE_CHECK=1`.
- **New: opt-in scheduled updates that are safe unattended.** `prism update
  [--if-idle]` updates ONLY the global npm package — host configuration,
  hooks, and hook trust are untouchable from it — and with `--if-idle` it
  defers while any Prism MCP server process is running (an unverifiable
  process list counts as busy). A single-instance lock prevents overlapping
  runs. `prism autoupdate enable|disable|status` manages a daily 03:30
  LaunchAgent (macOS) running exactly that. Configuration migrations stay
  behind a visible `prism connect`, which expects hosts to be closed — that
  is why the scheduler never runs connect.

## 20.11.1 — 2026-08-13

- **Fixed: `session_save_ledger`/`save_handoff` could refuse to save — and did.**
  The project resolver hard-rejected on declared-vs-derived mismatch while the
  registry it trusted contained auto-created junk (including a row whose
  repo_path was the user's home directory, which matches every absolute path).
  Agents received contradictory rejections and sessions ended unsaved. The
  resolver never refuses a write now: a mismatch saves under the DECLARED
  project and surfaces the derivation as an advisory warning in the save
  confirmation. Auto-create gained hygiene — only absolute, ≥3-segment
  prefixes that are not an ancestor of an existing entry can be registered —
  so the junk that caused this cannot be written again.
- **Fixed: `prism browser` screenshots were upscaled to the cap on macOS.**
  `sips -Z` resamples in BOTH directions, so every capture smaller than the
  limit came out at exactly 1900px on its long edge (a 1440×900 viewport was
  written as 1900×1187) — not evidence of what rendered, and a silent breaker
  of any gate that asserts captures are viewport-bound. Dimensions are probed
  first and only genuinely oversized captures are shrunk; the cap is 2000px
  (the per-dimension attach limit), so a standard 1920-wide viewport is never
  resampled.

## 20.11.0 — 2026-08-13

- **Fixed: mid-session skill injection silently degraded on both hosts.** The
  routing hook emitted up to 30k chars inline, but Claude Code hard-caps hook
  context at 10,000 chars (anything larger becomes a file plus a 2KB preview
  the model is never told to read — three live instances measured), and Codex
  truncates at ~2,500 tokens by default. Injections now fit a 9,800-char
  inline budget; anything larger is written to `~/.prism-mcp/route-context/`
  with an imperative Read pointer that LEADS the text, so it survives every
  preview window and even the final clamp. Codex registrations converge
  `additionalContextLimit: 0` (verified live: the full payload reaches the
  model). Budget enforcement is by construction, not by data staying small —
  each guard has a mutation-killing test.
- **New: `prism connect` is now a converge command.** It self-updates from the
  registry first, re-execs the new binary, and only then reconciles MCP
  registration, skills, and hooks — ending the "fresh config, stale code"
  machine state. Dev builds and source checkouts are never touched; an offline
  or failed update reports and continues rather than bricking connect.
- **Fixed: Codex hook trust is now honest.** The hook version rides in the
  registered command, so Codex's definition-hash actually changes when the
  script does; trust state is surfaced three ways (approved / awaiting your
  one-time `t` in `/hooks` / present-but-unverifiable) instead of a false
  green "registered".
- **Fixed: offline routing was dead.** The keyword table now loads
  persisted-first when current (0.5s offline instead of a 5.5s stall into
  nothing), and the hook's JSON parsing survives stdout pollution from
  NODE_OPTIONS wrappers.
- **Fixed: captures no longer poison the session that must look at them.**
  Every browser screenshot is normalized to a 1900px long edge at the source —
  past ~20 images, the Claude API enforces a 2000px cap against the whole
  conversation, and one oversized Retina capture blinded image attach for the
  rest of a session.
- The routed-payload cap rose 24k → 30k so the UI-review bundle it was sized
  for no longer trims its own third skill at the moment it matters most.

## 20.10.0 — 2026-08-12

- **Fixed: hosts that prefer `structuredContent` received no startup context.**
  `session_bootstrap` returned both a text block and `structuredContent`; a host
  may surface only the latter, and one popular host does — since 2026-07-22 its
  sessions got 129 bytes of JSON instead of the startup display, memory context,
  and skill routing. Bootstrap (and `skill_save`/`skill_manage`) now carry all
  data in the text; session facts ride a trailing `<prism_session />` line.
- **New: scoped skills route themselves.** Account/team/local skills may declare
  `prompt_triggers` (up to 5 regexes) in their own frontmatter. Matching runs
  on-device against the delivered copy, so private trigger words never enter the
  public routing table and the prompt never leaves the machine. Patterns that
  could backtrack catastrophically are refused at save time, server-side and in
  the client.
- Local-scope skills (written to the host skill roots) are scanned for triggers
  too — previously only delivered skills routed.

## [20.9.3] - 2026-08-11 — The Budget the Floor Never Spent

### Fixed
- **Unprotected skills can actually inline now.** The skill-injection budget
  compared against the whole assembled block — which the always-inlined
  protected floor had already filled — so with a floor larger than every
  tranche, no unprotected skill ever inlined at any normal context level, for
  anyone, since budgeting shipped. Prompt-matched skills now spend a budget
  the floor never touches, matching the documented ADDITIVE contract. Found
  tracing why a task-matched verification skill stayed name-only while an
  agent shipped unverified UI claims; an incident-shaped regression test now
  pins the fix, and reverting the accounting fails exactly that test.

## [20.9.2] - 2026-08-11 — Withheld Rules Still Bind

### Fixed
- **The skills-not-inlined manifest now binds instead of informing.** When the
  context budget withholds a skill's text, the list of withheld names read as
  optional extra material — and an agent claimed UI fixes it never rendered
  while the completion-evidence skill sat name-only in that very list. The
  manifest now states that the listed skills are rules the agent is bound by,
  spells out the consequence (load the governing skill before any completion
  claim, push, or PR), and names every mechanism for doing so. Paired with a
  server-side routing change that inlines the verification skills outright for
  UI-defect and completion-claim prompts.

## [20.9.1] - 2026-08-11 — Queueing, Not Failing

### Fixed
- **Config DB writes no longer lose races on multi-window machines.** libsql
  defaults to `busy_timeout=0` (a writer meeting any lock fails instantly) and
  rollback-journal mode (every reader blocks the writer). With several host
  windows sharing the file, a skill-manifest apply could starve indefinitely —
  measured at 10 consecutive losses. Connections now set `busy_timeout=5000`
  and `journal_mode=WAL` at creation; WAL is persistent and upgrades existing
  databases the first time a post-fix server starts with the file unlocked.
  If a stale pre-fix process still holds a long-lived lock, restart your host
  windows once.

## [20.9.0] - 2026-08-11 — Your Skills, Everywhere You Sign In

### Added
- **`skill_save` — save a skill at the scope you mean.** `local` keeps it a
  plain file on this machine (works signed out; the local-first path makes
  zero network calls). `user` attaches it to your signed-in account so every
  machine you sign into receives it via the managed sync. `team` shares it
  with a workspace — admin-writable, optionally targeted to specific members.
  An explicit scope always wins; signed-in saves default to `user` and the
  result says so; `team` is never a default.
- **`skill_manage` — list, delete, release, restore.** `release` deactivates a
  platform skill you never use, per user or per team, freeing host
  skill-catalog budget; `restore` brings it back losslessly. `delete` removes
  a scoped skill everywhere — after archiving its final content to
  `~/.prism-mcp/skill-archive/`, because the stored copy IS the content.
  The protected behavioral floor is not releasable: deployed clients validate
  it fail-closed, so honoring such a request would stop skill sync entirely.

### Fixed
- A sync already in flight when a save lands cannot contain it; the save now
  verifies its skill actually arrived and re-runs the sync once if not.

### Compatibility
- Existing clients receive account/team skills with no upgrade. The
  compatibility contract was proven against the released validator: scoped
  skills are paid-tier entries carrying `minimum_plan`, and free-tier
  manifests remain exactly the public startup package — the validator's own
  rules, pinned by tests on both sides.

## [20.8.2] - 2026-08-11 — The Sync That Reported Healthy

### Fixed
- **Skill delivery could die silently and report itself current.** A umask
  carrying the owner-execute bit turned the transaction directory's
  `mkdir(..., 0o700)` into `drw-------` — readable, writable, impossible to
  enter. Every staging `mkdtemp` then failed, and because the config DB commits
  before files are written, the client recorded each new generation while no
  file ever reached disk. Measured on a real machine: **nine days** of stale
  skill roots behind a green status. Managed directories that exist but cannot
  be entered are now repaired to exactly `0o700` — never widened — and every
  creation site builds level-by-level so a persistently hostile umask cannot
  reproduce the state one directory deeper.
- **The repair cannot be redirected.** Permission restoration goes through an
  `O_NOFOLLOW` descriptor, and the unreadable-directory fallback refuses
  symlinks — proven against a live symlink-to-unreadable-file exploit during
  review, then pinned as tests.
- **Divergence is now visible.** The client records which generation actually
  materialized to disk, separately from what the DB accepted. When they differ,
  the next startup says so — a ⚠️ line rendered directly under the *Prism
  System Ready* header, where display truncation cannot cut it (the first
  placement put it last, exactly where capped depths truncate first). A
  successful sync heals the divergence and silences the line; installs
  predating the marker never see a false alarm.
- **nanoid advisory cleared** and local CI now runs the two steps whose absence
  let earlier failures through (Linux `npm ci` parity via Docker, raw-inference
  chokepoint guard).

### Changed
- README documents `session_export_memory` and scopes the model-accuracy table
  to the internal routing suite it actually measures.

## [20.8.1] - 2026-08-07 — The Dashboard Was Never Loading

### Fixed
- **The dashboard's inline script has been parse-dead since 2026-05-29.** A
  quoting typo (`data-id='''`) introduced by the May XSS fix was a
  SyntaxError that killed the entire script at parse time — every dashboard
  from 20.6 through 20.8.0 rendered "Loading projects..." forever: project
  selector, neural graph, session ledger, all dead. Found while capturing a
  real screenshot for the README; the picture would not populate, and the
  reason was real. Fixed with a double-quoted attribute (escapeHtml escapes
  the quotes, so it stays injection-safe) and verified live: projects load,
  the graph renders, zero page errors.
- **The ES5 dashboard lint now parses the built output.** The lint existed
  precisely for quote-escaping traps and stayed green through ten weeks of a
  parse-dead dashboard, because it pattern-matched known traps instead of
  parsing. It now renders the built dashboard HTML and runs node --check on
  every inline script block — proven against this exact defect: broken source
  fails naming the line, fixed source passes.

### Changed
- README hero and docs images are now real captures of the running v20.8
  dashboard (scrubbed profile, authored demo data), replacing the generated
  mockup. Dead BFCL blog link now points at the canonical leaderboard, and the
  missing "What's New" entries for 20.7–20.8.0 are in place.

## [20.8.0] - 2026-08-06 — Found, Then Kept

### Added
- **First run proves the memory works instead of describing it.** A memory
  product's payoff is structurally deferred: "it remembered" cannot be felt
  until you come back, and most trial users never do. `session_bootstrap` now
  seeds one demo memory on first run and shows it *recalled* — rendered
  exclusively from the storage read-back, so a broken backend produces no block
  rather than a convincing fake one. Lives in its own `prism-demo` project,
  announces its own removability, one-shot via the durable first-run marker,
  and idempotent so concurrent first runs cannot double-seed.

### Changed
- **Discovery metadata rewritten across every surface.** The MCP Registry
  search is name-only: `memory`, `session memory`, and `coding agent memory`
  each returned Prism zero times, so nobody who did not already know the name
  could find it. npm descriptions led with acronyms ("SLERP-optimized GRPO
  alignment, Zero-Search HDC/HRR retrieval") and `package.json` carried 62
  keywords including `telepathy`, `morning-briefing`, and `reality-drift` — a
  spam signal registries downrank. Descriptions now lead with the four things
  measured as rare among 73 direct competitors (local inference: 2, drift
  detection: 2, associative recall: ~6 of 2298); keywords trimmed 62 -> 12.
- **Plugin description leads with the differentiators**, not the commodity
  phrase four community competitors use verbatim.

### Fixed
- **Codex plugin detection required only a cached manifest, never an enabled
  plugin.** A disabled or half-removed plugin leaves its `.mcp.json` on disk, so
  `connect` could skip its own registration for a plugin that was not providing
  the server — leaving the user with no `prism-mcp` at all.
- **The registry rejects a description over 100 characters (422).** npm has no
  such cap, so the rewrite passed every local gate and failed after merge. The
  publish guard now enforces the limit in the PR, bounded in bytes.
- **Registry publish no longer reports a red X for metadata-only merges.**
  Registry versions are immutable, so a `server.json` change without a version
  bump always returns "cannot publish duplicate version" — the expected
  outcome, not a failure. Only that rejection is tolerated; every other error
  still fails the job.
- **TLS is enforced rather than assumed** for cloud storage URLs: a remote
  `http://` endpoint is upgraded to `https://` instead of silently sending
  session content in the clear. The privacy policy's claim is now true by
  construction.

## [20.7.1] - 2026-08-06 — The Guard That Blocked Its Own Release

### Fixed
- **`closeStorage()` could install a dead connection.** It assigned
  `storageInstance = null` *after* `await close()`, so a throwing close left the
  broken instance in the singleton slot and every later `getStorage()` handed it
  to callers. The clear now happens in `finally`; the error still propagates so
  a caller like `restoreFromBackup` aborts before touching the database file.
- **Restore released the connection before swapping the file.** Replacing a
  database beneath a live connection leaves it on a stale page cache with a WAL
  that no longer describes the file — unsafe per SQLite's own documentation,
  independent of platform.
- **The publish gate blocked the registry republish it exists to protect.** The
  20.7.0 registry publish failed with `prism-mcp-server@20.7.0 is already
  published` — the guard is a `prepublishOnly` check, and the registry workflow
  runs *after* npm publish, where "this version is on npm" is the correct
  precondition. `--manifest-only` now scopes it. (An earlier commit removed a
  *phantom* `--manifest-only` that the script never parsed and whose `||`
  fallback failed open; this implements it for real, with both modes tested.)
- **The Codex plugin manifest sat at 20.6.0 through the 20.7.0 release.**
  `server.json` was guarded; that file was not, so a marketplace submission
  would have advertised a version that no longer exists. Every file declaring a
  version is now held to `package.json`.
- Test teardown no longer fails suites whose assertions all pass. See the
  disclosure below.

### Added
- `tests/verification/first-run-e2e.test.ts` drives the **built** server over
  real stdio through the MCP client. Unit tests call handlers directly and
  cannot catch a regression in transport, tool registration, or startup wiring.
  Falsified before shipping: reintroducing the old greeting turns it red.
- `.github/workflows/windows-diagnostic.yml` + a six-experiment probe. Six
  attempts at a Windows failure had been designed blind against a ~7-minute
  pass/fail matrix; this answers in **47 seconds** on windows-x64 and reports
  facts rather than pass/fail.
- `scripts/local-ci.sh` runs the CI job locally, and is explicit that it cannot
  substitute for the Windows legs.
- `scripts/ensure-dist.sh` rebuilds `dist/` when a checkout leaves it missing.
  Both hosts launch the MCP server by absolute path into the working tree and
  `dist/` is gitignored, so a clean or failed build stopped Prism loading in
  every session on that machine — surfacing far from its cause as "the MCP
  server won't connect".

### Known limitation (disclosure)
- **A dependency holds the database file open on Windows.** `libsql`'s
  `close()` does not finalize outstanding prepared statements, so the
  connection survives until GC runs finalizers
  ([libsql-js#228](https://github.com/tursodatabase/libsql-js/issues/228)).
  Measured on windows-x64: a `close()`, a WAL checkpoint, a 3-second wait, and a
  raw client with WAL disabled all still report `EBUSY` on `unlink`.

  **What it does not affect:** reading the file and overwriting it both
  succeed, so backup, restore, and every shipped feature work normally. The
  lock blocks `unlink`/`rename` only, and releases when the process exits.
  Three test suites hit it during cleanup; their teardown now warns instead of
  failing. An earlier draft of these notes claimed restore was broken on
  Windows — that was inferred from the unlink failure rather than measured, and
  the measurement refutes it.

## [20.7.0] - 2026-08-05 — A First Run That Demonstrates Something

A scrubbed-environment probe drove a brand-new install the way a host does. The
first turn greeted a first-time user with **"Welcome back"**, three `Not loaded`
rows, a warning, and three statements of what they did not have: no next step,
no price, no dashboard, and the tool the greeting pointed at rejected its own
documented bare call. The entire payload was absence.

### Fixed
- **First run is detected and answered with actions.** The greeting routes to
  `onboarding_wizard`, surfaces the dashboard, and points at
  `session_save_ledger`. Gated on a durable marker, so a user with saved
  sessions but no configured name is no longer greeted as a stranger every
  session.
- **The paid tier appears on the one guaranteed impression.** `upgrade_url`
  existed and was surfaced only *after* a user hit an entitlement gate; the
  startup path referenced it zero times.
- **`onboarding_wizard` honours the contract it advertises.** A bare call —
  the exact call its own description documents, and the first tool a new user
  touches — returned `Invalid arguments`, and `next`/`status`/`skip` all
  silently re-rendered step 1 because the handler read fields the validator
  never passed.
- **The dashboard is reported honestly.** Its URL reached stderr only, which
  MCP hosts discard. It is now in the payload, verified by requesting
  `/api/health` rather than by opening a socket: the default port is 3000, the
  most commonly occupied port on a developer machine, so a liveness check would
  have pointed a first-run user at their own dev server.
- `analytics._resetDb()` dropped its sqlite client without closing it.

### Added
- **Agent definitions ship through the skill-manifest pipeline.** Subagent
  routing policy — model tier, effort cap, tool surface — becomes versioned,
  reviewed, deployed content instead of a per-machine hand edit, materialized
  into Claude Code (`~/.claude/agents`), Codex (`.toml`, keys verified against
  the 0.146.0 binary), and Gemini CLI (reduced frontmatter). Hand-edited files
  are never overwritten; ownership is proven by digest, not assumed.
- Agents ride the manifest under their own `agents_generation`. Folding them
  into the skills hash would have broken every deployed client, which
  recomputes it and fails closed.

### Security
- Closed the check-then-act races CodeQL flagged in agent materialization:
  mutations claim a file out of the discovery root and re-hash the claimed
  bytes before acting, and installs use `link(2)` exclusivity. A racing edit is
  restored byte-identical and reported as a conflict rather than clobbered.
- Resolved all 10 outstanding `npm audit` findings (3 high, 7 moderate).

## [20.6.0] - 2026-08-04 — Delivery Is Not a Suggestion

### Known limitation (disclosure)
- **Skill delivery informs; it does not gate.** The 20.5.x on-device routing
  work ensures behavioral rules reach the agent's context on turn one, but a
  live cross-host probe during that work showed a host agent whose data path
  was blocked still fall back to editing unverified source — with the rule
  loaded. If your threat model includes an agent acting against a loaded rule
  under task pressure, you need a mechanical gate outside the model (hooks,
  permissions, least-privilege DB roles) in addition to this package. This has
  been true of every 20.5.x release and was not stated in any of their notes;
  stating it now.

### Added
- Startup names the skills a sync conflict is freezing (previously a bare
  count on a status line while safety skills sat months stale), with the
  resolution steps.
- `ask-first` and `feature-preservation` join the protected floor (14 → 16):
  the floor had outgrown every delivery budget, so unprotected skills were
  never inlined at all.

### Fixed
- CLI `--storage` rejected `auto` (its own documented default) and `synalux`
  (the production backend); the allowlist now mirrors the config union.

## [20.5.3] - 2026-08-03 — Grounding Evidence Carries Its Age

Prompted by an external review: *"the data stays local, but bad grounding
becomes permanent."* Correct diagnosis for local-first memory — storing
everything on your machine removes the outside pressure that would otherwise
surface a stale note.

### Added
- **Memory evidence is dated.** `query_memory_natural` labelled its sources but
  never dated them, so a two-year-old note and yesterday's reached the model
  identically. Evidence now reads:

  `[SOURCE 1: ledger:8286581d (recorded 2025-05-29, 431 days ago)]`

  The date already existed in storage and was being dropped at the snippet
  layer; this is plumbing, not new data collection.
- `tests/integration/grounding-staleness.test.ts` runs the reviewer's own probe
  — seed a deliberately outdated note alongside a contradicting fresh one and
  assert the model receives both, visibly dated. Anyone can run it.

### Fixed
- **Zone-less timestamps parsed as local time.** SQLite writes
  `YYYY-MM-DD HH:MM:SS` in UTC with no zone and `Date.parse` reads that as
  local, so west of UTC a ten-minute-old record parsed hours into the future
  and its age was suppressed entirely — the feature silently did nothing on the
  freshest memories. Formats are not uniform across tables, so they are
  normalised rather than assumed.
- Clock skew between machines no longer suppresses a date; a stamp slightly
  ahead reads as "today". Only more than a day ahead is treated as bad data.
- An absent or unparseable date renders as nothing rather than defaulting to
  now. Defaulting would make the oldest memories — the ones most likely to be
  stale — appear freshest.

### Notes
- **Not solved, and not claimed:** retrieval still ranks a stale note the same
  as a fresh one, and nothing detects that two stored notes contradict. The
  model is *shown* the discrepancy, not *told* about it. Tracked as
  `TECH_DEBT.md` #4.
- A memory's content date can never be older than its row: `saveLedger` stamps
  both date fields on write and `patchLedger` rejects date columns, so only a
  direct SQL write can backdate one. Provenance cannot be forged, but the label
  is strictly row age — anything imported through the public API reads as new.

## [20.5.2] - 2026-08-02 — Startup Budget Regression

Fixes a regression introduced in 20.5.1. **Upgrade if you auto-load more than
one project**, which is when it bites.

### Fixed
- **The inlined rule could exceed the entire startup budget and erase the
  session context.** 20.5.1 made the symptom-triggered block exempt from
  truncation — correct, so a tight budget cannot silently drop the diagnostic
  rule — but sized that block against the per-*level* limit while the display
  is capped against `min(level, nativeMaxChars)`. Bootstrap divides the budget
  across rendered projects, so the real per-project slice is routinely much
  smaller. At a 512-character slice the display emitted 1,919 characters and
  the session context was gone entirely, replaced by the rule meant to
  annotate it.
  The cap and the inline are now sized by one shared helper so they cannot
  drift, and below a usable minimum the rule body is dropped in favour of the
  name line, leaving the remaining space to context. Verified across slices:
  512 in, 512 out, context retained.
- The inlined rule no longer leads with the skill's YAML frontmatter. That was
  ~161 characters of authoring provenance taken from the rule's own budget,
  and it truncated the rule's Anti-Patterns section mid-word.

### Notes
- Single-project setups were unaffected by the overrun; the budget was never
  tight enough to trigger it.

## [20.5.1] - 2026-08-02 — Symptom-Triggered Skills Actually Arrive

20.5.0 surfaced the *name* of a matching skill and called that routing. It
wasn't. A live probe on a third-party host followed the instruction exactly,
got nothing back, and fell back to guessing at source — which is the failure
the routed skill exists to prevent.

### Fixed
- **The matched skill's body is now inlined in the startup display.** Naming a
  skill was never delivering it: bodies reach agents only as files under the
  canonical skills root, hosts outside that mirror have no path to the content,
  and no MCP tool serves it. 20.5.0's line pointed at a rule the agent had no
  way to read. It now carries the rule.
  Bounded to the top match, capped at the smaller of 1,800 characters and 40%
  of the display budget, so it cannot starve the context it annotates.
- **`knowledge_search("<skill name>")` rendered as `knowledge_search("")`.**
  The angle-bracket placeholder was parsed as an unknown tag by the host's
  markdown display and dropped, so the instruction asked the agent to search
  for the empty string. Text a host renders no longer contains placeholders.
- The canonical skills root is resolved through one exported helper rather than
  a path literal duplicated per module. It is overridable per caller and per
  home, so the copy was wrong on any machine that overrides either.

### Notes
- Requires a restart. Server instructions are dynamic; static host files are
  refreshed by `prism connect --refresh`.
- Whether an in-context rule changes agent behaviour is **not** claimed here.
  It is the one thing still unmeasured, and the reason this is a patch rather
  than a feature release: 20.5.0 advertised this capability and shipped it
  non-functional.

## [20.5.0] - 2026-08-02 — On-Device Prompt Routing

Privacy and correctness release. Symptom-triggered skills — the rules that fire
on "can't see X", "no rows", "the list is empty" — are meant to load on the turn
an incident report arrives. They never did: every host template told the agent
to call `session_bootstrap` with `{}`, so there was no prompt to match against.

Fixing the templates exposed a second, structural failure, and closing that
required deciding where matching happens. It now happens on your machine: the
28 keyword rules are already public, so there was nothing a local match could
not compute, and the raw first message no longer crosses the network.

### Security
- **The user's first message is no longer transmitted.** `/api/v1/prism/resolve`
  now receives `{project, role}` only. The keyword rules are fetched from the
  public routing table and matched on-device. `callPortal()` has no `prompt`
  parameter at all, so the message is out of scope at the only place a request
  body is built — the guarantee is structural, not a convention.
  Free and anonymous callers previously paid this privacy cost for nothing: the
  portal gates them to an empty skill set, so the prompt was transmitted, matched
  and discarded.
- **Paid skill *content* is unaffected.** It is gated at `/api/v1/prism/skill-manifest`,
  a separate authenticated route this change does not touch.
- **The private-identifier leak guard now covers four classes, not one.** It had
  checked a single term and stayed green while a private Vercel team slug, a
  private client project name and maintainer-local absolute paths shipped in the
  published package. It runs in CI *and* in `npm test`, so it fails before a
  publish rather than after one.

### Fixed
- **Turn-one routing never ran.** `session_bootstrap` passes the prompt into
  `sessionLoadContextHandler`, which sets `includeSkillContent:false` and returns
  from the native-context branch *before* skill resolution. The prompt was
  threaded all the way in and dropped. Bootstrap now routes before that return.
- **Offline routing died at the next restart.** Last-good persistence was wired
  below the same early return, so the bootstrap path could never cache the
  keyword table. Keyword routing now survives an unreachable portal — the
  incident case a diagnostic skill exists for.
- **`session_bootstrap`'s own tool description still said "call with an empty
  object."** That is the text a host reads to decide *how* to call a tool, so it
  outranked the server instructions in practice and kept hosts passing `{}`.
- **"Open vercel" sent every user to one maintainer's dashboard.** The cloud
  tool-link rules were hardcoded to a private Vercel team and doc repo. They are
  now vendor-generic and overridable via `buildRule7Cloud(links)`.
- `data-before-code` and `critical-thinking-debug` were marked protected by the
  portal but missing from the server's own hardcoded floor, so the two sources
  disagreed and both skills could arrive as bare names on a small budget.

### Added
- **Symptom-triggered skills are surfaced in the startup display.** Native hosts
  already hold every entitled skill as a file on disk, so routing cannot gate
  delivery — it names which skills the first message implicates, with an
  instruction to read them before proposing changes. Entitlement comes from the
  already-loaded manifest, so this costs no portal call.
  The line is carried in the display suffix, which the cap reserves space for:
  appended to the body it was the first thing truncated on a tight budget, which
  is exactly when a diagnostic rule matters most.
- Routing responses are cached per `(project, role)` instead of per prompt. The
  old key included the prompt, so it never hit and grew one dead entry per
  message.

### Notes
- Requires a restart to take effect. Server instructions are dynamic; the static
  host files (`CLAUDE.md`, `AGENTS.md`, `GEMINI.md`) are refreshed by
  `prism connect --refresh`.
- Free tier is unchanged and was verified against a live anonymous identity: a
  non-offline empty skill set, no `Authorization` header, no keyword-table
  request, a manifest limited to `prism-startup`, and no symptom hint.

## [20.4.0] - 2026-08-01 — An Explicitly Named Cloud Backend Fails Loud

### Fixed
- **`PRISM_STORAGE=synalux` or `=supabase` with incomplete credentials silently
  downgraded to local SQLite.** The switch was logged to stderr, which MCP hosts
  discard, so nothing surfaced it: sessions kept serving stale local context
  while the cloud held newer history, and `context_source` read `local` rather
  than any kind of warning. A session could run that way for weeks.
  Naming a backend outright is a strong statement of intent, so it now throws —
  naming the missing variables and the `PRISM_STORAGE=local` opt-out — instead
  of quietly splitting your session history.
- The skill block is budgeted by default rather than only when `max_tokens` is
  passed, so a large skill payload cannot crowd out briefing and history.

### Notes
- `auto` is unchanged: it keeps its documented synalux > supabase > local
  degradation, pinned by a test.

## [20.3.2] - 2026-07-30 — Web Scholar: SSRF Hardening

Security release. Web Scholar fetches article URLs taken from search-engine
output, so the target is attacker-influenceable through SEO poisoning, and
what it scrapes is persisted into the memory corpus and passed to the
configured LLM. A successful redirection to a local address was therefore a
read of an internal service plus exfiltration, not just an internal request.

Reachable only when scholar runs — `scholar_research`, or the background loop
when `PRISM_SCHOLAR_ENABLED=true` — and the attacker also controls DNS or a
search result. Upgrade if you use Web Scholar at all.

### Fixed
- **Six spellings of a local address bypassed the host guard**, which matched
  string prefixes rather than parsing the address:
  - `[::1]` — `URL.hostname` keeps the brackets, so the `'::1'` comparison missed
  - `127.0.0.2` — only `127.0.0.1` was enumerated, not all of `127.0.0.0/8`
  - `0.0.0.0` — never considered; routes to the local host
  - `[::ffff:127.0.0.1]` — IPv4-mapped IPv6 was not decoded
  - `localhost.` — a trailing-dot FQDN defeated the `.localhost`, `.internal`
    and `.local` suffix checks at once, and still resolves to `127.0.0.1`
  - `[64:ff9b::7f00:1]` — NAT64 (RFC 6052) embeds IPv4 in its low 32 bits
- **DNS rebinding.** Every check read the URL string, so a hostname the
  attacker controls passed them all and could still resolve to `127.0.0.1`.
  Targets are now resolved before connecting, every returned address is
  validated, and the request is pinned to those addresses so the name is never
  resolved a second time — which also closes the check-to-connect window.
- **Scrape failures were swallowed** by a bare `catch {}`, so a run that
  fetched nothing was indistinguishable from one that worked. Failures are now
  recorded, logged, and reported.

### Added
- Host classification additionally covers CGNAT, benchmarking, multicast and
  reserved ranges, and IPv6 unique-local and link-local.
- `PRISM_SCHOLAR_SCRAPE_BUDGET_MS` (default 60s) bounds the scrape loop.
  Scrapes are sequential with a 15s per-fetch timeout and the article count is
  env-tunable, so a raised count previously became a multi-minute stall.
- An 8 MiB response cap, which the previous `fetch` call did not have.

### Notes
- Private, link-local and metadata ranges are refused even under
  `PRISM_DEV_MODE=1`; that flag now only relaxes loopback.
- A compromised resolver, and a public address that a downstream device maps
  to something local, remain outside what a client-side guard can detect.

## [20.3.1] - 2026-07-29 — Prism Browser: Real Failure Signals

### Fixed
- **The stealth library had never been applied.** `Stealth(webgl_renderer=...)`
  is not a valid keyword (it is `webgl_renderer_override`), and the exception
  was swallowed into the audit log: 1,139 failures and 0 successes since
  2026-04-14, while `--stealth full` reported `playwright-stealth-v2` as
  active. Fixed, and a layer that cannot be applied now fails loudly instead
  of degrading silently.
- **The headless build announced itself.** `navigator.userAgentData` and the
  `Sec-CH-UA` request header both advertised `HeadlessChrome` while the UA
  string claimed Chrome. Identity is now set through CDP
  `Emulation.setUserAgentOverride` with full `userAgentMetadata`; request
  interception cannot fix client hints because Chromium re-adds them after
  the interception point.
- **A patch corrupted the page under test.** The
  `Object.getOwnPropertyDescriptor` override broke descriptor reads on
  iframes *and* on ordinary objects carrying a `contentWindow` key, was
  readable via `toString`, and was bypassed in one line by
  `Object.getOwnPropertyDescriptors`. Removed.
- **`open` discarded the HTTP status**, so a 500 reported `status: ok`. It now
  returns `http_status` and fails on 400 or higher (`--allow-http-error` opts
  out).
- **`--cleanup` was a no-op** in pipe and repl mode, the two modes agents use.
- **Screenshots could collide** within the same second and were never checked
  for an empty frame.
- **`--local-only` did not isolate.** WebSocket, EventSource, WebRTC and
  `sendBeacon` egress bypass request routing entirely; service workers were
  allowed. All are blocked now, and the previously unlogged escape is audited.
- **Audited URL paths were not sanitized**, so record identifiers in a path
  reached a log documented as content-free. The FileVault check now fails
  closed, and the fingerprint validator performs a real check instead of
  recording `consistent=true` unconditionally.

### Added
- Assertions: `assert-text`, `assert-visible`, `assert-hidden`,
  `assert-count`, `assert-url`, `assert-title`, `assert-eval`, and
  `assert-no-page-errors`. `eval` alone cannot fail a run, because a falsy
  result is a legitimate value.
- Console errors, uncaught page exceptions and failed requests are captured
  and attached to command output; `eval` returns native JSON with its type
  rather than a Python `repr`.
- `pages` / `switch-page` / `close-page` so popups are reachable,
  `--ephemeral-profile` and `--storage-state` for hermetic authenticated runs,
  `--fast`, `--fail-fast`, `--trace`, `--video`, `--har`, and
  `profiles --prune-older-than` for profile maintenance.

### Changed
- Site isolation, client-side phishing detection and popup blocking are no
  longer disabled, and geolocation is no longer auto-granted; profiles hold
  live authenticated cookies.
- `--viewport` fails loudly instead of silently falling back, and arguments
  accept shell-style quoting so a selector may contain spaces.

## [20.3.0] - 2026-07-28 — Semantic Search Restored + Hybrid Retrieval

### Fixed
- **Embedding writes were silently lost on paid tier** — three stacked faults
  meant 0 of 8,560 ledger rows carried a vector and semantic search returned
  nothing for every query: `save_ledger` returned no row id, `patchLedger`
  wrote to a direct Supabase URL paid installs don't have, and the portal had
  no action to store a vector. All three fixed; existing corpus backfilled.
- **Health check certified the outage as healthy** — `missingEmbeddings` was
  hardcoded to 0. It now reports the portal's real count, and says coverage
  "could not be verified" when the portal is unreachable instead of lying.
- **`session_backfill_embeddings` could not see what needed repairing**
  (direct-Supabase read → NXDOMAIN). Now portal-routed; verified repairing 9
  rows in production.
- **`knowledge_search` returned nothing for natural-language queries** —
  ranked relaxing search with honest `match_mode` (widened results are
  labelled leads, not exact hits).

### Added
- **Hybrid retrieval** (portal tier): `session_search_memory` fuses semantic
  similarity with exact-term lexical matching via weighted RRF. On blind
  probes: never worse than semantic alone, and rescues exact-identifier
  queries (TPNs, function names) that embeddings blur. Results state how they
  were found (`hybrid retrieval`, per-hit `sem#/lex#`, `exact-term match`).
  Local SQLite installs keep pure vector search.

## [Unreleased]

### Fixed
- Handoff history snapshots now retain the effective role and active branch,
  and save responses distinguish a durable primary handoff from a failed
  optional time-travel snapshot.

## [20.2.9] - 2026-07-26 — Reliable Releases and Sessions

### Fixed
- npm publication now fails before building when the checkout contains
  uncommitted or untracked files, preventing immutable registry artifacts from
  silently diverging from their reviewed Git source.
- Repacked the guarded-routing and native-acceptance release from its clean,
  tested commit.
- Removed the release-only `current-staging-acceptance` procedure from the
  protected startup floor. Ordinary coding sessions now rely on the phased
  `evidence-first-protocol`: one correlated reproduction during iteration,
  with strict artifact inspection reserved for completion, push, and release.
- Restricted unauthenticated and Free native manifests to the public hook-free
  startup package. Full protected skill files now require an authenticated paid
  entitlement, and Free startup no longer advertises paid package names.
- Realigned paid offline and native manifest contracts with the portal's
  12-guardrail protected floor plus hook-free startup.
- Delivered the same compact evidence workflow through managed startup
  instructions for Claude Code, Gemini CLI, and Codex, and through MCP
  initialize instructions for Cursor and Claude Desktop. Screenshot proof now
  explicitly requires the active agent to inspect the issue-specific visible
  state itself instead of asking the user to verify it.
- Behavioral verification now honors subscription credentials loaded from
  Prism's local config without requiring a key copied into host configuration. A packaged
  `prism verify-behavior` fallback preserves the real fail-closed scenario when
  a host's long-lived MCP transport has closed, and malformed portal responses
  now fail closed instead of being treated as permission to skip verification.
- Long-lived MCP servers now probe idle transports and exit cleanly when the
  client channel is gone, allowing native hosts to restart Prism instead of
  repeatedly returning `Transport closed`.
- Synalux handoff saves now unwrap and validate the portal's authoritative OCC
  result, persist authenticated history snapshots before short-lived clients
  exit, and fail loudly on malformed success envelopes.
- Optional semantic-index initialization can no longer turn a successfully
  persisted ledger, handoff, or experience into a false save failure. Responses
  now distinguish primary persistence from optional indexing.
- The Python coding gate now ignores Windows Store command aliases that never
  start the parser, preventing valid same-tier code repairs from being rejected
  as syntax errors on Windows.

### Tests
- Added regressions proving clean committed checkouts may publish while
  modified tracked files and untracked source files fail closed.
- Added regressions proving Free/native manifests install only public startup,
  never retain paid packages on a verified downgrade, and do not require or
  install the release-only staging gate.
- Added all-host instruction contracts plus same-tier refresh coverage that
  prunes the former release gate from every Prism-managed native skill root.
- Added CLI fallback and OAuth-only behavioral-verifier regressions so a dead
  MCP channel cannot be replaced with a self-authored scenario.
- Added healthy, rejected, timed-out, and closed MCP transport checks; current
  and legacy Synalux handoff-envelope contracts; awaited snapshot behavior; and
  optional-index initialization failure coverage.
- Added a Windows interpreter-selection regression that distinguishes an
  unavailable command alias from a parser-confirmed Python syntax failure.

## [20.2.8] - 2026-07-26 — Guarded Routing and Native Acceptance

### Added
- Added caller-supplied `allowed_tools` and `route_guard: auto|local` controls
  to direct `prism_infer` route mode.
- Added authenticated deterministic route correction for subscribed callers,
  while retaining a fully local override and local enforcement on every tier.
  Advertised custom host tools remain local instead of being sent to the
  seven-tool Synalux correction endpoint.
- Added `current-staging-acceptance` to the protected universal skill floor.
  `prism connect` materializes it for every supported native host and session
  startup reports it alongside the existing evidence-first guardrail.

### Fixed
- Canonical Prism tool-call envelopes no longer fail the generic quality gate
  as chat-style tool-call bleed.
- Malformed and unadvertised route calls are suppressed before reaching a
  host, and invalid portal corrections cannot replace tool arguments.

### Tests
- Added parser, advertised-registry, fallback, entitlement, argument-integrity,
  JWT-refresh, HTTP-boundary, and known routing-failure regressions.
- Added free-tier manifest, native-host materialization, offline injection,
  startup reporting, and protected-budget regressions for the acceptance gate.

## [20.2.7] - 2026-07-25 — Reliable Cross-Process Session Saves

### Fixed
- Persisted successful context-load receipts locally so
  `session_save_ledger` and `session_save_handoff` continue to recognize the
  active conversation after an MCP server restart or process handoff.
- Kept context authorization scoped to the exact project and conversation,
  bounded by the existing six-hour lifetime, and fail-closed for malformed,
  forged, future-dated, expired, and cross-project receipts.
- Stored only one-way scope hashes, never plaintext conversation or project
  identifiers.

### Tests
- Added restart and sibling-process recovery coverage plus malformed, forged,
  future-dated, expired, cross-project, storage-failure, and plaintext-leak
  regressions.

### Security
- Updated PostCSS to 8.5.23, resolving the high-severity previous-source-map
  path-traversal advisory and deduplicating Vite onto the patched release.

## [20.2.6] - 2026-07-22 — Safe Host Configuration Reads

### Fixed
- Replaced check-then-read handling for Claude, Cursor, Gemini, and Codex
  configuration files with descriptor-based reads and file-identity checks,
  closing the host-config TOCTOU window while preserving supported symlinked
  dotfiles.
- Dangling configuration symlinks now fail loudly instead of being mistaken
  for missing files, and Prism installation receipts cannot overwrite a
  planted symlink target.

### Tests
- Added cross-host regressions for dangling symlinks and installation-receipt
  symlink protection alongside the existing symlink-preservation and
  concurrent-edit coverage.

## [20.2.5] - 2026-07-22 — Release Integrity and Dependency Security

### Fixed
- Updated transitive dependency overrides so clean installs resolve patched
  Hono, `body-parser`, `fast-uri`, `protobufjs`, Sharp, and `tar` releases;
  `npm audit --audit-level=high` now reports zero vulnerabilities.
- Replaced the i18n workflow's direct push to protected `main` with a
  deterministic generated-document verification gate. Translation drift now
  fails CI without bypassing required branch checks.
- Made the six-platform CLI matrix portable: one Linux lane installs and
  verifies the optional Prism Browser runtime, Windows uses `USERPROFILE` for
  native skill materialization, Unix-only mode assertions stay Unix-only, and
  known libSQL test-handle cleanup behavior no longer masks passing behavior.
- Republished the 20.2.4 session-memory reliability changes from the final,
  CI-repaired source after the original npm artifact raced the repair commit.

### Tests
- Verified the complete Vitest suite, TypeScript build, dependency import
  smoke tests, clean audit, deterministic i18n generation, and npm package
  contents before release.

## [20.2.4] - 2026-07-22 — Reliable, Substantive Session Memory

### Fixed
- Greeting-only assistant replies are no longer written to the session ledger.
- Existing greeting-only rows are filtered from quick, standard, and deep
  context without deleting history or hiding rows with decisions, TODOs, files,
  or non-session event types.
- Direct MCP `session_bootstrap` and `prism bootstrap` use one bounded local
  last-good snapshot when Synalux has a transient rate, network, timeout, or
  server failure. Permanent authorization and validation failures remain loud,
  and later writes keep using the configured cloud backend.
- Identical concurrent context reads share one portal request without caching
  completed responses, reducing startup bursts while keeping later reads fresh.

### Tests
- Added regressions for observed VS Code greeting rows, immutable context
  filtering, transient-vs-permanent startup failures, local snapshot reuse,
  cloud-write preservation, concurrent read coalescing, and all five native
  host registration paths.

## [20.2.2] - 2026-07-21 — Automatic Tier Skill Sync

### Added
- Complete Synalux skill-manifest synchronization at `prism connect`, MCP
  startup, `session_load_context`, and a five-minute refresh interval.
- Native package materialization under `~/.agents/skills`, including complete
  multi-file packages, atomic replacement, ownership markers, recovery, and
  bounded cross-process locking.
- One canonical local-first orchestration policy for Claude Code, Claude
  Desktop, Cursor, Gemini CLI, and Codex. MCP initialize instructions carry it
  to every host; native instruction files reinforce it where supported.
- Memory-aware local workers: `prism_infer` accepts `project`,
  `context_depth`, and `conversation_id`, then loads bounded
  quick/standard/deep project history as untrusted historical data.

### Changed
- Platform skill activation now intersects the current manifest entitlement;
  dashboard writes cannot shadow the managed platform namespace.
- Free clients receive exactly the protected 12-skill foundation. Paid tiers
  receive the portal's current subscribed routing set.
- `prism connect` performs a one-time exact-match removal of legacy Prism-owned
  Claude lifecycle hooks. User hooks remain untouched; native skills and
  server-side reminders now own startup, sync, handoff, and drift behavior.
- Recognized legacy Prism startup sections in `~/CLAUDE.md` are retired only
  after native skill sync succeeds; all other global instructions are retained.
- Claude Code receives a small ownership-marked native `~/CLAUDE.md` block
  because live acceptance proved MCP metadata and skill discovery alone do not
  reliably trigger a first-turn tool call.
- Local delegation is now the default, with an explicit setting/environment
  opt-out. `session_task_route` returns the real `prism_infer` executor and
  bounded arguments instead of the nonexistent `claw_run_task` tool.
- `session_task_route` forwards a deterministic complexity hint but does not
  choose a model. `prism_infer` centrally selects 4B/9B/27B using complexity,
  memory/context fit, installed models, live RAM, entitlements, and explicit
  caller overrides.
- `prism connect` disables Codex and Gemini native fan-out. Codex retains a
  capped Terra/low fallback profile for an explicit future re-enable; Claude
  Code's fallback subagent model is pinned to Sonnet.

### Fixed
- Codex no longer needs a second restart after `prism connect`: the command
  waits until entitled native skills exist before returning.
- MCP metadata now selects `session_bootstrap({})` on the first turn instead of
  overriding native startup with a hardcoded `session_load_context` depth.
- Native bootstrap responses no longer re-inline the tier snapshot already
  installed by `prism connect`, avoiding 100 KB+ duplicate first-turn payloads.
- Downgrades prune only Prism-managed native and database entries; custom or
  locally modified skills are preserved and reported as conflicts.
- Failed, partial, invalid, or unauthenticated paid snapshots retain last-good
  state and fail loudly instead of silently changing entitlement.

### Tests
- Added tier-matrix, first-launch CLI, upgrade/downgrade, atomic rollback,
  ownership-conflict, lock-recovery, auth-refresh, dashboard-policy, and
  package-content regression coverage.
- Added exact legacy-hook migration coverage for success, sync failure,
  disabled sync, dry-run, idempotence, malformed settings, and near matches.
- Added cross-host policy, native setting preservation, router-to-executor,
  memory-depth, historical-data escaping, and explicit opt-out coverage.

## [20.2.1] - 2026-07-20 — Subscription-Aware Memory

### Changed
- `PRISM_STORAGE=auto` now uses Synalux memory only when the portal confirms
  `session_memory_unlimited`; portal-confirmed Free accounts stay on local
  SQLite, while Standard, Advanced, and Enterprise use Synalux memory.
- `prism connect` preserves an explicit `auto`, `local`, `synalux`, or
  `supabase` storage choice independently of the Synalux API key.

### Fixed
- Entitlement outages fail closed instead of silently selecting another
  backend and splitting session history.
- Credentials injected after module initialization are now visible to the
  entitlement and JWT clients.

### Tests
- Added tier-matrix, entitlement-provenance, explicit-storage, forced-local,
  runtime-credential, and process-level `prism connect` regression coverage.
- Made Codex host discovery and SQLite ledger cleanup portable across the
  Linux, macOS, and Windows CI matrix.

## [20.2.0] - 2026-07-20 — Host Auto-Registration

### Added
- **`prism connect`** — Detects Claude Code, Claude Desktop on macOS, Windows,
  and Linux, Cursor, Gemini CLI, and Codex, then registers the installed Prism server
  using absolute runtime and package paths. Supports `--host`, `--all`, and
  write-free `--dry-run` operation.
- **Safe managed refreshes** — `--refresh` updates only entries previously
  created by Prism, allowing a validated Synalux API key to be added later
  without overwriting custom configuration.

### Changed
- Host configuration uses atomic writes, preserves symlinked config files,
  detects concurrent edits observed before atomic replacement, and leaves
  existing `prism` or `prism-mcp`
  registrations untouched by default.
- Codex registration respects `CODEX_HOME` and preserves existing TOML while
  owning only a clearly marked `mcp_servers.prism-mcp` block.
- Onboarding and IDE setup now direct users through the single `prism connect`
  path instead of maintaining separate generated snippets.

### Tests
- Added cross-platform registration coverage for idempotency, refresh,
  dry-run, application detection, invalid JSON/TOML, symlinks, and concurrent
  host writes.

## [20.1.0] - 2026-07-20 — 🧭 Failure Contract, Oversize Prompts, Ctx Gate, Entitlements Provenance

Local-first plan v2 Phase 1 complete (§5.2–§5.5). Every terminal path of
`prism_infer` is now observable, oversize prompts are no longer blanket-refused,
silent prompt truncation is structurally impossible, and degraded entitlement
resolution is visible and optionally fail-loud.

### Added
- **Failure contract (`escalation: 'serve' | 'report'`)** — §5.2. Default
  `'serve'` keeps legacy behavior. Under `'report'`, safety refusals return a
  typed `{gate_outcome: {status:'refused'}, output:''}` result instead of
  throwing, and every serve carries a structured
  `gate_outcome {status: success|degraded|refused, reason, served_anyway}`.
  The gate-fail-without-cloud path previously served degraded output with NO
  flag at all — now marked on both `quality_gate_failed` and `gate_outcome`.
  Infra exhaustion still throws in both modes (an infrastructure failure is
  not a refusal). Refused results never touch the session accumulators —
  they previously would have counted as local serves and inflated
  cloud-tokens-saved.
- **Layer-1 oversize verdict `UNCERTAIN_LENGTH`** — §5.3. Prompts >4000 chars
  previously got a blanket UNCERTAIN → reserved handling → with cloud off,
  every big benign prompt was refused. Now: the deterministic keyword floor
  scans the FULL text first (reserved vocabulary anywhere short-circuits to
  OBVIOUS_RESERVED with no classifier call), then a bounded head+middle+tail
  excerpt is classified. A clean excerpt yields the distinct UNCERTAIN_LENGTH
  verdict, which routes LOCAL with an audit marker. Semantic UNCERTAIN still
  gets full reserved handling. The keyword floor also gains previously-missing
  vocabulary (basket/prone/supine/two-person holds, holding-the-client-down,
  rage episode).
- **Per-tier ctx gate (`ctx_insufficient`)** — §5.4. MODEL_TIERS context values
  are now aligned with the LIVE Modelfile `num_ctx` (verified inverted from
  the old table: 27b/9b bake 4096, 4b/2b bake 32768 — the old config was
  wrong on 3 of 4 tiers). The tier walk skips tiers whose ctx cannot hold the
  prompt; if no tier fits, cloud receives the FULL prompt when allowed,
  otherwise a loud error with the per-tier trail. Ollama previously truncated
  over-ctx prompts silently and answered from the fragment.
- **Entitlements provenance + strict mode** — §5.5. `PrismEntitlements.source`
  distinguishes `'portal'` (real data, incl. portal-confirmed free) from
  `'unconfigured'` (no key — free is correct) from `'fallback_free'` (portal
  configured but unreachable — free clamps were ASSUMED). New
  `strict_entitlements: true` arg fails loud on `fallback_free` instead of
  silently running under assumed limits. `fallback_free` never enters the
  5-min cache (recovery is immediate); a 25s negative cache caps retry cost
  during outages. Every result carries `entitlements_source`.

### Fixed
- Ledger rows now carry the structured `gate_outcome` and `refusal_reason`
  (columns pre-provisioned in 20.0.7); serve-mode keyword-backstop refusals
  now write a ledger row (previously silent).
- Stale "cached 1hr" entitlements docs corrected (resolution was already
  per-call with a 5-min cache).

### Tests
- 70+ new tests across four suites: three-terminal-path contract fixtures with
  drift guard, oversize excerpt/keyword-floor coverage (incl. an explicit
  pinned-residual fixture), ctx-gate tier skipping with never-silent-truncation
  proof, entitlements provenance per resolution path, negative-cache window,
  strict-mode contract. Full suite 108 files / 3200+ tests green. Each plan
  item shipped through an adversarial review pass; all confirmed findings
  fixed in the same commits.

## [20.0.8] - 2026-07-20 — Fix: verify_behavior MCP result contract

### Fixed
- **`verify_behavior` crashed on every invocation** — the handler
  (`src/tools/behavioralVerifierHandler.ts`) returned a bare
  `Promise<string>` instead of a `CallToolResult` object
  (`{ content: [{ type: "text", text }] }`). The MCP SDK (^1.27.1) strictly
  validates tool results and rejected the string at the root:
  `-32602 Invalid tools/call result: expected object, received string`.
  The bug shipped with the tool's introducing commit and had no test
  coverage, so it went unnoticed until the tool was invoked against a
  strict-validating SDK. The scenario text is now wrapped in a content
  array (`verifyBehaviorHandler` → `buildScenarioText`); all fail-closed
  branches (portal unreachable, missing JWT, non-OK response, malformed
  JSON) are preserved.

### Added
- **`tests/behavioralVerifierContract.test.ts`** — contract regression test
  asserting `verify_behavior` returns `{ content: [{ type: "text", text }] }`,
  not a bare string. Fails against the string-returning bug, passes with
  the fix.
- **`tests/behavioralVerifierPaths.test.ts`** — fail-closed-path tests
  pinning that the safety gate never skips: no-config, no-JWT, portal
  error, and malformed-JSON branches all return a valid result object.

## [20.0.7] - 2026-07-18 — 🛡️ Reserved-Content Safety + Skills Auth + Persistent Delegation Metrics

### Security
- **Reserved-content escalation is now Claude-or-refuse** — reserved clinical
  content (restraint / seclusion / physical-management class) refused by local
  Layer-1 could previously be escalated to the portal cascade and served by a
  SMALLER model (2B / OpenRouter) than the one that refused it. The client now
  sends `reserved: true` on escalation; the portal routes such requests to
  Claude directly or refuses — never a small local tier, on any plan.
- **Defense in depth** — if an unpatched portal still answers a reserved turn
  from an `ollama-*` / `openrouter-*` backend, the client refuses to serve it.
- **Typed refusals** — `ReservedRefusalError` with
  `refusal_reason='layer1_reserved'` lets callers distinguish a safety refusal
  from an infrastructure failure. Refusals are recorded in the metrics ledger
  with zero prompt content.
- **Credentialed portal fetches hardened** — `redirect: 'error'` on the skill
  resolve path (matches the existing `synaluxJwt` standard).

### Added
- **Skills JWT auth fallback** — when `PRISM_SKILLS_TOKEN` is absent,
  `skillRouting` exchanges `PRISM_SYNALUX_API_KEY` for a JWT (same per-user
  identity as inference). Fixes machines that resolved paid entitlements for
  inference but silently `tier=free` for skill delivery — the cause of
  behavioral skills (e.g. `local-inference-first`) never reaching sessions.
  Bounded 4s exchange; 401-invalidate + single retry; static token keeps
  precedence.
- **Persistent inference-metrics ledger** — append-only `infer_metrics` table
  in `prism-config.db` records every `prism_infer` call (backend, mode, tier,
  tokens, latency, RAM, gate outcome, refusal reason). The in-memory session
  counters previously reset with every server restart, making long-term
  local-vs-cloud delegation unmeasurable. `inference_metrics` tool gains
  `period: 'session' | 'all'`. Test-suite writes are sandboxed via
  `PRISM_DATA_DIR`; `safety_gate` calls are never persisted.
- **Skill-delivery budgeting** — `session_load_context` skill assembly now
  honors the caller's `max_tokens`: protected skills always inline in full
  (the documented floor), prompt-matched skills next, remaining skills by
  priority within a 60% tranche of the budget (the rest is reserved for
  session history/briefing), and everything else is listed in an overflow
  manifest — never silently dropped. Fixes paid-tier resolutions (~114KB
  measured) exceeding host tool-result caps, which caused the whole response
  to be file-diverted with the agent receiving nothing.
- **Per-skill routing metadata** — the portal resolve response now carries
  `{name, priority, protected, category}` per skill and the client consumes
  it (older portals fall back safely to name-only behavior).

### Fixed
- 3 review rounds (2 adversarial multi-agent) caught before release: protected
  flags fabricated client-side (floor was dead code), skill budget saturating
  the whole response budget (zero history delivered), offline floor defeated
  by dedupe, ledger rows from test suites polluting the production DB, silent
  permanent ledger disable on one transient init failure, and a mode column
  that would have been NULL forever.

### Release notes
- **20.0.6** (2026-07-15) was published from the same tree as 20.0.5
  (`gitHead d53b641`) with no code changes and no changelog entry — treat it
  as a republish of 20.0.5. 20.0.7 is the first release containing the
  changes above, plus the sync-skills leak-guard fix and CLA action pin from
  #98.

## [19.3.1] - 2026-07-06 — Cloud Tokens Saved Metric + Gemini Host Verification

### Added
- **`cloudTokensSavedEst`** counter in `inferenceMetrics.ts` — the honest local-inference routing metric. Accumulates `submittedEst + completionTokens` for every `used_cloud=false` call. Uses `submittedEst` (not `evaluated`) to correctly count KV-cached prompts. Displayed in both compact footer (`📊 … · N cloud tok saved`) and full `inference_metrics` block. Reset on session boundary.
- **`scripts/test-gemini-host.mjs`** — Gemini 2.5 Flash integration test for host-agnostic Arc 1 gates and Arc 2 routing. Spawns `dist/server.js` as a real subprocess over stdio JSON-RPC. 5 tests, 7 assertions: T1–T3 confirm gates are server-side (hard-block without context, pass after load, `""` hard-blocked); T4–T5 confirm Arc 2 routing instinct from tool descriptions alone without skill-file instructions. T4 is two-sided — "answered directly" fails. 7/7 across 4 independent runs.

## [19.3.0] - 2026-07-06 — 🔒 Host-Agnostic Session Enforcement + CI Guard

### Added
- **`src/session/sessionContext.ts`** — Server-side LRU session registry keyed on `conversation_id`. Replaces Claude Code-only hook enforcement; gates fire from the tool handler itself so every host (Gemini, cron, auto-push) sees the same behavior.
  - `markContextLoaded(conversationId, project, version)` — called by `session_load_context` handler after successful assembly.
  - `requireContextLoaded(conversationId | undefined) → GateResult` — fail-closed gate returning `null` (pass) | `{blocked:true, error}` | `{blocked:false, warning}`. `undefined` → allow (opt-in for session-agnostic hosts); `""` → block (not a bypass). LRU via Map insertion order + `touch()` (O(1)). TTL enforced on every read, not just eviction.
  - `noteInferenceForSession` — fire-and-forget telemetry; uses `sessions.get()` (not `getOrInit`) to prevent ghost stubs.
- **`src/session/__tests__/sessionContext.test.ts`** — Unit tests for the full gate surface: `undefined → null`, `"" → block`, expired TTL, LRU cap, ghost stub prevention.
- **`scripts/no-raw-inference.mjs`** — CI guard: scans all tracked `src/` TypeScript files for raw inference calls outside the allowlist. Exits 1 on untracked `src/` files. Uses `(?<!:)\/\/` negative lookbehind to preserve `http://` URLs while stripping comments. Individually-named allowlist entries with explicit reasons (no module-level allowlisting).
- **CI gate** (`ci.yml`) — `no-raw-inference.mjs` wired between Build and Test steps.
- **`conversation_id`** added to `SESSION_SAVE_HANDOFF_TOOL` and `SESSION_LOAD_CONTEXT_TOOL` schemas (was missing — caused permanent hard block for compliant clients).
- **Operating boundaries** prepended to every `session_load_context` response for non-Claude hosts (belt + suspenders: server enforces, payload informs).

### Fixed
- **13 bugs caught across 4 adversarial review rounds** (R1–R4):
  1. `(gate as any)` casts in `ledgerHandlers.ts` defeated TypeScript rename safety → proper discriminated-union narrowing
  2. `SESSION_SAVE_HANDOFF_TOOL` missing `conversation_id` schema → compliant clients were permanently hard-blocked
  3. `requireContextLoaded(undefined)` hard-blocked auto-push/resource-reader hosts → now returns `null` (allow)
  4. `evictStale` while-loop truthy check → `""` session key stalled the loop → changed to `!== undefined`
  5. `noteInferenceForSession` used `getOrInit` → created ghost stubs crowding out legitimate sessions → changed to `sessions.get()`
  6. Comment-strip regex `/\/\/.*/g` matched `://` in URLs → URL bypass patterns went blind → fixed with `(?<!:)\/\/` lookbehind
  7. Untracked `src/` files silently passed CI guard → exit 1 on untracked files
  8. Empty-string `conversation_id` bypassed gate (`!""` is truthy) → changed to `=== undefined`
  9. Stale intersection cast `args as typeof args & { conversation_id?: string }` after type guard → removed
  10. `(args as any).max_tokens` after type guard already narrows field → changed to `args.max_tokens`
  11. `isPrismInferArgs` missing `typeof a.conversation_id !== "string"` check → non-string truthy value passed guard
  12. `args.conversation_id!` non-null assertion across async `.then()` boundary → captured `const _convId` synchronously
  13. Stale ALLOWLIST entry for `layer1Integration.test.ts` → removed (file uses no SYMBOL_PATTERNS)
- **`isSessionSaveLedgerArgs` / `isSessionSaveHandoffArgs` / `isSessionLoadContextArgs`** — `conversation_id` validation added to all three type guards.
- **`isPrismInferArgs`** — `conversation_id` type-checked as string when present.

### Changed
- `session_save_ledger` and `session_save_handoff` now gate on `requireContextLoaded` at entry (hard block on unknown/expired session, soft warning on boundaries-version drift).
- `session_load_context` calls `markContextLoaded` in all 3 success paths (normal, fresh-project early-return, and third assembly branch).
- 3071 tests across 101 files.

---

## [19.2.9] - 2026-07-05 — ⚡ Auto-Evict + 27B Routing Fix

### Added
- **Auto-evict warm smaller models** — When `model_ceiling: "27b"` is requested and 27B is installed but not warm, the handler now automatically unloads any warm smaller-tier models (9B, 4B, 2B) if freeing them would provide sufficient RAM for 27B. Eliminates the need for callers to manually unload models before requesting a large-model ceiling.
  - Eviction is conditional: `freeBytes + warmBytes ≥ minFreeGb` must hold before any eviction fires.
  - Evictions run with `Promise.allSettled` (network error to Ollama cannot crash the inference call).
  - In-process mutex prevents concurrent requests from racing the eviction window.
  - 800ms settle before re-reading free RAM (measured Ollama buffer-release latency).
  - Live test: 9B warm (5.6 GB) → evicted → 27B loaded and ran locally. `used_cloud=false`, `attempts=[]`.

### Fixed
- **`model_ceiling: "27b"` ignored for enterprise plans** — Portal returns `model_ceiling: "32b"` for legacy enterprise/advanced accounts. Added normalization `32b → 27b` (same pattern as existing `14b → 9b`). Per-call `model_ceiling: "27b"` now resolves correctly without being clamped down.

### Changed
- 3096 tests across 101 files (up from 3031/101). 4 new auto-evict unit tests covering eviction condition guard (F1), parallel eviction with failure logging (F2), eviction mutex (F3), and ceiling-index guard (F4).

## [19.2.8] - 2026-06-24 — 🔧 ESM require() Fix + Schema-Code Audit Skill

### Fixed
- **`knowledge_ingest` broken** — `require("path")` in `ingestHandler.ts` crashes in ESM context (`"type": "module"`). Replaced with static `import { resolve } from "path"`. File-path ingestion was completely non-functional.
- **`sniffFormat` broken** — `require('node:fs')` in `migration/utils.ts` same ESM issue. Replaced with top-level `import { openSync, readSync, closeSync } from "node:fs"`.
- Zero `require()` calls remain in compiled output.

### Added
- **`schema-code-audit` skill** — Deep cross-reference audit technique: extracts every `.from()` call from API routes and verifies table names, column names, FK joins, onConflict constraints, and cross-table ID usage against actual migration DDL. Originated from a sweep that found 20 BLOCKER bugs across banking, billing, accounting, and clinical modules.
- **`pre-push-audit` rules 20-25** — Six new schema-code rules: phantom table, ghost column, invalid FK join, missing upsert constraint, nested insert anti-pattern, cross-table ID confusion.

## [19.2.7] - 2026-06-24 — 🔒 CodeQL Security Sweep

### Security
- **24 CodeQL alerts resolved** — full sweep of GitHub Code Scanning findings across prototype pollution, log injection, TOCTOU race conditions, insecure temp files, and URL sanitization.
- **Prototype pollution defense** — All dynamic-key objects use `Object.create(null)` + explicit `PROTO_KEYS` guards (`configStorage`, `commonHelpers`, `dashboard/server`).
- **Log injection hardened** — Exported `sanitizeForLog()` strips C0+C1 control characters (including 8-bit CSI U+009B) and ANSI sequences. Applied to 16 call sites across 8 production files.
- **TOCTOU file lock eliminated** — Scholar lock acquisition replaced with atomic `renameSync` pattern (POSIX atomic) + post-rename PID verification. No mutual-exclusion window.
- **Temp file prediction eliminated** — Export filenames now include `randomUUID` token in primary name, not just collision fallback.
- **URL substring sanitization** — DataDog URL check uses `new URL().hostname.endsWith()` instead of `.includes()`.
- **5 intentional file-access-to-http alerts dismissed** — ingest/API modules reading files and sending to first-party endpoints (Anthropic, Supabase, Synalux).

### Added
- `sanitizeForLog` test suite — 11 assertions covering C0, C1, ANSI, newline forgery, UTF-8 preservation.

### Changed
- 98 test files, 2880 tests (up from 97/2876).
- 17 test logger mocks updated with `sanitizeForLog` passthrough.
- Reviewed through 4 rounds including external adversarial review.

## [19.2.6] - 2026-06-22 — 📊 Analytics Stats Fix + Security Hardening

### Fixed
- **`api_analytics` now works** — Rewrote from dead `better-sqlite3` (never installed as a dependency) to `@libsql/client` (same SQLite client used by the storage layer). Tool calls are recorded to `~/.prism-mcp/data.db` with per-project and system-wide query support.
- **`recordInvocation` wired in dispatch** — Called on both success and error paths of the MCP tool dispatch loop. Isolated with try/catch so analytics never breaks tool responses. Timer `unref()`'d to avoid holding process open.
- **`api_analytics` scope param** — Handler now reads `scope` (matching the tool schema enum) instead of the undeclared `action` parameter.
- **Datadog context forwarding** — Added `tool`, `project`, `success`, `durationMs` to the DD `CONTEXT_ALLOWLIST`. Tool-level analytics now reach Datadog.
- **Analytics WAL mode** — `PRAGMA journal_mode=WAL` set during table init to prevent `SQLITE_BUSY` contention with the storage layer on the shared `data.db`.

### Security
- **Notifier DNS-rebinding TOCTOU closed** — Replaced `isAllowedUrl()` with `validateUrl()` that returns the resolved IP. New `pinnedDispatcher()` creates an undici `Agent` that forces `fetch` to connect to the pre-validated IP only — no DNS re-resolution between check and use. All 3 senders use pinned dispatchers with `dispatcher.close()` in `finally`.
- **Supergateway bind documented** — Supergateway has no `--host` CLI flag and ignores `HOST` env; binds `0.0.0.0:8001`. Security note added documenting that the proxy enforces bearer auth and the port is container-internal on Railway/Docker. Infra-level firewall recommended for other deployments.

### Added
- 31 new tests: analytics recording/flush/query (8), handler scope alignment (4), inference_metrics (3), DD allowlist (1), dispatch isolation (2), dispatch wiring guards (4), WAL mode (1), DNS pinning + dispatcher close (5), supergateway security (3).

### Changed
- 97 test files, 2876 tests (up from 96/2845).
- Reviewed through 6 rounds of adversarial external review.

## [19.2.5] - 2026-06-22 — 🔒 Security Advisory Fixes

### Security
- **GHSA-g3wf-5xg2-c4vh (Critical)** — HTTP bridge now requires bearer token auth (`PRISM_MCP_HTTP_TOKEN`). Constant-time HMAC comparison via `timingSafeEqual`. 503 if token not configured, 401 on mismatch.
- **GHSA-wpc9-r66q-pj2c (Medium)** — `session_export_memory` path confinement: `realpath` + allow-list, sensitive directory deny (resolves macOS `/private` symlinks), owner-only tmp subdir (mode 0700), exclusive-create write (`wx` flag) prevents symlink-following.
- **Notifier SSRF** — All notification senders now use `redirect: "error"` and DNS resolve-then-check to reject private/internal IPs.

### Added
- 4 security regression tests for export path confinement (outside-allow-list, sensitive-dir, positive control, symlink attack).

### Fixed
- Resolved 15 of 16 Dependabot vulnerabilities (hono, undici, ws, vite, tar, protobufjs, OpenTelemetry). Remaining: 1 low (esbuild Windows dev server, not applicable).

### Changed
- 96 test files, 2845 tests (up from 95/2841).
- Reviewed through 4 rounds of external security review.

## [19.2.4] - 2026-06-18 — 📊 `inference_metrics` Tool + Delegation Gate

### Added
- **`inference_metrics` MCP tool** — read-only, no args. Returns the session's local-delegation stats on demand (call count, local/cloud split, token totals, per-model breakdown). Description explicitly notes this tracks `prism_infer` delegation only, not Claude's own token spend.
- **Delegation opt-in gate** — `session_task_route` checks `delegation_enabled` setting before allowing local-model delegation. Off by default, enforced in code (not just skill prose). 4 tests.
- **Inline framing** — metrics title reads "local-model delegation (this session)" so the caveat travels with the data when relayed.

### Security
- Context allowlist applied to Datadog sink (was Supabase-only in 19.2.1). Both sinks now filter identically.
- `message` field capped at 200 chars.

### Changed
- Architecture skill corrected from stale 19.2.0 thin-client description to 19.2.1 local-first reality.
- Delegation skill rewritten to v2 (reviewer's canonical version): off by default, principle-first framing.
- 95 test files, 2841 tests (up from 94/2835).

## [19.2.1] - 2026-06-17 — 📊 Inference Metrics: Local-First Fix

### Fixed
- **Metrics now work for all users.** Restored local accumulator as the sole display source — works immediately with zero config, no portal dependency, no env vars. The 19.2.0 thin-client architecture silently returned empty for every user because the portal infrastructure (token + migration) was never deployed.
- **Startup warning** — `console.warn` when `TELEMETRY_WRITE_TOKEN` is not set, so dead portal forwarding is visible instead of silent.
- Portal `ddLog` forwarding remains as best-effort analytics (independent of display). Egress allowlist and write-auth headers preserved.

### Architecture note
Local accumulator = user-facing display (what did MY session do). Portal forwarding = business analytics (what is the fleet doing). These are independent streams — display never depends on portal connectivity.

## [19.2.0] - 2026-06-17 — 📊 Inference Metrics + Write-Side Hardening

### Added
- **Inference metrics** — `session_save_ledger` and `session_save_handoff` now show local vs cloud usage percentage, token counts (actual from Ollama), per-model breakdown, and avg latency. Metrics are aggregated by the Synalux portal (thin-client architecture).
- **Ollama token parsing** — `prism_infer` now captures `prompt_eval_count` and `eval_count` from Ollama responses and includes them in the MCP response header.
- **Datadog telemetry** — Per-call `prism_infer.usage` events forwarded to Synalux portal for aggregation. Safety gate intercepts excluded (HIPAA).
- **SECURITY.md** — Data inventory for inference telemetry, behavioral metadata classification, and multi-user gate checklist.
- **Contract tests** — Cross-repo field name pinning (emitter ↔ allowlist ↔ SQL RPC ↔ portal headers). Catches silent-regression class.
- 26 new tests: ddLogger write headers + allowlist (11), inference metrics fetch (9), contract pinning (6).

### Security
- **ddLogger auth** — Now sends `Authorization: Bearer ${TELEMETRY_WRITE_TOKEN}` + `X-Prism-Client` headers. Previously silently 401'd (events never reached portal).
- **Context allowlist** — 15-field static allowlist applied to BOTH Supabase and Datadog sinks. Stack traces, file paths, error messages, and prompt fragments no longer reach either vendor.
- **Message cap** — `ddLog` message field capped at 200 chars as backstop against interpolated sensitive data.

### Changed
- `inferenceMetrics.ts` rewritten from 129-line in-memory accumulator to 74-line thin-client portal fetch. No local state, no dedup complexity.
- 94 test files, 2826 tests (up from 92/2807).

## [19.0.1] - 2026-06-15 — 🔒 Security: 15 verification fixes + 9B fleet

### Fleet

- **14B retired, 9B default.** Qwen3.5-9B achieves 100% BFCL × 3 seeds at 36% smaller (5.8 GB vs 8.4 GB). Cascade updated: `9b → 4b → 2b → 32b → cloud`.
- Model picker, entitlements, CLI, and all tests updated. `prism-coder:14b` references removed.

### Security (6-round external audit)

- `fix(F1)`: Entitlement fetch failure now **fail-closed** — keeps last-known-good entitlements instead of downgrading to free tier (which disabled the grounding verifier). Stale cache no longer re-cached with fresh TTL.
- `fix(F9)`: Verification runner HTTP fetch uses `redirect: "error"` — prevents SSRF via 302 → internal IP.
- `fix(F10)`: Skipped gate/abort-level assertions treated as failures — prevents dependency-chain manipulation to bypass critical checks.
- `fix(F11)`: `computeRubricHash` now includes `min_pass_rate` when provided, and `verifyRubricHash` passes it — closes threshold-tampering vulnerability.
- `fix(F19)`: Gatekeeper bypass actor from `process.env.USER` marked as unauthenticated in audit trail.

### Verification pipeline (documented in README)

- New README section: Multi-Layer Verification table (L1 crisis gate → L3 tool routing → L3 NLI verifier → L4 hallucination judge).
- Honest BFCL disclosure: "Routing accuracy includes the deterministic L3 correction layer."
- Scoped claims: "Fail-closed on the verified path (Standard tier and up)" — no longer overstates free tier coverage.

### Git hooks (portable)

- New `pre-commit` and `pre-push` hooks that work with any editor/AI tool (no Claude Code dependency).
- Advisory mode by default; `PRECOMMIT_MODE=block` / `PREPUSH_MODE=block` for hard enforcement.
- Hooks look in repo `hooks/lib/` first, `~/.claude/hooks/` fallback, then minimal inline checks.

### Tests

- 10 new tests covering all audit fixes (`verification-audit-fixes.test.ts`)
- Full suite: 89/89 files, 2,672 tests passing

## [18.0.2] - 2026-06-12 — 🔒 Security: PHI, JWKS, ingest (adversarial review round 2)

### Security

- `fix(H1)`: JWKS audience + issuer now **required** (defaults to `prism-mcp` / `https://synalux.ai`). Prevents cross-service token confusion. `al_audit_url` treated as untrusted — truncated to 256 chars, never fetched.
- `fix(H3)`: `files_changed` now passes through `sanitizeArray` → `scanAndRedactPHI` before portal POST. File paths with client names (e.g. `/clients/jane_smith/`) were previously sent raw.
- `fix(H4)`: `knowledge_ingest` now redacts chunks BEFORE sending to cloud LLM. Previously sent raw source code (which may contain PHI in clinical codebases) to `api.anthropic.com`.
- `fix(H2)`: README privacy table corrected — "Nothing" → "Nothing (free tier)" for data sent externally.

---

## [18.0.1] - 2026-06-12 — 🔧 External review fixes

### Fixed

- `fix`: Auto-Scholar file lock — atomic `wx` flag + PID-checked release (eliminates TOCTOU race)
- `fix`: dedup delimiter — `"ai"` no longer false-matches `"ai agents"` entries
- `fix`: removed dead `startScholarWatcher` code (10s polling loop, never called)
- `fix`: restore strong test assertions — entitlements + max_tokens tests now pin exact values with env isolation via setup.ts (`PRISM_SYNALUX_API_KEY` deleted before tests)
- `fix`: README PHI Guard claim — "Names" removed from "zero false negatives" (regex can't guarantee name detection)
- `docs`: CHANGELOG 17.x entries added (17.0.0 → 17.1.1 were missing)
- `docs`: version labels in README corrected (v17+ instead of "new in v17")

---

## [18.0.0] - 2026-06-12 — 🛡 PHI Guard + Skill Routing + Tier Enforcement

### What's new

**PHI Guard** — Automatic Protected Health Information detection and redaction in the save pipeline. Every `session_save_ledger` and `session_save_handoff` call passes through a deterministic PHI scanner (18 HIPAA identifier categories). Fail-closed: detection errors block the save and always log to stderr. (`d0bd1ed`, `a8c49f7`, `b54bbf1`)

**Prompt-based skill routing** — 114 agent skills auto-load based on prompt keywords. The MCP server scans the user's prompt on `session_load_context` and injects relevant skill instructions into context before the AI responds. No manual skill selection needed. (`fffc1d0`)

**Tier-based monetization enforcement** — `prism_infer` now gates model ceiling, max tokens, daily limits, and cloud fallback by subscription plan. Free users get local-only up to 4b; paid tiers unlock 14b/32b, higher token limits, and Claude Sonnet 4 fallback. Flat-rate seat caps via `max_seats` per plan. (`8d149cf`, `a38d189`)

**HRR semantic drift detection** — `session_detect_drift` MCP tool using Holographic Reduced Representations for temporal trajectory encoding. Three domains (BCBA/Coding/AAC) with domain-specific safety signals. 306 tests. (`be84f7b`)

**Synalux portal routing** — All search and scrape operations now route through the Synalux portal for unified auth, billing, and audit logging. Telemetry rewired from Datadog-primary to Synalux portal + Supabase (primary), Datadog Logs (fallback). (`9366e66`, `3051f68`)

### Fixed

- `fix`: session dates showing `[undefined]` in `load_context` response (`334337d`)
- `fix`: adversarial review — correct README claims, reduce cache TTL to prevent stale data (`f4052b7`, `fe66943`)
- `fix`: skill block cap 30K chars + plug 3 bypass paths in `session_load_context` (`76408d8`)
- `fix`: entitlements tests now environment-independent (work with or without `PRISM_SYNALUX_API_KEY`)
- `test`: 2,676 tests across 89 files (up from 2,418 across 81)

---

## [17.1.1] - 2026-06-10 — 🔒 Adversarial review security fixes

### Fixed

- `fix`: adversarial review — correct README claims, reduce cache TTL to prevent stale entitlement data (`f4052b7`, `fe66943`)
- `fix`: session dates showing `[undefined]` in `load_context` response (`334337d`)

---

## [17.1.0] - 2026-06-08 — 💰 Tier enforcement + competitive positioning

### What's new

**Tier-based monetization enforcement** — `prism_infer` now gates model ceiling, max tokens, daily limits, and cloud fallback by subscription plan. Free users get local-only up to 4b. (`8d149cf`)

**Max seats entitlement** — flat-rate seat caps per plan via `max_seats` field. (`a38d189`)

### Fixed

- `fix`: skill block cap 30K chars + plug 3 bypass paths in `session_load_context` (`76408d8`)

---

## [17.0.1] - 2026-06-05 — 🔗 Portal routing

### What's new

**Synalux portal routing** — All search and scrape operations now route through the portal for auth, billing, and audit. (`9366e66`)

---

## [17.0.0] - 2026-06-01 — 🧠 HRR Drift Detection + PHI Guard

### What's new

**HRR semantic drift detection** — `session_detect_drift` MCP tool using Holographic Reduced Representations for temporal trajectory encoding. Three domains (BCBA/Coding/AAC). 306 tests. (`be84f7b`)

**PHI Guard** — Automatic Protected Health Information detection and redaction in the save pipeline. 18 HIPAA identifier categories, deterministic, fail-closed. (`d0bd1ed`, `a8c49f7`)

**Prompt-based skill routing** — 114 agent skills auto-load based on prompt keywords. (`fffc1d0`)

**Telemetry rewire** — Primary: Synalux portal + Supabase. Fallback: Datadog Logs. (`3051f68`)

---

## [16.1.1] - 2026-05-30 — 🔍 Handoff semantic search + uncertainty gate fix

### What's new

**Handoff semantic search** — `session_search_memory` now finds handoff content, not just ledger entries. Previously, `session_save_handoff` never generated embeddings and `semantic_search_ledger` only queried `session_ledger`, making all handoff data invisible to semantic search. This affected all users.

### Fixed

- `fix(session_save_handoff)`: add fire-and-forget embedding generation (float32 + TurboQuant) matching the existing ledger handler pattern
- `fix(semantic_search_ledger)`: RPC now UNION ALLs `session_handoffs` alongside `session_ledger` — zero caller changes needed. Dropped stale 5-param overload that shadowed the fix
- `fix(Tier-2 fallback)`: TurboQuant JS-side search in `supabase.ts` now also scans `session_handoffs` with compressed embeddings
- `fix(search)`: HDC uncertainty rejection gate (0.85 threshold) now only fires when `PRISM_HDC_ENABLED=true` — was rejecting relevant results (0.847 similarity) even with HDC disabled
- `fix(migration)`: drop stale 5-param `semantic_search_ledger` overload that shadowed the new 6-param UNION ALL version — callers were silently hitting the old ledger-only function
- `feat(storage)`: add `patchHandoff(project, userId, data)` to interface + Supabase + SQLite backends for embedding backfill
- `migration(042)`: adds `embedding vector(768)`, `embedding_compressed`, `embedding_format`, `embedding_turbo_radius` columns + HNSW index to `session_handoffs`

### Root cause

Bug introduced in v0.4.0 (`8047226`, 2026-03-19) — `session_handoffs` and semantic search were built in the same release but never wired together. Handoff embedding generation was simply never added. Undetected for 72 days because the normal workflow (`session_save_handoff` → `session_load_context`) reads by project name and never touches search.

---

## [16.0.0] - 2026-05-30 — 🧪 E2E test suite + embedding cache + Datadog + security sweep

### What's new

**Comprehensive E2E test suite** — 161 tests covering full workflow + correctness/stability across handlers and storage (`522b87a`)

**Embedding LRU cache + in-flight dedup** — Gemini/OpenAI adapters now cache embeddings and deduplicate concurrent requests for the same text. Cache key includes model name to prevent cross-model collisions (`be17500`, `0aec029`)

**Datadog server-side logging** — HTTP intake, no agent required (`64765f3`)

**Rate limiting** — webhook + ingest endpoints now enforce request limits (`a60d5b0`)

### Fixed

- `chore`: remove 3,000 lines of dead code + fix console.log/telemetry (`1676d54`)

---

## [15.7.4] - 2026-05-29 — 🛡 Security sweep + knowledge ingestion + CLI docs

### What's new

**Knowledge ingestion** — open interface for codebase RAG (`c57ab6b`)

**CLI reference** — all 15 commands documented (`38fa3fc`)

### Fixed

- `security`: fix 4 critical vulnerabilities in webhook + notifier (`8f8afdd`)
- `security`: fix SSRF bypass + 4 dashboard XSS issues (`01ccc88`)
- `security`: fix CodeQL alerts — log injection, property injection, temp files (`9b1fdd8`)
- `security`: sanitize export filename to prevent path traversal (`1987da0`)
- `security`: block path traversal in knowledge_ingest file_path (`8c3dcc9`)
- `fix(deps)`: update qs to fix DoS vulnerability (`56c03c8`)
- `fix(prism-mcp)`: fetch skills from .well-known static JSON (`d0f5457`)
- `fix`: cascade default to 14b, verifier to 4b (`c4b6e4b`, `2d506a7`, `3fddf51`)
- `test`: military-grade storage round-trip tests — 12 cases (`214d6d0`)
- `test`: prismInferHandler + compactionHandler coverage — 110 tests (`a58f624`)

---

## [15.6.1] - 2026-05-28 — 🎯 prism-coder:32b hits 300/300 (100%) on eval_300

### What's new

**prism-coder:32b swe14 — 100% on eval_300** — 300/300 strict accuracy across 17 tools, 9 categories (abstention, adversarial traps, disambiguation, cascade, edge cases, multi-intent, natural phrasing, param extraction, verifier), 3-seed validated with zero failures and zero hallucinations. Pushed to Ollama Hub (`dcostenco/prism-coder:32b`) and HuggingFace (`dcostenco/prism-coder-32b`).

**eval_300 validate_tool_call fixes** — Seven regex gaps in the post-processing layer caused 8 persistent failures at 292/300. Fixes: broadened milestone→`session_save_experience` remap, added `repair` to backfill trigger, narrowed `\bproject\b` in PRISM_INTENT to avoid false matches on "React project", added GENERAL patterns for generators/meta/recommendations, expanded social rejection patterns, added initialize→`session_load_context` remap. (`79af48b7`)

---

## [15.6.0] - 2026-05-27 — 🧠 Grounding verifier + knowledge_search fixes + stale-dist guard

### What's new

**L3 grounding verifier** — `groundingVerifier` now guards `prism_infer` against hallucinations when evidence is provided. Auto-verify fires when the MCP call includes an evidence payload; unverified claims are flagged before returning to the caller. (`10c42b5`, `74f2dab`, `73ff0e7`)

**Opt-in workspace scope for `knowledge_search`** — Set `PRISM_KNOWLEDGE_SCOPE=workspace` to restrict search to the current workspace. Default remains global so existing installs are unaffected. (`02c0eab`)

**Stale-dist startup guard** — Server now detects at startup when `dist/` is older than source (derived from `package.json` + `tsconfig`) and exits with a clear error rather than silently running stale compiled output. (`61c9ba7`)

**Zod wire contracts** — `knowledge_search` input/output schemas are now Zod-validated at the boundary; live smoke test included. (`4ac482d`)

### Fixed

- `fix(knowledge_search)`: stop auto-deriving `keywords[]` from free-text query — this was inflating result noise when callers passed a full sentence as the query (`5b16071`)
- `fix`: re-register orphaned `SESSION_BACKFILL_EMBEDDINGS_TOOL` that was silently missing from the MCP tool list after a prior refactor (`779dcd5`)

### Eval / internal

- Grounded-recall eval harness + updated training corpus (`b9a3ce8`)
- Prism-routing benchmark harness improvements + 1b7 system prompt tuning (`69ce1ef`, `546fcd0`)

## [15.3.0] - 2026-05-14 — 🛡 Storage hardening + multi-region deploy + license switch

> v15.2.1 was published as a stub version bump with no CHANGELOG entry. This release supersedes it and documents every commit since 15.2.0.

### What's new

**Three-layer storage reliability** — Synalux portal stays the paid-tier default, but `getStorage()` now falls back through synalux env vars → synalux dashboard config (`~/.prism-mcp/prism-config.db`) → direct Supabase env → direct Supabase dashboard config → local SQLite. Closes the silent-data-loss path where MCP clients (some VSCode extensions) didn't propagate `PRISM_SYNALUX_*` env vars and the server quietly demoted to local without ever picking up the dashboard credentials. Symmetric helpers `ensureSynaluxCredentials()` / `ensureSupabaseCredentials()` probe env then DB and inject into `process.env` so downstream constructors and `SyncBus` see them. (`aef54e5`, `ef7fdfd`, `c1384f5`, `2078642`, `b4c079b`)

**Railway + Fly.io deployment stack** — `feat(railway)` ships `railway.toml`, `.railwayignore`, and an HTTP transport mode for the MCP server suitable for managed hosting. Fly.io standby config covers the Supabase outage scenario. (`0d56e59`, `b301b73`, `d0bfbef`, `b4c079b`)

**Prism Coder 1.7B BFCL eval** — `prism-coder:1b7-v19-q8` ships at 90.0% tool-call accuracy on the public BFCL benchmark (eval methodology pinned in `tests/eval/`). Replaces the misleading "100% BFCL" claim from earlier docs with the verified internal-domain vs. public-benchmark split. (`c5db866`, `3d73b9e`, `ad440e5`)

**Routing benchmark suite** — 100-case Prism routing eval covering the full model fleet (1.7B / 7B / 14B / 32B) plus Claude comparison. Includes a `nothink`-template fix for 32B and an MLX↔Ollama parity test that closed a 17-pt thinking-mode gap. 3-seed mean ± std with verified ~0% variance; per-category breakdown lives in `tests/benchmarks/prism-routing-100/README.md`. (`cc03853`, `70d6718`, `c32c83e`, `5f894ba`, `2ab3a19`, `604f4bc`, `133d27b`)

**Local-to-portal migration script** — `scripts/migrate-local-to-portal.mjs` reads `~/.prism-mcp/data.db` and pushes ledger + handoff entries through `POST /api/v1/prism/memory`. Dry-run mode, project filter, JWT caching with refresh-leeway, rate-limit pacing. Uses `@libsql/client` (already a runtime dep) instead of `better-sqlite3` so it runs from a fresh checkout without an extra native build dep. The earlier bash version was dropped — its subshell counter and JWT-refresh both ran inside `| while read` pipes and silently lost updates.

### Changed

**License switch: BUSL-1.1 → AGPL-3.0** — `LICENSE`, `package.json`, `package-lock.json` now match the README badge and prism-aac. Commercial use moves to the Synalux subscription path for hosted/managed deployment. (`5b30807`, this release)

### Fixed

- `fix(ci)`: skip onnxruntime CUDA download on CI runners with no GPU (`596d8db`)
- `fix(railway)`: `npm install` instead of `npm ci` to absorb lock-sync drift (`b301b73`); subsequent `package-lock.json` regeneration (`d0bfbef`)
- `fix(32b)`: nothink-template fix lifts 32B routing accuracy 97% → 99% (`70d6718`)
- `fix`: license string + Windows CI `hookTimeout` 30s → 60s (`5b30807`)
- `fix(docs)`: ASCII diagram repairs, P0 README claims (model names, fallback cascade, eval caveats, 7B addition), infrastructure diagram cleanup (`0c6b8e3`, `cd9e011`, `5d32db9`, `d0d1d5b`, `e2301c0`, `747a7ef`)

### Test coverage added

- `test(eval)`: MLX↔Ollama parity test closes a 17-pt thinking-mode gap (`0c40be7`)
- `test(conversion)`: pinned MLX-4bit → dequant → Q4_K_M GGUF regression that was producing 60s+ TTFT (`eb1bee6`)
- `test(training)`: pre-flight validation of `train_*.sh` scripts as a $0 guardrail before paid GPU runs (`8972fd0`)
- `test(training)`: pre-flight validation expanded — flags wrong-base lineage, known-bad corpora, and excessive iteration counts in `train_*.sh` scripts at `$0` before any GPU allocation (`66d99f2`)
- `test(storage)`: dropped a divergent test-mirror that had been testing a frozen copy of the resolver instead of source; replaced with `tests/storage-resolver.test.ts` driving real `getStorage()` through mocked dashboard creds (`2078642`)

### Docs

- iOS deployment story corrected: llama.cpp Swift SPM, not CoreML (`011cbff`)
- Local-AI security/speed/cost comparison table + install commands (`435ab13`)
- Production infrastructure diagram with 3-layer reliability story (`e2301c0`)
- Claude-comparison context for benchmark scores — what they mean, what they don't (`133d27b`)
- README "honest current eval state" + retrain-regression note (`5316e8d`, `63d3d99`)

## [15.2.0] - 2026-05-10 — 🛡 Two-namespace skill architecture + Synalux dynamic content

### What's new

**Two-namespace skill separation** — Platform skills (`skill:*`) are read-only. User-local skills get their own `user_skill:*` namespace, written by dashboard only when `user_local.enabled=true` in routing table (off by default).

**Synalux dynamic skill content** — `GET /api/v1/skills/content` checks Supabase `platform_skills` table first (admin-updatable without redeploy), falls back to filesystem. Admin endpoint `POST /api/v1/admin/skills` gates on `isPlatformAdmin()`.

**Skill routing schema v2** — `resolveSkillsForProject` returns `{ names, user_local }`. Routing table gains `user_local: { enabled, key_prefix }`.

**New universal skills** — `execute-method-literally` (26-case test suite, verbatim May 2026 replay), `pre-push-audit` Rule 19 (`tsc --noEmit` before every push).

## [15.1.0] - 2026-05-10 — 🔗 Skill content via Synalux for paid tier

`fetchSkillContent()` in SynaluxStorage, skill content batch-fetched from Synalux on `session_load_context`, `execute-method-literally` in universal routing, Architecture docs Section 12.

## [15.0.0] - 2026-05-10 — 🔄 Proactive drift detection + evidence-first behavioral protocol

### What's new

**Proactive session drift detection** (`session_cognitive_route` pattern)
Three direct Prism calls — no scripts, no cron, no hooks — detect when an AI agent has drifted from stated goals mid-session and self-correct before the user notices. Returns `on_track / minor_drift / major_drift`. Routes major drift alerts to Synalux portal for cross-session visibility. 10 behavioral test cases cover: obvious drift, scope creep, on-track false positive, promise gaps, repeated fixes, cascading violations, and Synalux routing. Documented as the flagship v15 feature.

**Evidence-first behavioral protocol** (new skill + CLAUDE.md gates)
Prevents AI agents from reporting `done / fixed / working / 90%+` without observable evidence. Five hard gates that supersede all other instructions: (1) no positive completion claim without evidence; (2) diagnose before asserting causes; (3) write test before pushing any bug fix; (4) training quality gate BFCL ≥90%; (5) 60-min drift check for long sessions. Born from five May 2026 failures that each wasted 1-3 hours of production work. Evidence gate table maps every claim type to required proof.

**TTS audio protection** (prism-aac)
- `PROTECT_PLAY_MS=600ms`: autoSpeak calls that arrive within 600ms of a playing source are gracefully dropped instead of killing the audio. Fixes complete silence from rapid prediction-tile taps.
- `interrupt` parameter threaded through `speakAzure → decodeAndPlay`: replaces the shared `_nextSpeakInterrupt` flag that could be stolen by concurrent autoSpeak calls, silencing the Speak button.
- `volume=0` guard in `speak()`: early exit with console.warn before any network call.
- `vol=` and `rate=` added to TTS log for live diagnostics.
- 10 unit tests covering: flag theft, rapid-tap protection, interrupt override, volume=0, NaN volume, suspended AudioContext, 3 concurrent autoSpeak, Speak wins among concurrent calls.

**SW auto-bump** (prism-aac)
`NEXT_PUBLIC_BUILD_ID = VERCEL_GIT_COMMIT_SHA[:8]` on every Vercel deploy. SW killswitch version changes automatically — no manual bump needed. Identical pattern applied to Synalux portal (`synalux-sw-v` key in localStorage, fires once per deploy not every session).

**Search keyboard** (prism-aac)
- Opening Search now shows the keyboard immediately (no second tap needed).
- On-screen keyboard keys route to the search input via `searchKeyBridge.ts` pub/sub — tile taps no longer land in the message bar while searching.

**Tone fix** (prism-aac)
`toneToAzureStyle()` replaced invalid `'general'` (default) and `'gentle'` (empathetic) with valid `ToneStyle` members. `tone=general` no longer appears in TTS logs.

**SSML rate formula restored** (prism-aac)
`rate × 2` formula (capped at 1.4) confirmed working via tts-live-diag-rate.mjs. Stored slider 0.5 → SSML 1.0 (normal speed). Fixes Romanian/Ukrainian 2× slower regression.

**Marketplace catalog** 
`marketplace_modules` table created via migration `20260510_marketplace_modules.sql`. Resolves 500 on every `/api/v1/marketplace/catalog` call (table was never applied to prod Supabase).

**13 synalux stub fixes**
Unread count, mail sync (IMAP→501, OAuth→real Gmail fetch), inbox thread 503, accounting providers removed (no longer returned as 'planned'), Zoom 501→422, chat providers cleaned, e-sign 501→422, feature-flags DB error returns success:false, SMS send 501→503, marketplace/installed 401, MathPanel + MathKeyboardRegion stub comments removed.

**Inbox / messages** (prism-aac)
- `/api/v1/prism-aac/inbox/poll` now returns real Gmail unread messages (via user's OAuth grant) and unclaimed SMS from `inbound_sms` table. Previously returned `[]`.
- Per-message TTS on arrival: speaks "New message from [sender]: [text]" for ≤3 messages.
- Reply button (↩) on schedule message tasks opens AACChatPanel and pre-selects the sender contact.

**Twilio env fix**
`TWILIO_ACCOUNT_SID`, `TWILIO_AUTH_TOKEN`, `TWILIO_PHONE_NUMBER` were set but empty in Vercel production. Values pushed from `.env.local`.

### Why a major bump

The drift detection + evidence-first protocol represent a change in how Prism agents operate — not just what they can do. These behavioral guarantees are additive but meaningful enough to warrant a major version signal.

### npm

```
npm install -g prism-mcp-server@15.0.0
```

---

## [14.0.0] - 2026-05-07 — 🧠 Prism Coder: project rename + algorithm-stability contract

The project is renamed from **Prism MCP** to **Prism Coder** to reflect its full surface — the Mind Palace memory server *and* the `prism-coder:7b` / `prism-coder:14b` open-weights LLM fleet that ships alongside it. The npm package remains published as `prism-mcp-server` so existing install URLs (`npm install -g prism-mcp-server`, `npx prism-mcp-server`, the `mcp.json` entries every consumer already wrote) keep working without churn — but the `prism-coder` binary that package provides has been the canonical entry point since v12, and "Prism Coder" is now the user-facing project name across README, docs, and all new surfaces. v14.0.0 also formalises Prism's algorithm exports as a stable public contract so external consumers can depend on the constants without re-implementing them.

### What's new

- **Algorithm-stability contract.** The following exports are now considered stable public API under SemVer: `actrActivation.ts` (`baseLevelActivation`, `parameterizedSigmoid`, `compositeRetrievalScore`, all `ACT_R_*` / `DEFAULT_*` constants); `spreadingActivation.ts` (`applySpreadingActivation`, the 0.7/0.3 hybrid score blend, the `finalM=7` cap); `routerExperience.ts` (`getExperienceBias`, `MAX_BIAS_CAP=0.15`, `MIN_SAMPLES=5`, the bias-scale formula); `compactionHandler.ts` (default `threshold=50`, `keep_recent=10`, `MAX_ENTRIES_CHARS=25_000`); `graphMetrics.ts` warning ratios (0.20 / 0.30 / 0.40 / 0.85 with their min-sample gates); `config.ts` (`PRISM_ACTR_DECAY`, `PRISM_GRAPH_PRUNE_MIN_STRENGTH`, full `PRISM_GRAPH_PRUNE_*` family). Breaking changes go through deprecation cycles announced here in CHANGELOG.

- **`docs/WOW_FEATURES.md`** — citation-grade catalogue of Prism's algorithms with their constants, semantics, and reuse patterns. Written for engineers who want their thresholds backed by published implementations rather than guesswork.

- **`docs/releases/v14.0.0-prism-as-foundation.md`** — release notes covering what the contract guarantees, why now, and the migration path for systems that have been re-implementing Prism algorithms in their own code.

- **First reference consumer documented:** an external audit hooks framework (separate skill, not in this repo) that ports ACT-R decay, the spreading-activation hybrid blend, experience bias, and the graph-metrics warning ratios with citations. 327 tests in that consumer pin the constants — divergence from this repo's source is caught automatically.

### Why a major bump

External systems were already building on Prism algorithms with hand-tuned approximations. Two failure modes when that happens: (1) the consumer's thresholds drift from Prism's over time, and (2) a copy-pasted constant loses its citation in 6 months and nobody remembers why `0.15` was chosen. Formalizing the stability contract fixes both.

### What's NOT in this release

- No new MCP tools.
- No model changes — `prism-coder:7b` and `prism-coder:14b` unchanged from v13.1.x.
- No schema changes.

### npm

`prism-mcp-server` v14.0.0 is published to npm — same package name, semver-major bump aligned with the project rename + the new public API contract. Earlier 13.1.1 stays available for users who want the pre-rename release.

---

## [13.1.1] - 2026-05-05 — Tool-call format normalizer

### Local LLM client
- **`normalizeToolCallFormat`** new helper at `src/utils/normalizeToolCallFormat.ts` — coerces three stochastic v18-clean tool-call format variants into the canonical singular wrapper:
  1. Plural wrapper + XML-attr params: `<tool_calls><tool_call name="X"><param name="Y" value="Z"/></tool_call></tool_calls>`
  2. CJK angle brackets: `〈tool_call〉{...}〈/tool_call〉`
  3. `<functioncall>` envelope with stringified or object arguments
  
  All three normalize to: `<tool_call>{"name":"X","arguments":{"Y":"Z"}}</tool_call>`
- **`callLocalLlm`** pipes raw model output through the normalizer before the existing think-tag / multi-format extractor, so downstream parsers see only canonical input.
- **12-test suite** at `tests/normalizeToolCallFormat.test.ts` — covers each variant + multi-call + surrounding text + canonical pass-through + malformed JSON fallback.

### Test counts
- `tests/normalizeToolCallFormat.test.ts`: 12/12 passing in 82ms.

---

## [13.1.0] - 2026-05-04 — 🤖 Prism Coder 14B sibling + tier-aware local routing

Coordinated cross-product release with **portal v0.14.4** and **prism-aac v0.2.1**. No prism-mcp-server code changes (the model fleet lives in Ollama; npm package is unchanged) — this entry documents what ships through the Synalux portal that prism-mcp clients reach.

### Model fleet
- **`prism-coder:7b` re-trained from clean Qwen2.5-Coder-7B base.** Replaces v18aac-MAX (BFCL 47.2%) with v18clean-epoch0 (BFCL **88.1%** 3-run StdDev 0%, AAC realigned **47/48 (97.9%)**, caregiver targeted **20/20**, emergency_qa 13/13, text_correct 15/15, translate 8/8). +40.9pp BFCL recovery, no AAC regression.
- **`prism-coder:14b` sibling shipped.** Qwen2.5-Coder-14B base + AAC SYSTEM directive, **32K context**, BFCL 85.9%, AAC 46/48 (95.8%), caregiver targeted 18/20.
- **Rollback path:** `ollama cp prism-coder:7b-prev-20260504-1325 prism-coder:7b` (≤ 1 min restore).

### Tier-aware local routing (Synalux portal)
- New pure-function routing module with **39 TDD tests** pinning behaviour. Security-hardened: privilege boundary on tier sanitization, ReDoS-proof regexes, audit-safe reason strings (fixed enumeration), failsafe defaults, p99 < 1ms.
- Routing matrix:
  - `free` simple → `prism-coder:7b` local · medium → Gemini Flash · complex → Gemini Flash
  - `standard` simple → 7B · medium → `prism-coder:14b` local · complex → Claude Haiku
  - `advanced` / `enterprise` simple → 7B · medium → 14B local · complex → Claude Opus
- Saves ~$0.01–0.05 per paid-tier medium AAC query (Claude → local 14B). Estimated annual saving ≈ $190K–210K at 10K-user scale.

### Azure Neural TTS unblocked for all tiers
- Removed free-tier 403 gate on `/api/v1/tts`. Azure Neural voice + auto-tone-switch now work for every authenticated tier. Cost ≈ $480/mo at 10K users — acceptable AAC dignity baseline.

## [13.0.1] - 2026-05-02 — 🔧 Executable bin permissions

Bug fix: when installed globally via `npm i -g prism-mcp-server`, the
binaries (`prism`, `prism-coder`, `prism-mcp-server`, `prism-import`)
ended up without the execute bit, so MCP clients (Claude Code, Claude
Desktop, Cursor, etc.) couldn't launch the server — they'd get a
"permission denied" when trying to spawn it.

Root cause: `tsc` doesn't preserve or set the +x bit on its compiled
output, and the published tarball inherited the missing perm.

Fix:
- Added `npm run chmod-bins` to set 0755 on `dist/cli.js`,
  `dist/server.js`, `dist/utils/universalImporter.js`.
- `build` now runs `tsc && npm run chmod-bins`.
- `prepublishOnly` runs the full build to guarantee published tarballs
  have the right perms regardless of how the maintainer publishes.

If you hit "permission denied" on 13.0.0, either upgrade to 13.0.1 or
manually `chmod +x` the files in `~/.npm-global/lib/node_modules/prism-mcp-server/dist/`.

## <a name="1300"></a>[13.0.0] - 2026-05-02 — 🧬 The Adaptive Release

> **prism-coder now feels.** Every response the model returns is shaped in real time by the user's emotional register, motor rhythm, and ambient environment — without anyone writing a "be empathetic" instruction. PrismAAC, Synalux, and prism-mcp now share a single behavioral profile that travels with the user across surfaces, and skill routing is canonical at synalux instead of duplicated across three repos.

### ✨ Wow factor — what users notice immediately

- **Auto Tone Switch.** When a child types `"I need help!"` on PrismAAC, the TTS voice automatically softens to a calm, slower, emergency register — *and* the prism-coder response is shaped to validate first, then offer concrete next steps. No flag, no setting. The model receives an `<adaptive_context>` block on every chat carrying `dominant_mood`, `current_utterance_guidance`, and the user's preferred categories.
- **Cursor that learns.** PrismAAC's head/body/finger trackers feed actual dwell-to-trigger latency back into the adaptive engine. After ~10 selections the dwell time, smoothing alpha, and cursor sensitivity all adapt to the child's motor rhythm, clamped to safe ranges (`400–3000ms` dwell, never silences voice).
- **Identity-locked tracking.** Multi-camera face tracker and pose tracker now reject other faces in the frame via IoU continuity — no more cursor jumping to a sibling who walks behind the user.
- **One source of truth.** Skill routing for the entire prism-coder ecosystem now lives in synalux at `/api/v1/skills/routing`. Adding a new project skill is one PR in synalux; prism-mcp + future surfaces pick it up within 5 minutes via cached fetch.

<details>
<summary>🧬 Adaptive Engine — 5 systems, BCBA-aligned</summary>

The adaptive engine observes 5 dimensions of user behavior and shapes runtime parameters accordingly. All adaptations are **additive** (never restrict capability), all guarded by hard safety clamps tested as invariants:

1. **Tone** — `detectTone(text)` returns one of `neutral | friendly | excited | empathetic | serious`. Routes Azure TTS style, speech rate, and a system-prompt addendum injected into prism-coder. Detection is Unicode-aware tokenize + light stem so `"hurts"`, `"hurting"`, `"bleeding"` all match.
2. **Gesture speed** — running average of dwell-to-trigger latency + cursor velocity. After 1000 samples, switches from straight average to EMA (α=0.02, half-life ≈ 35 samples) so a real motor regression is still tracked.
3. **Pronunciation** — learns "wawa → water" patterns. Hard guard: emergency words (help/hurt/scared/911/bleeding/choking/fire/stuck/lost) are *uncorrectable* — neither `recordMispronunciation` nor `correctPronunciation` will let them be shadowed.
4. **Background noise** — EMA noise floor with `threshold = floor + 15dB`, **clamped at ≤ -20dB** so a loud environment never pushes the threshold above what voice can hit.
5. **Prompt patterns** — frequency-weighted category preference (`count × exp(-age_days/14)`), 30-day decay on time-of-day vocabulary so summer routines don't haunt the autumn UI.

`PROFILE_VERSION = 2` with v1 → v2 migration. Schema lives canonically at `the Synalux portal`; PrismAAC mirrors it for offline operation, with an internal structural drift check.

Hysteresis: `dominantMood` only flips when ≥6 of last 10 events agree, so a single emergency doesn't trap the system in `'urgent'` for the next half hour.
</details>

<details>
<summary>📡 Cross-system wiring</summary>

```
PrismAAC client ──► autoSwitchTone() ──► Azure style + rate
       │
       ├─► localStorage profile (free tier)
       │
       └─► POST /api/v1/adaptive/profile (paid tier sync)
                    │
                    ▼
             Supabase adaptive_profiles (RLS'd)
                    │
                    ▼
       /api/v1/chat ──► buildSystemContext({ latestUtterance })
                    │
                    ▼
       prism-coder receives <adaptive_context> block
```

For MCP clients (Claude Desktop, IDE assistants, voice agents), 5 new tools expose the same profile via prism-mcp:

- `adaptive_get_profile` — current profile + signals snapshot
- `adaptive_set_profile` — caregiver/admin replace
- `adaptive_record_event` — incremental write
- `adaptive_detect_tone` — pure function, no side effects
- `adaptive_reset` — caregiver wipe (`confirm: true`)
</details>

<details>
<summary>🛡️ Security hardening</summary>

- **CSP**: Removed global `'unsafe-eval'` from synalux portal CSP. MediaPipe WASM runs on the proxied `prism-aac.vercel.app` origin, so synalux pages don't need eval relaxations. The prior policy disabled CSP's primary defense across the entire portal.
- **Permissions-Policy**: Per-route allowlist. `/prism-aac/*` and `/telehealth/*` get camera+mic; everywhere else explicitly denies.
- **PHI redaction**: 50+ ABA/clinical-vocabulary phrase allowlist — `Applied Behavior Analysis`, `Discrete Trial Training`, `Functional Behavior Assessment` etc no longer redacted to `[REDACTED] [REDACTED] Analysis`. Real names still redacted.
- **Emergency endpoint**: Added per-destination rate limit (3 calls/hr to the same number from any source IP), max 5 contacts/request, E.164 validation. Closes the Twilio-abuse vector where rotating IPs could spam arbitrary numbers.
- **prism-mcp encryptedSync**: Wrapped `JSON.parse` so a malformed packet from a misbehaving peer no longer crashes the receiver with an unhandled `SyntaxError`.
- **prism-mcp SSRF**: Loopback gated behind `PRISM_DEV_MODE` flag instead of unconditionally rejected (private RFC1918 ranges still always denied).
</details>

<details>
<summary>🧪 Testing</summary>

- prism-mcp: 17 new tests covering skill routing fallback chain + encryptedSync corruption guard.
- synalux portal: 31 new tests for PHI clinical-allowlist + emergency endpoint validation.
- prism-aac: 121 tests pass (48 adaptive, 53 camera tracking + identity locking, 20 head-tracker edge cases).

</details>

### Migration

No client breaking changes. Adaptive profile localStorage is auto-migrated v1 → v2 on first read. Skill content keys (`skill:*`) unchanged — only the routing source moved.

### Acknowledgments

This release was driven by a deep code review that surfaced numerical correctness, safety, and cross-system architectural issues in prior agent-authored commits. The single-source-of-truth principle came from user direction: "do not just copy paste skills for each".

---

## <a name="1200"></a>[12.0.0] - 2026-04-23 — 💳 Unified Billing & Agent Skill Ecosystem

> **The Platform Unification Release.** Prism v12.0.0 aligns Prism and Synalux into a single, unified billing architecture with identical tier pricing, adds 54 production-ready agent skills, and introduces a 14-day free trial across all paid tiers.

### 💳 Unified Billing Architecture

- **Synalux-Priced Tiers** — Both Prism and Synalux now share identical pricing: Standard ($19/mo), Advanced ($49/mo), Enterprise ($99/mo). Prism retains an additional Free tier for community access.
- **14-Day Free Trial** — All paid tiers (Standard, Advanced, Enterprise) include a 14-day trial period. Configured via `DEFAULT_TRIAL_DAYS` constant with automatic Stripe `subscription_data.trial_period_days` injection.
- **Stripe Test-Mode** — Test-mode price IDs documented inline (`price_test_standard_19`, `price_test_advanced_49`, `price_test_enterprise_99`). Production IDs loaded from environment variables.
- **Removed Legacy Tiers** — Deleted `prism_pro` ($12) and `prism_elite` ($29) plan definitions. Synalux Free tier removed from `PlanId` type and `BASE_PRICE_TABLE`.
- **Prism Checkout Route** — Updated `/api/v1/prism/checkout` to use `DEFAULT_TRIAL_DAYS` (was hardcoded to 0). New users default to `prism_free` plan.

### 🧠 Agent Skill Ecosystem (54 Skills)

- **10 Super-Skills Compacted** — Reduced from 22,937 to 6,191 lines (73% reduction) by stripping verbose comparison matrices and code templates, retaining essential decision tables and checklists.
- **4 Medical Skills** — `hipaa-compliance`, `clinical-documentation`, `medical-billing-coding`, `patient-data-privacy` — healthcare-specific compliance and workflow automation.
- **10 Vendor Skills** — Vercel, Supabase, Stripe, Sentry, OpenAI, Addy Osmani, Garry Tan/gstack — tailored for the Synalux tech stack.
- **Skills Centralized** — Single source of truth at `/skills/`, symlinked to IDE extensions directory.

### 🎨 Pricing Page UI

- **Synalux Section** — 3-tier card layout (Standard, Advanced, Enterprise) with feature lists, hover animations, and CTA buttons wired to Stripe checkout.
- **Prism IDE Section** — New dedicated section for Prism Coder IDE Extension with 4-tier layout (Free, Standard, Advanced, Enterprise).
- **Multi-Currency Table** — USD, CAD, GBP, EUR, AUD, NZD pricing with volume discount tiers.
- **14-Day Trial Badge** — Prominent green banner across all paid tier cards.

### Engineering
- Files changed: `stripe.ts`, `pricing-engine.ts`, `pricing/page.tsx`, `prism/checkout/route.ts`, `package.json`, `CHANGELOG.md`
- Licenses verified: Prism (MIT), Synalux (BSL-1.1)
- TypeScript: clean, zero errors expected

---



## <a name="1160"></a>[11.6.0] - 2026-04-22 — 🏗️ Agent Infrastructure Resilience

> **The Multi-Agent Stability Release.** Prism v11.6.0 introduces production-grade infrastructure for running multiple AI agents concurrently without resource exhaustion, deadlocks, or zombie processes. Every component is cross-platform (macOS/Linux) with zero GNU dependencies.

### 🏗️ Agent Infrastructure

- **Serialized Execution Queue (`agent_queue.sh` v2.0)** — Complete rewrite replacing GNU `flock` with Python `fcntl.flock` for macOS-native file locking. Ensures strict mutual exclusion when loading Ollama models, preventing OOM crashes from concurrent model loads. Includes PID tracking and automatic cleanup on exit.
- **Memory Guardian Daemon (`memory_guardian.sh`)** — Background watchdog that proactively monitors RAM pressure via `vm_stat` page-out rate. Auto-evicts idle Ollama models before swap exhaustion occurs. Configurable thresholds with graceful degradation. Logs to `/tmp/memory_guardian.log`.
- **Queue Watchdog (`queue_watchdog.sh`)** — Detects and auto-drains hung queue entries based on PID file age (>10 min). Prevents deadlocks in long-running pipelines. Non-destructive: only removes entries whose owning process has exited.
- **Unified Status Dashboard (`agent_status.sh`)** — Color-coded CLI providing real-time visibility into queue depth, guardian health, Ollama model status, and system memory. Supports `--json` mode for programmatic consumption by other tools and CI/CD pipelines.

### 🧪 Testing & Verification

- **115/115 Tests Passing** across 5 test suites:
  - **Unit tests** (60) — Core `claw_agent_lite.py` logic: model selection, hardware detection, streaming buffer, error handling
  - **Concurrent tests** (17) — File lock contention, parallel agent serialization, race condition guards
  - **Shell integration tests** (21) — `agent_queue.sh`, `memory_guardian.sh`, `ollama_warmup.sh` lifecycle and interaction
  - **Mock Ollama integration** (8) — Self-contained HTTP mock server for deterministic pipeline testing without live models
  - **Live stress tests** (9) — Real Ollama integration under concurrent load with status dashboard verification

### 🔧 Codebase Hardening

- **Bash `set -e` Arithmetic Fix** — Resolved `((x++))` pitfall where zero-result arithmetic causes script exit under strict mode. Applied across all shell scripts.
- **macOS Compatibility** — Eliminated all GNU-specific dependencies (`flock`, `timeout`, `readlink -f`). All scripts work out-of-the-box on macOS and Linux.
- **10 Bug Fixes in `claw_agent_lite.py`** — JSON parsing resilience, null pointer guards, connection failure handling, streaming buffer for split `<think>` tags, and proper error propagation for programmatic integration.

### Engineering
- New files: `agent_queue.sh` (v2.0), `memory_guardian.sh`, `queue_watchdog.sh`, `agent_status.sh`, `test_integration_pipeline.py`, `test_shell_scripts.sh`, `test_live_stress.sh`
- Modified: `claw_agent_lite.py`, `ollama_warmup.sh`
- All changes verified on Apple M4 Max (36GB) and compatible with M3 (18GB)

---

## <a name="1151"></a>[11.5.1] - 2026-04-22 — 🛡️ Cross-Platform Reliability & CI Recovery

> **The Stability Patch.** This version fixes regressions in the CI pipeline and ensures the 100% precision release is fully compatible with Windows and macOS environments.

### 🛡️ CI & Cross-Platform Fixes
- **Cross-Platform Test Suite** — Replaced all hardcoded `/tmp` paths with `os.tmpdir()` across `imageCaptioner.test.ts`, `definitions.test.ts`, and `sessionExportMemory.test.ts`. This resolves test failures on Windows CI runners.
- **CI Workflow Optimization** — Split unit tests and heavyweight CLI integration tests into separate serial steps. This reduces resource contention and parallel load on GitHub Action runners, ensuring stable pass rates for process-level drift checks.
- **Broken Anchor Fix** — Corrected documentation links in README to point to the new v11.5.x changelog headers.

## <a name="1150"></a>[11.5.0] - 2026-04-22 — 🧠 Structural GRPO Alignment (100% Accuracy)

> **The Precision Release.** This version marks the successful completion of the Structural GRPO (Group Relative Policy Optimization) alignment phase, achieving perfect tool-calling scores and hardening the response pipeline against reasoning tag drift.

### 🧠 Structural GRPO Alignment & Hardening
- **100.0% Tool-Call Accuracy (Verified)** — Cross-validated the structural reward model on the Synalux clinical platform, achieving perfect scores in tool-name identification and parameter mapping.
- **Central Structural Tag Handler** — Added logic to `src/utils/localLlm.ts` to automatically strip `<|synalux_think|>` blocks and extract content from `<|tool_call|>` tags. This ensures downstream tools receive clean JSON even if the model's raw output contains internal reasoning tokens.
- **`<think>` Reasoning → `<tool_call>` Action** — Forced a strict response pattern where the model MUST provide CoT reasoning before invoking a tool. This eliminates "hallucinated action" by grounding every tool call in explicit logical steps.
- **Deterministic Reward Function** — Replaced stochastic reward models with a strict structural validator that penalizes non-standard tags and rewards project-standard structural blocks.

### 🧪 Benchmarks & Performance
- **JSON Validity: 100.0%** — Guaranteed schema adherence for all local model outputs.
- **Parameter Accuracy: 100.0% (Synalux) / 33.3% (Prism Base)** — Significant boost in parameter mapping for clinical toolsets; base Prism toolset undergoing Phase 2 alignment.
- **Inference Speed** — Optimized `prism-coder:7b` for 45.1 Tokens/sec on M4 Max hardware.

### Added
- **`grpo_align.py`** — New high-intensity alignment script with structural enforcement and synthetic preference injection.
- **`benchmark.py`** — Enhanced verification harness with robust JSON extraction and multi-format support.

---

## <a name="1101"></a>[11.0.1] - 2026-04-21 — 🧪 Zero-Search Field Testing & Security Refinement

> **Bridging Research and Practice.** This release documents the successful field testing of v11 Zero-Search Retrieval in the Synalux practice management system and finalizes the HIPAA-hardened security logic.

### 🔬 Zero-Search Retrieval (Field Testing)
- **Synalux Integration** — Verified the core mathematical unbinding engine (Circular Convolution + Superposition) in high-compliance clinical workflows.
- **O(1) Retrieval Performance** — Proved constant-time fact recovery regardless of working memory size. Synalux benchmarks show 1.17x speed advantage over traditional linear scans at 100+ facts.
- **Cognitive Suit Verification** — Full linkage to verified [math](./src/sdm/hdc.ts) and [tests](./tests/verification/cli-integration.test.ts).

### 🔒 HIPAA-Hardened Local LLM (Logic Merge)
- **Local Logic Finalization** — Complete merge of `prism-coder:7b` task routing and ledger compaction logic.
- **Fail-Closed Security** — Reinforced `PRISM_STRICT_LOCAL_MODE` behavior across all cognitive handlers to prevent accidental ePHI egress.
- **XML Injection Defense** — Universal escaping for user-controlled strings in compaction prompts.

### Engineering
- **Version Bump** — Incremented to `11.0.1` for formal release.
- **Cross-Repo Sync** — Documentation and roadmap alignment with Synalux private prototypes.

---

## <a name="1100"></a>[11.0.0] - 2026-04-18 — 🛡️ HIPAA-Hardened Local LLM Engine

> **The most security-hardened release in Prism history.** 22 adversarial findings identified and closed across 3 rounds of attack-surface review. Your agent's memory now runs entirely on-device — and stays there.

### 🔒 HIPAA-Grade Security Architecture

- **`PRISM_STRICT_LOCAL_MODE`** — New environment variable (default: `false`). When `true`, ledger compaction will **never** fall back to a cloud LLM if the local model fails. Throws a structured HIPAA error instead of silently exfiltrating ePHI to Gemini/OpenRouter. Critical for healthcare, legal, and defense deployments.
- **SSRF Redirect Prevention** — `fetch()` in `callLocalLlm()` now uses `redirect: "error"` to reject 3xx responses. Prevents SSRF chains where a malicious Ollama endpoint redirects to AWS IMDS (`169.254.169.254`) or internal services.
- **URL Credential Redaction** — New `redactUrl()` helper strips `user:pass@` from all log paths (startup log in `config.ts` + per-call `debugLog` in `localLlm.ts`). Malformed URLs safely return `"[invalid URL]"` via `try/catch`.
- **Entry-Boundary Truncation** — `buildCompactionPrompt()` truncation now splits on `\n\n` entry boundaries instead of raw character offsets. Prevents mid-tag XML breakout (`<raw_use` → malformed XML → prompt injection).
- **Full XML Escaping** — `escapeXml()` expanded from 2 entities (`< >`) to all 5 standard XML entities (`& < > " '`). Applied to all user-controlled fields: `summary`, `decisions[]`, `files_changed[]`, `id`, and `session_date`.
- **Task Boundary Tags** — `askLocalLlmForRoute()` wraps task descriptions in `<task></task>` delimiters with an explicit security boundary instruction. Description is XML-escaped before injection to prevent `</task>` breakout.
- **setTimeout Integer Overflow Guard** — `PRISM_LOCAL_LLM_TIMEOUT_MS` capped at `300,000` ms (5 min). Values exceeding `2^31-1` previously caused `setTimeout` to fire immediately, silently aborting every local LLM call.
- **Graceful HIPAA Error Handling** — `compactLedgerHandler()` wraps `summarizeEntries()` in `try/catch`. If `PRISM_STRICT_LOCAL_MODE` throws, returns a structured MCP error (`isError: true`) instead of crashing the server.

### Added
- **`callLocalLlm()` Utility** — New thin HTTP client for Ollama `/api/chat` (`src/utils/localLlm.ts`). Non-streaming, silent-fail (returns `null`), feature-gated by `PRISM_LOCAL_LLM_ENABLED`. Includes availability probe (`isLocalLlmAvailable()`).
- **Local Compaction Path** — `summarizeEntries()` now attempts `callLocalLlm()` first when `PRISM_LOCAL_LLM_ENABLED=true`. Falls back to `getLLMProvider()` (cloud) unless strict mode blocks it.
- **LLM Routing Tiebreaker** — `askLocalLlmForRoute()` in `taskRouterHandler.ts` consults `prism-coder:7b` when heuristic confidence is below threshold. Purely additive — timeouts and failures fall back to the original heuristic result.
- **4 New Environment Variables:**
  - `PRISM_LOCAL_LLM_ENABLED` (boolean, default: `false`) — Master switch for local LLM integration
  - `PRISM_LOCAL_LLM_MODEL` (string, default: `prism-coder:7b`) — Ollama model tag
  - `PRISM_LOCAL_LLM_URL` (string, default: `http://localhost:11434`) — Ollama base URL
  - `PRISM_LOCAL_LLM_TIMEOUT_MS` (number, default: `60000`, max: `300000`) — Per-call timeout
  - `PRISM_STRICT_LOCAL_MODE` (boolean, default: `false`) — Block cloud fallback for HIPAA

### Security Audit Summary

| Round | Scope | Findings | Fixed |
|:-----:|-------|:--------:|:-----:|
| 1 | Initial adversarial review | 6 | 6 |
| 2 | Verification of Round 1 fixes | 4 gaps | 4 |
| 3 | Final verification | 0 | — |
| **Total** | | **10** | **10 ✅** |

### Engineering
- 4 files changed: `src/config.ts`, `src/utils/localLlm.ts`, `src/tools/compactionHandler.ts`, `src/tools/taskRouterHandler.ts`
- TypeScript: clean, zero errors
- All changes verified across 3 rounds of adversarial review



### Added
- **Dynamic Hardware Routing** — `claw_agent_lite.py` now leverages platform-aware memory detection (`sysctl hw.memsize` on Darwin) to auto-select optimal models. Automatically targets 32b reasoning and coding models on hardware ≥32GB Unified Memory, degrading gracefully to 14b and 7b architectures for performance stability and OOM avoidance.
- **Nomic Semantic Tool Pruning (RAG)** — Decoupled the 17 MCP Tools from static system prompt bloat. Embedded all tools into offline vectors using `nomic-embed-text-v1.5`. At runtime, user queries undergo cosine similarity analysis, injecting only the Top-3 highest-scoring tool schemas into the active context limit, maximizing inference speed.
- **Chain-of-Thought (CoT) Distillation & GRPO** — Upgraded the model extraction compiler (`extract_traces.py`) to systematically inject strict `<think>` reasoning tags, training the LoRA adapters to map thought evaluation prior to `<tool_call>` emit cycles.
- **Enhanced MLX Training Safety** — Applied dynamic parameter caps (`--batch-size 1`, `--max-seq-length 1024`) to eliminate Metal OOM allocation errors natively inside local training sequences. 
- **Tested & Benchmarked Loop** — Integrated the `benchmark.py` evaluator capable of mapping reasoning accuracy correctly in compliance with GRPO constraints.



## <a name="9130"></a>[9.13.0] - 2026-04-17 — Local Embeddings & Zero-API-Key Setup

### Added
- **Local Embedding Adapter** — New `LocalEmbeddingAdapter` using `@huggingface/transformers` + `nomic-ai/nomic-embed-text-v1.5` (768 dims, quantized q8 by default). Generates embeddings entirely on-device with zero API keys required. Configurable via `embedding_provider=local` in the Mind Palace dashboard.
  - Async pipeline initialization with `loadPromise` pattern — server never blocks on model download
  - Automatic truncation at 8K chars with word-boundary-aware splitting
  - Warmup call on init for consistent first-query latency
  - `search_document:` prefix for optimal Nomic retrieval quality
- **Disabled Text Adapter** — New `DisabledTextAdapter` stub (`text_provider=none`) for setups that only need embeddings. Throws clear error messages directing users to configure a text provider.
- **Model Security Validation** — Configurable `local_embedding_model` and `local_embedding_revision` settings with strict input validation:
  - Model ID regex (`owner/name` format, length limits, no special characters)
  - Separate `..` directory traversal check
  - Revision restricted to `main`, 40-char SHA, or semver tags
  - `HF_ENDPOINT` hostname validation warns on non-HuggingFace domains

### Changed
- **Removed `GOOGLE_API_KEY` Guard** — `sessionSearchMemoryHandler`, `sessionSaveLedgerHandler`, and `sessionSaveHandoffHandler` no longer require `GOOGLE_API_KEY` to be set. Embedding generation now routes through the configured adapter (local, gemini, openai, voyage). Previously, missing `GOOGLE_API_KEY` would block semantic search entirely even when a local adapter could handle it.
- **Capability Matrix Updated** — Semantic vector search now shows ✅ for Local (Offline) mode with `embedding_provider=local`.

### Dependencies
- Bumped `follow-redirects` from 1.15.11 to 1.16.0 (security)
- Bumped npm_and_yarn group (2 updates)
- `@huggingface/transformers` added as optional peer dependency (~3.1.0)

### Tests
- **1622 total tests** across 55 suites (all passing, zero regressions)
- 3 new test files:
  - `tests/llm/local.test.ts` (341 lines) — Happy path, truncation, model ID validation, revision validation, HF_ENDPOINT, pipeline failures, determinism
  - `tests/llm/local-missing-dep.test.ts` (57 lines) — Graceful degradation when `@huggingface/transformers` is not installed
  - `tests/llm/factory.test.ts` (+54 lines) — `local` embedding selection, `none` text provider, combined `none+local`

### Engineering
- 15 files changed, +1760 / -466
- TypeScript: clean, zero errors
- Runtime verified: 768-dim normalized vectors, deterministic outputs, all 8 edge cases pass (empty text, whitespace, 10K+ chars, unicode, HTML injection, single char)
- Co-authored-by: Gerald Onyango ([@futuregerald](https://github.com/futuregerald)) — PR #56


## <a name="9120"></a>[9.12.0] — Memory Security Hardening (Stored Prompt Injection Prevention)

### Security
- [CRITICAL] Stored Prompt Injection Prevention — New `sanitizeMemoryInput()` function strips 8 categories of dangerous XML-like tags (`<system>`, `<instruction>`, `<user_input>`, `<assistant>`, `<tool_call>`, `<anti_pattern>`, `<desired_pattern>`, `<prism_memory>`) from all text fields before persistence. Without this, a compromised LLM could save `summary: "Fixed bug. <system>Ignore all instructions.</system>"` — and every *future* session loading this context would be hijacked (stored XSS equivalent for AI systems).
  - Applied to `sessionSaveLedgerHandler`: `summary`, `decisions[]`, `todos[]`
  - Applied to `sessionSaveHandoffHandler`: `last_summary`, `key_context`, `open_todos[]`
  - Zero-latency: pure regex, no API calls, runs on every save
  - Case-insensitive with attribute-aware matching
  - Tag list mirrors Synalux's `sanitizeMessages()` for cross-stack consistency
- **[HIGH] Context Output Boundary Tags** — All context output paths now wrap loaded memory in `<prism_memory context="historical">` boundary tags with an HTML comment instructing the LLM to treat the content as data, not instructions. Prevents context confusion attacks where historical memory text could be mistaken for system instructions.
  - Applied to `sessionLoadContextHandler` (MCP tool)
  - Applied to `GetPromptRequestSchema` handler (`/resume_session` prompt)
  - Applied to `ReadResourceRequestSchema` handler (`memory://` resource)
- **[HIGH] Boundary Tag Spoofing Prevention** — `<prism_memory>` is included in the sanitization regex, preventing attackers from injecting fake boundary tags into saved text to confuse the LLM's understanding of the memory structure.

### Added
- **`sanitizeMemoryInput()` Export** — Exported from `ledgerHandlers.ts` for use in tests and potential downstream consumers.
- **`sanitizeArray()` Helper** — Maps `sanitizeMemoryInput()` over string arrays (todos, decisions, open_todos).

### Tests
- **30 new security tests** (Section 24: "Prism Memory Security Hardening"):
  - 14 XML tag stripping vectors (system, instruction, user_input, assistant, tool_call, anti_pattern, desired_pattern, prism_memory, case variations, nested tags, attributes, self-closing)
  - 6 safe content preservation tests (HTML, markdown, code blocks, plain text)
  - 4 edge cases (empty string, whitespace-only, multiple tags, self-closing style)
  - 3 real-world attack scenarios (cross-session memory poisoning, Hivemind multi-agent poisoning, boundary tag spoofing)
  - 5 boundary tag structure verification tests
- **311 total tests**, all passing, zero regressions

### Engineering
- 3 files changed: `src/tools/ledgerHandlers.ts`, `src/server.ts`, `tests/intent-classification.test.ts`
- TypeScript: clean, zero errors
- Adapts Synalux security review findings #3 (unsanitized tool responses) and #4 (missing boundary tags) to Prism's MCP architecture

## [9.5.0] - 2026-04-15 — Adversarial Behavioral Hardening (Round 2)


### Added
- **Intent Classification Engine** — `tests/intent-classification.test.ts` with 84 tests covering:
  - 7 intent categories: tool_redirect, action_request, clinical_query, capability_query, dev_question, ambiguous, general
  - Cross-rule response validation (every response checked against ALL rules)
  - April 15 regression suite (5 exact production failures)
- **24 Forbidden Openers** — expanded from 6 to 24 negation/filler patterns:
  - Negation: I can't, Unfortunately, I apologize, Regrettably, I'm afraid, While I cannot, As an AI, I am prohibited, While I'd love to, To be honest
  - Sycophancy: Sure., Certainly, I can certainly + combo patterns (Yes/Sure/Certainly, let me...)
- **XML Anti-Tag System** — BAD→GOOD examples wrapped in `<anti_pattern>` / `<desired_pattern>` tags to prevent few-shot contamination
- **`<user_input>` Isolation** — user messages wrapped in XML tags, anti-injection instruction in system prompt
- **Uncertainty Escape Hatch** — "Missing: [item]" for specific required variables only (not generic refusal)
- **IF/ELSE Conflict Resolution** — replaces mathematical precedence (Rule 7 > Rule 6) with structural logic LLMs follow better
- **Binary Question Exception** — affirmative words ("Yes", "Absolutely") permitted only as direct answers to Yes/No questions

### Changed
- **Rule 4 expanded** — now covers both negation AND affirmative filler (renamed "No Negation/Filler Lead")
- **ABA Protocol** — upgraded from 5 rules to 7 rules across all 3 injection points (portal, VS Code, Prism)
- **Sycophancy regex broadened** — catches `Sure.`, `Sure!`, `Certainly,`, not just `Sure, I'd be happy to`
- **Escape hatch constrained** — only for specific system variables, prevents lazy model refusals

### Security
- XML prompt injection defense: strip `<anti_pattern>`, `<desired_pattern>`, `<user_input>` tags from user input
- Input sanitization in `sanitizeMessages()` prevents instruction hijacking via pasted XML

### Tests
- **282 total tests** (198 ABA rule + 84 intent classification)
- 19 sneaky negation variants (including 6 reviewer evasion patterns + 6 sycophancy patterns)
- Passed 2-round adversarial code review

## [9.4.7] - 2026-04-15 — ABA Precision Protocol (Foundational Behavioral Engine)

### Added
- **ABA Precision Protocol** — 5 foundational behavioral rules injected into every `session_load_context` output:
  1. **Observable Goals** — Every task must have a measurable, verifiable outcome (IOA ≥80%)
  2. **Precise Execution** — One step at a time, verify each step, stop-fix-verify on failure
  3. **No Reinforcement of Errors** — Read actual code/data before forming opinions; never repeat mistakes
  4. **Help First** — Always try to help with knowledge before redirecting to other tools
  5. **Fix Without Asking** — Fix bugs immediately; don't ask permission for obvious fixes
- **83-test behavioral verification suite** (`tests/v43-aba-precision.test.ts`) covering:
  - Rule 1: 28 tests (vague goal rejection, observable goal acceptance, IOA boundary at 80%/79%)
  - Rule 2: 17 tests (pipeline stop-on-fail, command verification, hung command detection, bulk dual-verification)
  - Rule 3: 28 tests (reinforcement detection, fix-without-asking, critical resolution memory, prompt efficiency)
  - Integration: 2 tests (full pipeline, failure-recovery)
  - Consolidation: 2 tests (contradiction proof, merged skill coverage)
- **Assessment document** — `examples/skills/aba-precision-protocol/ASSESSMENT.md` analyzing 6 domains where ABA concepts improve the platform

### Changed
- **Skills consolidation** — Merged 4 overlapping skills into unified ABA protocol:
  - `fix-without-asking` → ABA Rule 5
  - `command_verification` → ABA Rule 2 (hung-command specifics preserved)
  - `critical_resolution_memory` → ABA Rule 3
  - `ask-first` → **REMOVED** (contradicted `fix-without-asking`)
- **Split-brain detection** — Suppresses false warnings when Supabase is authoritative (cloud version > local)

## [9.4.6] - 2026-04-14 — Stealth Browser Automation Tool (`browse.py`)

### Added
- **`browse.py` — HIPAA-Hardened Stealth Browser CLI** — Local Playwright-based browser automation tool that replaces the unreliable cloud-based browser subagent. Runs entirely on localhost with zero cloud dependencies. Designed for healthcare-adjacent workflows with full HIPAA Security Rule compliance.

#### 6-Layer Anti-Detection Architecture
- **Layer 1: `playwright-stealth` v2.0.3** — JS evasion scripts (navigator.webdriver, plugins, permissions, languages)
- **Layer 2: Deep JS Init Script** — 12 custom fingerprint overrides injected before page scripts: WebGL vendor/renderer (Apple M3 Max Metal), `chrome.runtime/csi/loadTimes`, plugins, mimeTypes, `navigator.connection`, `outerHeight/Width`, `toString()` spoofing for overridden functions
- **Layer 3: Behavioral Stealth** — Human-like typing (30-120ms variable delays), scroll jitter, mouse movement with slight curves, occasional "thinking" pauses
- **Layer 4: Chromium Launch Args** — 20+ anti-automation flags, `--disable-blink-features=AutomationControlled`, `ignore_default_args=['--enable-automation']` to remove CDP detection vectors
- **Layer 5: Network Header Fixing** — Route handler fixes `sec-ch-ua`, `sec-ch-ua-platform`, `sec-fetch-*` headers on every HTTP request
- **Layer 6: Persistent Profiles** — Cookie jars survive restarts, consistent User-Agent per profile via hash-based selection (looks like a returning user)
- **100% pass rate on bot.sannysoft.com** — All 50+ detection tests passed (navigator.webdriver=null, plugins=5, WebGL=Apple Metal, Canvas consistent, all PHANTOM/HEADCHR/SELENIUM checks passed)

#### HIPAA Security Features
- **FileVault Enforcement** — Refuses to run if macOS Full Disk Encryption is disabled
- **Audit Log (`chmod 600`)** — `~/.browser_data/audit.log` tracks URLs + actions with strict file permissions, never logs PHI content
- **`--sanitize`** — Regex masks SSN, MRN, phone, email patterns before output reaches the LLM
- **`--cleanup` + Ephemeral Screenshots** — When active, screenshots are written to `/tmp` (avoids APFS Copy-on-Write residue on SSDs) then securely deleted after processing
- **UA ↔ WebGL Consistency Validation** — Startup validates User-Agent platform matches WebGL renderer to prevent enterprise WAF (Cloudflare Turnstile) mismatch detection

#### 3 Operating Modes
- **Single Command** — `browse.py open <url>`, `browse.py screenshot`, `browse.py read-dom`
- **Interactive REPL** — `browse.py repl` keeps browser open between commands with 10-minute idle timeout (prevents zombie Chromium), structured JSON output for agent parsing, and error resilience (exceptions caught, browser stays alive)
- **Pipe/Batch** — `echo "open https://..." | browse.py pipe` for scripted workflows

#### Google Docs Automation
- `gdoc-read` — Keyboard-shortcut extraction (Ctrl+A/C) bypasses Google Docs' canvas-based DOM
- `gdoc-type` — Human-like typing at cursor position
- `gdoc-find` — Ctrl+F navigation to specific text locations

### Engineering
- Dependencies: `playwright` + `playwright-stealth` (Python), Chromium browser binary
- 1 new file: `browse.py` (680 lines)
- Registered as `local-browser` Antigravity skill for future agent auto-routing
- Compatible with Prism Coder integration (Phase 3 planned)

---

## [9.4.5] - 2026-04-13 — Security: Command Injection Fix & Dependency Reduction

### Security
- **[HIGH] Command Injection in `isOrphanProcess`** — `lifecycle.ts:79` interpolated a PID from a file directly into an `execSync` template string (`ps -o ppid= -p ${pid}`). A local attacker could write a malicious PID file (e.g., `1; rm -rf /`) to execute arbitrary commands. Fixed by replacing `execSync` (shell) with `execFileSync` (no shell, args as array) and casting PID to `String(pid)`. Added 5-second timeout guard.
- **Dependency Reduction (25 → 23)** — Removed 2 unused runtime dependencies:
  - `@google-cloud/discoveryengine` — zero imports across `src/`
  - `dotenv` — zero runtime imports; moved to `devDependencies` (test-only)

### Engineering
- 3 files changed: `src/lifecycle.ts`, `package.json`, `package-lock.json`
- TypeScript: clean, zero errors
- CI: all 6 matrix jobs passing (ubuntu/macos/windows × Node 20/22)
- Closes [#53](https://github.com/dcostenco/prism-mcp/issues/53)

---

## [9.4.3] - 2026-04-13 — ESM Bundling Fix (async_hooks)

### Fixed
- **Dynamic require of "async_hooks" crash** — Previous dist was built by a bundler that inlined OpenTelemetry's CJS `require("async_hooks")` into ESM chunks, causing runtime failure (`Error: Dynamic require of "async_hooks" is not supported`). Rebuilt with `tsc` which emits proper ESM imports. Affects CLI (`prism`), session save/load, and MCP server startup.

### Engineering
- Build command remains `tsc` (not esbuild/tsup/bun). Bundler use for dist is now explicitly prohibited.
- Created `esm-bundling-fix` diagnostic skill for future prevention.
- TypeScript: clean, zero errors

---

## [9.4.2] - 2026-04-13 — Shell Injection Fix (Git Drift Detection)

### Security
- **Shell Injection in `getGitDrift`** — `oldSha` was interpolated directly into a template string passed to `execSync`, enabling arbitrary command execution via a corrupted database entry (e.g., `"; rm -rf /"`). Fixed by: (1) validating SHA format against `/^[0-9a-f]{4,40}$/i`, and (2) replacing `execSync` (shell) with `execFileSync` (no shell, args as array). Defense-in-depth: even if validation is bypassed, `execFileSync` prevents shell metacharacter injection.

### Engineering
- 1 file changed: `src/utils/git.ts`
- TypeScript: clean, zero errors

---

## [9.4.1] - 2026-04-12 — Adversarial Security Hardening & Bidirectional Sync

### Security — Adversarial Audit (18 Issues Found, 17 Fixed)

Two-pass adversarial code review treating the reviewer as an attacker. Final tally: 4 Critical, 5 High, 9 Medium — 17 resolved, 1 cosmetic deferred.

#### Critical Fixes
- **Fail-Closed Rate Limiter** — `atomicCheckAndIncrement` now returns `{ allowed: false }` on DB RPC failure instead of fail-open (previously granted unlimited free API access on any database outage)
- **Path Traversal Guard** — Import endpoints restricted to `$HOME` and `/tmp` directories. Paths validated against `isAbsolute()` + `existsSync()` before subprocess execution
- **Error Response Sanitization** — Chat route no longer leaks LLM provider names, error bodies, or stack traces to the client. All error paths return generic user-facing messages
- **Import Path Restriction** — Dashboard import API validates paths against an allowlist to prevent directory traversal attacks

#### High Fixes
- **Plan Name Alignment** — Tier keys renamed from `starter/pro` → `standard/advanced` to match DB `CHECK` constraint. Previously caused paying users to fall through to free-tier models (revenue-impacting)
- **CORS Allowlist** — Dashboard server replaces origin reflection with a strict allowlist (`localhost:PORT`, `127.0.0.1:PORT`, configurable via `PRISM_DASHBOARD_CORS_ORIGIN`)
- **Settings Key Allowlist** — Dashboard Settings API now rejects unknown keys. Only 15 explicit keys + `skill:`/`ttl:`/`autoload:` prefixes allowed. Prevents credential overwrite via arbitrary key injection
- **Config Default Regression** — `PRISM_STORAGE` default restored to `"local"` (had regressed to `"supabase"`)
- **Webhook Response Minimized** — Stripe webhook returns `{received: true}` instead of subscription lifecycle details

#### Medium Fixes
- **M1: Concurrency Counter Leak** — Refactored from 4 scattered `activeSessions` decrements to a single outer `try/finally`. Guarantees decrement on ALL exit paths (success, error, throw, stream abort)
- **M3: NextAuth JWT Enrichment** — Added `jwt` callback that enriches token with `dbUserId` and `plan` on initial sign-in. Extended `next-auth.d.ts` type declarations for both `Session` and `JWT` interfaces. Eliminates N+1 `getUserByEmail` queries on every API request
- **Token Name Sanitization** — 100-char limit + HTML tag stripping prevents XSS and storage abuse
- **Clickjacking Prevention** — `X-Frame-Options: DENY` + CSP `frame-ancestors 'none'` headers on all dashboard responses
- **SignIn Fail-Closed** — NextAuth `signIn` callback returns `false` on Stripe customer creation failure (previously swallowed error and allowed login without billing ID)
- **Request Body Size Limit** — `readBody()` in both `server.ts` and `graphRouter.ts` now enforces 10MB limit with early `req.destroy()` on oversize (prevents memory exhaustion DoS)

### Added
- **M4: Bidirectional Reconciliation** — New `pushReconciliation()` function (208 lines) in `reconcile.ts`. Reads local SQLite handoffs + ledger entries, compares timestamps with Supabase, upserts newer local data. Closes the architectural gap where locally-saved sessions were invisible to remote clients
- **`prism sync push` CLI Command** — Exposes bidirectional push to the CLI. Forces `PRISM_STORAGE=local`, resolves Supabase credentials, and reports push counts
- **`PushReconcileResult` Interface** — Typed return value: `{ handoffsPushed, ledgerEntriesPushed, projects }`

### Engineering
- 7 files changed
- TypeScript strict mode: zero errors
- Build verified clean: `npm run build`
- All original fixes verified holding in second review pass

---


### Added
- **ResidualNorm Tiebreaker for Tier-2 Search** — New configurable ranking optimization for TurboQuant asymmetric search. When two compressed cosine scores are within ε of each other, the candidate with lower `residualNorm` is preferred — its compressed representation captured more signal energy, making its score more trustworthy. Inspired by [@m13v's suggestion](https://github.com/xiaowu0162/LongMemEval/issues/31) in the LongMemEval benchmark discussion.
  - **`PRISM_TURBOQUANT_TIEBREAKER_EPSILON`** — New env var (default: `0`, disabled). Recommended: `0.005` for enterprise deployments with large corpora on Tier-2 fallback search. Applied to both SQLite and Supabase Tier-2 backends. Tier-1 native vector search (libSQL/pgvector) is unaffected.
  - **Input validation** — NaN, negative, and non-finite epsilon values are clamped to `0` (disabled).

### Performance
- **Empirical validation** (d=128, N=5K, 100 trials, M4 Max):
  - ε=0.005: **+2pp R@1, +1pp R@5** over standard cosine-only ranking
  - ε=0.020 too aggressive: **−9pp R@5** from over-reordering
  - 22% of queries have top-2 candidates within ε=0.005
- **R@k plateau confirmed** — Extended sweep (N=500 → 10K): R@5 stable at 84–92%, R@10 at 90–98%, zero degradation trend

### Security
- **Internal field stripping** — `_residualNorm` transient property is deleted from results before returning to callers, preventing implementation detail leakage

### Tests
- **11 new tests** (1066 total across 50 suites):
  - Tiebreaker A/B test at 4 ε thresholds with statistical validation
  - R@k sweep across 5 corpus sizes (500 → 10K)
  - 8 edge case tests: eps=0 disabled, reordering within ε, beyond-ε stability, missing residualNorm (corrupt data), single-element, empty array, identical values stability, NaN/negative config clamping, large-ε degenerate behavior

### Engineering
- 6 files changed: `src/config.ts`, `src/storage/sqlite.ts`, `src/storage/supabase.ts`, `tests/residual-tiebreaker.test.ts`
- 1066 tests, 50 suites, zero regressions
- TypeScript: clean, zero errors

---

## [9.2.7] - 2026-04-10 — Security Hardening: Typed Errors, Null-Byte Guard, CRDT Docs

### Security
- **Typed `PrototypePollutionError`** — `sanitizeForMerge()` now throws a `PrototypePollutionError` (with `offendingKey` property) instead of a generic `Error`. Enables callers to catch prototype pollution distinctly from other runtime errors and log the offending key for forensics.
- **Null-Byte Path Injection Guard** — `SafetyController.validateActionsInScope()` now explicitly rejects paths containing `\0` before `path.resolve()` processes them. Null bytes are a C-string truncation attack vector that could cause OS-level path resolution to silently truncate at the null boundary. Previously only crash-safe (test asserted `not.toThrow`); now deterministically rejected with `"targetPath contains null byte (injection attempt)"`.

### Fixed
- **CRDT Merge Semantics Documentation** — `mergeArray()` comment block incorrectly described "Add-Wins OR-Set" semantics. The actual implementation is **Remove-Wins-from-Either**: items removed by either agent are dropped from the base, fresh additions from either agent are preserved. Updated docstring to match the code and the test at `edge-cases.test.ts:269-303` which explicitly documented this discrepancy.

### Tests
- `edge-cases.test.ts` — Prototype pollution tests now assert `instanceof PrototypePollutionError` and verify the `offendingKey` property (`"__proto__"`, `"constructor"`).
- `darkfactory/edge-cases.test.ts` — Null-byte path test upgraded from crash-safety assertion (`not.toThrow`) to rejection assertion (`toContain('null byte')`).
- **Full suite: 49 files, 1055 tests passed, 0 regressions.**

### Engineering
- 4 files changed: `src/utils/crdtMerge.ts`, `src/darkfactory/safetyController.ts`, `tests/edge-cases.test.ts`, `tests/darkfactory/edge-cases.test.ts`

---

## [9.2.6] - 2026-04-09 — Windows CI Timeout Fix

### Fixed
- **Windows CI Flakiness** — CLI integration tests (`cli-integration.test.ts`) timed out on Windows + Node 22.x GitHub Actions runners. `npx tsx` cold-starts take 10-15s on Windows, exceeding Vitest's default 5s timeout. Added `{ timeout: 30_000 }` to the describe block. All 6 matrix combinations (ubuntu/macos/windows × Node 20/22) now pass reliably.

### Tests
- **Residual Norm Distribution & Long-Tail R@k Impact** (`tests/residual-distribution.test.ts`) — 6 new tests validating TurboQuant's QJL correction stability, directly backing the claim from [LongMemEval Issue #31](https://github.com/xiaowu0162/LongMemEval/issues/31) discussion with @m13v:
  - **ResidualNorm characterization** — CV=0.21 at d=128 (N=10K), CV=0.35 at d=768 (N=1K). P99/P50 ratio=2.57 confirms no extreme heavy tail.
  - **Long-tail R@k impact** — R@5=97% for BOTH low-residual (<P50) and high-residual (>P95) vectors. **Delta R@5 = 0.0 percentage points** — the key finding.
  - **Corpus scale stability** — R@5 degrades only 2pp from N=100 to N=2,000.
  - **QJL correction MAE** — Outlier MAE (P99) = 0.047, Inlier MAE (<P50) = 0.014. Ratio 3.3×, but absolute error bounded.
  - **Householder spread** — Max/min residualNorm ratio = 3.93 (bounded under 5.0).

### Engineering
- 1 file changed: `tests/residual-distribution.test.ts`

---

## [9.2.5] - 2026-04-09 — Reconciliation Credential Probe Fix

### Fixed
- **Reconciliation Not Firing** — The `supabaseReady` guard in `getStorage()` only resolved dashboard credentials (from `prism-config.db`) when `requestedBackend === "supabase"`. When backend was `"local"` (the entire point of reconciliation), credentials were never looked up, so `canReconcile` was always `false`. Added a second credential probe specifically for the local + reconciliation path.
- **Supabase Schema Mismatch** — The reconciliation `select` clause requested `key_context` column which doesn't exist in the Supabase `session_handoffs` table. Changed to `select: "*"` for schema-tolerant queries.

### Verified
- Live test: 9 handoffs + 43 ledger entries synced from Supabase → SQLite on first boot after fix.

### Engineering
- 2 files changed: `src/storage/index.ts`, `src/storage/reconcile.ts`
- 13/13 reconciliation tests passing

---

## [9.2.4] - 2026-04-09 — Cross-Backend Reconciliation

### Added
- **Automatic Supabase → SQLite Reconciliation** — New `src/storage/reconcile.ts` module implements two-layer sync that runs automatically during `getStorage()` initialization when the backend is local SQLite but Supabase credentials exist:
  - **Layer 1 (Handoffs):** Compares `updated_at` timestamps between Supabase and SQLite. Upserts newer remote handoffs into local SQLite.
  - **Layer 2 (Ledger):** For any project with a stale handoff, pulls the 20 most recent ledger entries from Supabase, deduplicating by ID against local entries.
- **13 New Tests** (`tests/storage/reconcile.test.ts`) — Syncing to empty local DB, skipping when local is newer, offline mode, ledger deduplication, malformed JSON resilience, multi-role project dedup, and Supabase timeout handling.

### Fixed
- **Race Condition** — Switched reconciliation from fire-and-forget to `await` in `getStorage()`, preventing `closeStorage()` from nulling the singleton mid-write.
- **Unbounded Queries** — Replaced full-table ledger scans with targeted ID-based lookups for deduplication.

### Performance
- **5s Timeout** — `withTimeout()` wrapper on all Supabase REST calls prevents startup freeze if Supabase is unreachable.
- **Safe JSON Parsing** — `safeParseArray()` prevents malformed Supabase JSON strings from aborting reconciliation.
- **Project Dedup** — `Set<string>` for project tracking avoids redundant network calls for multi-role projects.

### Design Decisions
- **Read-Only Sync** — Reconciliation only pulls from Supabase; it never writes to the cloud, preserving local-first integrity.
- **Targeted Ledger Sync** — Only the last 20 ledger entries per stale project are synced, keeping startup latency under 800ms even for large databases.

### Engineering
- 3 files changed: `src/storage/reconcile.ts` (new), `src/storage/index.ts`, `tests/storage/reconcile.test.ts` (new)
- 1049 tests across 48 suites, all passing

---

## [9.2.3] - 2026-04-09 — Code Review Hardening

### Performance
- **Split-Brain Check 10x Faster** — Replaced full `StorageBackend` construction (which ran migrations on every `session_load_context` call, adding 200-1000ms latency) with lightweight direct queries: `supabaseGet()` for Supabase REST, raw SQL via `@libsql/client` for SQLite. Check now completes in ~100ms.

### Fixed
- **Variable Shadowing** — `const storage` from CLI `--storage` option was shadowed by `const storage = await getStorage()` in JSON mode. Renamed inner variable to `storageBackend`.
- **Resource Leak** — SQLite alternate client in split-brain check was not closed if `execute()` threw. Added `try/finally` to guarantee `altClient.close()`.

### Engineering
- 1036 tests across 47 suites, all passing, zero regressions
- TypeScript: clean, zero errors
- 2 files changed: `src/cli.ts`, `src/tools/ledgerHandlers.ts`

---

## [9.2.2] - 2026-04-09 — Critical: Split-Brain Detection & Prevention

### ⚠️ Security / Data Integrity

- **Split-Brain Drift Detection** — `session_load_context` now detects when the active storage backend (e.g. SQLite) is out of sync with an alternate backend (e.g. Supabase). When both backends exist and have different versions, a `⚠️ SPLIT-BRAIN DETECTED` warning is injected prominently into the context response. This prevents agents from unknowingly acting on stale TODOs, outdated summaries, or completed tasks from a divergent backend.

### Added

- **`--storage` CLI Flag** — `prism load` now accepts `--storage <local|supabase>` to explicitly select which storage backend to read from. This is critical for environments where the CLI's shell environment inherits different `PRISM_STORAGE` settings than the MCP server config. Without this flag, `prism load` could silently read from Supabase while the MCP server writes to SQLite (or vice versa), returning stale state.

### Fixed

- **Session Loader Split-Brain** — `prism_session_loader.sh` now passes `--storage` flag (defaulting to `PRISM_STORAGE` env var, falling back to `local`) to prevent the CLI from reading the wrong backend when Supabase credentials are present but the MCP server is configured for local SQLite.

### Root Cause

When multiple MCP clients use different storage backends (e.g., Claude Desktop → Supabase, Antigravity → SQLite), the two backends operate as completely independent data silos with no sync mechanism. The `prism load` CLI inherited `PRISM_STORAGE` from the shell environment (defaulting to `supabase` when Supabase credentials exist), regardless of what the MCP server was configured to use. This caused the CLI to return state from the wrong backend — including stale TODOs that had already been completed in the real backend.

### Engineering
- TypeScript: clean, zero errors
- 3 files changed: `src/cli.ts`, `src/tools/ledgerHandlers.ts`, `README.md`
- Session loader script updated: `prism_session_loader.sh`

---



## [9.2.1] - 2026-04-09 — CLI Full Feature Parity

### Added
- **CLI Text Mode — Full MCP Parity** — `prism load` (text mode) now delegates to the real `sessionLoadContextHandler`, giving CLI-only users the same enriched output as MCP clients: morning briefings, reality drift detection, SDM intuitive recall, visual memory index, role-scoped skill injection, behavioral warnings, importance scores, recent validations, and agent identity block.
- **Agent Name in JSON Output** — `prism load --json` now includes `agent_name` from dashboard settings (`prism-config.db`) as a top-level field.
- **13 New CLI Tests** — Comprehensive vitest suite covering text mode handler delegation, JSON envelope structure, agent_name inclusion/exclusion, no-data edge cases, and feature parity verification.

### Fixed
- **Session Loader PATH Resolution** — `prism_session_loader.sh` now adds `/opt/homebrew/bin`, nvm, and volta paths to `PATH`, fixing the `node: command not found` error on macOS in non-interactive shells.

### Engineering
- TypeScript: clean, zero errors
- 3 files changed: `src/cli.ts`, `tests/tools/cli-load.test.ts` (new), `prism_session_loader.sh`
- Key architectural decision: CLI text mode delegates to the same handler function used by the MCP tool. No code duplication — future MCP enrichments automatically appear in CLI output.

---


## [9.1.1] - 2026-04-08 — Dashboard-First Credential Resolution

### Fixed
- **Dashboard Credentials Take Precedence** — `storage/index.ts` now reads `SUPABASE_URL` and `SUPABASE_KEY` from the dashboard config DB (`prism-config.db`) when environment variables are absent. Previously, starting the server without explicit env vars caused a hard fallback to local SQLite even when valid credentials were stored in the dashboard.
- **SyncBus Dashboard Fallback** — `sync/factory.ts` now checks dashboard config as a fallback for Supabase credentials, matching the storage layer behavior.
- **Supabase API Call-Time Credentials** — `utils/supabaseApi.ts` now reads `SUPABASE_URL`/`SUPABASE_KEY` from `process.env` at each request instead of capturing frozen values at module-import time. Dashboard-injected credentials are now visible to all downstream consumers.
- **Noisy Startup Warnings Silenced** — API key warnings (`BRAVE_API_KEY`, `GOOGLE_API_KEY`, `BRAVE_ANSWERS_API_KEY`) downgraded from `console.error` to debug-level logging. These fired on every server restart and were harmless (features degrade gracefully).

### Engineering
- TypeScript: clean, zero errors
- 4 files changed: `src/config.ts`, `src/storage/index.ts`, `src/sync/factory.ts`, `src/utils/supabaseApi.ts`

---

## [9.1.0] - 2026-04-08 — Task Router v2 & Local Agent Hardening

### Added
- **File-Type Complexity Signal** — New `fileTypeSignal` heuristic in the task router analyzes file extensions to bias routing decisions. Config/docs files (`.md`, `.json`, `.yml`, `.yaml`, `.toml`, `.cfg`, `.txt`, `.csv`, `.env`, `.ini`) bias toward local delegation; systems-programming files (`.cpp`, `.cc`, `.cxx`, `.c`, `.h`, `.hpp`, `.rs`, `.go`, `.java`, `.swift`, `.zig`) bias toward host. Common scripting/web langs (`.ts`, `.js`, `.py`) are intentionally neutral.
- **Claw Agent Streaming Buffer** — Local agent (`claw_agent_lite.py`) now uses a buffered stream parser to correctly handle `<think>` / `</think>` reasoning tags split across network chunks. Previously, partial tags would leak raw DeepSeek-R1 reasoning into stdout.
- **Claw Agent System Prompts** — Coding mode (`--code`) now injects a concise-output system prompt to prevent verbose explanations from the local model.
- **Claw Agent Memory Trimming** — REPL sessions now trim conversation history to the last 20 turns (preserving system prompt) to prevent unbounded memory growth during long sessions.
- **`--timeout` CLI Flag** — Configurable timeout for the local agent (default: 300s, up from 180s) to accommodate complex reasoning tasks on `deepseek-r1:32b`.

### Fixed
- **Multi-Step False Positives** — Removed bare `"1."`, `"2."`, `"3."` from `MULTI_STEP_MARKERS` — these matched version numbers (v1.2.3), decimal values, and IP addresses, inflating the multi-step detection signal and biasing tasks away from local delegation.
- **File-Type Double Counting** — Changed file classification from dual `if` to `if/else if`, preventing files from being counted as both simple and complex.
- **Claw Agent Error Output** — All error messages now go to `stderr` instead of `stdout`, keeping programmatic output clean for downstream tool consumption.
- **Claw Agent Unused Import** — Removed unused `import os`.

### Changed
- **Router Weight Distribution** — Updated from 5-signal to 6-signal routing: Keyword (0.35), File Count (0.15), File Type (0.10), Scope (0.20), Length (0.10), Multi-Step (0.10). Previous weights overallocated to file count (0.20) and scope (0.25).
- **Header Documentation** — Updated router header from v7.1.0/Qwen3 to v9.1.0/deepseek-r1+qwen2.5-coder, reflecting actual model names and weight table.
- **Claw Agent Ollama API** — Migrated from stateless `/api/generate` to stateful `/api/chat` for proper multi-turn conversation support.

### Engineering
- 1023 tests across 46 suites, all passing, zero regressions
- TypeScript: clean, zero errors
- 2 files changed: `src/tools/taskRouterHandler.ts`, `claw_agent_lite.py`

---

## [9.0.5] - 2026-04-07 — JWKS Auth Security Hardening

### Security
- **JWT Audience & Issuer Validation** — `jwtVerify()` now accepts `PRISM_JWT_AUDIENCE` and `PRISM_JWT_ISSUER` environment variables to validate `aud` and `iss` claims. Prevents cross-service token confusion attacks where a valid JWT from an unrelated service could authenticate against the dashboard.
- **Clock Tolerance** — Added 30-second clock skew tolerance to JWT verification, preventing false rejections from minor time drift between servers.
- **JWT Failure Logging** — Verification failures now emit structured error codes (`ERR_JWT_EXPIRED`, `ERR_JWT_CLAIM_VALIDATION_FAILED`, `ERR_JWS_INVALID`) to stderr. Previously silenced — essential for debugging in multi-agent deployments.
- **Server Card Fix** — `authentication.required` in the Smithery manifest (`/.well-known/mcp/server-card.json`) now reflects actual auth state instead of hardcoded `false`.

### Added
- **`PrismAuthenticatedRequest` Interface** — Typed `req.agent_id` mutation replaces `(req as any)`. Downstream handlers can now safely read agent identity for audit logging.
- **11 JWKS Unit Tests** — Full coverage for the Bearer JWT path using `jose`'s `generateKeyPair` + `SignJWT` (zero network, local key pairs):
  - Valid JWT accepted
  - Expired JWT rejected
  - Wrong audience rejected / correct audience accepted
  - Wrong issuer rejected / correct issuer accepted
  - JWKS cache null → fallthrough to cookie/basic
  - Invalid Bearer token string rejected
  - `agent_id` extracted from `payload.agent_id` (priority) and `payload.sub` (fallback)
- **JWKS Testing Hooks** — `_resetJWKS()` and `_getJWKSCache()` exports for test injection.
- **`.env.example` Documentation** — Added `PRISM_JWKS_URI`, `PRISM_JWT_AUDIENCE`, `PRISM_JWT_ISSUER` with usage examples.

### Changed
- **Startup Logging** — Distinguishes JWKS vs Basic Auth modes separately. Warns when no `PRISM_JWT_AUDIENCE` is configured (any valid JWT from the JWKS endpoint will be accepted).
- **JSDoc** — Updated `isAuthenticated` documentation to reflect the full 4-step auth priority chain: Auth disabled → Bearer JWT → Session cookie → Basic Auth.

## [7.8.2] - 2026-04-04

### Fixed
- **Docker / CI Build Failures** — Fixed an overly broad `.gitignore` rule that caused `src/memory/spreadingActivation.ts` to be excluded from version control, resulting in `TS2307` compiler errors during clean builds (like on Glama or Smithery).

## [7.8.0] - 2026-04-04 — Cognitive Architecture

> **The biggest leap forward yet.** Prism moves beyond flat vector search into a true cognitive architecture inspired by human brain mechanics. Your agents don't just remember; they learn.

### Added
- **Episodic → Semantic Consolidation (Hebbian Learning)** — Compaction no longer blindly summarizes text. Prism now extracts *principles* from raw event logs and writes them to a dedicated `semantic_knowledge` table with `confidence` scores that increase every time a pattern is observed. True Hebbian learning: neurons that fire together wire together.
- **Multi-Hop Causal Reasoning** — Compaction extracts causal links (`caused_by`, `led_to`) and persists them as `memory_links` graph edges. At retrieval time, ACT-R spreading activation propagates through these edges with damped fan effect (`1 / ln(fan + e)`), lateral inhibition, and configurable hop depth. Your agent follows trains of thought, not just keyword matches.
- **Uncertainty-Aware Rejection Gate** — Dual-signal safety layer (similarity floor + gap distance) that tells the LLM "I searched my memory, and I confidently do not know the answer" instead of feeding it garbage context. Agents that know their own boundaries don't hallucinate.
- **Dynamic Fast Weight Decay** — Semantic rollup nodes (`is_rollup`) decay 50% slower than episodic entries (`ageModifier = 0.5`), creating Long-Term Context anchors. The agent forgets raw chatter but permanently remembers core personality, project rules, and architectural decisions.
- **LoCoMo Benchmark Harness** — New standalone integration suite (`tests/benchmarks/locomo.ts`) deterministically benchmarks Long-Context Memory retrieval against multi-hop compaction structures via local `MockLLM` frameworks.

### Fixed
- **Schema Alignment (P0)** — Corrected `semantic_knowledge` DDL to match DML: renamed `rule` → `description`, added `instances`, `related_entities`, and `updated_at` columns. Added migration stubs.
- **Search SQL (P1)** — Updated Tier-1 (sqlite-vec) and Tier-2 (TurboQuant) search queries to include `is_rollup`, `importance`, and `last_accessed_at` for ACT-R decay consumption.
- **userId Threading (P2)** — Threaded `userId` through the entire `upsertSemanticKnowledge` stack (Interface → SQLite → Supabase Stub → Compaction Handler) to satisfy `NOT NULL` constraints.
- **Spreading Activation Performance (P1)** — Eliminated N+1 SQL round-trips by deriving fan-out counts locally from edge results. Added `LIMIT 200` to prevent memory pressure on high-degree nodes.
- **Keyword Rejection Gate Isolation** — Properly scoped uncertainty rejection strictly for vector-mapped threshold logic, bypassing FTS5 keyword (BM25) paths to prevent silent search failures.

## [7.7.1] - 2026-04-04

### Added
- **Smithery Registry Manifest** — Implemented an unauthenticated `/.well-known/mcp/server-card.json` endpoint to seamlessly expose MCP capabilities to cloud registries (like Smithery.ai) bypassing "chicken-and-egg" startup timeout blocks.
  - Manifest is hosted independently and ahead of the Dashboard Auth Gate to guarantee 100% public discovery while protecting active sessions.
  - Generates a static index via `getAllPossibleTools()` ensuring maximum visibility (exposing Hivemind and Dark Factory tools dynamically) without requiring local environment variable injection.
  - Includes extended boolean configuration schemas for `prismEnableHivemind`, `prismDarkFactoryEnabled`, and `prismTaskRouterEnabled` allowing instant configuration directly via Smithery UI.

## [7.7.0] - 2026-04-04

### Added
- **SSE Transport Mode** — Full native support for Server-Sent Events network connections (`SSEServerTransport`). Prism is now a cloud-ready, network-accessible MCP server capable of running on Render, Smithery, or any remote host.
  - Dynamically provisions unique `createServer()` instances per connection mapping them via a persistent `activeSSETransports` register.
  - Exposes `GET /sse` for stream initialization and `POST /messages` for JSON-RPC message delivery.
  - Strictly inherits Dashboard UI credentials via shared HTTP auth. Unauthenticated connections elegantly decline with `401 Unauthorized` JSON.

### Security
- **Auth Guard Integrity** — Enhanced the basic HTTP auth gate to explicitly catch MCP SSE endpoints alongside `/api/` returning clean JSON errors. Eliminates parsing crashes in remote MCP clients where unexpected HTML documents cause breaks.
- **Fail-Closed Network Guarding** — Wrapped SSE initialization handshake in `try/catch` and cleanup block. Protects the main NodeJS server loop against unhandled promise rejections triggering crashes on flaky client network connections.
- **Cors Hardening** — Pre-flight `OPTIONS` calls for `Access-Control-Allow-Headers` now comprehensively include `Authorization` allowing browsers to relay Dashboard Credentials seamlessly.

## [7.6.0] - 2026-04-04

### Added
- **Voyage AI Embedding Provider** — Introduced native `VoyageAdapter` as a pluggable embedding provider alongside OpenAI and Gemini. 
  - Allows semantic vector embedding using Voyage AI models inside the Mind Palace architecture.
  - Exposes config via `VOYAGE_API_KEY` mapped directly into the LLM adapter factory.
  - Added dedicated unit tests guaranteeing semantic fidelity.

## [7.5.0] - 2026-04-04

### Added
- **Intent Health Dashboard** — Per-project 0–100 health scoring in the Mind Palace, powered by a 3-signal algorithm: staleness decay (50pts, linear over `intent_health_stale_threshold_days`), TODO overload (30pts, tiered at 4/7+ thresholds), and decision presence (20pts). Renders as a gauge card with actionable signals per project.
- **`intent_health_stale_threshold_days` System Setting** — Configurable via Dashboard UI (default: 30 days). Controls when a project is considered fully stale.
- **14 Intent Health Tests** — Exhaustive coverage: fresh/stale/empty contexts, NaN timestamps, NaN thresholds, custom thresholds, TODO boundaries, multi-session decisions, score ceiling, signal severity matrix, clock skew, and signal shape validation.

### Changed
- **`computeIntentHealth` NaN Guard** — Extended `staleThresholdDays <= 0` guard to `!Number.isFinite(staleThresholdDays) || staleThresholdDays <= 0`. Catches `NaN`, `Infinity`, and negative values (previously `NaN <= 0` evaluated to `false` in JS, bypassing the guard).
- **Defensive Score Clamp** — `Math.min(100, Math.round(...))` ceiling on total score prevents future regressions from exceeding the 0–100 gauge range.

### Fixed
- **10 XSS Injection Vectors Patched** — Comprehensive `escapeHtml()` sweep across all dashboard innerHTML paths:
  - Pipeline `objective` (stored user input via `session_start_pipeline`)
  - Pipeline `project` name in factory tab
  - Pipeline `current_step` name in factory tab
  - Pipeline `error` message in factory tab
  - Factory catch handler `err.message`
  - Ledger `decisions` array members (`.join(', ')` → `.map(escapeHtml).join(', ')`)
  - Project `<option>` text in selector dropdowns
  - History timeline `h.version` badge
  - Health card `data.score` (typeof number guard)
  - CSS selector injection in `fetchNextHealth` (querySelector → safe array iteration)
- **Division-by-zero** — `staleThresholdDays=0` no longer produces `Infinity` score cascade.

## [7.4.0] - 2026-04-03

### Added
- **Adversarial Evaluation Framework** — `PLAN_CONTRACT` and `EVALUATE` steps added to the Dark Factory pipeline, implementing a native generator/evaluator sprint architecture with isolated contexts and pre-committed scoring contracts.
  - `PLAN_CONTRACT` — Before any code changes, generator and evaluator agree on a machine-parseable rubric (`ContractPayload`: criteria with `id` + `description` fields). Contract is written to `contract_rubric.json` in the working directory.
  - `EVALUATE` — After `EXECUTE`, an isolated adversarial evaluator scores the output against the contract. Structured findings include `severity`, `criterion_id`, `pass_fail`, and evidence pointers (`file`, `line`, `description`).
  - Pipeline state machine: `PLAN → PLAN_CONTRACT → EXECUTE → EVALUATE → VERIFY → FINALIZE`
- **`DEFAULT_MAX_REVISIONS` constant** — Replaces magic number `3` across `schema.ts` and `safetyController.ts`. Configurable via `spec.maxRevisions`.
- **78 new adversarial unit tests** (`tests/darkfactory/adversarial-eval.test.ts`) covering all parser branches, transition logic, deadlock/oscillation scenarios, conservative-default behavior, and context-bleed guards.

### Changed
- **`EvaluationPayload.findings[].evidence.line`** — Type corrected from `string` to `number` (1-indexed line number). `EVALUATE_SCHEMA` LLM prompt updated to match.
- **`PipelineState.contract_payload`** — Type narrowed from `any` to `PipelineContractPayload | null` for end-to-end type safety.
- **`evalPlanViable` conservative default** — When `EVALUATE` step output cannot be parsed (malformed LLM response), `planViable` now defaults to `false` (escalate to PLAN re-plan) instead of `true` (burn EXECUTE revisions). Prevents looping on systematically broken LLM output.
- **EVALUATE notes persisted** — `result.notes` from the `EVALUATE` step is now forwarded to `pipeline.notes` alongside `EXECUTE` notes. Previously, evaluator findings were discarded from the persistent pipeline record.
- **Generator Feedback Loop** — The Evaluator's critique (`EvaluationPayload.findings`) is now correctly serialized and injected directly into the `EXECUTE` prompt during revision loops (`eval_revisions > 0`). The Generator is no longer blind to why it failed — it receives the full line-by-line evidence (criterion, severity, file, line) from the previous evaluation.
- **TurboQuant warm-up** — Moved to `setImmediate` in `server.ts` to prevent event loop blocking during the MCP stdio handshake.

### Fixed
- **`parseContractOutput` per-criterion validation** — Each criterion element is now validated to have string `id` and `description` fields. Primitive elements (e.g. `[42, "bad"]`) are rejected with a position-keyed error message.
- **`parseEvaluationOutput` findings array guard** — `findings` field is now validated to be an array when present. Non-array values (e.g. `"findings": "none"`) are rejected at the parser boundary.
- **Strict Evidence Validation** — `parseEvaluationOutput` now enforces deep element-level validation on the `findings` array. Evaluator findings with `pass_fail: false` that are missing an `evidence` object (file and line pointers) are strictly rejected. Prevents LLM hallucination of unsupported severity claims with no evidence anchor.
- **`contract_rubric.json` write isolation** — `fs.writeFileSync` is now wrapped in try/catch. Disk/permission errors immediately mark the pipeline `FAILED` instead of leaving it stuck in `RUNNING` indefinitely.
- **Dead `STEP_ORDER` array removed** — Unused constant in `safetyController.ts` replaced by the authoritative `switch` statement.
- **`'evaluation_result' as any`** — Invalid event type replaced with the correct `'learning'` literal for the experience ledger call.
- **SQLite backfill migration** — `ALTER TABLE DEFAULT` only applies to new inserts; existing rows now explicitly have `eval_revisions = 0` set via a `WHERE eval_revisions IS NULL` backfill `UPDATE`.
- **Supabase `listPipelines` parity** — `contract_payload` was missing JSON deserialization in `listPipelines`. Fixed to match the behavior of `getPipeline`.

### Storage Schema (v7.4.0 migration)
- New columns on `dark_factory_pipelines`: `eval_revisions INTEGER DEFAULT 0`, `contract_payload TEXT`, `notes TEXT`
- Supabase: same columns via `prism_apply_ddl` RPC
- SQLite backfill: `UPDATE ... SET eval_revisions = 0 WHERE eval_revisions IS NULL`

### Engineering
- 978 tests across 44 suites (78 new adversarial evaluation tests), all passing, zero regressions
- TypeScript: clean, zero errors
- 10 files changed, +1027 / -73

---

## [7.0.0] - 2026-04-01

### Added
- **ACT-R Activation Memory** — Scientifically-grounded memory retrieval based on Anderson's ACT-R cognitive architecture. Base-level activation `B_i = ln(Σ t_j^{-d})` replaces flat similarity search with recency × frequency scoring that mirrors human cognitive decay. Memories accessed recently and frequently surface first; stale context fades naturally.
- **Candidate-Scoped Spreading Activation** — Activation spreads only within the current search result set, preventing "God node" centrality bias where highly-connected nodes dominate every query regardless of relevance.
- **Composite Scoring** — `0.7 × similarity + 0.3 × σ(activation)` blends semantic relevance with cognitive activation. Sigmoid normalization keeps activation in `[0,1]` regardless of access pattern. Weights configurable via `PRISM_ACTR_WEIGHT_SIMILARITY` / `PRISM_ACTR_WEIGHT_ACTIVATION`.
- **Verification Operator Contract & JSON Modes** — `verify status` and `verify generate` now fully support `--json` output modes providing strict schema adherence (`schema_version: 1`). Integrations guarantees deterministic exit codes (`0` for passing/warning/bypassed, `1` for blocked drift).
- **AccessLogBuffer** — In-memory batch-write buffer with 5-second flush window resolves `SQLITE_BUSY` contention during parallel multi-agent tool calls. Registered with `BackgroundTaskRegistry` for graceful shutdown — no orphaned writes on `SIGTERM`.
- **Zero Cold-Start** — Memory creation now seeds an initial access log entry. New memories are immediately rankable without a warm-up period.
- **Supabase Migration 037** — `actr_access_log` table + RPC functions for access log writes and activation computation. Full feature parity with SQLite backend.
- **5 New Environment Variables** — `PRISM_ACTR_ENABLED` (default: `true`), `PRISM_ACTR_DECAY` (default: `0.5`), `PRISM_ACTR_WEIGHT_SIMILARITY` (default: `0.7`), `PRISM_ACTR_WEIGHT_ACTIVATION` (default: `0.3`), `PRISM_ACTR_ACCESS_LOG_RETENTION_DAYS` (default: `90`).

### Changed
- **Cognitive Memory Pipeline** — `cognitiveMemory.ts` refactored to integrate ACT-R activation scoring into the retrieval pipeline. When `PRISM_ACTR_ENABLED=true`, search results are re-ranked with composite scores; when disabled, falls back to pure similarity.
- **Tracing Integration** — OpenTelemetry spans added for ACT-R activation computation, access log writes, and buffer flushes.

### Documentation
- **README Overhaul** — Added "Mind Palace" terminology definition, promoted Universal Import to top-level section, added Quick Start port-conflict collapsible, added "Recommended Minimal Setup" TL;DR for environment variables, updated dashboard screenshot to v7.0.0, added dashboard-runs-in-background reassurance.
- **ROADMAP** — v7.0.0 entry with full ACT-R feature table. "State of Prism" updated to v7.0.0. Future tracks bumped to v8.x/v9+.

### Architecture
- New file: `src/utils/actrActivation.ts` — 250 lines. ACT-R base-level activation, sigmoid normalization, composite scoring.
- New file: `src/utils/accessLogBuffer.ts` — 199 lines. In-memory batch-write buffer with 5s flush, `BackgroundTaskRegistry` integration.
- New migration: `supabase/migrations/037_actr_access_log_parity.sql` — 121 lines. Access log table, RPC functions, retention cleanup.
- Extended: `src/storage/sqlite.ts` — Access log table creation, write/query methods, retention sweep.
- Extended: `src/storage/supabase.ts` — Access log RPC calls, activation computation.
- Extended: `src/tools/graphHandlers.ts` — ACT-R activation integration in search handler.
- Extended: `src/utils/cognitiveMemory.ts` — Composite scoring pipeline with ACT-R re-ranking.
- Extended: `src/utils/tracing.ts` — ACT-R span instrumentation.

### Engineering
- 705 tests across 32 suites (49 new ACT-R tests), all passing, zero regressions
- New file: `tests/utils/actr-activation.test.ts` — 695 lines covering activation math, buffer flush, cold-start seeding, SQLite/Supabase parity, decay parameter edge cases
- TypeScript strict mode: zero errors

---

## [6.5.3] - 2026-04-01

### Added
- **Dashboard Auth Test Suite** — 42 new tests (`tests/dashboard/auth.test.ts`) covering the entire auth system: `safeCompare` timing-safety, `generateToken` entropy, `isAuthenticated` cookie/Basic Auth flows, `createRateLimiter` sliding window, and full HTTP integration tests for login, logout, auth gate, rate limiting, and CORS.
- **Rate Limiting** — `POST /api/auth/login` is now protected by a sliding-window rate limiter (5 attempts per 60 seconds per IP). Resets on successful login. Stale entries are auto-pruned to prevent memory leaks.
- **Logout Endpoint** — `POST /api/auth/logout` invalidates the session token server-side (deletes from `activeSessions` map) and clears the client cookie via `Max-Age=0`.
- **Auth Utilities Module** — Extracted `safeCompare`, `generateToken`, `isAuthenticated`, and `createRateLimiter` from `server.ts` closures into `src/dashboard/authUtils.ts` for testability and reuse.

### Security
- **CORS Hardening** — When `AUTH_ENABLED`, `Access-Control-Allow-Origin` is now set dynamically to the request's `Origin` header (not wildcard `*`), and `Access-Control-Allow-Credentials: true` is sent. Wildcard `*` is only used when auth is disabled.
- **Cryptographic Token Generation** — `generateToken()` now uses `crypto.randomBytes(32).toString("hex")` instead of `Math.random()` for session tokens.
- **Colon-Safe Password Parsing** — Basic Auth credential extraction now uses `indexOf(":")` instead of `split(":")` to correctly handle passwords containing colon characters.

### Engineering
- 42 new auth tests (unit + HTTP integration), zero regressions in existing 14 dashboard API tests
- New file: `src/dashboard/authUtils.ts` — extracted pure functions with injectable `AuthConfig`
- New file: `tests/dashboard/auth.test.ts` — 5 describe blocks, 42 test cases

---

## [6.5.2] - 2026-04-01

### Engineering
- **SDM/HDC Edge-Case Test Hardening** — 37 new tests (571 → 608 total) covering critical boundary conditions across the cognitive routing pipeline:
  - **HDC Engine** — Bind length mismatch rejection, empty bundle handling, single-vector identity, XOR self-inverse property, permute empty/single-word edge cases, density preservation invariant.
  - **PolicyGateway** — All 4 constructor rejection paths, exact-at-threshold boundary routing (0.85 → CLARIFY, 0.95 → AUTO_ROUTE), null-concept override behavior.
  - **StateMachine** — Constructor/transition dimension guards, defensive cloning, `injectStateForTesting` guard, initial-state immutability.
  - **SDM Engine** — Hamming identity/complement properties, reverse mode cross-talk isolation, write/read dimension guards, k=0 boundary, `importState` guard, `exportState` → `importState` lossless roundtrip.

---

## [6.5.1] - 2026-04-01

### Fixed
- **Dashboard Project Selector Bootstrap Failure** — Resolved a startup failure where `/api/projects` returned errors and the selector remained stuck on "Loading projects..." when `SUPABASE_URL`/`SUPABASE_KEY` were unresolved template placeholders (e.g. `${SUPABASE_URL}`).
- **Storage Backend Fallback Safety** — Added runtime guardrails to automatically fall back to local SQLite storage when Supabase is requested but env configuration is invalid/unresolved, preventing dashboard hard-failure in mixed/local setups.

### Changed
- **Config Sanitization** — Added Supabase env sanitization and URL validation to ignore unresolved placeholder strings and invalid non-http(s) values.

### Release Process
- Delivered as a **single pull request** post-publish hardening pass to keep code + docs + release notes aligned in one review artifact.

---

## [6.5.0] - 2026-04-01

### Added
- **HDC Cognitive Routing** — New `session_cognitive_route` MCP tool composes an agent's current state, role, and action into a single 768-dim binary hypervector via XOR binding, resolves it to a semantic concept via Hamming distance, and routes through a three-outcome policy gateway (`direct` / `clarify` / `fallback`). Powered by `ConceptDictionary`, `HdcStateMachine`, and `PolicyGateway` in `src/sdm/`.
- **Per-Project Threshold Overrides** — Fallback and clarify thresholds are configurable per-project via tool arguments and persisted via `getSetting()`/`setSetting()`. **Phase 2 storage-parity scope note:** No new storage migrations are required — the existing `prism_settings` key-value table already abstracts SQLite/Supabase parity. Threshold values are stored as decimal strings (e.g., `"0.45"`) and parsed back to `Number` on read.
- **Explainability Mode** — When `explain: true`, responses include `convergence_steps`, raw `distance`, and `ambiguity` flag. Controlled by `PRISM_HDC_EXPLAINABILITY_ENABLED` (default: `true`).
- **Cognitive Observability** — `recordCognitiveRoute()` in `graphMetrics.ts` tracks 14 cognitive metrics: total routes, route distribution (direct/clarify/fallback), rolling confidence/distance averages, ambiguity count, null-concept count, and last-route timestamp. Warning heuristics fire when `fallback_rate > 30%` or `ambiguous_resolution_rate > 40%`.
- **Dashboard Cognitive Card** — Route distribution bar, confidence/distance gauges, and warning badges in the Mind Palace metrics panel (ES5-safe). On-demand "Cognitive Route" button in the Node Editor panel.
- **Dashboard API Endpoint** — `GET /api/graph/cognitive-route` in `graphRouter.ts` exposes the handler for dashboard consumption with query parameter parsing (project, state, role, action, thresholds, explain).

### Architecture
- New tool: `session_cognitive_route` — `src/tools/graphHandlers.ts` (`sessionCognitiveRouteHandler`)
- New API route: `GET /api/graph/cognitive-route` — `src/dashboard/graphRouter.ts`
- Extended: `src/observability/graphMetrics.ts` — `CognitiveMetrics` interface, `recordCognitiveRoute()`, cognitive warning heuristics
- Extended: `src/dashboard/ui.ts` — Cognitive metrics card, cognitive route button (ES5-safe)
- Config: `PRISM_HDC_ENABLED` (default: `true`), `PRISM_HDC_EXPLAINABILITY_ENABLED` (default: `true`)

### Fixed
- **Dashboard `triggerTestMe` Regression** — Restored `async function triggerTestMe()` declaration that was stripped during v6.5 code insertion. Removed duplicate `cognitiveRouteBtn` DOM block (duplicate IDs). Restored `testMeContainer` div in panel flow.

### Engineering
- 566 tests across 30 suites (all passing, zero regressions)
- 42 new tests: 26 handler integration tests (`tests/tools/cognitiveRoute.test.ts`) + 16 dashboard API tests (`tests/dashboard/cognitiveRoute.test.ts`)
- TypeScript strict mode: zero errors

---


## [6.2.1] - 2026-04-01

### Fixed
- **Dashboard ES5 Compatibility** — Refactored all inline `<script>` code in the Mind Palace dashboard to strict ES5 syntax. Replaced `const`/`let`, arrow functions, optional chaining (`?.`), and template literals with ES5 equivalents (`var`, `function` expressions, manual null checks, string concatenation). Fixes `SyntaxError: Unexpected identifier 'block'` that prevented the dashboard from initializing in certain browser environments.
- **Compatibility Rule Enforcement** — Added a mandatory ES5-only compatibility comment block at the top of the inline `<script>` tag to prevent future regressions.

### Engineering
- 510 tests across 28 suites (all passing)
- TypeScript strict mode: zero errors

---

## [6.2.0] - 2026-03-31

### Added
- **Edge Synthesis ("The Dream Procedure")** — Automated background linker (`session_synthesize_edges`) discovers semantically similar but disconnected memory nodes via cosine similarity (threshold ≥ 0.7). Batch-limited to 50 sources × 3 neighbors per sweep to prevent runaway graph growth.
- **Graph Pruning (Soft-Prune)** — Configurable strength-based pruning (`PRISM_GRAPH_PRUNING_ENABLED`) soft-deletes weak links below a configurable minimum strength. Includes per-project cooldown, backpressure guards, and sweep budget controls.
- **SLO Observability Layer** — `graphMetrics.ts` module tracks synthesis success rate, net new links, prune ratio, and sweep duration. Exposes `slo` and `warnings` fields for proactive health monitoring.
- **Dashboard Metrics Integration** — New SLO cards, warning badges, and pruning skip breakdown (backpressure / cooldown / budget) in the Mind Palace dashboard at `/api/graph/metrics`.
- **Temporal Decay Heatmaps** — UI overlay toggle where un-accessed nodes desaturate while Graduated nodes stay vibrant. Graph router extraction + decay view toggle.
- **Active Recall Prompt Generation** — "Test Me" utility in the node editor panel generates synthetic quizzes from semantic neighbors for knowledge activation.
- **Supabase Weak-Link RPC (WS4.1)** — New `prism_summarize_weak_links` Postgres function (migration 036) aggregates pruning server-side in one RPC call, eliminating N+1 network roundtrips. TypeScript fast-path with automatic fallback.
- **Migration 035** — Tenant-safe graph writes + soft-delete hardening for MemoryLinks.

### Fixed
- **Scheduler `projects_processed` Semantics** — Now tracks all attempted projects, not just successes, for accurate SLO derivation.
- **Router Integration Test** — Added `GET /api/graph/metrics` integration test to validate the full metrics pipeline.
- **Export Test Mock Staleness** — Added missing `PRISM_GRAPH_PRUNE*` config exports to `sessionExportMemory.test.ts` mock (transitive import fix).
- **Dashboard `const` in Switch** — Fixed `const` declaration in switch-case scope (`pruneSkipParts`) that caused strict-mode errors in some browsers.

### Architecture
- New module: `src/observability/graphMetrics.ts` — in-memory metrics with SLO derivation and warning heuristics.
- New migration: `supabase/migrations/036_prune_summary_rpc.sql` — server-side aggregate RPC.
- Extended: `src/backgroundScheduler.ts` — synthesis telemetry, pruning telemetry, sweep duration recording.
- Extended: `src/dashboard/graphRouter.ts` — `GET /api/graph/metrics` endpoint.
- Extended: `src/dashboard/ui.ts` — SLO cards, warning badges, pruning breakdown.

### Engineering
- 510 tests across 28 suites (all passing)
- TypeScript strict mode: zero errors

---

## [6.1.9] - 2026-03-31

### Added
- **Tavily Support** — Added `@tavily/core` integration as a robust alternative to Brave + Firecrawl for the Web Scholar pipeline. Supports `performTavilySearch` and `performTavilyExtract`.

### Fixed
- **Tavily Chunking & Error Handling** — Implemented URL array chunking (batches of 20 URLs) for `performTavilyExtract` to bypass API limits and prevent data loss.
- **Upstream Network Resilience** — `performTavilySearch` is wrapped in a `try...catch` block to cleanly return empty arrays on API failure/timeout, avoiding unhandled promise rejections.

---

## [6.1.8] - 2026-03-30

### Fixed
- **Missing Type Guard** — Added `isSessionCompactLedgerArgs` for `SESSION_COMPACT_LEDGER_TOOL`. The tool existed with no corresponding guard; an LLM hallucinating `{threshold: "many"}` would reach the handler unchecked.
- **Array Field Validation** — `isSessionSaveLedgerArgs` now validates `todos`, `files_changed`, and `decisions` with `Array.isArray`, preventing string coercion into array-typed fields.
- **Enum Literal Guard** — `isSessionExportMemoryArgs` now rejects `format` values outside the literal union `'json' | 'markdown' | 'vault'` at the MCP boundary.
- **Numeric Guards** — `isSessionIntuitiveRecallArgs` now validates `limit` and `threshold` as `typeof number`, blocking `{limit: "many"}` style coercion.
- **Legacy Guard Migration** — `isMemoryHistoryArgs`, `isMemoryCheckoutArgs`, `isSessionSaveImageArgs` migrated to the uniform `Record<string, unknown>` pattern. `isMemoryHistoryArgs` also gains a missing `limit` number check.

---

## [6.1.7] - 2026-03-30

### Fixed
- **Toggle Persistence** — `saveSetting()` now returns `Promise<boolean>` and UI toggles (Hivemind, Auto-Capture) roll back their optimistic state on server failure.
- **Cache-Busting** — `loadSettings()` appends `?t=<timestamp>` to bypass stale browser/service-worker caches.
- **HTTP Error Propagation** — Explicit 4xx/5xx detection in `saveSetting()` surfaces toast notifications to the user on failed saves.

---

## [6.1.6] - 2026-03-30

### Fixed
- **Type Guard Hardening (Round 1)** — Audited and refactored 11 MCP tool argument type guards to include explicit `typeof` validation for all optional fields. Prevents LLM-hallucinated payloads from causing runtime type coercion errors in handlers.

---

## [6.1.5] - 2026-03-30

### Added
- **`maintenance_vacuum` Tool** — New MCP tool to run `VACUUM` on the local SQLite database after large purge operations, reclaiming page allocations that SQLite retains until explicitly vacuumed.

### Fixed
- **Prototype Pollution Guards** — CRDT merge pipeline hardened against `__proto__` / `constructor` injection via `Object.create(null)` scratchpads.

### Tests
- **425-test Edge-Case Suite** — Added comprehensive tests across 20 files covering CRDT merges, TurboQuant mathematical invariants, prototype pollution guards, and SQLite retention TTL boundary conditions.

---

## [6.1.0] - 2026-03-30

### Added
- **Smart Memory Merge UI (Knowledge Gardening)**: Integrated a dynamic dropdown directly into the graph's `nodeEditorPanel`. Users can now instantly merge duplicate or fragmented keywords directly from the UI without backend refactoring.
- **Deep Purge Visualization (Memory Density)**: Added an intuitive "Memory Density" analytical stat within the `schedulerCard`. This zero-overhead metric visualizes the ratio of standard insights versus highly-reinforced (Graduated) ideas, rendering immediate feedback on the project's learning efficiency.
- **Semantic Search Highlighting**: Re-engineered the payload rendering for vector results to utilize a RegEx-powered match engine. Found context fragments dynamically wrap exact keyword matches in a vibrant `<mark>` tag, instantly explaining *why* a vector was pulled.

---

## [6.0.0] - 2026-03-29

### Added
- **Context-Boosted Vector Search**: Intelligent API param `context_boost` biases semantic queries by organically injecting current handoff state/working context into the embedding model alongside user queries.
- **AbortController Concurrency Safety**: Hardened the UI `performSearch` loop to elegantly cancel in-flight API requests during rapid debounce typing.

---

## [5.4.0] - 2026-03-28
- **CRDT Handoff Merging**: Replaced strict OCC rejection with automatic conflict-free multi-agent state merging. When two agents save concurrently, Prism now auto-merges instead of rejecting.
  - Custom OR-Map engine (`crdtMerge.ts`): Add-Wins OR-Set for arrays (`open_todos`), Last-Writer-Wins for scalars (`last_summary`, `key_context`).
  - 3-way merge with `getHandoffAtVersion()` base retrieval from SQLite and Supabase.
  - `disable_merge` bypass parameter for strict OCC when needed.
  - `totalCrdtMerges` tracked in health stats and dashboard.
- **Background Purge Scheduler**: Unified automated maintenance system that replaces all manual storage management.
  - Single `setInterval` loop (default: 12 hours, configurable via `PRISM_SCHEDULER_INTERVAL_MS`).
  - 4 maintenance tasks: TTL sweep, Ebbinghaus importance decay, auto-compaction, deep storage purge.
  - Dashboard status card with last sweep timestamp, duration, and per-task results.
  - `PRISM_SCHEDULER_ENABLED` env var (default: `true`).
- **Autonomous Web Scholar**: Agent-driven background research pipeline.
  - Brave Search → Firecrawl scrape → LLM synthesis → Prism ledger injection.
  - Task-aware topic selection: biases research toward active Hivemind agent tasks.
  - Reentrancy guard prevents concurrent pipeline runs.
  - 15K character content cap per scraped article for cost control.
  - Configurable: `PRISM_SCHOLAR_ENABLED`, `PRISM_SCHOLAR_INTERVAL_MS`, `PRISM_SCHOLAR_TOPICS`, `PRISM_SCHOLAR_MAX_ARTICLES_PER_RUN`.
- **Scholar ↔ Hivemind Integration**: Scholar registers as `scholar` role agent with lifecycle heartbeats at each pipeline stage. Telepathy broadcast fires on completion to notify active agents. Task-aware topic selection biases research toward topics matching active agent tasks.
- **Updated Architecture Documentation**: 3 new sections in `docs/ARCHITECTURE.md` covering Agent Hivemind, Background Scheduler, and Web Scholar with mermaid diagrams.

### Architecture
- New module: `src/scholar/webScholar.ts` — 281 lines, full pipeline with Hivemind integration.
- New module: `src/crdtMerge.ts` — OR-Map engine with 3-way merge algorithm.
- Extended: `src/backgroundScheduler.ts` — unified maintenance + Scholar scheduling.
- Storage interface: `getHandoffAtVersion()` for CRDT base retrieval.

### Engineering
- 362 tests across 16 suites (10 new Scholar tests)
- Clean TypeScript build, zero errors
- Backward compatible: all new features are opt-in via env vars

---

## [5.3.0] - 2026-03-28

### Added
- **Hivemind Health Watchdog**: Server-side active monitoring system for multi-agent coordination. Transforms the Hivemind from a passive registry into a self-healing orchestrator.
  - **State Machine**: Agents transition through `ACTIVE → STALE (5m) → FROZEN (15m) → OFFLINE (30m, auto-pruned)` based on heartbeat freshness.
  - **OVERDUE Detection**: Agents can declare `expected_duration_minutes` on heartbeat. If the task exceeds this ETA, the Watchdog flags the agent as OVERDUE.
  - **Loop Detection**: DJB2 hash of `current_task` is computed on every heartbeat. If the same task repeats ≥5 times consecutively, the agent is flagged as LOOPING. Detection runs inline in the heartbeat hot path (~0.01ms overhead).
  - **Telepathy (Alert Injection)**: Watchdog alerts are appended **directly to `result.content[]`** of tool responses, bypassing MCP's `sendLoggingMessage` limitation where LLMs don't read debug logs. This guarantees the LLM reads the alert in its reasoning loop.
  - **Configurable Thresholds**: All thresholds configurable via env vars (`PRISM_WATCHDOG_INTERVAL_MS`, `PRISM_WATCHDOG_STALE_MIN`, `PRISM_WATCHDOG_FROZEN_MIN`, `PRISM_WATCHDOG_OFFLINE_MIN`, `PRISM_WATCHDOG_LOOP_THRESHOLD`).
- **`expected_duration_minutes` parameter**: New optional parameter on `agent_heartbeat` tool for task ETA declarations.
- **Health-State Dashboard**: Hivemind Radar now shows color-coded health indicators (🟢/🟡/🔴/⏰/🔄), loop count badges, and auto-refreshes every 15 seconds.
- **`getAllAgents()` / `updateAgentStatus()`**: New storage backend methods for cross-project agent sweeps and whitelist-guarded status transitions.
- **Supabase Migration 032**: `task_start_time`, `expected_duration_minutes`, `task_hash`, `loop_count` columns + user_id index.

### Architecture
- New module: `src/hivemindWatchdog.ts` — 270 lines of pure business logic, zero MCP Server dependency, fully testable in isolation.
- Alert queue: In-memory `Map<string, WatchdogAlert>` with dedup key `project:role:status` — fire-and-forget, no persistence needed.
- Dual-mode alerting: Direct content injection (primary, for LLMs) + `sendLoggingMessage` (secondary, for operators).
- Graceful degradation: All sweep errors are caught and logged, never crash the server. `PRISM_ENABLE_HIVEMIND` gate prevents any CPU overhead for single-agent users.

### Engineering
- 10 files changed, ~600 lines added
- Clean TypeScript build, zero errors
- Backward compatible: all new columns have defaults, watchdog is no-op without `PRISM_ENABLE_HIVEMIND=true`

---

## [5.2.0] - 2026-03-27

### Added
- **Cognitive Memory — Ebbinghaus Importance Decay**: Entries now have `last_accessed_at` tracking. At retrieval time, `effective_importance = base × 0.95^days` computes a time-decayed relevance score. Frequently accessed memories stay prominent; neglected ones fade naturally.
- **Context-Weighted Retrieval** (`context_boost` parameter): When enabled on `session_search_memory`, the active project's branch, keywords, and context are prepended to the search query before embedding generation — naturally biasing the vector toward contextually relevant results.
- **Smart Consolidation**: Enhanced the `session_compact_ledger` prompt to extract recurring principles and patterns alongside summaries, producing richer rollup entries.
- **Universal History Migration**: Modular migration utility using the Strategy Pattern. Ingest historical sessions from Claude Code (JSONL streaming), Gemini (OOM-safe StreamArray), and OpenAI/ChatGPT (JSON) into the Mind Palace.
  - **Conversation Grouping**: Turns are grouped into logical conversations using a 30-minute time-gap heuristic. A 100MB file with 200 conversations → 200 summary entries (not 50,000 raw turns).
  - **Idempotent Deduplication**: Each conversation gets a deterministic ID. Re-running the same import is a no-op.
  - **Dashboard Import UI**: File picker (📂 Browse) + manual path input, auto-format detection, real-time result display.
  - Features `p-limit(5)` concurrency control and `--dry-run` support.

### Security
- **SQL Injection Prevention**: Added 17-column allowlist to `patchLedger()` in SQLite storage. Dynamic column interpolation now rejects any column not in the allowlist.

### Fixed
- **Supabase DDL v31**: Added missing `last_accessed_at` column migration for Supabase users. Without this, the Ebbinghaus decay logic would have thrown a column-not-found error.
- **context_boost guard**: Now logs a warning and continues gracefully when `context_boost=true` is passed without a `project` parameter, instead of silently failing.
- **Redundant getStorage() call**: Removed duplicate storage initialization in the Ebbinghaus decay block.
- **README dead link**: Fixed `#supabase-setup` anchor (inside `<details>` blocks, GitHub doesn't generate anchors).

### Engineering
- 9 new migration tests (adapter parsing, conversation grouping, dedup, tool keyword preservation)
- 352 tests across 15 suites
- 17 files changed, +1,016 lines

---

## [5.1.0] - 2026-03-27
### Added
- **Deep Storage Mode**: New `deep_storage_purge` tool to reclaim ~90% of vector storage by dropping float32 vectors for entries with TurboQuant compressed blobs.
- **Knowledge Graph Editor**: Transformed the Mind Palace Neural Graph into an interactive editor with dynamic filtering, node renaming, and surgical keyword deletion.
### Fixed
- **Auto-Load Reliability**: Hardened auto-load prompt instructions and added hook scripts for Claude Code / Antigravity to ensure memory is loaded on the first turn (bypassing model CoT hallucinations).
### Engineering
- 303/303 automated tests passing across 13 suites.

## 🚀 v5.0.0 — The TurboQuant Update (2026-03-26)

**Quantized Agentic Memory is here.**

### ✨ Features

- **10× Storage Reduction:** Integrated Google's TurboQuant algorithm (ICLR 2026) to compress 768-dim embeddings from 3,072 bytes to ~400 bytes. Zero external dependencies — pure TypeScript math core with Householder QR, Lloyd-Max scalar quantization, and QJL residual correction.
- **Two-Tier Search:** Introduced a JS-land asymmetric similarity search fallback (`asymmetricCosineSimilarity`), ensuring semantic search works even without native DB vector extensions (`sqlite-vec` / `pgvector`).
- **Atomic Backfill:** Optimized background workers to repair and compress embeddings in a single atomic database update (`patchLedger`), reducing lock contention for multi-agent Hivemind use cases.
- **Supabase Parity:** Full support for quantized blobs in the cloud backend (migration v29 + `saveLedger` insert).

### 🏗️ Architecture

- New file: `src/utils/turboquant.ts` — 665 lines, zero-dependency math core
- Storage schema: `embedding_compressed` (TEXT/base64), `embedding_format` (turbo3/turbo4/float32), `embedding_turbo_radius` (REAL)
- SQLite migration v5.0 (3 idempotent ALTER TABLE)
- Supabase migration v29 via `prism_apply_ddl` RPC

### 📊 Benchmarks

| Metric | Value |
|--------|-------|
| Compression ratio (d=768, 4-bit) | **~7.7:1** (400 bytes vs 3,072) |
| Compression ratio (d=768, 3-bit) | **~10.1:1** (304 bytes vs 3,072) |
| Similarity correlation (4-bit) | >0.85 |
| Top-1 retrieval accuracy (N=100) | >90% |
| Tests | 295/295 pass |

### 📚 Documentation

- Published RFC-001: Quantized Agentic Memory (`docs/rfcs/001-turboquant-integration.md`)

---

## v4.6.1 — Stability (2026-03-25)

- Fixed auto-load reliability for `session_load_context` tool
- Dashboard project dropdown freeze resolved

## v4.6.0 — Observable AI (2026-03-25)

- OpenTelemetry distributed tracing integration
- Visual Language Model (VLM) image captioning
- Mind Palace dashboard improvements

## v4.3.0 — IDE Rules Sync (2026-03-25)

- `knowledge_sync_rules` tool: graduated insights → `.cursorrules` / `.clauderules`
- Sentinel-based idempotent file writing

## v4.0.0 — Behavioral Memory (2026-03-24)

- Active Behavioral Memory with experience events
- Importance scoring and graduated insights
- Pluggable LLM providers (OpenAI, Anthropic, Gemini, Ollama)

## v3.0.0 — Hivemind (2026-03-23)

- Multi-agent role-based scoping
- Team roster injection on context load

## v2.0.0 — Time Travel (2026-03-22)

- Version-controlled handoff snapshots
- `memory_history` + `memory_checkout` tools
- Visual memory (image save/view)

## v1.0.0 — Foundation (2026-03-20)

- Session ledger with keyword extraction
- Handoff state persistence
- SQLite + Supabase dual backends
- Semantic search via pgvector / sqlite-vec
- GDPR export and surgical deletion
