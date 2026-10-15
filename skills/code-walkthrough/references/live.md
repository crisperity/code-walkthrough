# Live mode: the daemon, setup, cost, and remedies

Read this once before relying on live mode, and again whenever `walkthrough_start` or
`walkthrough_get` reports a `remedy` you don't recognise. SKILL.md's "1b. Live mode" carries the
calling convention; this file carries the mechanics behind it.

Live mode moves the capture, split, worker, gate and render steps to a daemon process, and the
worker conversations are no longer this agent's own subagent spawns: every diff hunk, every
prompt and every file a worker reads goes to whichever model backend `config.json` points at. A
`claude-code` role runs `claude -p` under the same account and routing your own Claude Code uses,
whether that's a subscription, an API key, or a gateway set in `settings.json`'s `env`, and counts
against that; the page banner shows its tokens only, with no `cost_usd`. An `openai` role instead
bills per token against that profile's own API key: only an Ollama or vLLM instance on the same
machine keeps that traffic local, a proxy, OpenRouter or any hosted API sees it the same as any
other client. `walkthrough_get`'s `usage` and the page banner show the running total either way,
with a `cost_usd` once an openai profile carries `price_per_mtok`.

## Setup

With `claude` on PATH, `python3 scripts/cw_mcp.py setup` writes a working claude-code config;
there is nothing to edit. Installing this skill as a Claude Code plugin registers the MCP server
automatically, but plugin users still run `setup` once to get this config; under the plugin,
`setup` just writes that config and skips registration, for either `--agent`. A manual clone (or any
other MCP-capable harness) needs one command instead:

```bash
python3 scripts/cw_mcp.py setup --agent claude    # registers with `claude mcp add -s user`
python3 scripts/cw_mcp.py setup --agent print      # prints the mcpServers JSON for any other harness
```

Either form also writes `~/.code-walkthrough/config.json` from a template the first time it
runs, the claude-code template when `claude` is on PATH, otherwise the proxy template below, and
never overwrites an existing one; paste a profile in instead.

## Config keys

```json
{"profiles": {
   "claude": {"kind": "claude-code", "model": "sonnet"},
   "proxy": {"base_url": "http://localhost:4000/v1", "model": "<a model your proxy routes>",
             "api_key_env": "LITELLM_API_KEY"},
   "local": {"base_url": "http://localhost:11434/v1", "model": "<an Ollama model with tools>"}
 },
 "roles": {"analysis": "claude", "prose": "claude", "visuals": "claude", "ask": "claude", "escalate": "proxy"},
 "max_concurrency": 4, "timeout_s": 300, "max_conversation_tokens": 200000,
 "small_diff_lines": 1500, "batch_max_lines": 400,
 "trust": {"repos": ["owner/name"], "orgs": ["owner"]},
 "repos": {"owner/name": "/abs/path/to/existing/clone"}}
```

A profile's `kind` is `openai` (the default; needs `base_url` and `model`) or `claude-code`
(needs only `model`, an alias or full name passed straight to `claude -p --model`). `timeout_s`
bounds each profile's call either way, HTTP request or claude process; `max_conversation_tokens`
and `price_per_mtok` apply to the openai kind only. `roles.escalate` is optional and falls back to
`roles.prose`; it is the fresh retry a batch gets after failing its fragment gate twice.
`roles.visuals` is optional and falls back to `roles.prose`, so a stronger model can be mapped to the
pictures alone; its usage is booked under the "visuals" role.
`roles.thread` is the optional role for thread turns and falls back to `roles.ask` when unset; its
usage is booked under the "thread" role. `small_diff_lines` and `batch_max_lines` mirror the fan-out thresholds in `static.md` step 2 and
step 2a. An openai profile may also carry `price_per_mtok: {"input": x, "output": y}`, which is what
turns a usage total into `cost_usd`; no price table ships, since one would go stale.
`trust.repos` and `trust.orgs` (both default to empty, matched case-insensitively) say where Full
access may be offered (`trust.repos` also lets a repo clone without asking), see "Full access" and "Repos without a
local clone". `repos` maps `owner/name` to an existing absolute directory and wins over the cache.

## `check`

```bash
python3 scripts/cw_mcp.py check
```

