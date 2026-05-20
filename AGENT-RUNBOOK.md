# Agent runbook — browxai

> Hand this doc to an MCP-capable coding agent (Claude Code, Codex, anything that drives the
> filesystem + a shell + git). It explains what browxai ships today, what's still open, the
> rules that constrain you, and what "done" looks like for the open items.
>
> **You are the agent.** This document addresses you in the second person.
>
> **What browxai is:** a general-purpose, MCP-native, model-agnostic autonomous-browser
> control server. It owns its Playwright/CDP transport and exposes a curated, token-efficient
> tool surface (`snapshot` / `find` / action primitives with structured `ActionResult`s) for
> *any* agent driving *any* website — autonomous task execution, multi-session/multi-user
> scenarios, canvas/WebGL apps, form-heavy SPAs. site-docs's calibration loop is **one
> consumer**, not the assumed one; where this doc uses it as an example, that's all it is.
>
> Repo: `kalebteccom/browxai` (private; MIT; will go public per the spec's 4-condition trigger
> in Phase 3). Canonical design lives in the portfolio repo `kalebteccom/project-ideas` →
> `projects/agent-browser-bridge/` (`spec.md`, `roadmap.md`, `progress.md`). When this repo's
> docs conflict with the portfolio, the portfolio wins — fix the conflict in *both*.

## Status at a glance (2026-05-18)

- **Phase 0** — closed 2026-05-13. Design + divergence notes + lifecycle port-plan + repo skeleton.
- **Phase 1** — closed 2026-05-15 by a real adoption run on a heavy-SPA authed target.
- **Phase 1.5** — shipped 2026-05-15. 17 of 19 backlog asks landed in one cycle.
- **Phase 2** — code-side complete. Rounds 5/6/8 shipped 2026-05-15; the non-Claude-consumer
  verification leg is **MET** (Codex drove a real authed SPA end-to-end, "gappy green").
- **Phase 2.5** — session & config architecture, opened 2026-05-18. Shipped: config substrate
  (MCP-driven `get/set/reset_config`, env demoted to legacy), session registry (per-session
  isolated state, `session` arg on every tool, `open/close/list_session`), session modes
  (persistent / incognito / attached). Remaining: general-driving defaults + this docs pass.
- **Phase-2 close** — **MET 2026-05-19.** The headless-CI keystone landed
  (`test/keystone/headless.keystone.test.ts`, `pnpm test:keystone`, isolated CI job) and is
  green end-to-end against a real headless Chromium: the six non-trivial primitives, the
  MCP-driven config model (zero `BROWX_*` config env), two-user cookie-jar isolation, and
  incognito no-trace — also closing the three `[~]` Phase-2.5 exit criteria. `await_human` /
  the `__browx` visual banner are the documented headless gap (human-in-the-loop by design).
- **Phase 3** — public release. Gated on the 4-condition trigger in the spec.

The full chronology lives in the portfolio's `projects/agent-browser-bridge/progress.md`.

## Sessions & config (Phase 2.5 — read this before driving)

- **Every browser-touching tool takes an optional `session` id** (default `"default"`).
  Distinct ids are fully isolated browser contexts (own cookie jar, own refs, own buffers).
  Omitting it is byte-identical to the old single-session behaviour.
  - Multiple agents on one server → give each its own `session`; they can't collide (no
    server-global "active session").
  - Multi-user / multiplayer → different users go in different sessions; cookie jars don't bleed.
  - `open_session({ session, mode?, profile? })` / `close_session` / `list_sessions`.
    `mode ∈ persistent | incognito | attached`.
- **Config is MCP-driven** — no env vars, no hand-edited files required. `get_config` /
  `set_config({ scope:"user"|"project", patch })` / `reset_config`. Precedence:
  `defaults < env(legacy) < user < project < session`. `BROWX_*` still work as a documented
  legacy layer; `BROWX_WORKSPACE` is a *location* anchor, not config.

## What's shipped (current tool surface)

Tool surface listed in **`docs/tool-reference.md`** — read that for the per-tool input/output
shapes. The headline pieces:

