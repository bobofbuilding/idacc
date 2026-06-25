# Changelog

All notable changes to **ID Agents Control Center** are recorded here, newest
first. Versions track the desktop app (`idctl-desktop/package.json`); the
`idctl` TUI shares the same backend and version line.

Every change pushed or merged to `main` carries its version number in the commit
subject (`vX.Y.Z: …`), stamped automatically by the `commit-msg` hook — see
[CONTRIBUTING.md](CONTRIBUTING.md).

## [0.1.164] — 2026-06-25
- **Retired the managed-secrets `.gitignore` standard (reverts 0.1.154 + 0.1.163).** It appended a
  tool-branded secrets block to every project and auto-committed it — but every repo already ignored
  `.env`, so the block was redundant noise, and stamping the tool's name into others' repos was just
  confusing. Removed the auto-add/auto-commit entirely; repos own their own `.gitignore`. The blocks
  already committed to the project repos were reverted by hand.

## [0.1.163] — 2026-06-25
- **The secrets-gitignore standard now commits itself — no more “uncommitted in every project.”**
  `ensureSecretGitignore` added a managed `.gitignore` block to every project but never committed it,
  so all 12 projects sat perpetually dirty. The standard now **commits** the block the moment it adds
  it (scoped to only `.gitignore`, never sweeping in unrelated work) and best-effort pushes it to the
  current branch — a protected branch / offline / no-upstream just leaves it committed for the next
  sync. Idempotent: it self-heals each repo exactly once. (Existing dirty `.gitignore`s were committed
  and pushed manually as part of this fix.)

## [0.1.162] — 2026-06-25
- **Dependencies are now ENFORCED at dispatch, not just drawn on the board.** The Work pipeline's
  wave-dispatch used to release a dependent task as soon as its prerequisite was *handed out* — so the
  manager (which has no deps field) could complete an aggregation task before its inputs existed. A
  dependent now waits for each prerequisite to actually **complete** (the manager reports it done)
  before it runs. This also serializes each owner's tasks by completion — one agent finishes a task
  before its next is dispatched, which keeps local-model agents from thrashing a single GPU. A
  generous per-task safety deadline prevents a wedged prerequisite from deadlocking the chain.
- **Out-of-order completions are surfaced.** A task that finished while a prerequisite is still
  pending now shows a red **“⚠ ran before #…”** badge (instead of a muted line), so a dependency that
  was bypassed before this fix is visible and can be re-verified.

## [0.1.161] — 2026-06-25
- **Per-agent reasoning effort, to stop burning subscription tokens.** New **Effort** column in the
  fleet grid lets you set `low` / `medium` / `high` (or `default`) per agent. The choice is stored on
  the agent (`metadata.effort`), injected as `ID_AGENT_EFFORT`, and applied on rebuild: codex passes
  `-c model_reasoning_effort`, the Claude Code CLI passes `--effort`. Lower effort = fewer tokens spent
  per turn. The control shows **—** for `ollama`/`cursor-cli`, which have no reasoning-effort knob —
  local models don't consume subscription tokens, so effort isn't relevant there.

## [0.1.160] — 2026-06-25
- **The team lead floats to the top of its group** in the HR-Manager / Health fleet grid. The
  actual ★ coordinator (even a custom one like `researcher`) now sorts first within its team, not
  just an agent literally named "lead".
- **Local-model token usage is now self-refreshing.** Removed the Refresh button; it auto-updates on
  the fleet poll and every 15s (so new agents/models and fresh generations appear on their own), with
  a live **“updated Ns ago”** timestamp in its place.

## [0.1.159] — 2026-06-25
- **Blocked tasks now actually auto-move to Holding Pattern.** Fix: a dispatched task carries a
  stored `doing` lane overlay, and `laneOf` was checking that overlay *before* the blocked check —
  so a task that became blocked stayed in **Doing** (showing 🔒 blocked / ⏸ waiting but in the wrong
  column). Blocked states now take precedence over a stored lane: dependency-blocked → **Holding
  Pattern**, decision-blocked → **Adjustment Loop**, and a manual placement only applies once the
  task is unblocked. So a task transitioning to blocked drops into Holding automatically.

## [0.1.158] — 2026-06-25
- **Local-model token usage: accuracy fix + all local models.**
  - **Accuracy:** the per-agent "total tokens" was **output-only**, so it didn't sum to the 24h/7d
    window total (which is input+output). Now per-agent (and per-model) totals are **input+output**
    and **reconcile exactly** with the window total (verified live: 6 agents summed to 72,190 =
    the 24h total). New per-agent `input`/`total` fields.
  - **All local models:** added a **By model · 24h** breakdown — the `ollama` runtime is the umbrella
    for Ollama / LM Studio / any OpenAI-compatible local server, so this already covers every local
    model (e.g. qwen3:4b / qwen3:1.7b). Panel relabeled accordingly.
  - Manager-side (`/usage`) now tracks per-agent input and emits a per-model breakdown (patch saved
    under `brain/control-center/patches/`; reapply after an id-agents reinstall).

## [0.1.157] — 2026-06-25
- **Inbox decisions are ordered by dependency** — a prerequisite task's decision now sorts before
  any decision that depends on it (depth over the `taskDeps` graph, stable for unrelated items), so
  you answer them in the order that actually unblocks the chain.
- **Decision layout reflows:** the agent's options are listed **top-to-bottom, left-aligned**, with
  **✎ Comment · 🛠 I'll handle it · Skip** underneath them (instead of all in one wrapped row).

## [0.1.156] — 2026-06-25
- **Adjustment-loop state machine for tasks blocked on a USER decision.** A task moves through the
  board automatically as its Inbox decision is handled:
  - decision raised for it → **Needs Adjustment**;
  - you respond (option / comment / “I’ll handle it”) → **Under Review**;
  - it gets blocked again → **Rework**;
  - the block passes (task completes, or it’s been Under Review and progressing for 10m+) → it
    returns to **Holding / To Do / Doing** as fits.
  Dependency-blocked tasks still sit in **Holding Pattern** (unchanged). A manual drag or **Skip**
  clears the state. Cards show **⚖ needs your decision / 👁 under review / ↻ rework** badges. New
  app-side `taskReview` overlay + `tasks:review`/`setReview`. (Transitions verified, incl. the
  re-block→rework promotion.)

