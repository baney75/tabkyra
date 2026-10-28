# Decisions

Conventional defaults chosen while implementing the Done Criteria (DC-1 to DC-14), and the
owner's answers to the questions that changed the outcome. Newest last. Each entry names
the criterion it serves.

## D1. Tabkyra skill metadata lives in `skill.toml`, not in SKILL.md frontmatter (DC-3)

DC-3 lists name, description, triggers, required tools, permissions, version and
provenance as frontmatter. Harnesses read SKILL.md frontmatter, and some act on keys they
recognize (Claude Code's `allowed-tools` pre-approves tools), so extra keys there are an
escalation route. SKILL.md keeps `name`, `description` and `license`, which every harness
reads the same way. The Tabkyra fields go in `skill.toml` in the same folder, which only
Tabkyra reads and the lint validates. The installer copies only SKILL.md into harness
folders. Same information, no new attack surface in the harness.

## D2. CAPTCHA handling (DC-10, DC-12)

Owner, 2026-10-25: allow solving for search, removing your own data from brokers (ghost),
and OSINT on companies and domains, "with the exception of exploitation like scalping".
Implementation default:

- Off by default. Turned on once at setup, behind a plain warning that solving breaks
  most sites' terms and can get an account or IP flagged. The setting then syncs to the
  user's other devices.
- Tabkyra ships no solver. When the setting is on, the agent may use a solver extension
  the user installed themselves (Buster), one challenge at a time at human pace.
- Allowed for search engines, the `ghost` skill and the `osint` skill's company and domain
  research. Never for buying, ticketing, account creation, posting, or any site the user
  hasn't allowed. People research hands the challenge to the user, as the owner's chosen
  option said.
- Everything else gets the DC-10 handoff: pause, notify, user solves, resume.
- CI fails any first-party skill that bundles a solver or calls a solving service.

## D3. People research scope (DC-12 osint)

The osint skill covers companies, domains, public figures, a person's professional
footprint, and genealogy of the user's own family or of people who consented. It does
not unmask anonymous accounts or people, and it doesn't compile a private person's home
address, phone, relatives or routine for someone else. These are the stalking and doxxing
uses the safety rules exist to stop, so the skill refuses them instead of gating them.

## D4. "ChatGPT Daybreak" (DC-14)

Owner, 2026-10-25: it is the Codex `daybreak` flag. It runs as an optional
second-opinion security reviewer through `codex exec` on the user's own sign-in, with
no API billing. Until Daybreak supports the review model, calls pass `-c daybreak=false`
for gpt-6.1-sol, as the existing field note documents.

## D5. Bug report transport (DC-13)

Owner, 2026-10-25: GitHub issues filed through the user's own `gh` sign-in on
baney75/tabkyra. Reports are de-duplicated by a fingerprint of the scrubbed error (an
open issue with the same fingerprint gets a comment instead of a new issue). Off by
default. Without `gh` signed in, the report falls back to the prefilled issue link the
user submits.

## D6. Personal and shared skills (owner note, DC-5)

Every skill has a category in `skill.toml`: `personal` or `shared`. `tabkyra` classifies
it automatically and the stricter answer wins. Anything matching personal data (emails,
phone numbers, street addresses, account or student IDs, home paths, names the user marks
as private, signed-in site data) makes it `personal`. Personal skills are never submitted,
pushed, uploaded to GitHub or put in the skill DB, in any form. They sync only to the
user's own devices, end-to-end encrypted. Submission refuses a personal skill outright;
it doesn't ask.

## D7. Clean-container check for the install prompt (DC-1)

Pasting the prompt into each harness needs that harness signed in and calling a model.
That uses the owner's sign-ins and, for some harnesses, metered API use, which is not
allowed without the owner. The default check runs the prompt's commands, unchanged, in a
fresh container per harness with that harness's binary installed. It checks harness
detection, skills folder, MCP config and `tabkyra doctor`. The model-in-the-loop
transcripts are recorded as blocked until the owner signs in a harness for the run.

## D8. Stacked pull requests

#13 (skills, lint, CI), #14 (library) and #15 (private mode, bug reports) are reviewed
and merged in order. Owner, 2026-10-25, answering whether to run a second review series
on #13 and then review and merge #14 and #15: "Yes, review and merge".

## D9. Remote MCP and tunnels (DC-2, DC-9)

`tabkyra serve` speaks MCP over Streamable HTTP and binds to loopback only; it refuses any
other address. Every request needs a bearer token from `tabkyra token create`. Tokens are
per client, stored as SHA-256 hashes, revocable at once, and limited to named scopes
(`browser.read`, `browser.navigate`, `browser.act`, `browser.script`, `library.read`,
`library.write`). There is no wildcard. A session sees only its scopes' tools, and another
token can't reuse it. The stdio server that a local harness runs keeps full access: it
runs as the user, so a token there would protect nothing. TLS comes from the tunnel:
`tabkyra tunnel tailscale` (tailnet only; `--public` uses Funnel and warns) or
`tabkyra tunnel cloudflare` (a quick tunnel under the user's own `cloudflared`).

## D10. Appearance customization and the contribution network (owner, 2026-10-25)

Users and their agents customize Tabkyra's look through a theme file: design tokens and
CSS custom properties as data, checked by a linter. A theme can't contain code, URLs or
selectors that hide controls. A modified build is still allowed (AGPL-3.0).

"Lose access to the contribution network if they tamper with the code" is enforced where
it can actually hold. The client can't prove it is unmodified: it is open source, so any
check inside it can be patched out or faked. So the network never trusts the client.

- Every contribution (skill fix, success or failure report, bug report) is signed with a
  per-install key and carries the build's hash. Builds whose hash isn't in the signed
  release manifest are labeled `unofficial build`. Their contributions go to a separate
  queue that is never auto-accepted.
- Every contribution, from any build, passes the same server-side gates: CI lint, the
  red-team suite, adversarial review, and a maintainer for sensitive scopes. Security
  rests on these gates, not on trusting the client.
- Abuse (repeated rejected or malicious submissions) revokes that install key.

## D11. Worldwide successes and failures (owner, 2026-10-25)

Off by default and opt-in at first run, next to bug reports. When on, a skill run's
outcome is scrubbed by the DC-7 scrubber and contributed. It includes the skill name and
version, the model class, pass or fail, the step that failed, and the fix if `/fix`
produced one. Personal skills (D6) and page content are never included. Outcomes reach
the shared library only through D10's gates, as proposed fixes. Raw data never edits a
skill directly.

## D12. Small-model context budget (owner direction; numbers set by Claude, 2026-10-25)

The owner asked that skills not bloat context, "especially for the super small models"
(2026-10-25). He set no number; the figures below are Claude's. Harnesses see only each skill's name and its one-line description. The full SKILL.md
loads when the skill is invoked. Each first-party skill stays under 150 lines and
8,000 characters (about 2,000 tokens; `BUDGET_LINES` and `BUDGET_CHARS` in
`cli/src/skill-lint.ts`). Claude first set 1,500 tokens and raised it the same
day, because every well-specified skill exceeded it; the owner hasn't ruled on the number. Enforced by the lint's `budget` rule, and longer material is
split into separate skills, not appendices. The
router (DC-3) picks at most one skill per task for small models. The `rsi` and `fix`
skills apply their edits with `tabkyra skill apply`, which runs the same lint, so an improvement can't bloat a skill past it (`fix` also aims for under 150 lines).

## D13. Local model providers (owner, 2026-10-25)

A "Local models" provider set in the side panel. It finds OpenAI-compatible servers
(Ollama :11434, LM Studio :1234, llama.cpp and vLLM :8080 and :8000) on this machine and on
the user's tailnet peers. The native host asks `tailscale status --json` for the peers and
probes each port with a short timeout. A model on a tailnet peer counts as local for
private mode only once the user lists it as their own (#15's rule in `src/privacy/private-mode.ts`: only loopback is trusted automatically).

## D14. Fix submissions and tier variants (owner, 2026-10-25)

`submit` in `~/.config/tabkyra/rsi.json` takes `"ask"` (default), `"auto"` or `"never"`.
The owner asked that users be able to submit fixes automatically, which overrides DC-5's
confirm-each-submission default for users who choose `"auto"`. Auto submission still only
opens a pull request: CI, adversarial review and a maintainer decide what enters the
library (D10). A skill classified personal (D6) is never submitted under any setting.
When a fix for a small model would weaken a skill that works for large ones, `/fix`
writes a `<name>-lite` skill instead of editing the original. The router (DC-3) picks the
variant by model tier.

## D15. Voice and mail skills (owner, 2026-10-25)

The writing-voice skill learns the user's style only from the user's own mail and
documents, read in place through their signed-in Tabkyra tabs or their Drive. It keeps
just a style profile (sentence length, word choice, openings, sign-offs, a few short
example lines), not the messages. The profile is a personal skill (D6): it stays on the
user's devices and is never submitted, synced to shared storage or put in a bug report.
Email organization reads freely, but creating labels, moving mail or changing filters acts
under the user's sign-in. It shows the plan and waits for the user's yes, per the safety
rules.

## D16. SDKs and vendor terms (owner, 2026-10-25: "we don't want to break ToS")

No user should risk a ban for using Tabkyra.

- **Harnesses the user runs** (Claude Code, Codex, pi, OMP, OpenCode, Cursor) connect to
  Tabkyra as an MCP server, a pi extension or skills. The user's own harness, signed in
  however its vendor allows, calls Tabkyra. Nothing is borrowed or impersonated, so this
  is the primary integration.
- **pi** (`@mariozechner/pi-ai`, `pi-agent-core`, `pi-web-ui`, MIT) already powers the side
  panel with API keys. OMP is integrated through MCP config.
- **Vendor agent SDKs** (Claude Agent SDK, Codex SDK) are used only with an API key the
  user supplies and pays for, never with a subscription sign-in inside Tabkyra. Products
  built on these SDKs are expected to use API keys, and reusing a consumer sign-in in
  another app is what got the old Sitegeist sign-ins removed (docs/auth-policy.md).
- `/fix` and `adversarial-review` run a stronger model by calling the user's own CLI
  (`claude -p`, `codex exec`) on their machine, the same way the user would.

## D17. Adapted third-party skills and the mechanism dataset (Claude, 2026-10-26)

The owner asked for a `visual-explainer` skill adapted from nicobailon/visual-explainer
(MIT) and a `mechanism-design` skill informed by arXiv 2409.03763. Defaults chosen:

- **Adapt, don't vendor.** A skill folder holds `SKILL.md` and a license only, under the
  D12 budget, so upstream's `references/` files, its CSS/JS kit, its renderer and its
  slide and video tooling are not copied. Their rules (figure choice, grid layout, shape
  meanings, captions, motion restraint) are rewritten into one `SKILL.md`. The MIT notice
  with Nico Bailon's copyright is at the end of that `SKILL.md`, because `tabkyra skill
  install` copies only `SKILL.md`, and also in `skills/visual-explainer/LICENSE`. The skill
  is MIT; the rest of Tabkyra stays AGPL-3.0.
- **Inline SVG, not Mermaid.** Upstream loads Mermaid, Chart.js and three.js from a CDN.
  The `artifacts` rules forbid outside scripts, and inlining Mermaid would add megabytes of
  layout code to every page for diagrams a model can draw by hand. Upstream itself makes
  hand-drawn SVG the default and Mermaid opt-in. A user's Mermaid source is redrawn as SVG
  and kept as text in the page.
- **Upstream's checks are replaced by Tabkyra's**: serve the page's own folder,
  `navigate`, start `read_console` and `read_network` and reload, `screenshot`, and
  `run_js` checks for captions, SVG labels, the script count and 375px overflow. The page's
  Content-Security-Policy (first in head: `default-src 'none'`, `script-src 'none'` or the
  SHA-256 of its one script, `form-action 'none'`, `base-uri 'none'`) is the control that
  blocks injected script and form posts; a check confirms it word for word.
- **Link the mechanism dataset, never bundle it.** Its images were scraped from a YouTube
  channel, DMG-lib and Artobolevsky's book, partly under copyright, and its code repository
  states no license. `mechanism-design` cites the paper and points to the repository as a
  catalogue of mechanism names only.

## D18. Artifact previews for more file types (Claude, 2026-10-27)

The owner asked for previews of more document types in the side panel's artifact viewer
("add preview for more docs too please", 2026-10-26, after a `.pptx` showed "Preview not
available"). Defaults chosen:

- **Own readers, no new libraries.** pptx, odt, odp, RTF and notebooks are read by small
  readers in `src/artifacts/preview/` over the JSZip already in the bundle. `pptx-preview`
  (ISC) was the only maintained pptx renderer found; it ships minified code and pulls in
  ECharts, lodash and uuid, about a megabyte. `rtf.js` (MIT) was last released in 2022.
  `marked`, already bundled for mini-lit's markdown, becomes a direct dependency for the
  notebook preview; the build aliases it, SheetJS, JSZip and highlight.js to one copy each.
  The previews add about 58 KB unminified (18 KB gzipped) to `sidepanel.js`. The build has
  no code splitting and AGENTS.md forbids dynamic imports, so nothing is lazy-loaded.
- **Viewers live in Tabkyra, not the pi-mono patch.** pi-web-ui gains one hook,
  `setArtifactViewerFactory` (through `patches/pi-mono.patch`), which the artifacts panel
  asks before its built-in viewers; `src/artifacts/viewers.ts` answers it. The fork patch
  stays small, and the viewers are ordinary Tabkyra source with Tabkyra's tests and review.
- **Spreadsheets** (`xlsm`, `xlsb`, `ods`, `numbers` and templates) go through the SheetJS
  build already bundled. CSV and TSV get a table with a toggle to the raw text.
- **Untrusted input.** Nothing in a file runs or reaches the network: text is set as text,
  external images and links to files outside the package are dropped, notebook HTML outputs
  go through an allow-list sanitizer with only inline `data:` images, notebook markdown
  turns remote images into links, and SVG outputs show as `<img>`. The XML reader never
  expands DTD entities. Size limits (`PREVIEW_LIMITS` in `preview/content.ts`) bound each
  whole file, not each part: the file, every inflated zip entry (read through a stream that
  stops at the cap), the archive, the entries it lists, Apple Numbers' Snappy streams
  (checked before SheetJS inflates them), and what a deck, document, table or notebook draws.
- **No preview for legacy binaries** (`doc`, `ppt`, `key`, `pages` and a few others): the
  message names the format and says what to save it as.
- **Slides show as a scrolling column** scaled to the panel width, which suits a narrow
  side panel better than one slide with a thumbnail strip.

## D19. Updates from the side panel (Claude, 2026-10-27)

The owner asked for "a great update system" (2026-10-26) with Update now, checkout mode,
Settings > Updates and an automatic choice defaulting to "Tell me". Defaults chosen:

- **The mode comes from where the native host runs**: `~/.local/share/tabkyra/app` is a
  release, a Tabkyra git checkout is a checkout, anything else updates only from a terminal.
  The browser's extension folder is confirmed by its `build-info.json` (build ids are new for
  every build); if it differs from the host's folder, Update now refuses, because updating
  the host's folder would not change what the browser runs.
- **A checkout rollback restores the builds, not git.** It swaps `dist-chrome` and
  `cli/dist` with the kept ones and leaves HEAD alone; Update now rebuilds HEAD. Resetting a
  branch the user may have work on is not the updater's call.
- **Untracked files don't block a checkout update**; tracked changes, another branch and a
  diverged main do. `git pull --ff-only` itself refuses an untracked file it would overwrite.
- **Build first, swap when idle.** Downloading, verifying, pulling and building run while
  agents work; the swap of live files (activation, rollback) and the reload wait for idle and
  follow each other at once, so the browser doesn't run old and new files side by side.
- **"Idle"** means no side panel run (counted while its heartbeat is under 3 minutes old) and
  no bridge request in flight; a harness also counts as running for 30 seconds after a
  browser call. Automatic updates wait for 3 quiet minutes.
- **A checkout trusts its origin** as a manual `git pull` and build would; there is no
  signature to check. Automatic updates are still offered in a checkout; docs/updates.md says
  what that means.
- **Automatic updates never undo a rollback**: not the release rolled back from, and in a
  checkout only new commits. A failed automatic attempt isn't retried for the same version.
- **Skill refresh only rewrites what Tabkyra wrote.** A hash record of installed files decides;
  a copy without a record is refreshed only if it matched the old CLI's text right before the
  swap. Anything else is reported, never overwritten.
- **What's new is plain text.** Release notes come from GitHub and are rendered as text, never
  HTML; links must be https.

## D20. ask_user: agents ask the user questions (Claude, 2026-10-27)

The owner asked, after watching Claude Code's AskUserQuestion tool, to "make it so it can ask
questions too" (2026-10-27). Defaults chosen:

- **One shape everywhere.** The side panel tool and the MCP tool take the same arguments
  (1 to 4 questions; header, question, 2 to 4 options with label and description,
  multiSelect), checked by one function (`src/ask/core.ts`). "Other" free text is always
  offered, so an option can't be named Other.
- **No answer is an answer.** Skip, Stop, a closed or reloaded panel, the timeout and a
  disconnected agent all return a result that says there was no answer and tells the model
  not to assume one. A question cut off by a panel reload gets that result on the next turn
  (`src/messages/message-transformer.ts`).
- **External agents' questions go to the panel, not the harness.** They wait in
  `chrome.storage.session` like site-permission prompts, show above the chat in every open
  panel with the agent's name, badge the toolbar icon, and give up after 5 minutes. The panel
  answers by request id; the request id carries the client id and a random UUID, and only the
  waiting request with that id takes it, so an answer goes back only to the agent that asked.
  No bridge method answers a question, so a harness can't answer its own or another's.
  `chrome.storage.session` is closed to content scripts, so a page can't either.
- **Remote sessions need their own scope**, `user.ask`, never implied by the others: a remote
  agent that can ask questions can put text in front of the user.
- **Two open questions per agent at most.** One call already carries up to four, and a cap keeps
  one agent from filling the panel. An agent that gives up on its call (its tool timeout, or the
  user stopping it) withdraws the question with `ask_user.cancel`, which names that call and
  only ever reaches the calling agent's own questions.

## D21. Side panel transcript and composer menus (Claude, 2026-10-27)

The owner asked to clean up the side panel chat, remove the in-chat Artifacts pill, and add a
`/` menu that runs skills and an `@` menu that references tabs (2026-10-27). Defaults chosen:

- **Reasoning under 40 characters gets no row.** It is still shown inside the step it led to.
- **A step list longer than 8 rows shows its last 5** behind an "N earlier steps" row.
- **Per-step usage is a tooltip and part of the expanded row**, not a line under each step;
  the run total below the composer is unchanged.
- **Artifact tool calls stay full cards**: the card is how the user opens what was made.
- **The `/` menu order** is site skills matching the current page, then the library, then site
  skills for other sites. A name shows once, in its first section.
- **A library skill runs by loading its SKILL.md into the user message**, with a note that its
  tool names are Tabkyra's MCP tools and the panel agent uses its own (navigate, repl).
- **References resolve when the message first goes to the model** (prompt, queue and Send now
  all pass through `convertToLlm`), once per message, and are frozen on it. Messages loaded
  with a saved chat are never resolved again.
- **A referenced tab owned by any other session stays with it**, not only a bridge agent's:
  the reference is consent for this chat, not permission to take another agent's tab.
- **A referenced tab never becomes current.** The model is told to switch to it with navigate
  `switchToTab`; a reference queued mid-run must not move the agent's next action to another page.
- **Browser pages, private tabs, tabs without a readable URL and tabs in another window are
  not referenceable.** The menu lists only the panel's window; a typed id elsewhere is refused.
- **References that fail to resolve are frozen as unusable**, with a toast, so a chip never
  looks shared when nothing was.

## D22. A dropped bridge: reads are resent, input is never replayed (Claude, 2026-10-27)

Owner, 2026-10-27: a tool call during an extension reload or native host restart "retries
safely or fails with a clear retryable error, never a hang". Defaults chosen:

- **What counts as a read** is a fixed list in `src/bridge/protocol.ts` (`isIdempotent`):
  status, tab listing and selection, snapshot, text, HTML, find, screenshot, wait, console
  and network reads, and `navigate` to a URL (loading the same URL again repeats a GET).
  Everything else, including `navigate` back or forward, `tabs.create` and `actions`, is
  input and is sent at most once.
- **The host answers for the extension.** When the extension goes away with requests out
  (reload, update, worker restart, a bad frame), the native host answers each one with
  `interrupted` before it exits, so no client waits on a reply that can't come. A stopping
  host keeps each client's socket open until that client has been quiet for 250 ms (2 s at
  most), and a request that arrives then gets `not_sent`. A request the extension refuses
  during an update install gets `not_sent` too: it never ran.
- **The client resends** a read cut off in flight and anything that never left (no socket, or
  `not_sent`), after the bridge is back, up to three sends in all. A cut-off input request
  fails with `interrupted` at once, without waiting for the bridge, telling the agent it may
  have run and to check the page before repeating it; the next call reconnects. This replaces
  the one blind retry, which ran a click twice when a reload cut off its reply.
- **A refusal is waited out, not counted as a drop.** A live host's `not_sent` (an update
  installing, a host stopping) is resent after 250 ms, 500 ms, 1 s, 2 s... within the budget.
  A half-closed socket takes no request; one an answer showed is retiring is no longer used
  but not cut under the requests still waiting on it.
- **Same browser, for a resend.** Each profile keeps a random id (`tabkyra.browserId`) that
  the host passes on. A call's resends go only to the browser it started in, never to another
  browser or to a host that hasn't said which it is; when that browser doesn't come back within
  the budget the call fails, and the next call takes whatever browser is up. A reconnect on a
  host whose extension never answers keeps looking, without redialing its own host; nothing is
  written to a host whose extension isn't there.
- **No new waits.** From its first drop, one call waits at most 40 s in all for the bridge,
  however many times it drops (time the request itself ran isn't charged); concurrent calls
  share one reconnect and one connect, a socket is used only once it is welcomed and chosen,
  and a client never holds more than one.
- **Cut off means stopped.** When the native host goes away while the extension lives (a host
  crash or restart), the extension stops the running request from sending more input, a
  request still in its preamble (update gate, session open) never reaches its handler, and
  nothing queued for that client starts, so the agent's "check the page, then repeat" can't
  race a handler still running.
## D23. Sessions follow the project; the user's gestures on a group are commands (Claude, 2026-10-27)

Owner, 2026-10-27: sessions "resumable across restarts of the harness", "a clear rule for the
default name (cwd or project plus harness)", and "improve group management too". Defaults
chosen:

- **The default session is the project**, not the harness conversation: the git root of the
  MCP server's working directory (or the directory), named `<folder>-<4 hex of its path>`.
  `--session` and `TABKYRA_SESSION` override it. Harness conversation ids
  (`CLAUDE_SESSION_ID`, `CODEX_THREAD_ID`) no longer pick it: each new conversation made a new
  group and lost the old one's tabs. Outside a project (the disk root or the home folder, even a
  home that is a git repository, where GUI harnesses often start servers) each process gets its
  own session, so unrelated agents never resume each other's tabs.
- **A default is never shared by two live clients.** The second gets `<name>-2` and is told
  (`session_assigned`) so a reload can't swap it onto the first one's tabs. A restarted harness
  that connected before its old process hung up gets the base session back if it hasn't
  opened its `-2` yet. A name the user chose is shared on purpose.
- **Group titles** are `Tabkyra · <agent> · <project or session name>`, plus an optional label
  the agent sets (session_info), sanitized as plain text, at most 32 characters, never
  starting with "Tabkyra".
- **Gestures apply to agent sessions only.** Side panel chats keep their rules: their tabs are
  the user's already. A tab counts as moved out only once it was seen inside the group, so a
  tab still being grouped is never handed over by mistake. A closed window is not a gesture.
- **An agent never lands on a page it didn't choose**: when the user takes or closes its
  current tab, it has no current tab until it picks one or navigates.
- **15 tabs per session**, refused with `tab_limit` and what to do. Popups the foreground
  guard adopts are not refused (they come from the page, not the agent).
- **`tabkyra sessions` acts as the user**, like the side panel: any local process that can
  reach the bridge socket can list, rename, end, focus or collapse agent sessions.

## D24. Past chats are readable by local agents, by default (Claude, 2026-10-27)

Owner, 2026-10-27: "Make it so tabkyra threads are accessible locally too for the agents using
the mcp, and cli, and such." Defaults chosen:

- **On by default**, with a Settings > Privacy switch that turns it off: no agent reads a past
  chat, live or from files, and the files are deleted.
- **Only chats from this version on**, unless the user ticks "Also chats from before <date>".
  Older versions saved private-mode chats without a mark, so nothing created before this build
  first ran (`threads.sharedSince`) is shown or mirrored by default.
  The files sit in the user's own data folder, readable only by the user, the same reach a local
  agent already has over the user's other files.
- **Never private-mode chats.** A chat saved while private mode is on is marked private for
  good; turning private mode off later doesn't expose it.
- **Redacted and trimmed, in every form** (text, Markdown and JSON). Keys and tokens are removed,
  including keys written only in hex (32 or 64 digits; a 40-digit commit id stays); reasoning is
  left out; tool results are cut to 300 characters; images and attachment contents appear by
  name only.
- **One folder per browser profile** (`threads/<browserId>/`), so two browsers never delete or
  overwrite each other's copy; the CLI and MCP read all of them.
- **Local stdio MCP may read threads; remote sessions need `threads.read`**, a scope no other
  scope implies.
- **Data, not instructions**: the tool descriptions, the MCP instructions and every rendered
  thread say so, since a past chat can hold page text an attacker wrote.

## D25. Side panel polish: fewer header buttons, Share only when it acts, six settings tabs (Claude, 2026-10-28)

Owner, 2026-10-28: "also work on the UI a bit", then "fix this button, and improve speed
provider, session, and setting management and UI making it less cluttered and easy to use".
Defaults chosen:

- **Header**: chat title, then Past chats, New chat, More, Settings. Copy chat, Record a skill
  and the theme moved under More. Every icon has a name that shows as a tooltip on hover and on
  keyboard focus. Recording shows a red "Recording" pill that stops it.
- **No share button: the tab in front goes with the message.** Owner, 2026-10-28: "No we
  shouldn't need to press share this tab it should all be available". Sending a message gives
  the agent the tab the user is looking at and makes it the agent's page; "Send now" mid-run adds
  it without swapping the run's page. A tab another agent is driving stays with that agent, and
  browser pages (settings, the extension's own pages, the web store) never go to the agent; a
  blank new tab does. Other tabs are referenced with `@`.
- **Hover is neutral, brass means on.** The theme's accent text (blue in light, yellow in dark)
  made a hovered icon look switched on.
- **Settings has six tabs** that all show at the panel's width: Providers (API keys, then custom
  providers), Skills, Bridge, Privacy (with the CORS proxy), Costs, About (with updates). The
  provider list has a search box, lists providers with a key first, saves on Enter and offers
  "Choose a model" after a save.
- **Past chats**: the search box has focus when the list opens and Enter opens the top match;
  each row renames in place and deletes with Undo instead of a confirm box. Bulk import, export
  and delete are under the list's More menu (bulk delete still asks).
- **Starter chips**: Summarize this page (runs), Research with sources, Fill a form and Compare
  tabs (each fills the chat input for the user to finish; Compare tabs opens the `@` tab menu).