**Read tools:**

- **`snapshot`** — compact a11y-tree dump augmented by a DOM-walk pass (so heavy-SPA targets
  whose accessibility tree is sparse still surface their interactive elements). Optional
  `scope: <ref>` / `maxNodes: N` / `omit: ["pattern", …]` for token-cheap subsetting.
  Stable `[ref=eN]` refs persist across snapshots within a session.
- **`find`** — ranked candidate locators for a natural-language query, with `selectorHint`,
  `stability ∈ "high"|"medium"|"low"`, visible-rect `bbox`, and `actionable ∈ true|"disabled"|
  "off-screen"|"covered"`. Optional `contextRef` / `confidenceFloor`. Test-attribute
  selectorHints carry the *matched attribute name* (e.g. `[data-type="…"]`, not hardcoded
  `[data-testid="…"]`).
- **`screenshot`** — viewport or element-cropped PNG; pass `describe: true` for a structured
  one-line caption alongside the image.
- **`console_read`** — recent console messages (ring buffer; per-action attribution lives in
  `ActionResult.console`).
- **`network_read`** — session-wide ring buffer of recent network requests (cap 500;
  per-action attribution in `ActionResult.network`).

**Action tools** (each emits a structured `ActionResult` with `navigation` / `structure` /
`console` / `pageErrors` / `element` / `snapshotDelta` / `network`):

- **`navigate({ url, mode?, maxResultTokens? })`** — gated by `BROWX_ALLOWED_ORIGINS` (if set)
  + the `navigate_off_allowlist` confirm hook.
- **`click` / `fill` / `press` / `hover` / `select` / `wait_for`** — accept exactly one of
  `ref` / `selector` / `named` (see "Named refs" below). Each does an action-window pre/post
  diff (a11y tree, structure changes, console errors, network) and emits the structured
  result. `wait_for.timeoutMs` cap: 600 000 ms.
- **`go_back` / `go_forward`** — history navigation.

**Helpers:**

- **`await_human({ kind, prompt, choices?, timeoutMs? })`** — block until the human responds
  in the page. Kinds: `acknowledge` (call `__browx.proceed()`), `confirm` (`__browx.confirm(true|false)`),
  `choose` (`__browx.choose(<index>)`), `input` (`__browx.input("text")`). `pick_element` is
  still deferred (needs an in-page hover-pick overlay).
- **`name_ref({ name, ref })`** + **`list_named_refs()`** — bind a mnemonic to a ref;
  subsequent actions accept `named: "<name>"` in place of `ref` / `selector`.
- **`find_feedback({ query, ref })`** — session-scoped learned ranking. Tells browxai which
  candidate was right; subsequent finds with overlapping token sets boost matching candidates.
- **`start_recording({ flowName })` / `end_recording()` / `record_annotate({ copy, arrow?, … })`** —
  record action calls during a calibration walk; `end_recording` emits a draft flow-file YAML
  (site-docs-flavoured) with a locators block + steps with selectorHint-derived targets.