## [0.1.155] — 2026-06-25
- **Plan blockers/decisions now land in the Inbox, not the plan card.** The ▶ Work pipeline's
  blocker scan now returns structured decisions (each with the agent's 2-4 **best options**) and
  files them in the Inbox's **“Decisions needed.”** The plan card shows only a compact `⚠ N → Inbox`
  pointer.
- **Inbox decisions are now answerable three ways:** pick a **best option**, **✎ Comment** a free-text
  response/instructions, or **🛠 I'll handle it** — which tells the agent you're doing it manually so it
  sets the item aside and won't re-raise it. (Plus Skip.) Each delivers back to the blocked agent.

## [0.1.154] — 2026-06-25
- **Secrets are gitignored as a standard, everywhere.** New `ensureSecretGitignore` appends a managed
  block (`.env`/`.env.*` keeping `.env.example`, `*.pem`/`*.key`/private keys, `*.keystore`,
  `service-account*.json`, `.netrc`, `.pgpass`, …) — applied automatically on **link**, **create
  repo**, and **before every commit request**. The commit instruction also teaches git-manager to
  gitignore + `git rm --cached` any tracked secret and **never commit one**.
- **GitHub token lookup is now resilient to naming.** `githubToken()` matches any MCP server whose
  name contains "github" (e.g. `github pat`, `github-mcp`) or that carries a
  `GITHUB_PERSONAL_ACCESS_TOKEN`, then falls back to the env — so a server-name quirk can't silently
  break GitHub auth (which is exactly what caused the earlier "API 404" link failure).

## [0.1.153] — 2026-06-25
- **🔗 Link existing repo no longer fails on a missing/expired GitHub API token.** It now confirms
  reachability via **SSH/HTTPS `ls-remote`** (the transport git actually uses) when the API can't —
  so a reachable private repo links even with no API token. Fixes "Link failed: GitHub API 404" for
  repos you can reach over SSH. `githubToken()` also falls back to `GITHUB_PERSONAL_ACCESS_TOKEN` /
  `GH_TOKEN` env vars. (Create-repo and Fork still need a real API token — those are API-only.)

## [0.1.152] — 2026-06-25
- **▶ Work now PARTITIONS the plan across teams instead of duplicating it.** The compile step
  decomposes the plan **once**, groups the sub-tasks into **dependency clusters** (interdependent
  tasks stay together so ordering is honored), then spreads the clusters across every active team
  **weighted by capacity** (running-agent count). Independent clusters run in parallel on different
  teams; each team balances its slice across its own agents. One plan → split across the whole
  active fleet, never duplicated. (Verified: no task assigned twice, all deps kept within a team in
  valid order.)

## [0.1.151] — 2026-06-25
- **Plans: one ▶ Work button** replaces the three brain-plan actions (Audit status / Find blockers /
  Compile & dispatch). It runs them as a unified pipeline: ① **audit** the plan's real status →
  ② **scan for blockers** → ③ **compile into tasks + dispatch to EVERY active team & agent
  automatically** — the primary team gets trackable task cards (auto-assigned), every other active
  team gets the plan handed to its lead in parallel. **No team picker** — work is delegated and
  assigned as needed. One live toast shows all three phases.

## [0.1.150] — 2026-06-25
- **Self-healing, standardized git guards** so the commit/sync process stays clean across every
  project:
  - **⇩ Pull is now resilient (`smartPull`).** It fetch-prunes, then: a live upstream → `pull
    --ff-only`; an **orphaned branch whose remote was deleted after a merged PR** → switches back to
    the default branch, fast-forwards, and drops the stale branch; a default branch with no upstream
    → sets it + ff; an **orphaned branch with UNMERGED work** → left untouched with guidance (never
    loses work). It never force-pushes or auto-merges. Validated against both the merge-deleted and
    unmerged scenarios.
  - **Projects flag it:** an orphaned branch shows **⚠ orphaned branch · Pull to heal** in the git
    status.
  - **Commit requests carry the same standard procedure** — git-manager is told to fetch, get OFF a
    `[gone]` branch onto the default branch, pull-then-commit-then-push, so agent-driven commits
    self-heal too.

## [0.1.149] — 2026-06-25
- **Projects are owned by the DEFAULT team, which delegates git work to git-manager.** New projects
  (New / Import / clone / fork / Sync) now default to **`default`** (was ops-team). Commit requests —
  manual **and** checkpoint auto-commit — route to the **project's team lead**, who DELEGATES the
  actual commit & push to **git-manager** (cross-team `/ask ops-team/git-manager` when needed), with
  the pull-first-then-commit instruction preserved. So the owning team coordinates and the
  responsible agent executes.

## [0.1.148] — 2026-06-25
- **New projects default to the ops team** (holds git-manager) — New project, Import folder, Add
  from GitHub (clone/fork), and Sync workspace all assign `ops-team` by default (editable). So every
  project going forward can commit/push + checkpoint-auto-commit out of the box.
- **The Work board now runs on auto-pilot — manual buttons removed.** Triage, re-dispatch-stalled,
  and surface-blockers all fire automatically:
  - **Auto-triage** unassigned To-Do tasks across **every** team (each team's lead assigns to active
    agents), ~90s cadence.
  - **Auto-re-dispatch stalled** tasks (stuck >30m, excluding blocked) to a different active agent, ~6m.
  - **Auto-surface-blockers**: if work stays stuck, the lead surfaces decisions to your Inbox, ~30m.
  - A single-flight lock + per-action cooldowns keep it from hammering the fleet; a passive
    **⚙ auto-pilot** status (with live to-triage / stalled counts) replaces the buttons. Removed the
    **Triage**, **Re-dispatch stalled**, **auto** toggle, **Surface blockers**, and **Clear archived** buttons.

## [0.1.147] — 2026-06-25
- **Projects: checkpoint auto-commit.** Per-project **⟳ Auto-commit** dropdown — **off / on any task
  done / on plan validation**. When a (matching) task completes in the project's team and the repo
  has uncommitted changes, the app auto-drafts a commit message (lead reads the diff) and routes a
  commit & push to ops-lead — the same pull-then-commit flow as the manual button. Baselines on
  enable (existing done-tasks don't fire), only fires when dirty, throttled to once / 10 min per
  project, needs a `team` + `path`. New `autoCommit` field on projects.

## [0.1.146] — 2026-06-25
- **Projects: link an existing repo, clearer git buttons, combine duplicates, pull-before-commit.**
  - **🔗 Link existing repo** (on folder-only projects): connect a folder to a repo that ALREADY
    exists on GitHub — verifies it, sets `origin` (SSH), and fetches. (Sits beside ＋ Create repo.)
  - **Git buttons relabeled** for clarity: **⤓ Fetch**, **⇩ Pull**, **◔ Status**, **☰ Log**, **± Diff**,
    each with a tooltip spelling out the exact `git` command and what it does.
  - **⧉ Combine duplicates** (header, shown only when dupes exist): merges projects that point at the
    same folder/repo into one — keeps the richest entry, unions tags/links/notes, drops the rest
    (folders untouched). Resolves same-name/same-repo doubles like NFTFactory ⊕ nftfactory.
  - **Up-to-date before commit:** the Request-commit instruction now tells ops-lead to fetch + pull
    (or rebase) onto the latest remote BEFORE committing, so changes never land on a stale base.
  - New bridge: `project:linkRepo`.

## [0.1.145] — 2026-06-25
- **Projects: AI-assisted commit requests + create/fork GitHub repos.**
  - **⤴ Request commit** is now an inline composer with **✨ Draft with AI** — the team lead reads
    the project's working diff (`project:diff`, truncated) and drafts a commit message (subject +
    bullets) you review/edit before routing the commit task to ops-lead.
  - **＋ Create GitHub repo** appears on any folder-only project (no remote): names + creates a repo
    via the GitHub API and connects it as `origin` over SSH (`git init` if needed; never auto-pushes,
    so secrets/node_modules don't leak — the composer opens so you push with a good message).
  - **Add from GitHub → Fork & clone**: forks a repo to your account, clones the fork, and wires the
    original as `upstream`.
  - GitHub API calls authenticate via the github MCP token (Authorization header only — never argv);
    git remotes use SSH (token never embedded). New bridge: `project:diff`/`createRepo`/`fork`.

## [0.1.144] — 2026-06-25
- **Blocked tasks wait in Holding, not Doing.** A task with an unfinished prerequisite no longer
  sits in the Doing lane — `laneOf` parks it in **Holding Pattern** until its prerequisites
  complete, then it flows back automatically. Knock-on effects: blocked tasks are excluded from
  **stalled** detection / re-dispatch (they’re waiting, not stuck) and from **Triage**/unassigned
  counts (the `todo`-lane filters skip them), so nothing dispatches a task that can’t start. Cards
  show a blue **⏸ waiting** badge instead of “working/stalled”.

## [0.1.143] — 2026-06-24
- **Plans now show created/updated timestamps.** Draft plans display **created … · updated …**
  (relative, with exact local date-time on hover) on each card, plus an explicit created/updated/
  version line in the expanded detail (the data was already stored — `PlanSummary` just didn’t
  expose `createdAt`). Brain plans now show **updated &lt;ago&gt;** from the plan file’s mtime
  (`listBrainPlans` stamps each with `mtime`).

## [0.1.142] — 2026-06-24
- **Task dependencies are now visible on the board.** When Plan decomposition creates tasks with
  “after #N” edges, those are persisted app-side (`taskDeps` overlay — the manager has no deps
  field) and each card shows **⇢ after &lt;ref&gt; ✓/⏳**, turning into an amber **🔒 blocked** when a
  prerequisite isn’t done yet. Cards that others depend on show **· blocks N**. A removed
  prerequisite counts as satisfied (never blocks forever). New bridge: `tasks:deps`/`tasks:setDeps`.
  Note: only plans decomposed from this version on record edges; pre-existing tasks show none.

## [0.1.141] — 2026-06-24
- **Work › Create is now a 5-mode creator** (was just auto-decompose). The fold-out has a mode
  switch — all decoupled per team:
  - **Plan** — auto-decompose an objective into balanced sub-tasks (the original flow).
  - **Assign** — hand a task to chosen agent(s); creates one task per agent and dispatches now,
    keeping the exact owner (`work:createPlan` gained `respectOwners`).
  - **Schedule** — recurring check-in (interval or calendar days/time) with talk/internal delivery.
  - **Loop** — re-run a standing objective every interval (internal wake → review/next-step/report).
  - **Dream** — a slow, no-deadline background aspiration the agent advances in spare cycles.
  Schedule/Loop/Dream ride the manager's `/schedule` surface (team-routed `addHeartbeat`/
  `addCalendarCheckin`) and show up in the Schedule tab (pause/stop there). Toolbar button renamed
  **⚡ Create work**.

## [0.1.140] — 2026-06-24
- **Dashboard activity feed now truly spans all teams (and is live, not stale).** Two bugs in
  the holistic `events:multi` aggregator: it fetched each team's **oldest** events (`since=0`
  returns the start of the log → every row was hours old), and a single hyperactive team could
  fill all 80 slots. Now it **probes each team's latest seq and fetches its newest events**, with
  a **per-team cap** (`max(8, ⌈limit/teams⌉)`) so every team is represented; the union is then
  time-sorted. Verified live: feed shows a fair mix across teams with recent timestamps.

## [0.1.139] — 2026-06-24
- **Cleanup:** removed the dead `CreateTeamModal` (~200 lines) left over from the Build-page
  consolidation — the unified inline `TeamBuilder` replaced it. No behavior change.

## [0.1.138] — 2026-06-24
- **Per-page team pickers — nothing rides on a global "active team" anymore.**
  - **Dashboard** has a "talk to" picker: choose which team's **lead** you chat with (each option
    shows the team's lead; the manager's active team is marked). The chat, its sessions, and every
    dispatch now scope to the chosen team — switching teams elsewhere no longer hijacks this chat.
  - **Work › Assign** has a **team** selector above the lead. Decompose, create-plan/dispatch, and
    **Triage To Do** all act on the chosen team; the unassigned-To-Do counts scope to it too.
  - Plumbing: `dispatch:start`, `work:decompose`, `work:createPlan`, and `work:triage` now take an
    optional team and route via `withTeam(...)` (queries stay global by id).
  - **Dashboard activity feed is now holistic** (every team's events, each row tagged `[team]`),
    matching the all-teams model — no longer pinned to one team's stream.

## [0.1.137] — 2026-06-24
- **Team pickers list only active teams.** The Build form's existing-team selector and the
  Capabilities team dropdown now show only teams with **running agents** (idle teams hidden) —
  matching "only track active teams." (New-team name collision-checks still consider every team.)

## [0.1.136] — 2026-06-24
- **HR Manager → Build is one inline form (no popouts).** The Build tab now renders the team
  builder inline: pick a team (**new or existing**), **start from** a library template/saved
  config (prepopulates the description) or describe with AI, review the roster, and build —
  all in place. The separate "+ From template" / "Build a team" / "Build & add agents" popout
  buttons are gone.
- **Removed the "Coordinator preset" button** from HR Manager (Structure + Manage); use **✦ AI
  draft** to generate lead instructions instead.
- **Capabilities defaults to "All teams"** (all-teams is the standard per page now).

## [0.1.135] — 2026-06-24
- **Re-dispatch actually recovers stalled tasks now.** A stalled task is handed to a *different*
  active agent (not the original owner) — because the owner can be **wedged while still reporting
  "running"**, which is exactly why the task stalled. The bulk re-dispatch spreads the batch
  across agents. (If an agent is wedged, also Rebuild it from the Health fleet grid.)
- **Dropped the "all teams" labels + show only active agents.** The status bar now reads just
  **N agents active · K teams running**; the Health **Fleet** grid shows only **running** agents
  by default with a **show stopped (N)** toggle to reveal/start the rest.

## [0.1.134] — 2026-06-24
- **Fix self-update "github 403".** The updater no longer hits the rate-limited
  `api.github.com` (60 unauthenticated requests/hour) for the version check — it resolves the
  latest release via the `github.com/<repo>/releases/latest` redirect (no such limit) and
  downloads the asset by direct URL. The API is only a fallback, and a 403/404 there is now
  treated as "nothing to update this cycle" instead of a red error.

## [0.1.133] — 2026-06-24
- **All-teams is now global — no view toggle.** Removed the status-bar view selector; the whole
  app (Dashboard, Health, Work board, HR graph, status counts) is permanently holistic across
  every team. The status bar just shows **★ all teams · N/M agents active · K teams running**.
  (Where a single team is still needed — the lead chat, Assign-work/Triage, Capabilities "This
  team" scope, HR Manager Build/Route — it follows the manager's active team, switchable from
  HR Manager and the Capabilities team dropdown.)

## [0.1.132] — 2026-06-24
- **Set the lead from HR Manager → Structure.** Selecting an agent in the team graph now shows a
  **★ make lead** button in its panel (★ when it's already the team's coordinator) — set any
  team's lead right from the structure view, same as the ★ in the Health fleet grid.

## [0.1.131] — 2026-06-24
- **Capabilities: apply across all teams / all leads.** The apply-to picker now has a **scope**
  selector — **This team / All teams / All team leads** — so you can attach an MCP server or
  install a skill across every team's agents (or just every team's lead) in one action. Each
  apply routes to the agent's own team; incompatible-runtime agents are still excluded.