For an openai role, sends the profile one tiny request carrying one tool and asserts the reply is
a tool call, since tool-call support is the one capability every role depends on and small local
models often lack it. For a claude-code role it instead runs `claude auth status`, then one tiny
`claude -p` call with a schema. Prints `ok <role> (<profile>/<model>)` or `FAIL <role>: <error>`
with its remedy, and needs no daemon running.

## Workers on claude-code

A claude-code worker runs `claude -p --safe-mode --restricted` with only the `Read`, `Grep` and
`Glob` tools, cwd set to the walkthrough's `head` worktree; your own hooks, plugins, MCP servers
and `CLAUDE.md` are not loaded. Reads outside that worktree are denied. The live `head` worktree
is checked out with `core.symlinks=false`, so a worker reading a symlink sees a regular file
holding the link's target text instead.

Thread turns differ: they run `claude` without `--safe-mode`, since safe mode disables MCP servers,
but still with `--restricted`, the read-only `Read`, `Grep` and `Glob` tools, `--strict-mcp-config`
and a per-turn stdio outcome server. Review threads can call `propose_resolve`, `propose_page_edit`,
`propose_github_draft`, `propose_task` and `post_draft_comments`; Full threads (see
[Full access](#full-access)) drop `propose_task` and add `reload_walkthrough`. `CLAUDE.md` and user
settings are verified not to load under `--restricted`. Each thread is one Claude Code session (first
turn `--session-id`, later turns `--resume`), stored in `~/.claude/projects` for the head checkout;
a lost session is reseeded from the thread's Q&A. Stop sends SIGTERM to the turn's process group
(SIGKILL after 3 s) and the session stays resumable. A `ctx/` folder in the walkthrough directory
holds copies of `analysis.json` and `raw.diff` the agent may read.

## The pictures step

Step `visuals` runs after the analysis and the background steps, authors the PR picture and one
picture per group into `visuals.json`, and never fails the run: on error the step is marked
`failed` and the page has no pictures. It skips when `visuals.json` already exists.
`python3 scripts/cw_run.py visuals --dir <dir> --force` re-runs it, then `pipeline.py render`
rebuilds the page. What a picture may contain: `references/graphs.md`.

When the code index returns no language, the same step also asks the model for the call edges of
the diff and writes them to `symdelta.model.json`; see `references/graphs.md`.

## Page details

While a walkthrough builds, the page shows placeholders where the Overview, System change and the
per-hunk notes will land, and the Threads dock stays hidden until there is a thread to show. A
reload after the rebuild replaces the placeholders. The Walkthrough heading no longer has an
explanations toggle: notes are always on.

A changed file that can be previewed (`.md`/`.markdown` and images) has a Preview button in its
header. It swaps the diff for the rendered file and back. Images open in preview, since there is no
text diff to show; markdown opens as the diff. Previews are built from the repo at build time and
need `--repo`, `--base` and `--head`, which the daemon passes. Limits: 1 MB per image, 256 KB per
markdown file and 8 MB of previews per page; anything over shows "too large to preview". A git
failure skips the preview quietly.

## Repos without a local clone

`walkthrough_start`'s `repo` is an absolute path or `owner/name`. The daemon resolves `owner/name`
in this order: the `repos` map in `config.json` (a value that is not an existing absolute directory
fails with the remedy `fix repos.<name> in config.json`), then the cache clone at
`~/.code-walkthrough/repos/github.com/<owner>/<name>`, then a fresh clone, then a refusal. A
refusal reads `<name> is not cloned on this machine`, and its remedy is the question to ask the
user (clone it, about N MB, into that path), what to call next on yes (`walkthrough_start` again
with `clone: true`) and what to do on no (the static path, `gh pr diff`). The clone happens without
the question only when the repo is in `trust.repos`. It is blobless and checkout-less
(`gh repo clone`, `--filter=blob:none --no-checkout`) with `GH_TOKEN` and `GITHUB_TOKEN` stripped;
the clone's own config points `github.com` at `gh auth git-credential`, so blobs fetched later
authenticate. It lands in a temp directory and is renamed into place only on success, so a retry
after a timeout is safe. A mapped or cached repo then fetches the PR head and base before the build
when `pr` is set or `base` starts with `origin/`.

## Full access

A thread normally runs in Review: read-only tools, the PR's own files, no edits. Full runs your own
Claude Code in a shared worktree, so the agent can edit files and run what your own settings allow.
Full is off by default and only offered when the walkthrough's repo is in `trust.repos`, its owner in
`trust.orgs` (for a non-PR local target the repo is read from `origin`), or the PR is the signed-in
user's own (cached when the build syncs the PR). It is never offered on sibling pages, and needs a
claude-code `thread` profile. `POST .../comment` with `mode: "full"` answers 400 without such a
profile or on a bad mode, 409 on a sibling page, 403 when the repo is not trusted, 400 when bubblewrap
is missing.

The Threads panel always has an access line saying whether Full is on and, when it is off, why. The
daemon checks in this order and reports the first that fails, with a remedy: no claude-code `thread`
profile, an updated (sibling) walkthrough, bubblewrap missing, repo not trusted. Trust comes last, so
the trust buttons only show when trusting would actually turn Full on. They are Trust repo and Trust
all of org, each behind a confirm that says a fork PR into a trusted repo also gets Full and that
org trust covers every repo the org owns. When Full is on because of `trust.repos` or `trust.orgs`,
the line offers Stop trusting (no confirm). Your own PR needs no trust and has no button. The page
writes `trust` in `config.json` for you, so there is no need to edit it by hand.

`POST /api/walkthrough/<key>/<wid>/trust` takes `{"scope": "repo"|"org", "action": "add"|"remove"}`
and answers 200 `{agent}`. The repo or org comes from the walkthrough, never from the body. It
answers 400 on a bad body or unreadable config, 403 on a failed auth check, and 409 on a sibling
page or a repo that is not on github.com. Every change emits an `agent` SSE event carrying the same
`agent` object.

The `agent` object in the live payload, next to `agent.stale`, adds `full_off` (null when Full is
on, else `{reason, remedy, fixable, repo, org}` where `fixable` is `"trust"` when trusting would fix
it) and `trusted` (null, or `{by: "own_pr"|"repo"|"org", value}`).

What loads: `--setting-sources user`, so your own settings (including `permissions.allow`), skills,
user-level MCP servers and `CLAUDE.md`. The PR branch's `.claude/settings`, hooks, `.mcp.json` and
`CLAUDE.md` do not load. The turn's cw outcome tools are added, with the `prompts/agent.md` rules
appended to the system prompt.

Full needs Linux with bubblewrap and overlayfs. Without them Full is unavailable (the page does not
offer it and `mode: "full"` answers 400) and Review still works.

The agent runs under bubblewrap. The filesystem is read-only except the shared worktree, the cw turns
directory, Claude session state (only this agent's own `~/.claude/projects/<encoded cwd>`,
`session-env` and `sessions`, plus `.credentials.json`) and rtk history. Anything the agent leaves in
the turns directory is re-validated by the daemon before it is accepted. `~/.claude` itself stays read-only, so the agent cannot plant hooks or settings.
`/tmp` is private and discarded. `~/.ssh`, `~/.gnupg` and `/run/user` are masked when they exist, after
the repo overlay, and the docker sockets are hidden.
The main repo's `.git` is an overlay, so any git write the agent makes is discarded and the daemon
commits the worktree after the turn. `WebFetch` and `WebSearch` are disallowed for the Full agent.

Not confined: reads (home stays readable), and network, which follows your own Claude settings and
sandbox, so a broad allow rule still applies to everything except writes outside the worktree.
Push and `gh` rules remain best effort. Refreshing the Claude login token inside the sandbox is
untested. The agent can read your gh token files (the daemon token, `server.json` and `config.json` are masked), so treat Full like running
Claude Code yourself on that repo.

What is blocked, best effort: git transports are disabled in the agent's environment
(`cw_llm.no_push_env`, so fetch and clone fail too) and `git push` and other push-like commands are
denied by rule. Neither is a sandbox. Your own walkthrough MCP tools are disallowed
(`FULL_DISALLOWED`), so the agent cannot start or reply to walkthroughs as you. The daemon itself
never pushes. Edits are accepted automatically inside the worktree. Anything else that would prompt
is denied rather than asked, and the page lists it on the turn as "Needs permission".

The agent runs with your `permissions.allow`, so a broad `Bash` or `Write` allow rule
applies in full, and `gh` and network access (`gh api`, `curl`) follow your own settings. The PR
text it reads can try to steer it. Keep broad allow rules out of your user settings if you use Full
on code you do not trust.

The `/trust` route needs the daemon token, which the Full sandbox hides, so the agent cannot widen
trust. Review agents have no shell and cannot reach the route.

Trust is by repo, org or your own PR only. A fork PR into a trusted repo also gets Full, so list
only repos you accept that for. The PR author's `.claude` settings, hooks, `.mcp.json` and
`CLAUDE.md` are not loaded.

All Full turns of a walkthrough share one worktree at `agent/` in its store directory, on the branch
`cw/<id>/agent`, created on the first Full turn from the head the walkthrough had then. Only one Full turn runs
at a time per walkthrough: a second waits and shows "Queued behind <thread>", and Stop cancels it
while it waits. Review turns never wait. After each turn the daemon commits what changed and records
an `edits` card with the files and line counts. Show opens a sibling walkthrough on that commit;
Discard drops the worktree, the branch and every agent edit at once, and answers 409 while a Full
turn is running. If the daemon restarts mid-turn it leaves a dirty worktree, and the next Full turn
commits it. A Full turn can run long, so you may need to raise `timeout_s`.

When the PR gets new commits, a refresh keeps the agent's edits (and a dirty worktree) instead of
discarding them, and marks them stale (`agent.stale` in the live payload). The next Full turn first
merges the new head into the agent branch; if that conflicts the turn fails and asks you to discard
the agent edits and ask again. Until then Show and Reload refuse with "The PR changed since these
edits were made". A refresh, or any walkthrough_start that rebuilds, answers an error while a Full
turn is running on that walkthrough; re-opening an unchanged one still works. `fresh: true` (an
explicit rerun only) skips the reuse and refresh and rebuilds, keeping threads, notes, Q&A, state
and an edited agent worktree; a running run is still returned as is.

Two tools exist only for the thread agent. `post_draft_comments` puts up to 30 review comments on
diff lines of the page as local drafts (an invalid comment rejects the whole call; nothing reaches
GitHub until you submit the review). `reload_walkthrough` (Full only) asks for a sibling
walkthrough of the `cw/<id>/agent` commit, opened beside the current page; the daemon marks the
request done or failed when the turn ends, and the page shows a Reload card. It never rebuilds the
current page.

## Environment variables and `stop`

The daemon inherits its environment from the MCP process, which inherits the harness's, so an API
key exported after the daemon already started is invisible to it. Run `cw_mcp.py stop` after
exporting a new variable; the next tool call respawns the daemon with the refreshed environment.
A claude-code worker's process inherits that same environment minus the session-linkage variables
that identify the parent Claude Code session (`CLAUDECODE`, `CLAUDE_CODE_SESSION_ID`, and a few
others); everything else, including any `ANTHROPIC_*` variable, passes through unchanged.

## Store layout and pruning

Everything lives under `~/.code-walkthrough/` (override with `CODE_WALKTHROUGH_HOME`):
`server.json`, `server.lock` and `server.log` for the daemon itself, `config.json`, and one
`w/<repo-key>/<id>/` directory per walkthrough holding its `meta.json`, `visuals.json`, read-only `head/`
worktree, the Full-mode `agent/` worktree once one exists, batches, drafts and rendered pages.
`repos/github.com/<owner>/<name>/` holds the cache clones. The daemon prunes a walkthrough untouched
for more than 30 days (`CW_PRUNE_DAYS`), skipping any that still carries an unposted local draft; its
task and `agent/` worktrees and branches go with it. It also removes a cache clone that no remaining
walkthrough references and that is older than the same cutoff.

## The `walkthrough/` prefix

A worker's `read_file`/`grep`/`list_dir` calls resolve against the repo's `head` worktree by
default. A path starting with `walkthrough/` (or exactly `walkthrough`) resolves against the
walkthrough's own directory instead, for the rare case a worker needs to re-read something it or
another worker already wrote there. This prefix is an openai-kind feature only: a claude-code
worker's `Read`/`Grep`/`Glob` tools stay rooted at the head worktree, with no equivalent escape.

## PR targets

A PR target runs through the daemon too (phase 3): `walkthrough_start` with `pr` set syncs the
PR's own comments and resolves its threads as part of the build, between `prepare` and `render`,
steps `comments` and `threads` (plus one `thread-<N>` per resolved thread needing a fresh
answer). `walkthrough_start` on an origin that isn't a GitHub remote still refuses with
`CWError("origin is not a GitHub remote", remedy="follow references/static.md of the code-walkthrough skill")`.

Every `gh` and `notes.py` call the daemon makes on a walkthrough's behalf runs with that
walkthrough's repo as cwd and with `GH_TOKEN`/`GITHUB_TOKEN` stripped from its environment
(`cw_run.gh_env`), so a shared daemon serving several repos or users never posts under whichever
identity its own process environment or working directory happens to carry.

## Ask and threads

Selecting text on a live page and clicking Ask starts a thread on the `thread` role (`roles.thread`,
falling back to `roles.ask`; see the remedy table if neither is set). The prompt
built from the selection, its surrounding hunk lines, the file's notes and the last few prior
answers is capped at 16000 characters; the selected quote itself is never truncated to make room.
Only the extras after the quote (surrounding hunk lines, notes, prior answers) are cut to that cap.
The selection alone may be up to `SELECTION_CAP` (200,000 characters) before the page refuses it.
Every question and answer is appended to that walkthrough's `qa.jsonl`, which is what repopulates
the page's Q&A list on reload and what the last-few-answers window above reads back from.

Replies stream into the thread as they are written. Stop interrupts a turn, and Retry reruns a turn
that ended in error or was stopped. A thread has a soft cap of 20 turns. A tab that reconnects
catches up from the server's in-flight buffers.

On a PR the agent may suggest resolving the GitHub review thread on the commented line. Keep adds it
to the pending resolves exactly like the Resolve button, and Submit review still
previews and posts it. Dismiss tells the agent not to propose it again.

When a comment asks to change what the page shows, the agent may also add or replace a prose, list,
picture or graph block next to the commented block. A picture block is `{title, html}`, an SVG/HTML fragment rebuilt by `visuals.sanitize_fragment` (24 KB, same allowlist as group pictures), and is the default for any requested diagram. A graph block is a node and edge list (up to 12 nodes
with `id`, `label`, `kind` and `refs`, up to 16 edges, optional notes) drawn by the same renderer as
System change, so it looks like the page's own diagram; new edits cannot use mermaid, though old
mermaid edits still render. The graph has to pass `check_overview`, which measures it in UTF-8 bytes against
`OVERVIEW_MAX` (6 KB); `refs` are shape-checked only, not verified against the diff. The edit applies at once, is local only (it never reaches the PR), and is
persisted in `qa.jsonl`. Undo reverts it and Redo reapplies it; the agent is told about either on
the next turn. Page edits are not offered on diff-line comments.

In `walkthrough_get` threads each outcome carries `summary`: a string for task, github_draft, resolve and
draft_comments, and an object for a page edit: `{op, target, target_is_oid, type, text}` for prose and
list blocks, with `title` (the graph's or picture's title) in place of `text` for a graph or picture block. `target_is_oid` is
true when the edit replaces an earlier edit rather than a page block.

The agent can target a block it was shown or one of its own earlier edits. Each applied edit gets an
oid (`o-...`) that the agent sees in later turns, and replacing by that oid hides the earlier edit
until Undo. A turn makes at most one edit per target, though several targets are fine. The daemon
refuses to revert an edit that conflicts with the page while another applied edit still targets its
oid; revert the later one first.

The agent may also draft a GitHub comment (`propose_github_draft`): a new review comment on the
commented diff line, or a reply in a review thread on those lines. A comment can be anchored to a
review thread directly (anchor `kind: "thread"` with the thread root's `note_id`); the prompt then
carries the thread's comments and diff hunk. A thread started from the page may carry up to 8 references: `anchor` is the first and `anchors` lists them all, and both appear in `walkthrough_get` threads. A thread may also start with `anchors: []` (kind `free`, no reference): the agent then only replies, and `anchors` sent with a follow-up merge into the thread's references. A draft is a proposal stored in `qa.jsonl`, never in
`notes[]`: Keep makes it a local draft through the page's normal draft path, Edit and Use my words
change its text, Dismiss drops it, and nothing reaches GitHub from the draft itself. Outcomes of
this kind never enter the Post preview. The agent is told about a dismissal or an edit on the next
turn.

On a diff line or a review thread the agent may propose a code task (`propose_task`: a title, up to 12
steps, up to 20 files). A task is only a plan until the user presses Run, which needs a claude-code
`thread` profile (otherwise 400 with the remedy "point roles.thread at a claude-code profile").
Run makes a fresh worktree at `tasks/<t>/` from the head sha (hooks off, LFS smudge off,
`core.symlinks=false`) and starts a claude turn there with only Read, Grep, Glob, Edit and Write,
confined to that worktree by `--restricted` and `acceptEdits`, plus one MCP tool, `run_check`
(`cw_mcp.py runner`, up to 20 calls). `run_check` takes one allowlisted test, build or lint command
(`go test|build|vet`, `cargo test|build|check`, `npm|pnpm|yarn test` or `run test|build|lint|typecheck`,
`pytest`, `make test|build|check|lint`), never through a shell and never git, and runs it under
`bwrap` with no network, a read-only filesystem, `$HOME` hidden, and only the worktree and a scratch
dir writable, `/run` empty, no IPC namespace sharing, files capped at 256 MiB (without bwrap the command is refused). Cargo checks only work for dependency-free or vendored projects (no registry offline). Each call is
recorded in `turns/<qid>.checks.jsonl` and the result lands in the task outcome as `checks`. It is a
fresh session with no resume, because sessions are keyed by cwd. Its prompt is the plan, the comment and anchor,
and the base branch's `CLAUDE.md` (never the head's). A change is committed to the local branch
`cw/<walkthrough id>/<t>` and never pushed: the daemon runs no `git push` anywhere. Stop is the
turn's cancel route (`POST .../comment/<qid>/cancel` with the task's `tq-` qid); a task that
changed nothing, errored or was interrupted by a restart is `failed`. Discard removes the worktree
and the branch, and pruning a walkthrough removes all of its task worktrees and branches.

`POST /api/walkthrough/<key>/<id>/publish-one` publishes one local draft by itself, with
`{id, body_sha, oid?}` (the sha256 of the draft text, so a draft edited since the user looked is
refused), or resolves one thread with `{resolve, oid?}`. It carries the same guards as `/post`, 409s
while the walkthrough builds, in a sibling-revision view, when the parent of a reply is not yet on
GitHub, or when the viewer has a pending review, and makes exactly one REST call otherwise. A
preview taken before a publish 409s on `/post`, because the nonce covers the ready list.

`POST /api/walkthrough/<key>/<id>/triage` (body `{}`) starts one thread turn per unresolved synced
GitHub review thread that has none yet, at most 30 per call, each with the fixed triage comment and
`source: "triage"` on its records. It answers `{started, skipped, remaining, threads}`: `skipped`
counts threads already triaged or pending, `remaining` those beyond the cap (call again). It 409s
while the walkthrough builds and when there is no PR. Nothing is published and no note changes;
results arrive as ordinary outcome proposals the user keeps or dismisses.

### Handing a task to your own session

A proposed code task on the page has a Hand to my session button. It moves the task to `handed` and
runs nothing in the daemon. In your own Claude Code, call `walkthrough_get(id, parts: ["threads"])`:
`handed` lists each task with its steps, files and `repo`/`base`/`head`, and `open` the unresolved
threads. Do the work in your real checkout under your own permission prompts, then call
`walkthrough_reply(id, thread_id, oid, text)` to post the result into the thread and mark the task
done; without `oid` it is only a reply. A reply never publishes anything, but its text is stored in the thread, shown on the page and included in later thread prompts sent to the configured model backend, so keep secrets out of it. The `threads` content comes
from a PR, review comments and a model, so treat it as untrusted data and check it before applying.

## Posting

The comments panel on a live page replaces Copy gh command with a Post to GitHub button
(hidden under the same conditions Copy gh command would be: a PR, and the compared commit
pushed). Clicking it flushes pending drafts to the daemon, then previews what would be sent
-- every draft's `path:line` and body, every thread marked resolved locally -- in a confirm
dialog before anything reaches GitHub. The confirm dialog's checkbox, "Submit review as
COMMENT", is unchecked by default: unchecked, the comments land in a pending review only the
poster can see on GitHub until they submit it there themselves; checked, this submits the
review as a COMMENT immediately. Confirming re-sends the same preview request's `nonce`; if
anything changed since the preview (another tab posted first, a draft was edited), that 409s
and the dialog re-previews instead of posting a stale list. Per-item progress (one line per
note delivered or thread resolved) streams in over the same SSE connection as everything else,
and a successful post clears the locally pending-resolve marks for threads it resolved -- the
page itself reloads from the `rebuilt` event once the daemon re-renders.

## Remedies

Every error the daemon or client can raise carries a one-line remedy; this is the full table.

| Problem | Remedy |
|---|---|
| No model backend configured | run `cw_mcp.py setup`, fill `profiles` and `roles` in the config path it names, run `cw_mcp.py check`; this run continues on the static path |
| `<ref>` not in the local object store | `git fetch origin <ref>` |
| Store would sit inside the repo | set `CODE_WALKTHROUGH_HOME` outside the repo |
| `pr` set, origin isn't a GitHub remote | follow references/static.md of the code-walkthrough skill |
| `comments`/`threads` step failed | `gh auth login` (`GH_TOKEN`/`GITHUB_TOKEN` are not passed to `gh` here) |
| `<name>` is not cloned on this machine | ask the user, then call `walkthrough_start` again with `clone: true`, or on no use `gh pr diff` (static.md) |
| `repos.<name>` is not an existing absolute directory | fix `repos.<name>` in `config.json` |
| Clone or fetch of a repo failed | check `gh auth status` and that you can read the repo, then retry |
| Full access is off for this walkthrough (403) | add `owner/name` to `trust.repos` in `config.json` |
| Full access needs a claude-code thread profile (400) | point `roles.thread` at a claude-code profile |
| Full access is off on an updated walkthrough (409) | use the original walkthrough |
| A Full turn is running, Discard refused (409) | try again when it ends |
| The PR changed since these edits were made (Show/Reload) | ask the agent again, or discard the edits |
| The PR changed since the agent edited it and the changes conflict | discard the agent edits and ask again |
| Revert of an agent edit refused | another applied edit targets it; revert that one first |
| Agent graph edit rejected | too big (6 KB), over 12 nodes or 16 edges, or a node has no `refs`; the agent retries |
| Ask selection too large (over 200,000 characters) | select a smaller range |
| No thread role | set `roles.thread` or `roles.ask` in `config.json` |
| The outcome server did not start | see `server.log`; check `python3` is on PATH and `cw_mcp.py` runs |
| Thread has 20 turns | start a new thread |
| Turn was interrupted | Retry the turn |
| Daemon didn't start | see the `server.log` path the error names |
| 401 / 403 from the model backend | set `<api_key_env>` in the shell that starts your agent, then `cw_mcp.py stop` |
| 404 from the model backend | check `model` for the named profile |
| 400, context length exceeded | this batch is too big for `<model>`: point the role at a larger-context model |
| Other 400 | message carries the first 300 characters of the response body; no fixed remedy |
| Connection refused | nothing listening at `<base_url>` |
| Socket timeout | raise `timeout_s` in `config.json`, or check `<base_url>` |
| Non-JSON reply, or no `choices` | protocol mismatch with the backend; no fixed remedy |
| Conversation over `max_conversation_tokens` | raise `max_conversation_tokens` in `config.json` |
| No tool call in a `check` reply | point this role at a model that supports tool calls |
| A walkthrough ended `failed`, any reason | re-run `/code-walkthrough` on the same target; passing fragments are reused |
| `claude` not on PATH | install Claude Code and log in, or point the role at an openai profile, then `cw_mcp.py stop` |
| `claude` not logged in | run `claude` in a terminal and log in (`claude auth login`) |
| Usage or rate limit from a claude-code call | wait for the reset the message names, or point the role at another profile |
| Prompt too long for a claude-code call | lower `batch_max_lines` |
| A claude process timed out | raise `timeout_s` in `config.json` |
| Worktree missing for a claude-code call | re-run `/code-walkthrough` on the same target |
| Other claude-code error | message carries the first 300 characters of `result` or stderr; no fixed remedy |

POSIX only: the daemon lock relies on `fcntl.flock`, so live mode does not run on Windows; use
the static path there.