- **`eval_js({ expr, returnType })`** — escape-hatch JS evaluation in the page's main frame.
  **Off by default** (the `eval` capability isn't in `DEFAULT_CAPABILITIES`); the return
  value is page-controlled and tagged untrusted.

**CLI subcommands** (run via `pnpm browxai <sub>` or the `browxai` bin):

- **`browxai doctor`** — environment & connectivity health-check (build / workspace /
  test-attrs / cdp-attach reachability / chromium binary / capabilities / confirm-hooks /
  origins). One-line fixes per ✗.
- **`browxai chrome [start|stop|status]`** — owns the `--cdp` Chrome lifecycle. `start`
  uses persistent profile at `$BROWX_WORKSPACE/chrome-profile/`; `--insecure` opts into
  `--disable-web-security` (use only against test/dev targets).
- **`browxai init <workspace>`** — bootstrap a per-consumer workspace: creates
  `<workspace>/.browxai/`, writes a workspace-scope `.mcp.json` with both managed +
  attached MCP entries, sniffs the codebase for the dominant test-attribute convention.

## The unstable tool lane (W-Q7–Q11)

A second tier of tools — heavier media-editor / race-condition QA primitives — ships behind
the off-by-default **`unstable`** capability. They are **explicitly experimental** and **not
part of the v0.1.0 frozen stable surface** (see `docs/tool-reference.md` "Stability &
semver"): their shapes may change or vanish in any release, and a round that only touches
this lane does not reset the Phase-3 API-stability clock.

**What's in it** (per-tool shapes in `docs/tool-reference.md` "Unstable tools"):

- **Pointer gestures** — `drag`, `double_click`, `mouse_down` / `mouse_move` / `mouse_up`.
- **Network route mocking** — `route`, `route_queue` (per-response `delayMs` → make backend
  responses arrive out of request order), `unroute`.
- **`act_and_diff`** — run one action, diff DOM class / `aria-*` / `data-*` / inline-style
  within a `scope` (selection-heavy UIs where state isn't text or a11y).
- **`act_and_wait_for_network`** + **`poll_eval`** — precise async assertions.
- **`screenshot_region`**, **`name_region`** / **`region`**, **`cross_session_sample`**,
  **`export_session_report`**.

**How an agent uses them — enabling is a launch-time grant, not an agent action:**

1. The `unstable` capability must be in `BROWX_CAPABILITIES` **when the server starts**.
   Capabilities are resolved **once at server start** (`resolveCapabilities` at
   `createServer` time) — an agent **cannot** self-grant a capability mid-session; that's
   the security posture. Set it in the MCP client's server-launch env:

   ```jsonc
   // .mcp.json — the env the browxai server is launched with
   "env": { "BROWX_CAPABILITIES": "read,navigation,action,human,unstable" }
   ```

   Add `eval` as well (`…,unstable,eval`) if you need `poll_eval` — it evaluates page JS and
   requires **both** `unstable` and `eval`. `set_config({ capabilities })` persists the
   change but only takes effect on the **next** server start (capabilities are not
   re-resolved per call).

   ⚠ **Precedence gotcha.** `capabilities` is an *array* and arrays **replace** across config
   layers — they do not merge. A persisted `set_config({ capabilities:[…] })` (user/project
   layer) therefore **overrides the `BROWX_CAPABILITIES` env value entirely**: if that patch
   omits `unstable`, the env var is silently ignored. Include *every* capability you want in
   the one authoritative place. `get_config({ scope:"resolved" }).capabilities` reports the
   **live enforced** set (what tool gating uses); if it carries a `capabilitiesPendingRestart`
   block, the config changed but the server hasn't been restarted yet — restart it.

2. Once enabled, they are ordinary MCP tool calls — e.g.
   `drag({ from:{ref:"e12"}, to:{coords:{x:740,y:300}}, steps:20 })`.

3. When `unstable` is **not** enabled, every tool in this lane returns a structured refusal —
   `tool "drag" is disabled (capability not in BROWX_CAPABILITIES)` — which is also how an
   agent discovers it needs the operator to add the grant. `get_config` reports the active
   capability set, so an agent can check before attempting these.

Read `docs/threat-model.md` before enabling `unstable` (route mocking + `poll_eval` are the
sharp edges).

## The no-trace consumer-repo contract (read this first)

browxai is designed to be **invoked from inside any other repo without leaving traces in
it**. Concretely:

- The browxai *implementation* lives at its own checkout (referred to below as `<browxai>`).
- All **transient state** — managed-profile Chromium dir, captured `storageState`, logs,
  screenshots, helper artefacts — lives in a **`BROWX_WORKSPACE` directory outside any
  consumer repo**, default `~/.browxai/`.
- A consumer repo is **never** written to by browxai. After a session, `git status` in any
  consumer / target repo is clean.

Two MCP-client configuration patterns satisfy this — pick one. **Never** drop a `.mcp.json`
inside a consumer repo just because that's where your editor is open.

- **(A)** User-scope MCP registration in `~/.claude.json`'s `mcpServers` — available from
  any project session; nothing touches the consumer repo.
- **(B)** A workspace-scope `.mcp.json` *inside the `BROWX_WORKSPACE` dir* (outside any
  consumer repo); open your MCP-client session against that workspace dir, not the
  consumer repo.

The **`cwd` of the spawned MCP server is the browxai repo** (so pnpm finds the deps), but
**`BROWX_WORKSPACE` env points outside any consumer repo**. The consumer repo is never in
either path.

### Dual-registration recipe (managed + BYOB)

Two user-scope MCP entries, one for each session-lifecycle mode:

```bash
# managed (default — browxai launches its own Chromium at $BROWX_WORKSPACE/profile/)
JSON='{"command":"node","args":["/path/to/browxai/dist/cli.js"],"env":{"BROWX_WORKSPACE":"/Users/<you>/.browxai"}}'
claude mcp add-json -s user browxai "$JSON"

# attached (BYOB — attaches to an externally-launched Chrome on loopback:9222)
JSON='{"command":"node","args":["/path/to/browxai/dist/cli.js"],"env":{"BROWX_WORKSPACE":"/Users/<you>/.browxai","BROWX_ATTACH_CDP":"http://127.0.0.1:9222"}}'
claude mcp add-json -s user browxai-attached "$JSON"
```

Use `browxai` for ad-hoc / first-time / public-target work. Use `browxai-attached` when
some other process (a consumer's `capture-auth --cdp`, your own `browxai chrome start`,
your local Chrome started with `--remote-debugging-port=9222`, …) has already launched the
auth-bearing Chrome on `:9222`; the attached browser is treated as not-owned and survives
the session.

### Environment variables

Full list in `docs/tool-reference.md`. The frequently-touched ones:

| Env | Default | What |
|---|---|---|
| `BROWX_WORKSPACE` | `~/.browxai/` | Root for all transient state. **NEVER** `cwd`. |
| `BROWX_ATTACH_CDP` | unset | Loopback CDP endpoint (BYOB attach). Off by default. |
| `BROWX_HEADLESS` | `0` | Managed-mode only. `1` launches headless. |
| `BROWX_TEST_ATTRIBUTES` | `data-testid,data-test,data-cy,data-qa` | Order-sensitive; add the target codebase's convention here. |
| `BROWX_CAPABILITIES` | `read,navigation,action,human` | Off-by-default: `eval`, `byob-attach`, `network-body`, `clipboard`, `unstable`, `file-io`. Resolved **once at server start** — see "The unstable tool lane". |
| `BROWX_CONFIRM_REQUIRED` | `navigate_off_allowlist,byob_action` | Policy hooks that route through `await_human` first. |
| `BROWX_ALLOWED_ORIGINS` | unset | Comma-separated; wildcards (`https://*.example.com`) supported. |
| `BROWX_BLOCKED_ORIGINS` | unset | Overrides the allowlist. |

The threat model that motivates the capability / allowlist / confirm-hook machinery is in
**`docs/threat-model.md`** — read it before enabling `eval` or `byob-attach`.

## Open verification work (what the next agent run is for)

Phase 2's code-side is shipped and the **non-Claude-consumer leg is already MET**: a Codex
session drove browxai end-to-end through a real authed SPA on 2026-05-15 ("gappy green" —
report at `docs/adoption-report-nonclaude-spa-2026-05-15.md`; the rough edges it surfaced
shipped as round-8 G1–G5). The remaining Phase-2-close item is a single exercise:

### Headless-CI keystone — DONE 2026-05-19 (Phase-2 close)

**Status.** Landed and green end-to-end on a real headless Chromium:
`test/keystone/headless.keystone.test.ts` (+ `test/keystone/fixture.ts`, a zero-dep Node
`http` fixture), run via `pnpm test:keystone` (own `vitest.keystone.config.ts`) in a
dedicated CI job that installs Chromium — the hermetic `pnpm test` unit job stays
browser-free. Drives the real MCP tool handlers in-process via the new `createServer().handlers`
seam: six non-trivial primitives (`snapshot`→`find`→`fill`→`choose_option`→`text_search`→`inspect`)
with token-equality asserts, the MCP-driven config model under **zero `BROWX_*` config env**,
two-user cookie-jar isolation, and incognito no-trace (cwd untouched, no profile dir). The
`await_human` / `__browx` banner case is a deliberately-skipped, *named* headless gap. The
historical detail below is kept for context.

**Goal.** Confirm `BROWX_HEADLESS=1` works against a real flow end-to-end, not just a smoke
test.

**Suggested shape.** A vitest keystone test under `test/keystone/` that spins up the MCP
server in-process (or out-of-process via `tsx src/cli.ts`) and drives a flow against a
fixture or a stable public target. Wire it into the existing GitHub Actions CI
(`.github/workflows/ci.yml`). The fixture should:

- Cover the same six "non-trivial" primitives as the non-Claude run above.
- Run under `BROWX_HEADLESS=1`.
- Have a deterministic finish (asserts, not just "didn't crash") — token equality of
  `actionable`, `stability`, structured shape of `ActionResult`.

If you find the headless path actually doesn't work end-to-end (the `__browx` banner is
invisible under headless, `await_human` would be unusable headless — but the rest should
work), document that in the keystone test as a deliberately-skipped case + name the gap.

**Reporting.** No separate report unless it surfaces real gaps; the keystone test landing +
CI green is the deliverable.

## When to use which tool

Quick decision tree for the common cases:

- **"Where is X on this page?"** → `find({query})`. Read the top candidate's `stability` /
  `actionable`; if `low` or non-`true`, fall through to `snapshot()` and read the row directly.
- **"Click / fill / etc. the X I just found"** → action tool with `ref: <eN>` (preferred) or
  `selector: <selectorHint>`. After the first hit, optionally `name_ref({name, ref})` so
  subsequent calls use `named:` and survive the next snapshot.
- **"Did anything happen?"** → look at the action's `ActionResult.{navigation, structure,
  console, element}`. Set `mode: "scoped_snapshot"` to get the changed subtree (auto-promoted
  to `none` when there's no nav/structure change — W-A6).
- **"Page text is huge"** → `snapshot({scope: <ref>, maxNodes: N, omit: ["noisy-pattern"]})`.
- **"The page has a long-running operation"** → `wait_for({selector, timeoutMs: <up to 600_000>})`.
- **"The agent needs the human's input"** → `await_human({kind, prompt, choices?, timeoutMs?})`.
- **"I need to call a page-side function the app exposes"** → enable the `eval` capability
  (loud warning) and use `eval_js({expr})`. Treat the return value as untrusted page content.
- **"I'm calibrating a multi-step flow"** → `start_recording({flowName})` → drive the flow →
  `end_recording()` produces a draft YAML you can transcribe / commit.
- **"Find() picked the wrong candidate"** → after the agent locates the right one, call
  `find_feedback({query, ref})` so the next find with overlapping query gets a boost.
- **"I need drag / a custom gesture, network mocking, a DOM-state diff, an async
  network/poll wait, or a visual region"** → the **unstable tool lane** (`drag`, `route`/
  `route_queue`, `act_and_diff`, `act_and_wait_for_network`, `poll_eval`,
  `screenshot_region`/`name_region`, `cross_session_sample`, `export_session_report`).
  These need the `unstable` capability enabled at server launch — see "The unstable tool
  lane". If a call returns `tool "…" is disabled (capability not in BROWX_CAPABILITIES)`,
  ask the operator to add `unstable` to `BROWX_CAPABILITIES`; an agent can't grant it itself.

## Adopter quick-reference

**Reading a snapshot.** The header shows `url:`, `title:`, `stats:` (with `a11yInteractive`,
`domWalkEntries`, `domWalkNew`, `domWalkCombined`), and optional `scope:` / `warnings:` blocks.
Body lines look like:

```
role "name" [ref=eN] [<test-attr>="…"] [from-dom|from-both] [state]
```

`[from-dom]` = node found by DOM-walk only (expected on heavy SPAs; act on the ref normally).
`[from-both]` = both the a11y tree and the DOM walk found it (good sign).

**Selector preference order** (asks #4 + #10): `[<test-attr>="…"]` (tier 1, `stability:
"high"`) → `role=<role>[name="…"]` (tier 2, `medium`) → tier 3 (covered by tier 2 in
practice) → `#<id>` for stable-looking ids (tier 4, `low`) → `role=<role>` last-resort
(tier 5, `low`). The emitted selector preserves the matched attribute name.

**Configuring for a codebase with non-standard test attrs.** Edit the MCP env block:

```jsonc
{
  "env": {
    "BROWX_WORKSPACE": "/path/to/workspace",
    "BROWX_TEST_ATTRIBUTES": "data-testid,<your-conv>,data-test,data-cy,data-qa"
  }
}
```

The order is meaningful — first match on a node wins. Put the most-trusted convention first.

**Stability semantics.** `stability: "high"` means *uniquely identifies this element in this
snapshot*. It does **not** mean "survives content rotation across deploys." A card with
`[data-testid="card-12345678"]` (content-keyed numeric suffix) is `high` for this snapshot
but rotates with content. For a flow-file that needs to survive day-to-day rotation, prefer
a structural/name selector or compose: `[data-testid^="card-"]:has-text("…")`.

## Where to look

- **`docs/tool-reference.md`** — the per-tool input/output reference.
- **`docs/threat-model.md`** — Phase-2 security model (capabilities, allowlist, confirm hooks).
- **`docs/phase-1-design.md`** — the implementer-facing Phase-1 design (module layout,
  `ActionResult` shape, ref scheme, `__browx` helper, MCP wiring, no-trace contract).
- **`docs/divergence-notes.md`** — what we borrow from `@playwright/mcp` and Vercel
  `agent-browser`; the deliberate divergences.
- **`docs/first-consumer-asks.md`** — status board for the asks tracker (rounds 1–4 + the
  wishlist round-4).
- **`docs/site-docs-lifecycle-port-plan.md`** — historical: what was ported from a sibling
  Kalebtec OSS project during Phase 1.
- **`docs/adoption-report-*.md`** — prior adoption-run reports (sanitised). Read them
  before writing yours — the shape is consistent.
- **`spec.md` / `roadmap.md` in the portfolio** (`kalebteccom/project-ideas` →
  `projects/agent-browser-bridge/`) — source of truth for *what* and *why*.

## Ground rules

- **Stay on TS/Node, ESM, Node ≥20.** `playwright-core` for browser, `@modelcontextprotocol/sdk`
  for MCP. Already in `package.json`. Don't pull in new runtime deps without naming why.
- **Idiomatic, clean code.** Thin `src/index.ts`. Modules under `src/{session, page, helper,
  policy, util, cli}/`. Tests alongside (`*.test.ts`, vitest). Typecheck + tests on Node 20 /
  pnpm in CI (already wired).
- **stderr is the only logging channel.** stdout is the MCP wire — anything written there
  corrupts the protocol. `console.log` in `src/` is a bug; use `src/util/logging.ts`.
- **Page content is untrusted.** `snapshot` / `find` / `ActionResult.snapshotDelta` /
  `eval_js` return values are attacker-controlled. The server doesn't interpret them;
  tool descriptions tell the host agent the same. Phase 2's capability toggles + allowlist
  + confirm hooks enforce a tighter posture — see `docs/threat-model.md`.
- **No-trace contract.** Every output path roots at `$BROWX_WORKSPACE`. `cwd` is never used
  for paths. There's a static source-grep test (`src/util/no-trace.test.ts`) that fails CI
  if a refactor accidentally re-introduces a cwd-relative write — don't disable it.
- **Public-release hygiene.** This repo is heading public in Phase 3. New docs / commits
  must be **sanitised** of identifying client / product / asset names. The replacement file
  from earlier rewrites is at `/tmp/browxai-replace.txt`; run it on anything you copy in
  from a consumer workspace. The audit grep, with patterns customised to your target:
  `grep -RIniE "(<client-acronym>|<product-name>|<feature-area>|<asset-token>)" --exclude-dir={node_modules,.git,dist}`.
- **Commits.** Single-line conventional-commit subjects, **≤72 chars**, no body, no AI
  trailer (the `.claude/hooks/` guards enforce this — they'll reject you if you try).
  One logical change per commit; push when a commit is logically complete. Don't `git add .`
  — stage explicitly.
- **When the design fights you, fix the design.** If implementing something forces a change
  to `docs/phase-1-design.md` / `docs/threat-model.md` / the portfolio `spec.md` /
  `roadmap.md`, update *all* of them — they have to agree. Mirror the change into the
  portfolio's `progress.md` per the repo's cycle rule.
- **If you get blocked, surface it.** Don't grind for 50 tool-calls on a Playwright timeout
  / CDP attach failure / MCP-client misbehaviour. Write a `docs/blockers/<topic>.md`, push
  the branch, summarise in the chat so the human can unblock.

## Definition of done — Phase 2 close — MET 2026-05-19

The roadmap's Phase-2 exit criteria (`projects/agent-browser-bridge/roadmap.md` § Phase 2)
are **all 7 ticked**:

- [x] **A non-Claude MCP client has driven a non-trivial task through browxai successfully.**
      MET 2026-05-15 (Codex / `docs/adoption-report-nonclaude-spa-2026-05-15.md`).
- [x] **Headless/CI mode works.** MET 2026-05-19 — the headless-CI keystone landed and is
      green end-to-end on a real headless Chromium (validated locally; the dedicated CI
      `keystone` job runs the same `pnpm test:keystone` and confirms on each push). It
      exercises the *session/config model* (config via `set_config`, explicit `session`,
      `incognito`) — not the env-var singleton — and also closes the three `[~]` Phase-2.5
      criteria (zero-env config, two-user isolation, incognito no-trace). Headless gap
      (`await_human` / `__browx` banner) documented as a deliberate skip.

Phase 2 is closed. The next genuinely-next phase is **Phase 3 public release**, gated on the
4-condition trigger (below) — still not met (#1 stuck-landed-*weeks* and #2 API-stable-~1mo
remain open; the round cadence is the #2 bottleneck).

When it closes, sync back to the portfolio (`progress.md` + roadmap status + portfolio
table), open `/gpd:advance-stage` if you want, and the next genuinely-next phase is **Phase 3
public release** — gated on the 4-condition trigger in the spec:

1. Phase 1 done and stuck-landed for weeks.
2. Public API stable (~1 month) + tool-ref doc + semver.
3. Phase-2 security baseline at least partly shipped.
4. A real demand signal — a second non-site-docs consumer, *or* clear external pull with a
   named maintenance owner.

## When the human asks "is browxai ready to use for the verification run?"

It is once:

- [ ] `pnpm install` + `pnpm install-browser` succeeded in the browxai repo.
- [ ] `pnpm typecheck` + `pnpm test` pass (197 tests as of 2026-05-18).
- [ ] `pnpm build` produced `dist/cli.js` (executable, shebang preserved).
- [ ] `pnpm browxai -- doctor` (or `node dist/cli.js doctor`) — all ✓.
- [ ] You've registered browxai with your MCP client per the recipe above (user-scope
      `~/.claude.json` or workspace-scope `.mcp.json` outside any consumer repo); MCP client
      restarted so the registration is live.
- [ ] If your consumer codebase has project-conventional test attributes (e.g. `data-type`),
      added them to `BROWX_TEST_ATTRIBUTES` in the env block.
- [ ] You've skimmed `docs/tool-reference.md` so you know what `[from-dom]` / `[from-both]`
      / the `warnings:` block / the `actionable` field mean.

Then drive your target flow per the "Open verification work" section above, and write
the report (sanitised, generic) into `docs/`.