## [0.1.130] — 2026-06-24
- **No more task pile-ups.** Decompose/compile and Triage now **spread** assignments across the
  active roster (best-fit up to a cap, overflow to the least-loaded agent) instead of dumping
  many tasks on one agent, and dispatch **one task per owner at a time** (sequential per agent)
  so a single agent is never hit with N concurrent /ask — the original cause of the stalled pile.
- **Fan out to all team leads.** The Work fan-out picker has a **★ All team leads** button that
  selects every team with a running lead in one click.

## [0.1.129] — 2026-06-24
- **Dashboard polish.** Activity tile is ~⅔ wider (340→560px) and its top now squares with the
  chat card (offset past the chat's control row) when no project is focused. Removed the
  "talking to lead · default" caption from the header. **Deleting a chat now asks to confirm.**

## [0.1.128] — 2026-06-24
- **Work board honors "All teams."** The Tasks Kanban was stuck on the active team even with
  "All teams" selected — now it shows **every team's tasks** (each card tagged with its team),
  and per-task actions (lane/status change, assign, delete, re-dispatch, clear) route to that
  task's **own team**. The assign dropdown lists the task's team's agents. (Lead-driven bulk
  actions — Triage / Assign-work / Surface-blockers — still operate on the active team's lead;
  the Triage count is scoped to the active team accordingly.)

## [0.1.127] — 2026-06-24
- **Re-dispatch stalled tasks.** Stalled cards (⏳, no update in 30m+) now have a **↻** button to
  re-send the task to its owner — and if the owner is stopped, it's auto-reassigned to an active
  agent first. A toolbar **↻ Re-dispatch stalled (N)** button does the whole batch at once. This
  answers "if tasks stall, how do I refresh them."

## [0.1.126] — 2026-06-24
- **Dashboard fixes.** The lead-chat controls are now one row in order **＋New · select chat ·
  focus · chat name**, and the **activity tile on the right is back** (explicit layout + its own
  scroll). The **Chat page was removed from the nav** — the Dashboard *is* the lead chat now.
- **Fleet grid moved to Health.** The agent table (runtime/model/actions/probe) now lives on the
  **Health** page (combined with the token-usage + probe tiles), not HR Manager.
- **Set the lead from the fleet grid.** Each agent row has a **★** — click it to make that agent
  its team's coordinator (lead). (The graph's "lead" is this per-team coordinator setting, which
  is why it could show a non-"lead"-named agent; now you can fix it in one click.)

## [0.1.125] — 2026-06-24
- **Projects: per-project "⤴ Request commit."** Each project with a path now has a button that
  routes a **GitHub-commit task to ops-lead** (commit + push that project's changes, init the
  repo if needed) — you describe the change, it creates the ops-team task + nudges the lead.
  Publishing per project now flows through the ops team, matching the release flow.

## [0.1.124] — 2026-06-24
- **Heavy models auto-hide.** Ollama models too big for your machine's RAM/disk are hidden
  from the catalog and collapsed under a **"show N models too heavy for this machine"** toggle
  at the bottom (installed ones always stay visible).
- **Port warnings de-noised.** Local-LLM-stack ⚠ now appears **only when a port is actually in
  use** right now — the "also default for N others" notices (not real conflicts) are gone.
  Help text + the in-use message clarified.
- **Subscriptions Re-check feedback.** The Re-check button now shows **Checking…** while it
  re-probes the CLIs, so you can see it's working.

## [0.1.123] — 2026-06-24
- **Health: runtime/model controls + live.** The Health roster is now the shared **AgentTable**
  — per-agent runtime/model dropdowns + lifecycle actions + per-row **Probe**, live and holistic
  (all teams grouped in "All teams" view). Probe routes to each agent's own team.
- **Token-usage labels clarified.** The gauge is labelled **throughput (rate) · last run**, and
  the by-agent column now reads **"N tokens · Nq"** (totals) and **"N tok/s avg"** (rate) — so the
  large per-run tok/s numbers aren't mistaken for totals.

## [0.1.122] — 2026-06-24
- **Dashboard is now your lead.** The Dashboard is a chat **locked to the team lead** (no
  agent picker) beside a slim, **properly-detailed** live activity feed (recent events with
  real descriptions — fixes the stale/terse feed from the holistic change).
- **Fleet grid moved to HR Manager** (Structure tab) and made **holistic** — it lists every
  team's agents grouped by team when "All teams" is selected, with per-agent runtime/model
  switching + lifecycle actions routed to each agent's own team. This is also the fix for
  "All teams didn't show all teams." (New shared `AgentTable` component.)

## [0.1.121] — 2026-06-24
- **Honest task status (no more false "working").** A task card only shows the green
  **● working** pulse when it *recently* entered Doing. A task left in Doing 30m+ with no
  status change now shows an amber **⏳ stalled Nh** badge (and "no update Nh") instead —
  so an agent that was handed work but stopped progressing reads as stalled, not "working."
- **Uninstall local models from the chip list.** Each installed Ollama model chip now has a
  ✕ (two-step confirm) to uninstall it, not just the catalog rows.

## [0.1.120] — 2026-06-24
- **HR Manager reorganized.** Team-creation (**+ From template** / **✦ Build a team**) moved
  from the page header into the **Build** tab; the **teams table** (switch/manage/delete) moved
  to the **Manage** tab; **Lead hierarchy & coordinators** moved to the **Route** tab. The
  **Structure** tab is now just the live team graph + selected agent/team panels, and the graph
  now updates in lock-step with the app's live all-teams poll (more reactive). _(First of a
  multi-part UI reorg — Dashboard, Health, Settings & Projects changes follow.)_

## [0.1.119] — 2026-06-24
- **Holistic "All teams" view by default.** The app now opens showing the **whole fleet**
  instead of a single team. The status-bar selector defaults to **★ All teams**; the
  **Dashboard** lists every team's agents grouped by team (each group headed
  `team · N/M running`), and the **activity feed** merges all teams' events (tagged by team).
  Per-agent actions in this mode route to each agent's own team. Pick a specific team from the
  selector to scope the action-centric pages (Work, Chat, HR Manager, Capabilities, Computer Use)
  as before; the choice is remembered across launches. Status-bar counts now read fleet-wide
  ("N/M agents active · K teams running") in All-teams mode.

## [0.1.118] — 2026-06-24
- **Plans organizer tweaks.** Renamed the "Brain plans" section (and the `brain:` filter
  label) to **"Plans"**, and moved **clear filters** to the far left of the filter row
  (always shown, disabled when no filters are active).

## [0.1.117] — 2026-06-24
- **Status bar shows active teams & agents.** The footer team selector no longer just
  lists teams by total size — each option now shows **running/total** with ● (has running
  agents) vs ○ (idle), **active teams sorted first**, and the trailing count reads
  **"N/M agents active · K teams running"** instead of a bare total. Makes it obvious
  which teams are live and switchable, not just that `default` is selected.
- **Product spec.** Added `docs/PRODUCT_SPEC.md` — a complete, page-by-page specification
  of the app as it ships, produced by reviewing every page.

## [0.1.116] — 2026-06-24
- **Lead triage of unassigned To Do tasks.** New **⚖ Triage To Do (N)** button on the
  Tasks toolbar: the team lead reviews every unassigned task in the To Do lane, assigns
  each to the best-fit **active** agent, and dispatches it to start work (Backlog/Holding
  waiting-lanes are left alone). An **auto** checkbox keeps the lead doing this for newly
  unassigned To Do tasks as they appear (throttled ~90s). A progress toast reports the
  result and survives page navigation.
- **Clearer Inbox.** The Manager-inbox card no longer claims "the manager is blocked on
  your reply" when nothing is waiting — it now reads **"nothing needs a reply right now"**
  when empty (and "N waiting on your reply" when there is), matching the empty state.

## [0.1.115] — 2026-06-24
- **Dispatch notifications you can't miss + leave the page freely.** Compile & dispatch,
  fan-out, and "Assign work to fleet" now raise a global toast that shows a spinner while
  working and updates to **✓ created N tasks / dispatched to <team>/<lead>** (or an error)
  when done. The toast lives above page routing, so the confirmation **persists even if you
  navigate to another page** — and the work itself was always running in the background
  (it's done in the manager process; switching pages never stopped it). Toasts auto-dismiss
  after a few seconds or on click.

## [0.1.114] — 2026-06-24
- **One compile/dispatch step.** Merged "Compile to tasks" and "Fan out to teams" on
  brain plans into a single **⤳ Compile & dispatch** picker. Check the **active team**
  (with a lane — its cards land on the board you're viewing) and/or any **other teams**
  (handed to their active lead, greyed out when none are running), then one **Go** does
  it all in parallel. No more two-button dance.

## [0.1.113] — 2026-06-24
- **Cross-team fan-out.** Hand one objective to several teams at once: in **Assign work
  to fleet** (Tasks) pick other teams to fan it out to, and on any **brain plan** use the
  new **⇄ Fan out to teams** button. Each chosen team's **active lead** gets the objective
  scoped to its own team (`/ask <team>/<lead>`) and runs it independently, in parallel —
  so you can drive ops-team, research, technology-security, etc. from one action, not just
  the active team.
- **Auto-route to active agents.** Assignment and decomposition now route only to agents
  that are actually **running** — the lead is told never to assign a `[STOPPED]` agent,
  stopped owners are auto-reassigned to a live one at dispatch, and teams with no running
  agent are reported and skipped (never dispatched into the void). Owner dropdowns mark
  stopped agents `· stopped`; the fan-out picker shows each team's live agent count and
  greys out teams that can't take work (e.g. skillmesh — 0/38 running). Below the full-width Adjustment Loop band, the **Waiting Areas**
  group is now ⅓ width and **Main Flow** ⅔ width (a 1:2 split that mirrors the
  Adjustment band on top). Lanes compress further before the row starts scrolling.
- **Richer task cards.** Each card now shows an **● working** pulse when an agent has
  actively claimed it (green-bordered), plus a fuller timeline — *created Xm ago*,
  *working Xm* (how long it's been in progress), and *done Xm ago* — each with the exact
  timestamp on hover. Assigned-but-not-started tasks read *◴ queued*.
- **Global team switcher.** The status bar's team label is now a dropdown listing every
  team (with agent counts). Switching it re-scopes assignment, task routing, and the
  activity feed to that team's fleet — so you can drive ops-team, research, skillmesh, etc.,
  not just `default`. (Cross-team routing *within a single decompose* is still a follow-up.)

## [0.1.111] — 2026-06-24
- **Adjustment Loop moved to the top.** The Needs Adjustment / Under Review / Rework
  band now sits as a full-width row above the Waiting Areas and Main Flow groups, so
  the rework path is the first thing you see on the board.

## [0.1.110] — 2026-06-24
- **Done tasks auto-archive.** Completed tasks now drop off the Kanban automatically
  to keep the board focused on active work — nothing is deleted (they stay `done` on
  the manager). A new **show archived (N)** toggle (and a **🗄 N archived · show**
  affordance in the Done lane) reveals them on demand. The old "Clear completed" button
  is now **Clear archived** — it still permanently deletes the completed ones.

## [0.1.109] — 2026-06-24
- **Compile a plan into a chosen lane, and let the lead run it.** "⤳ Compile to tasks"
  now asks which lane (Backlog / Holding / To Do / Doing). **Doing** → the lead
  auto-sorts the tasks into dependency order, assigns each to its agent, and dispatches
  them to work independently to completion (the board auto-updates as they progress).
  **Backlog / Holding / To Do** → the tasks are queued unowned in that lane (with the
  lead's suggested owner noted) for you to start later by dragging to Doing.
- **Blocker decisions now reach the Inbox.** New **⚠ Surface blockers** button (Tasks
  toolbar): the lead scans open tasks and, for any blocked on a decision only you can
  make, raises a multiple-choice question. These appear in the Inbox under **Decisions
  needed** with clickable options — picking one delivers your answer to the blocked
  agent and clears the question. App-side queue; no manager changes.

## [0.1.108] — 2026-06-24
- **Tasks board scrolls sideways.** The grouped lane board now scrolls horizontally
  within its card instead of stretching the page, so all three groups are reachable.
- **Dashboard Activity tile shows all events.** It was capped at the last 120; it now
  shows the full live event history (buffer raised 250 → 1000), scrollable, with a count.
- *(Cards already auto-reposition between lanes as a task's status changes — e.g. an
  agent claiming a task moves its card to Doing — via the board's 5s live refresh.)*

## [0.1.107] — 2026-06-24
- **Tasks Kanban is now a grouped, multi-lane workflow board.** Eight lanes in three
  groups — **Waiting Areas** (Backlog · Holding Pattern), **Main Flow** (To Do · Doing ·
  Done), and **Adjustment Loop** (Needs Adjustment · Under Review · Rework). Drag a card
  to any lane. Since the manager only stores todo/doing/done, the fine-grained lane is an
  **app-side overlay** that maps onto a real status (Backlog/Holding→todo;
  Doing/Needs-Adjustment/Under-Review/Rework→doing; Done→done) — so agents still see the
  coarse status, and if an agent changes a task's status the card falls back to that
  status's default lane.

## [0.1.106] — 2026-06-24
- **Three clearly-labeled per-plan actions** on each brain plan: **✦ Audit status**
  (verify vs codebase + write back), **⚠ Find blockers** (agent lists what's blocking
  it, shown inline), and **⤳ Compile to tasks** (decompose the plan into tasks and
  create them for the team — see the Tasks tab). Plus a **⏳ Set pending** button to
  reset a plan's status.
- **Auto-archive done plans.** Marking a draft "done" now auto-moves it to archived;
  done/archived plans (and brain DONE plans) collapse out of the active list into an
  **Archived** section, revealed with the **show archived** toggle.
- **Unified organizer bar at the top** — search, sort, group-by-status, show-archived,
  the **+ Request a plan** button (moved up), and all the status + tag filters (brain
  and drafts) now live in one bar covering both sets.

## [0.1.105] — 2026-06-24
- **Auto-check a brain plan's real status (the “why is everything PARTIAL?” fix).**
  The brain README hand-marks status, so it drifts — 33 of 60 plans sat at 🔄 PARTIAL,
  many likely stale. Each brain plan now has a **✦ check** button: an agent audits the
  plan against the actual codebase + its knowledge, returns a verdict (DONE / PARTIAL /
  PENDING + a one-line "what's done / what's left"), shows it inline, and **writes the
  verdict back to the README's Status column** so the index stays fresh. The write is
  surgical (only that row's status cell, atomic) and verified idempotent.

## [0.1.104] — 2026-06-24
- **Plans are now organizable.** A shared toolbar over both sets (brain plans + your
  drafts): **search**, **sort** (most-recent / title / status), and **group by status**.
  Each set has **status-filter chips** (Done/Partial/Pending/On hold for brain;
  draft/active/done/archived for drafts), and drafts gain **tags/categories** — assign
  them per plan and filter by tag.
- **Richer per-plan AI editing (drafts).** When a draft is open you can now **pick which
  agent revises** it, and **✦ Suggest improvements** asks that agent to propose concrete
  changes and drops them into the instruction box to review/edit before applying (still
  versioned with a changelog). Brain plans stay read-only.

## [0.1.103] — 2026-06-24
- **Updates surface faster + stop hoarding disk.**
  - **Auto-prune staged downloads.** Each applied update used to leave its ~100 MB zip
    in `staged-update/` forever (had grown to ~4 GB / 43 files); the updater now keeps
    only the pending download and removes the rest after staging.
  - **Default update check is now hourly** (was every 4h).
  - **Focus re-check debounce dropped to 1 min** (was 5 min) — clicking back into the
    app surfaces a fresh release almost immediately.

## [0.1.102] — 2026-06-24
- **Fix: Plans → Brain plans said "brain plans dir not found" even when configured.**
  The brain-plans reader called the projects-root detector with no argument, so it
  never consulted the **saved `projectsRoot`** (the one the Projects page sets). It now
  falls back to that setting, so the brain's live plan index loads as intended.

## [0.1.101] — 2026-06-24
- **New Dream tab (Work page).** An agent runs an offline "dream" — a reflection pass
  over its recent work and the shared brain — and returns a report with four sections:
  **Consolidation** (facts worth keeping), **Insights** (patterns), **Ideas** (proposed
  tasks/plans), and **Simulations** (speculative futures). **✦ Dream now** runs it on a
  chosen agent and saves the report as a morning digest; **Schedule nightly** sets up a
  recurring 03:00 dream. Per the research, Ideas &amp; Simulations are explicitly
  **proposals for review — nothing is auto-executed**. (Grounded in the dream-research
  brief: CLS/“sleep-time compute” consolidation + Generative-Agents reflection.)
- *Completes the Work-page overhaul: Kanban tasks, live brain Plans, Schedule cleaner,
  AI agent-chains, and Dream.*

## [0.1.100] — 2026-06-24
- **Loops can now string agents + tasks into an AI-drafted chain.** The Loops tab
  leads with **Agent chains**: describe a goal, hit **✦ Draft chain**, and an agent
  designs an ordered sequence of steps — each step = (agent + task). Review/edit the
  steps (reorder, swap the agent, rewrite the task, add/remove), then **Run** it: each
  step executes in order via `/ask`, and **every step's output is fed to the next as
  context**, with live per-step status + output. Chains are **saved and re-runnable**.
  The original single-agent recurring loop is still here, renamed **Scheduled
  objectives**.

## [0.1.99] — 2026-06-24
- **Plans now shows the brain's live plan set.** The Plans tab leads with a **Brain
  plans** section read straight from the brain's `plans/` directory (its `README.md`
  status index — DONE / PARTIAL / PENDING / ON HOLD — plus each plan file), **self-
  updating every 10s** as the brain edits its files on disk. Click any plan to read it
  inline. It's strictly read-only (the brain owns those files); your own AI-generated
  drafts live below under "Your drafts." The directory is auto-located from your
  projects root.

## [0.1.98] — 2026-06-24
- **Work page, part 1 of an overhaul:**
  - **Tasks is now a live Kanban board.** Three columns matching the manager's task
    states (To do / Doing / Done); **drag a card between columns** to change its status,
    and the board **auto-refreshes every 5s** so it stays current as agents claim and
    complete work. Search + hide-routine carry over; per-card assign and delete remain.
  - **Plans is now the first tab** of the Work page (and the default landing tab).
  - **Schedule has a one-click cleaner** — a **🧹 Clean up** button closes every
    supervision check-in still watching a finished or removed task, in bulk.
- *(Coming next in this overhaul: Plans live from the brain, AI-assisted multi-agent
  loops, and a Dream tab.)*

## [0.1.97] — 2026-06-24
- **The lead/coordinator preset now prioritizes orchestration over doing the work.**
  Applied to a lead (via the Coordinator preset button, the Team Builder's auto-wiring,
  or HR Manager → Structure/Manage), the directive now drives an explicit five-step
  loop, narrated as it goes: **1. Compress** the request to its essential intent +
  constraints, **2. Break it up** into the smallest self-contained sub-tasks, **3.
  Delegate** each to the best owner — a teammate (`/talk-to`) **or another team's lead**
  (`/ask <team>/<lead>`), **4. Summarize step by step** (compress each delegate's reply
  to 1–3 lines and post a running update as results land, not just at the end), and
  **5. Close out** with one synthesized answer. The roster-aware variant names the
  actual teammates that were created.

## [0.1.96] — 2026-06-24
- **Skills are now auto-categorized, so the catalog's tag search actually works.**
  Skills created in other sessions land in the library with no `metadata.tags`, so
  the Capabilities → Skills tag filter was empty for them. Now any untagged skill is
  automatically tagged on catalog load:
  - **AI batch categorization** — one `/ask` to a running agent tags every untagged
    skill at once from a controlled category vocabulary (research, coding, messaging,
    wallet, onchain, knowledge, …); falls back to an **offline keyword heuristic**
    when no agent is up, so it always produces tags.
  - **App-side overlay** — derived tags are cached in the control center's settings
    and merged into the catalog display + tag search; the skill's `SKILL.md` is never
    modified. Auto-tags are shown with an `auto` style; **↻ re-categorize** re-runs it.
  - The existing **search box + tag-chip filter** now spans both frontmatter and
    auto‑derived tags, so every skill is findable by tag.

## [0.1.95] — 2026-06-24
- **Internal:** added a unit test for the AI Team Builder's design sanitization
  (`sanitizeDesignedTeam` — drops off‑list runtime/model/skill picks, dedupes agent
  names, guarantees exactly one lead). Also consolidated the two `0.1.88` changelog
  entries below: the AI Team Builder and the interactive Inbox both shipped as
  `v0.1.88` (two commits stamped the same version), so they're now one entry.

## [0.1.94] — 2026-06-24
- **Local‑model concurrency now persists across manager restarts.** Your chosen
  “parallel local inferences” value is saved in the app and **re‑applied to the
  manager automatically every time the app connects** — including after the manager
  restarts — so it sticks without needing the `LOCAL_MODEL_CONCURRENCY` env var.

## [0.1.93] — 2026-06-24
- **No more false “health probe failed” on freshly‑built agents.** A just‑spawned
  agent needs a second or two to bind its HTTP server, so the onboarding probe used
  to fire too early and red‑flag a perfectly healthy agent (`request to …/talk
  failed`). The probe now retries for a short startup grace (~12s) before declaring a
  failure, so it only reports agents that are actually unreachable.

## [0.1.92] — 2026-06-24
- **Tune local‑model parallelism + fix a local‑agent deadlock.** Local (`ollama`)
  agents share one model server, so the manager runs them through a concurrency gate
  (cloud runtimes like codex/claude always parallelize). Two changes:
  - **Settings → Local models** now has a **“parallel local inferences”** control —
    raise how many ollama agents run at once (1–16, applies live) when your hardware
    can handle it, with a live `running · queued` readout. *(Needs a manager that
    exposes the control.)*
  - **Deadlock fix:** an ollama agent that's *blocked delegating* to another ollama
    agent now frees its slot while it waits, so a local coordinator can hand work to a
    local teammate instead of the two wedging on the single slot until a timeout.

## [0.1.91] — 2026-06-23
- **Start, stop, probe, and rebuild whole teams.** In HR Manager → Structure, click
  a team (in the graph or **Manage** in the team list) to open its panel, then act on
  **every agent at once**: **▶ Start all**, **■ Stop all**, **◇ Probe**, **↻ Rebuild
  all**. Start/stop/rebuild fan out per agent (best‑effort — a failure is reported and
  the rest still run); Probe health‑checks the team in one call. Stop and Rebuild ask
  for a one‑click confirm since they interrupt running agents; results show
  `done/total ✓` with any failures named.

## [0.1.90] — 2026-06-23
- **Lead hierarchy is now an actionable cross‑team coordinator table.** Instead of a
  static list (which rendered a broken `team/` entry for any team whose coordinator
  was unset), each team now shows a **coordinator picker** (choose the lead from that
  team’s agents) and a **make‑primary** button — set or change any team’s coordinator
  and promote one to the primary cross‑team lead, right from HR Manager → Structure.

## [0.1.89] — 2026-06-23
- **HR Manager refactored into four focused tabs + a live team graph.** The page is
  now organized around the things you actually do — **Structure / Build / Manage /
  Route** — instead of one long scroll.
  - **Structure:** a **live, interactive hierarchy graph** — one column per team, the
    lead on top (⭑ = primary cross‑team coordinator) and its workers below, with
    status dots and runtimes. **Click any agent or team** to open an inline panel:
    edit its **goals & instructions** (Coordinator preset, **✦ AI draft**, Save &
    rebuild), **reassign team**, **rebuild**, or jump to its routing. Selecting an
    agent in another team focuses that team automatically.
  - **Build:** the AI Team Builder + templates. **Manage:** the per‑agent
    instructions editor (now with **✦ AI draft**). **Route:** cross‑team relay +
    per‑agent overrides.
  - **AI assistance at every level** — drafting goals/instructions anywhere via
    **✦ AI draft** (dispatches to your team’s coordinator), plus the existing AI
    Team Builder. *(AI‑assist needs a running agent; you’ll be told if none is up.)*

## [0.1.88] — 2026-06-23
- **The Teams page is now the “HR Manager” page.** Same spot in the sidebar and the
  same underlying team data — just renamed (nav label + page heading) to reflect that
  it manages the agent workforce.
- **One AI Team Builder replaces “Import from spec” + “Onboard agents.”** A single
  flow now builds teams and agents end to end:
  - **Describe in plain English or paste a spec** — a live deterministic parse drafts
    the roster as you type; **✦ Build with AI** designs it from messy or high‑level
    input.
  - **AI designs the whole roster** — each agent comes back with a suggested runtime,
    model, skills, and one ★ lead, grounded by the runtimes/models/skills actually
    available (off‑list picks are dropped, nothing is invented).
  - **Rich per‑agent review** — name · runtime · model · role, with an expandable row
    for each agent’s persona and per‑agent skills; shared MCP / heartbeat / wallet /
    probe apply to the batch.
  - **Build in one pass** via `onboard:run`, which now carries each agent’s persona,
    with a live per‑agent checklist. Targets a new or existing team.
  - **Auto‑wiring** — after the agents land, the ★ lead is made the primary
    coordinator and gets the delegate‑to‑teammates preset, and the team’s cross‑team
    relay policy is applied (each shown as its own checklist row). The coordinator and
    rebuild calls are team‑scoped so wiring a brand‑new team works even when it isn’t
    the active one.
- **The Inbox is interactive — reply to or dismiss what’s waiting.** Each item now
  has an inline reply box (⌘/Ctrl+Enter to send) and a **Dismiss** button; both
  clear the item from the manager’s pending queue. Previously the Inbox was
  read‑only, so anything parked there was stuck.
- **AI Team Builder / “Ask AI to parse” no longer clog your Inbox.** They were
  sending the design/parse prompt to the manager’s human inbox (awaiting *you*),
  so they never auto‑answered. They now dispatch to a team **agent** via `/ask` and
  read its reply directly — nothing lands in your Inbox. If no agent is running,
  you get a clear “onboard an agent first” message instead of a silent park.

## [0.1.87] — 2026-06-23
- **Add Agent is now one streamlined “Onboard agents” flow.** The inline add‑agent
  form on the Teams page is gone; the **Onboard agents** button opens a single modal
  that does everything:
  - **Assign to a team** — pick an existing team or **＋ new team…** (created on the
    first spawn). After onboarding, the app switches to that team.
  - **Create multiple agents at once** — add as many agent rows as you want and
    onboard the whole batch in one pass, with a per‑agent ✓/✗ result list.
  - **Per‑agent runtime + model** — every agent picks its own inference runtime and
    model; shared skills / MCP / heartbeat / wallet / probe apply to the batch.
  - Reserved command words and duplicate names are caught before any spawn.

## [0.1.86] — 2026-06-23
- **Each chat is now its own conversation — no more cross‑chat “creep.”** Every
  message a chat sends now carries that chat’s id as a conversation key, so the
  agent resumes only *that* chat’s thread instead of whatever it last worked on.
  Previously all chats to the same agent shared one rolling context, so a reply in
  one chat could continue an unrelated task from another. *(Requires a manager +
  agents that thread the conversation id and resume per chat; without them the id
  is simply ignored and behavior is unchanged.)*

## [0.1.85] — 2026-06-23
- **Imported agents now keep their full description, not just the one‑line role.**
  The spec parser now captures each agent’s complete description (the `Role:` line
  **plus** the richer sentences under it), and that text is sent as the agent’s
  **persona** — it becomes the agent’s actual operating instructions, not just a
  peer‑discovery blurb. (Previously the importer sent neither role nor description as
  the persona, so imported agents started with no real mandate.)
  - The Import modal now shows an **editable description box** per agent (in addition
    to the one‑line role), pre‑filled from the spec; “✦ Ask AI to parse” returns a
    description too.
  - Inline markdown (`**bold**`, `` `code` ``) is cleaned out of the persona text, and
    the role/description length caps are now applied uniformly across the paste, AI,
    and manual‑edit paths. *(Requires a manager that accepts `roleBody` on spawn.)*

## [0.1.84] — 2026-06-23
- **Import a team from a pasted spec.** New **“↥ Import from spec”** button on the
  Teams page: paste a free‑form team description (e.g. a “Recommended Agent Creations
  For \`brain\`” list) and it auto‑detects the team name and each agent, then spawns
  them into a new team in one click — the team is created on the first spawn.
  - **Deterministic parser** extracts the team + agents (name + role) live as you
    paste; for messy formats, **“✦ Ask AI to parse”** dispatches the prose to your
    team’s lead for strict JSON and falls back to the deterministic parse on failure.
  - Every detected agent shows in an **editable, reviewable list** (rename, fix role,
    remove) with **runtime + model pickers** applied to the whole import.
  - Guards from an adversarial review: prose bullets are no longer mistaken for agents,
    reserved command words (`status`, `team`, `verify`, …) are caught **before** any
    spawn, the team name is no longer pulled from stray “…for …” prose, a partial
    import leaves only the failures queued so re‑clicking Create retries just those,
    and the app only switches to the new team when an agent actually landed there.

## [0.1.83] — 2026-06-23
- **Local models (Ollama) can now use MCP servers.** Previously MCP attach was
  Claude/Codex‑only — local models had no way to call MCP tools. The manager now
  runs an agentic tool‑calling loop for Ollama (connect attached MCP servers →
  expose their tools → call/observe/continue), so a tool‑capable local model (qwen3,
  qwen2.5, llama3.1+, etc.) can actually use them. The control center now offers
  **Attach MCP** for Ollama agents; a model without tool support degrades gracefully
  to plain text. *(Requires a manager that includes the Ollama tool loop.)*

## [0.1.82] — 2026-06-23
- **Reassign an agent to another team.** Each agent in Teams now has a *“reassign
  to…”* picker — pick a team and the agent moves there (the manager rebuilds it
  under the new team, carrying its wallet, subscriptions, check-ins, and history).
  Refuses a name that already exists in the target team.
- **Delete an empty team.** Teams with **zero agents** (except `default`) now show a
  **Delete** button; the manager refuses to delete `default` or any team that still
  has agents. Remove its agents first (or move them out), then delete.
- **Activity log keeps correct times across restarts.** The live fleet feed was
  stamping most of the re-fetched backlog with the current time after a restart, so
  everything collapsed to the same age (e.g. “18s”). It now uses each event’s real
  occurred-at time, so ages are accurate and survive an update + relaunch.
- **Reopens where you left it.** The app now restores its window **position, size,
  and maximized state**, and the **last page** you were on — including after a
  self-update relaunch. (Falls back to centered if the saved spot is off-screen.)

## [0.1.81] — 2026-06-23
- **Chat live activity recovers after a manager restart.** The inline "what the
  agent is doing" feed (tool/file steps) polls the manager's per-agent activity
  ring. If the manager restarted mid-dispatch, its in-memory ring reset *below* the
  chat's cursor, so the feed froze showing only "<agent> working… Ns" with no steps.
  The poll now detects when the ring is behind its cursor and resyncs to the tail, so
  the agent's ongoing actions stream again. (Pairs with the matching `/events` cursor
  fix.)
- **Each activity / behind-the-scenes step now shows its time.** Every live tool/file
  step and delegation line — and the captured trace on a finished reply — is prefixed
  with the clock time (HH:MM:SS) it happened, so you can see *when* each action ran,
  not just the running elapsed counter.

## [0.1.80] — 2026-06-23
- **Background updates now ping you system‑wide.** The app already checked for
  updates in the background (on launch, every few hours, and on window focus) and
  showed a sidebar “Restart & update” chip — but you'd only really notice it on the
  Settings page. Now, the first time a background check downloads a new version, you
  get a native **macOS notification** (“Update ready — v0.1.x downloaded, restart to
  apply”); clicking it brings the app forward. Fires once per version, even when the
  app is unfocused or minimized.

## [0.1.79] — 2026-06-23
- **Agent identity lives on the Identity & Keys page now.** The per‑agent onchain
  identity (ENS / ID‑chain domain, OWS wallet, and **Register identity** /
  **Provision wallet** actions) moved off the Teams › Cross‑team relay panel and
  onto **Identity & Keys**, alongside that agent's Safe account and session keys —
  one place for an agent's identity. The Teams page keeps the per‑agent relay
  overrides (it's no longer cluttered with identity rows).

## [0.1.78] — 2026-06-23
- **Honest about manager compatibility.** Some panels (skills install/create/
  uninstall, plugins, MCP attach, per‑agent instructions, runtime switch, cross‑team
  relay delegates) call manager endpoints that a stock or older upstream id-agents
  may not expose. When such an action hits a 404, the app now shows a clear
  *“… requires a newer id-agents manager”* message instead of a raw
  `POST /… → 404`, and the rest of the app keeps working. No functional change
  against a manager that already has those routes.
- **README:** added a **Manager compatibility** section documenting which features
  need which manager routes, and marked the Identity & Keys panel as running on a
  simulated key provider today (real OWS / Safe‑4337 signing is the planned swap).

## [0.1.77] — 2026-06-23
- **Desktop team creation now uses a full Create team modal.** Operators can pick
  the default template, a library team template, or a deployable server config,
  validate the slugged team name, preview deploy preflight details when
  supported, and see install/deploy progress while the new team starts.

## [0.1.76] — 2026-06-23
- **Desktop Teams now has a real agent onboarding wizard.** The new flow reuses
  shared onboarding logic for preflight, spawn, MCP attach, rebuild, and health
  probe steps, with a checklist and retry support for failed post-spawn steps.

## [0.1.75] — 2026-06-23
- **Teams now shows each agent’s onchain identity inline.** Per-agent rows display
  the ID-chain domain, OWS wallet, and Safe account status, with one-click
  identity registration and wallet provisioning from the Teams page.

## [0.1.74] — 2026-06-23
- **Critical fix: blessing an agent for Computer Use no longer breaks it.** The
  Computer Use tool was registered under the name `computer-use`, which **Claude Code
  reserves** — so once you blessed a Claude agent, *every* request to it failed with
  “failed” / “Claude Code produced an empty result.” The tool is now `mac-control`,
  and the app detects + cleans up the old broken name. **If an agent of yours is
  currently failing, re-bless or remove it once in the Computer Use tab to fix it.**
- **Computer Use: stronger per-agent security.** Each blessed agent now gets its
  own private token (instead of one shared key), and the controller identifies the
  caller by that token rather than a self-reported name — so one agent can’t act as
  another, and removing an agent immediately revokes its access. Re-bless any agent
  you’d previously granted Computer Use (one click) to issue its new token.

## [0.1.73] — 2026-06-23
- **Computer Use: you don’t have to approve *everything* anymore.** A new risk
  classifier means you can turn **off** “Approve every action” and the agent runs
  ordinary clicks/moves/typing on its own — but the app **still holds the risky
  ones** for your OK: destructive keyboard shortcuts (Quit, Empty Trash) and
  dangerous typed commands (`rm -rf`, `sudo`, `drop table`, `--force`, …). The
  approval prompt now tells you *why* something was flagged. Supervised
  (approve-everything) remains the default and recommended mode.
- Stronger guidance to the agent: the type/key tools now explicitly say never to
  type credentials and that dangerous commands will be held for you.

## [0.1.72] — 2026-06-23
- **Computer Use can now DRIVE your Mac — safely.** A blessed Claude/codex agent can
  move the mouse, click, type, scroll, and drag on your primary display (not just
  see it), all through the in-app broker. This is the input release, and it ships
  with its full safety net on by default:
  - **Approve every action (supervised mode, default on):** the agent is *held* on
    each click/keystroke until you press **Allow** (or **Deny**) in the app. Turn it
    off only when you trust a task.
  - **PANIC** — a red button **and** a global hotkey (**⌘⌥⇧P**) that instantly stops
    everything from anywhere, even if the app isn't focused.
  - **Pause** blocks the agent without disarming; **Disarm** ends the session and
    releases any held mouse button.
  - Input also requires **Accessibility** permission (one-click Open Settings +
    Relaunch), and the agent must **screenshot first** so every action is anchored
    to something you can see.
  - Every action is in the **activity log** (and Chat); **keystrokes are recorded as
    a length only** — never the literal text — so secrets you type never hit disk.
  - Hardened across two adversarial review rounds before release.

## [0.1.71] — 2026-06-23
- **New: Computer Use (watch your Mac live + let an agent see your screen).** A new
  **Computer Use** tab streams your primary display live inside the app, and you can
  **bless** a Claude/codex agent to let it take screenshots of your Mac (so it can
  see what you see while helping). This first release is **watch + screenshot only**
  — mouse/keyboard control, live take-over, and a panic kill-switch are coming next.
  - **Safety is built in.** Disarmed by default (the agent can’t even screenshot
    until you press **Arm**); only agents you explicitly bless can reach it; the
    capture runs through a loopback-only, token-authed in-app controller that
    rejects cross-origin/rebinding probes; the live capture only runs while the tab
    is open; and on-screen text is treated as **data, never instructions**.
  - Screen Recording permission is detected with one-click **Open Settings** +
    **Relaunch** helpers. No native modules, so nothing extra to install.

## [0.1.70] — 2026-06-22
- **Chat replies survive long tasks, navigating away, and restarts.** Dispatches
  are now resumable: the in-flight query is persisted on the chat, and the chat
  resumes polling when you come back to it — instead of giving up with “timed
  out waiting for reply” and losing the answer. Switching pages and returning no
  longer wipes the live activity; it re-attaches and the reply lands when ready.
  Replies always land in the **right** chat (with an unread badge if you’ve moved
  on), and **every** waiting chat resumes after a restart — not just the last one
  you had open. (Replaces the single fixed-timeout long-poll with a renderer-owned
  resumable poll loop; while the manager is reachable it never abandons a running
  task — it defers to the manager’s own result/expiry — and a brief outage just
  keeps waiting with a soft notice instead of dropping the reply.)
- **More reliable delegation.** The Coordinator preset now tells the lead to
  prefer synchronous \`/talk-to\` (the manager handles the wait) over hand-rolled
  async polling, which could hang waiting for a teammate that never woke.
- **Sturdier composer + plans.** The composer is locked while a reply is in
  flight so a fast double-press can’t fire two dispatches (or two billed image
  generations); a plan request still auto-saves to **Work › Plans** even when its
  reply lands after you navigated away or restarted; and the per-reply “behind
  the scenes” trace is captured per dispatch.

## [0.1.69] — 2026-06-22
- **Readable supervision check-ins.** The check-in list no longer shows cryptic
  `chk_…` ids. Each row now reads **“Watching: <task title> · <owner> · every
  10m · checked 6× · next in 3m”** with the live status, sorted active-first.
  A header flags any check-in still watching finished work (“⚠ N watching
  finished work”), each active one gets a **Close** button, and closed ones are
  dimmed with their reason. (The manager now resolves each check-in’s linked
  task title/owner; older managers degrade to “a delegated task”.)

## [0.1.68] — 2026-06-22
- **Coordinator preset no longer leaves stale “doing” tasks.** When the lead
  delegated synchronously it was auto-attaching a tracked task that never closed
  (a sync reply doesn’t mark its own task done), so the board filled with
  perpetual “doing” rows. The Coordinator preset now tells the lead to skip the
  tracked task for synchronous delegations (it gets the reply inline; the live
  activity feed already shows the hand-off) and to reserve — and close —
  tracked tasks only for async hand-offs.

## [0.1.67] — 2026-06-22
- **Settings re-checks for updates on open.** The Self-update card now kicks a
  fresh check whenever you open Settings, so it never shows a stale “latest”
  version (previously it showed the last cached check until the next interval /
  focus re-check or a manual “Check now”).

## [0.1.66] — 2026-06-22
- **Chat survives an agent restart.** Dispatches now auto-retry transient
  failures — the target agent briefly rebuilding, the manager restarting, or a
  network blip — with a “reconnecting…” note, instead of surfacing a hard
  “agent failed” / “fetch failed”. Timeouts (work still in flight) are not
  retried. If it still can’t connect after retries, the error explains it
  plainly (the agent may be restarting).

## [0.1.65] — 2026-06-22
- **Make the lead actually coordinate its team.** New **Teams → Agent
  instructions** section: a persistent per-agent system-prompt directive with a
  one-click **Coordinator preset**. Apply it to your lead and it delegates
  implementation to `coder` and research to `researcher` (via the inter-agent
  skill), then synthesizes their results — instead of doing everything itself.
  Verified live: the lead delegated to both teammates and reported who did what.
  The directive survives rebuilds (stored as a per-agent sidecar). “Save &
  rebuild” applies it. (The lead *could* delegate before — it has the
  inter-agent skill — but nothing *instructed* it to; this fixes that.)

## [0.1.64] — 2026-06-22
- **Paste images & files into chat.** Paste a screenshot or a copied file
  straight into the message box and it’s attached (alongside the 📎 button),
  then sent into the focused project / agent workspace on Send like any other
  attachment. Plain-text paste is unaffected. 25 MB per item.

## [0.1.63] — 2026-06-22
- **Local image generation (free) — preferred over the cloud.** Image creation
  in chat now uses a **local image server first**, falling back to the cloud
  (OpenRouter) only if none is set or it’s unreachable. Settings → Inference has
  a **Local image generator** card: point it at Automatic1111 / Forge (Stable
  Diffusion WebUI on `:7860`, started with `--api`) or a LocalAI-style OpenAI
  images API (`:8080`), or click **Detect** to find one on localhost. Supports
  both the `/sdapi/v1/txt2img` and `/v1/images/generations` APIs. (Note: the
  Claude/ChatGPT/Cursor subscriptions and Ollama models are text/vision-only and
  can’t generate images — a local image server or the cloud are the options.)

## [0.1.62] — 2026-06-22
- **Cleaner composer.** Removed the helper hint line under the chat input
  (image/plan/live-feed tips); the behavior is unchanged.

## [0.1.61] — 2026-06-22
- **Chat auto-scrolls to follow new activity.** The thread now stays pinned to
  the latest as replies and the live “working” feed stream in, so you don’t have
  to scroll down to keep up. Scrolling up to read history pauses the follow (it
  won’t yank you back down); sending a message or opening a chat re-pins to the
  bottom.

## [0.1.60] — 2026-06-22
- **Live agent activity streamed into chat.** While an agent works on your
  message, the chat now shows what it’s actually doing — files it creates/edits,
  commands it runs, searches, web fetches, and work it delegates to other
  agents — as an inline “working · live” feed (Claude-app style), with an
  elapsed timer. A compact record of the steps is kept with the finished reply.
  (Agents stream their tool/file steps to the manager; needs the local manager +
  a one-time agent rebuild to light up — claude-code agents today.)

## [0.1.59] — 2026-06-22
- **Unread badges on Chat & Inbox.** The Chat nav item now shows a count when an
  agent reply lands in a thread you haven’t viewed; opening the thread (or the
  Chat view, for the most recent) clears it. Unread threads are also marked with
  a ● in the chat switcher. The Inbox badge (pending manager questions) is
  unchanged. Both are scoped to the active team.

## [0.1.58] — 2026-06-22
- **Select & copy chat text + spellcheck.** Chat messages — both what you type
  and the agent’s replies (plus the live trace and generated-image captions) —
  are now selectable, so you can highlight and copy them. The composer is
  spellchecked, and a right-click menu offers spelling suggestions / Add to
  Dictionary plus Cut/Copy/Paste/Select All. App chrome (nav, buttons) stays
  unselectable for the native feel.

## [0.1.57] — 2026-06-22
- **Ask for a plan in Chat → it auto-saves to Plans.** When a chat message
  clearly asks for a plan (“draft a plan for…”, “/plan …”), the agent’s reply is
  also saved to **Work › Plans** with an auto-titled entry — a chat line
  confirms the save. Conservative detection (won’t fire on “planet”/“planner” or
  “according to plan”).
- **Live “behind the scenes” feed in Chat.** While an agent works, the reply
  bubble shows an elapsed timer plus a live activity feed built from the fleet
  event stream — including work the lead farms out to other agents, so you can
  see things running **in parallel**. A compact trace is kept with the finished
  reply (expand “behind the scenes”).
- **Auto-decompose work on assign.** New **⚡ Assign work to fleet** in the Tasks
  tab: describe an objective, the lead splits it into concrete sub-tasks (each
  owned by the best-suited agent, with dependencies), you review/adjust owners,
  then **Create & dispatch** — independent tasks are farmed out in parallel and
  dependents follow their prerequisites. Every sub-task appears in the Tasks
  view with live status, so parallel execution is visible.

## [0.1.56] — 2026-06-22
- **New Plans tab in Work.** Request a plan and an agent drafts it (Markdown),
  saved to the Plans tab. **Generate** new plans right from there (objective +
  agent), **update** an existing plan with instructions — each update is a new
  **version** with a **changelog** entry — and browse/restore-view past
  versions. Rename, set status (draft/active/done/archived), delete. Plans are
  stored per-plan under `~/.config/idctl/plans/`.

## [0.1.55] — 2026-06-22
- **Unified composer — one Send, no 🎨 button.** The composer now auto-decides
  between chat and image generation from your prompt. A clear image request
  ("generate an image of…", "draw a logo…", or a leading `/image …`) generates
  an image; everything else goes to the agent. The decision is a **free, local**
  heuristic (no metered API), it defaults to chat so it never spends on image
  generation by accident, and chat continues to run on your **subscription /
  local** agent runtime. (Image generation itself still uses OpenRouter — the
  only image-capable provider configured.)

## [0.1.54] — 2026-06-22
- **Image generation: no more model picker.** The model is now auto-selected
  from your prompt (a higher-quality model when the prompt asks for it —
  photorealistic / detailed / logo / 4k — otherwise the fast, cheap default).
- **Chats are only saved once they have a real message** — empty "New chat"
  shells aren't cached, and leftover empties are pruned from the list.
- **Chat titles are auto-generated** from the opening message by a local Ollama
  model (free, no cloud cost), with the first-message text as an instant
  fallback. Renaming still locks the title.

## [0.1.53] — 2026-06-22
- Renamed the **Tasks** nav item + page heading to **Work** — it now covers
  Tasks, Schedule, and Loops under one inclusive title. (The first tab is still
  "Tasks".)

## [0.1.52] — 2026-06-22
- **Tasks page is now tabbed: Tasks · Schedule · Loops.** The Schedule page is
  folded in as a tab (no more separate nav item; heartbeats + supervision live
  there). **New Loops tab** — build a recurring *objective* for an agent
  (objective + cadence) that the manager runs on a schedule (24/7, even when the
  app is closed), with a tracker (status, last run, Run-now, pause/resume).
- **Health page now lists the whole fleet, grouped by team**, with running
  agents at the top of each group and the active team first (e.g. "41 agents ·
  41 running"). Probe stays scoped to the active team.
- **Chat sessions are auto-named** (a default that the first message refines)
  and the name is editable any time — renaming locks it.
- **Editing a project now opens in place** — the form expands at the card you're
  editing instead of jumping to the top of the page.

## [0.1.51] — 2026-06-22
- Update checks now also fire **when you focus the app window** (debounced to
  once per 5 min), so a release cut while the app is open surfaces the
  "Restart & update" chip in seconds instead of waiting up to the periodic
  timer. Default check interval lowered 12h → 4h as a backstop.

## [0.1.50] — 2026-06-22
- **Chat is now saved and resumable.** Every conversation is a persisted session
  (one JSON file under `~/.config/idctl/chats/`), so threads survive navigation
  and restarts. A **session switcher** + **＋ New** in the header let you jump
  back to any past chat; each remembers its own title, agent, and focused
  project. Rename inline, delete with the ✕. Auto-saves as you go.
- **Generate images in chat.** A 🎨 button turns the composer text into an image
  via your OpenRouter provider (model picker — default `gemini-2.5-flash-image`),
  renders it inline, and **caches it** under `chats/images/` so it persists with
  the thread. Cost is shown per image. Images load as data URLs (CSP-safe); the
  reader is locked to the cache directory.

## [0.1.49] — 2026-06-21
- **Chat: focus on a project.** A new "focus" dropdown scopes the conversation
  to a tracked project — its name, folder path, and repo are sent to the agent
  as context with every message, so it knows what you're working on. The
  selection persists per team, and the focused project's path shows under the
  header with an "open ↗".
- **Chat: attach images and files.** A 📎 button in the composer opens a
  multi-file picker; selected files are copied (binary-safe) into the focused
  project's `uploads/` folder — or the target agent's workspace if no project is
  focused — and their paths are included in the message so the agent can read
  them (images included). Attachments show as removable chips before sending.

## [0.1.48] — 2026-06-21
- Self-update: a build that was already downloaded in a previous session now
  surfaces the "Restart & update" chip **immediately on launch**, instead of
  waiting for the next online re-check (which could fail offline and hide a
  ready update). The chip appears whenever a staged build is newer than the
  running one.

## [0.1.47] — 2026-06-21
- The folder picker (Add from GitHub's "Clone & add", Import folder, Browse,
  change-root) now **opens at your standard projects folder** by default — so
  new clones and imports land alongside the rest instead of wherever the dialog
  last was. Falls back to the auto-detected workspace projects root.

## [0.1.46] — 2026-06-21
- **Sync the Projects page from your id-agents workspace.** New "⟳ Sync
  workspace" button auto-discovers the projects folder
  (`$ID_WORKSPACE_DIR/projects`, detected from the manager's launchd config) and
  tracks each subfolder as a project — pulling **name + description from the
  README**, the **git remote as a link**, and a `workspace` tag. The merge is
  additive and idempotent: it dedupes by folder, adopts a same-named manual
  entry, and never overwrites your edits or deletes anything.
- On first run with no projects yet, the page **auto-syncs** the detected
  workspace, so it's populated out of the box. The root is shown with a
  "change…" link to point it elsewhere.
- Git tracking now only treats a folder as a repo when it's the repo's **own
  root** — a plain folder nested inside a larger repo no longer borrows the
  enclosing repo's branch/status/remote.
- Standard install: an `io.bittrees.projects-sync` launchd agent keeps the
  tracker in sync with the workspace folder on a schedule, so a fresh idagents
  install has its projects tracked without opening the app.

## [0.1.45] — 2026-06-20
- **Add a project straight from a GitHub URL.** New "⤓ Add from GitHub" on the
  Projects page: paste a repo URL, pick where to clone it, and the app **clones
  the repo** (SSH first, HTTPS fallback) and **auto-fills the name, description,
  and tags** — description + topics + primary language come from the GitHub API
  (using your configured token for private repos), falling back to the README.
- **✨ Refine with lead** button on the project form routes the
  description/tags through your team lead, which can use its GitHub tools to
  write a cleaner summary — handy for repos with no GitHub description/topics.
- The cloned folder is wired in immediately, so the new project shows git
  tracking (branch, ahead/behind/fork, fetch/pull/…) the moment you save.

## [0.1.44] — 2026-06-20
- Projects page now tracks **folders and git repos**. Each project can point at a
  local folder; for git repos it shows the **branch and whether you're up to date,
  ahead, behind, or a customized fork** (ahead/behind measured vs the relevant
  remote's main branch — upstream's for forks), plus an "uncommitted" flag.
- One-click **git commands** per project (fetch / pull / status / log / diff) with
  inline output, an "open folder", and a "remote ↗" link.
- **Import folder…** (and a Browse + Read-README button on the form) pulls a folder
  in and **auto-fills the name and description from its README**.

## [0.1.43] — 2026-06-20
- Tasks page overhaul. **Fixed broken actions** — the buttons sent malformed
  commands (`/task <id> claim`, `/task <id> complete`, `/task add …`) that the
  manager ignored; they now use the correct verbs (`create`/`done`/`assign`/
  `status`/`remove`). Added: search, status filter (all/open/done), a **hide
  routine** toggle that hides the noisy heartbeat tasks, an **Age** column,
  open/done counts, per-task **assign-to-agent**, **Done/Reopen**, **Delete**
  (with confirm), and a **Clear completed** bulk action.

## [0.1.42] — 2026-06-20
- Chat: the selected agent now **persists** — it's saved per-team and restored
  when you return to Chat (or restart the app), instead of resetting to the lead
  every time you navigate away.

## [0.1.41] — 2026-06-20
- Dashboard layout: the agents table now sizes to its content (all columns show,
  no horizontal scroll on open) and the **Activity feed absorbs the horizontal
  stretch** when you widen the window.
- Activity lines carry more context: each query now shows the **kind of response**
  (message / heartbeat / error / code / question) and a **preview of the reply**
  text — e.g. `coder replied · message · "Sent reply to remote"`.

## [0.1.40] — 2026-06-20
- Dashboard, Chat, and Teams now list the team's **coordinator (lead) first**.
  In Chat the lead is also **auto-selected** as the message target (falling back
  to it on a team switch), so you can start typing to the lead immediately.

## [0.1.39] — 2026-06-20
- Update prompt repositioned to the **bottom-left of the sidebar, under Settings**
  — a small card (`⬆ vCURRENT → vNEW` + Restart & update + ✕) pinned to the
  sidebar's bottom.

## [0.1.38] — 2026-06-20
- Update prompt moved into the **status bar** as a compact chip (`⬆ vCURRENT →
  vNEW · Restart · ✕`), just left of the "● online" pill, instead of a floating
  corner toast.

## [0.1.37] — 2026-06-20
- Self-update **now relaunches** after applying. The freshly-swapped (unsigned)
  bundle carried a `com.apple.quarantine` xattr that made macOS silently refuse to
  reopen it; the apply helper now strips quarantine, has a robust `open` fallback,
  always runs the relaunch (no early `set -e` exit), and logs to
  `staged-update/apply-update.log`.
- The "update available" notice is now a **bottom-corner toast** (styled like a
  tile) that shows **vCURRENT → vNEW** with **Update & restart** / **Later**,
  instead of a top banner.

## [0.1.36] — 2026-06-20
- Dashboard **Activity** feed is now readable: agent ids resolve to **names** and
  events render as plain English ("coder replied", "lead is thinking",
  "researcher went offline") instead of `query:delivered agent_178…`. The panel
  is wider, rows wrap to show the full line, and live events show a relative time.

## [0.1.35] — 2026-06-20
- Settings → Self-update: removed the **manifest URL** field. Updates come from
  the app's GitHub releases; the self-hosted-manifest override was an unused
  advanced option that just cluttered the tile (still settable via config for
  anyone who genuinely self-hosts an update feed).

## [0.1.34] — 2026-06-20
- Dashboard: the model dropdown now **probes every backing provider on entry** and
  offers the full live model list per runtime — the free-text **"custom…"** entry
  has been removed (no more typing model ids by hand).

## [0.1.33] — 2026-06-20
- Runtime picker (Dashboard + Teams): the **claude-sdk** runtime
  (`claude-agent-sdk`) is now only offered when an **Anthropic API backend is
  live** — i.e. an `anthropic` inference backend is enabled, has a key (config or
  env), and last Connect&sync returned live. It's the only runtime that uses the
  metered Anthropic API, so without a working key it's hidden. An agent already on
  that runtime keeps it regardless.

## [0.1.32] — 2026-06-20
- Dashboard: switching an agent's **runtime** now picks a compatible model for
  the new runtime, **auto-opens the model dropdown** to fine-tune, and
  **auto-rebuilds** the agent — with no confirmation popup. Changing the **model**
  also rebuilds automatically. (The destructive delete still confirms.)

## [0.1.31] — 2026-06-20
- Teams: moved the **Lead hierarchy** card to the bottom of the page, below the
  team list, add-agent, and relay sections.

## [0.1.30] — 2026-06-20
- Settings now opens with a **Hardware** card — the commanded machine's compute
  spec (chip/CPU, CPU + GPU cores, unified/RAM, free-of-total disk, platform),
  the same machine local-model size warnings are checked against.
- Moved the **Lead hierarchy** tile from Settings to the **Teams** page, where it
  sits with the rest of team/coordinator management.

## [0.1.29] — 2026-06-20
- Local LLM stacks: simplified the row UI — dropped the always-visible command +
  copy button. **Install / Uninstall** is one click; the exact command is revealed
  only at the confirm step before it runs in your Terminal.

## [0.1.28] — 2026-06-20
- Local Models: each model now shows its **download size, parameters and context
  window**, with a per-model **⚠ warning** when it's too large for the commanded
  machine's RAM/disk (the manager host's CPU/RAM/free-disk is shown above the
  list). One-click **Download** and **Remove** for models.
- Local LLM stacks: **clickable Install / Uninstall** — opens the command in your
  Terminal (visible and abortable; nothing runs silently), app-only stacks link
  to their download — instead of copy-only. Plus a **port-collision ⚠** when a
  stack's default port is already in use on the machine or shared by another stack.

## [0.1.27] — 2026-06-20
- New **Local LLM stacks** catalog (Settings) — 21 self-hostable serving stacks
  from [awesome-llm-services](https://github.com/av/awesome-llm-services) you can
  run next to Ollama (llama.cpp, vLLM, mistral.rs, MLX, LM Studio, KoboldCpp…),
  each with its default port, OpenAI-compat, a copy-able install command and docs
  link. "Scan running" reuses discovery to flag which are live.
- Local Models card is now a browsable **model catalog** — ~50 Ollama-pullable
  models (Qwen3, Llama, Gemma 3, Phi-4-mini, Qwen2.5-Coder, DeepSeek-R1, vision,
  embeddings…) with size/params/capability tags, search + filters, one-click
  download and installed detection.

## [0.1.26] — 2026-06-20
- Fix: the **ollama** runtime's model picker no longer offers cloud (e.g.
  OpenRouter) models — only models from local providers, so you can't select a
  model the local harness can't load (which previously failed with
  "model not found" at probe/run time).

## [0.1.25] — 2026-06-20
- New **Discover local servers** (Settings → Inference backends) — scan localhost
  for running LLM servers (Ollama, LM Studio, llama.cpp, vLLM, Jan, …) and add
  them as inference backends in one click, with their model list. Hardened to
  ignore non-LLM services on the same ports.

## [0.1.24] — 2026-06-20
- Subscriptions: the **OpenAI (ChatGPT)** tile now shows the connected email and
  plan (decoded from the codex OAuth token), matching the Claude and Cursor tiles.

## [0.1.23] — 2026-06-20
- Capabilities: attaching MCP servers / skills / plugins is now **gated to the
  runtimes that can use them** — incompatible agents are shown disabled (with a
  reason) and skipped by apply/attach/install actions, instead of silently doing
  nothing. (MCP: Claude + Codex runtimes; local models gain it once the
  tool-calling loop ships.)

## [0.1.22] — 2026-06-19
- Subscriptions: the "Install…" action for a missing CLI (e.g. Cursor) now opens
  your Terminal and runs the vendor's official installer (falling back to copying
  the command if Terminal automation is blocked), then re-checks — instead of
  surfacing a "sign-in failed" message.

## [0.1.21] — 2026-06-19
- UI: the Settings → Inference backends card now grows to fit its content
  (its bottom help text was getting clipped below the tile on long pages).
- Subscriptions: when a CLI isn't installed (e.g. Cursor's `cursor-agent`), the
  row now says "CLI not installed" with an install hint instead of a silent
  OAuth failure.

## [0.1.20] — 2026-06-19
- New **Projects** page — track projects locally (name, status, description,
  team link, tags, links, notes) with status filters; stored in your config.
- Capabilities → MCP servers: a bigger **catalog** — Playwright, Browser MCP,
  Fetch, Context7, Tavily, Exa, Firecrawl, Notion, Figma, Slack — and the
  Brave Search entry repointed to its current official package.

## [0.1.19] — 2026-06-19
- Settings → Inference backends: a **provider catalog** — pick Groq, OpenRouter,
  Together, Mistral, DeepSeek, xAI, Fireworks, Cerebras, Gemini, DeepInfra,
  Nebius, Perplexity, or a local server (vLLM / llama.cpp / LocalAI / Jan) and
  its endpoint is filled in; Connect & sync discovers the live model list.
- Settings → **Local models (Ollama)**: list installed models and **download** a
  new one with live streamed progress (Ollama `/api/pull`).
- Settings → Subscriptions: add **Cursor** (`cursor-agent`) alongside Claude and
  ChatGPT.

## [0.1.18] — 2026-06-19
- UI: fix tiles/cards being compressed below their content on long pages — every
  view now keeps cards at their natural height and scrolls instead of clipping
  buttons/info (was previously fixed only for the Capabilities/Teams views).

## [0.1.17] — 2026-06-19
- Capabilities → Skills: **remove skills** — delete a skill from the library
  (two-step inline confirm) and uninstall a skill from the selected agents.

## [0.1.16] — 2026-06-19
- Self-update: treat a GitHub `releases/latest` **404 as "up to date"** (no
  published releases) instead of surfacing it as an error.

## [0.1.15] — 2026-06-19
- Health: **local-model (Ollama) token throughput gauge** plus 24-hour and
  7-day token-usage averages, with a per-agent breakdown. Cloud API runtimes are
  intentionally excluded.

## [0.1.14] — 2026-06-19
- Capabilities → Plugins: the **provider column is now a clickable link** that
  opens the source/homepage in the system browser.

## [0.1.13] — 2026-06-19
- Capabilities → Skills becomes a **searchable, tag-filtered catalog** with a
  **Create-skill** form following the [agentskills.io](https://agentskills.io)
  `SKILL.md` standard.
- Capabilities → Plugins: shows each plugin's **provider** (author / source).

## [0.1.12] — 2026-06-19
- Initial public release: the ID Agents Control Center desktop GUI (`idctl-desktop`)
  and terminal TUI (`idctl`) — a standalone control client for an
  [id-agents](https://github.com/idchain-world/id-agents) manager.

[0.1.22]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.22
[0.1.21]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.21
[0.1.20]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.20
[0.1.19]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.19
[0.1.18]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.18
[0.1.17]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.17
[0.1.16]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.16
[0.1.15]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.15
[0.1.14]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.14
[0.1.13]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.13
[0.1.12]: https://github.com/bobofbuilding/id-agent-control-center/releases/tag/v0.1.12
