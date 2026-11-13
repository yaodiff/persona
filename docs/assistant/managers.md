# Managers

A manager is the assistant's process, `personad assistant` (`docs/assistant/assistant.md`("Process")). One hub can have several managers, and **they are all equal**: each one is a whole assistant with its own main conversation, conversations, scheduled tasks, inbox, knowledge base, model settings, memory, computers and sources. There is no chief manager: nothing is escalated, handed down, or seen "all at once".

- The assistant the hub starts itself (id `assistant`) is the first manager and, to begin with, the **default manager**: entry points that belong to no manager (Siri, the **Ask Persona** shortcut, the assistant page as the app opens) go to the default manager, which can be changed in settings.
- Everything belongs to one manager (computers, sources, inbox events, sessions, model settings, the knowledge base), and the hub forwards by ownership; list endpoints are merged by the hub, each item carrying `manager` (the manager's id).
- Each manager keeps its own data: a Postgres of its own, which `personad manager install` sets up in Docker the way `personad hub setup` sets up the hub's (or one the user gives with `--database-url`). The hub never touches a manager's database. The default manager keeps using the hub's database, with nothing migrated.
- Where a manager runs is the user's choice: another service on the hub machine, a service on another computer, or a container. Bots, channels, plugins and sources are set up in each manager's own settings; none of it is global.

## Repository references

Repository bindings (#5330) belong to one manager's Settings entry `assistant.repositories`, not a hub-wide catalog.
The document uses Settings CAS and a revision; at most 200 active records contain a stable ID, provider, HTTP(S)
instance, full namespace path, canonical URL, optional name/aliases/purpose and `verified_at`. No credentials,
computer or checkout are stored. HTTP(S), `git@host:path.git` and `ssh://git@host/path.git` normalize to the same
identity. GitHub Enterprise and self-hosted GitLab require an explicit provider; nested GitLab groups are preserved.

The web form parses locally on every URL/provider change and immediately shows the provider, full repository path,
canonical web root and an explicit not-yet-checked state. No preview button or remote request is needed. The server
reparses on preview and save; both parsers share `spec/fixtures/repository-remotes.json`. GitHub repository pages
(such as `/pull/5581`) and GitLab's `/-/` project pages discard their page suffix, ordinary query and fragment.
GitLab paths without `/-/` keep every namespace segment; ambiguous old page URLs are not guessed by taking two
segments. Explicit credential-bearing URLs and credential query parameters remain invalid. Only exact known
aliases (`www.github.com`, `api.github.com/repos/...`, SSH `ssh.github.com` and `altssh.gitlab.com`) map to public
providers; lookalike subdomains never imply trust. Public HTTP/SSH references become HTTPS web roots. Custom
instances keep their web scheme/port, while an unknown SSH port cannot imply a web port. No `.git`, page suffix,
query, fragment or clone form is stored. Static parsing never claims remote existence.

The checker makes one anonymous GitHub REST or GitLab projects metadata GET, never a Git subprocess, clone, content
fetch or model call. Its total budget stays eight seconds (including DNS/body), with three-second TCP/TLS limits,
a four-second header limit and no request retry. All DNS answers pass policy before numeric dials start; attempts
are staggered by 250 ms with at most four in flight, and losing connections are canceled/closed. This prevents a
stalled first address from hiding another reachable one without relaxing DNS pinning. Cancellation has its own
error, distinct from deadline expiry. The browser allows the server's budget plus five seconds for mutations; an
expired browser wait is an unconfirmed write, so the draft stays and the user is told to refresh before retrying.
Late replies cannot replace a different assistant or a new draft. Public GitHub checks use this manager's
`github.proxy` when configured; otherwise checks use the process's `HTTP_PROXY` / `HTTPS_PROXY` and `NO_PROXY`
(including lowercase spellings). Explicit `github.proxy` takes priority over environment bypass rules, as for the
extension market. GitLab and self-hosted instances use the environment rules. An invalid explicit GitHub proxy
fails the check rather than falling back to another route; a selected proxy failure never falls back to direct.
Proxy tunnels carry only validated numeric destinations (HTTP CONNECT or SOCKS5); destination DNS is never
delegated to the proxy. HTTP(S) and SOCKS5 environment proxies are supported; plain HTTP repository endpoints
also require the HTTP proxy to permit CONNECT to their port. A rate limit is not a timeout diagnosis.
The shared server routes serve every caller; repository binding UI currently exists only on the web, not Apple or
Android. Browser fixtures cover synthetic saves, while Go route and isolated database tests cover persistence.

The manager-owned `/api/v1/assistant/repositories` routes list/create; `/{id}` reads/updates/unbinds;
`/preview` parses without contacting a remote. Mutations require full access. `/{id}/restore` accepts the unbind
receipt once within ten minutes and restores the original ID and verification evidence, without a new probe.
The latest 20 removed references are retained for undo. A failed persistence acknowledgement is not success.

Creation and remote-identity changes require positive, matching provider repository metadata (including empty
repositories). Descriptive edits and reads do not probe or synchronize. Checks are anonymous and establish only
existence, never identity, membership, ownership, roles or push permission. Hidden/private 404, login HTML,
authentication failures, rate limits, timeouts and ambiguous metadata cannot pass verification.

Checks retain a self-hosted instance's HTTP(S) scheme and web port, reject redirects, use no repository
cookies/credentials, cap body/headers/time, validate all DNS answers and dial pinned numeric destinations with
ordinary TLS hostname verification. Configured proxy credentials go only to the proxy, never to the repository. Special, metadata,
loopback and link-local addresses are always refused. Private RFC1918/ULA destinations require an operator's
explicit `repository_trusted_targets` entry in this manager's `manager.json`; no Web/API input can grant trust:

```json
{"repository_trusted_targets":[{"instance_url":"https://code.example.com","networks":["<private CIDR>"]}]}
```

The exact HTTP(S) instance (including nondefault port) and private CIDR must both match. Broad public/default-route
CIDRs cannot opt in private networks. Configure only infrastructure the operator trusts; this is not a connector
or sign-in system. Public-only installations need no configuration.

Read-only MCP `repositories_list(query?, cursor?, limit?)` and `repository_get(id)` return only this manager's saved
metadata. Search covers name, aliases, namespace path and purpose (200-character query, at most 50 records/page).
Cursors are bounded and tied to query/document revision; edits invalidate old cursors. Neither tool accepts a
manager selector or fetches source. Their descriptions and the existing `task_plan` description guide identity
resolution: explicit user URLs/paths win, references grant no authorization, and machine/cwd must never be inferred.
There is no forced lookup preflight, injected list, new prompt or launcher-dependent behavior.

## Steps

1. **Roster and identity** (below): the roster, each manager's own token, install codes, `/api/v1/managers`. Behavior unchanged.
2. **Ownership and forwarding by owner** (see "Ownership" below): computers, sessions, cards and list items carry `manager`, and the hub forwards by it and merges lists; for now everything belongs to the default manager, so behavior is unchanged.
3. A second manager runs: its own database and directory, connected to the hub, taking over the computers and sources given to it.
4. Clients: **Settings › Managers**, switching managers on the assistant page, grouping, per-manager push switches (all four platforms; see "Clients" below).

## Roster

The roster is the bus's identity table `bus_identities` (`docs/protocol/protocol.md`, "Bus"): every row with role `manager` is a manager. Migration 0419 adds where its last handshake said it runs (`host`, `os`, `arch`, `deploy`, `version`) and `last_seen` (recorded on handshake and on disconnect), so the app can show an offline manager's place and "Last synced…".

- The hub gives the assistant it starts a new token on every start, but **the name stays**: a name the user gave it is kept.
- Manager ids: `m-` plus 6 hex digits for one made in the app; `assistant` for the hub's own.
- Names: 1–40 characters, no control characters (C0 or C1) and no bidirectional formatting characters.

## Install codes

**New manager** in the app (`POST /api/v1/managers {name}`) returns a one-time install code `mi_…`, **valid for 10 minutes and usable once**; the hub keeps only its sha256 (table `manager_install_codes`). Until the code is traded, the manager shows in the roster as installing (`installing` is when the code expires). It stays there when the code expires unused: `installing` is then a time in the past (the apps show 「码已过期」), the expired code no longer joins, `POST /api/v1/managers/{id}/code` gives it a new one, and `DELETE /api/v1/managers/{id}` calls it off. A manager never installed whose last code expired more than **7 days** ago leaves the roster, and its codes are deleted with the next code the hub makes (`db.ManagerInstallKept`). Codes used, and expired codes of an installed manager, are deleted a day later.

The new manager trades the code for its bus token: `POST /api/v1/bus/join {"code"}` → `{id, name, token, hub_id}`. This endpoint needs no credential (like the bus, it sits outside the apps' auth); failed trades count against the source and go `429 rate_limited` past the limit, as a bad token does. A manager that already has a token and trades another code (`POST /api/v1/managers/{id}/code`, to install it somewhere else) gets a new token: the old one stops working at once and a connection using it is closed with 4002. Only the latest code a manager was given works: making a new one voids the ones not used yet, and a join uses up all of them, so a leftover code can never take the token from the manager installed with the new one. Over plaintext from the public internet the join is refused (`403 tls_required`), as the bus and `/i/<code>` are: it hands out a token. The code such a join or `/i/<code>` request carried is voided, since it crossed the internet in the clear and whoever saw it on the way could trade it over TLS: it expires at once, so the roster shows the manager's code as expired and the app offers a new one. These refusals go through the source's limit first (`429 rate_limited` past it, without asking the database), and a code that voids nothing (unknown, used, or not a code) counts against it, as an unknown code over TLS does. `personad manager join` itself refuses an `http://` hub address on the public internet (a public IP, or a name that resolves to one; a NAT64 address counts as the IPv4 address in it, and one of a prefix inside `64:ff9b:1::/48` other than the /48 itself or `64:ff9b:1::/96` counts as public) before trading the code, unless `--allow-plaintext`. A code the hub refuses (`401`) and the hub's `403 tls_required` are configuration errors (any other `403`, a proxy's say, is a plain error): `manager join` exits 2, and `manager run --join --dir D` (a container) prints one line saying what to do and waits for a `manager.json` in `D` instead of exiting, since `--restart unless-stopped` restarts on exit 2 too. Without `--dir`, `manager run --join` exits 2 as well: there is no directory to wait on. Install codes in request paths (`/i/<code>`) are masked in the hub's log.

The install commands handed out (`curl … /i/<code> | sh`, `docker run …`) and `personad manager join` are described under "A second manager" below.

## Revoking

`DELETE /api/v1/managers/{id}` deletes its identity and codes in one transaction, codes first (for one still being installed too): a join in flight holds its code's row, so the delete waits for it, and then removes the identity that join saved, so a join that commits meanwhile leaves no manager behind: the token stops working at once and a connection using it is closed with 4002; for a manager still being installed it calls off the code. The default manager can't be deleted (make another one the default first: `409 default_manager`), nor can the assistant the hub starts (`409 builtin_manager`). Its machines go back to the carrier (below, "Moving a machine or a source").

## Ownership

Who owns a thing is decided in one place: `server/internal/hub/ownership.go`. When step 3 moves a computer or a source to another manager, this ownership is what changes, and forwarding and lists follow.

| Thing | Owner | How the hub knows |
| --- | --- | --- |
| Computer | One of the hub's own list: the manager it was added to (a device's **Add Computer**, `add.manager`; a dedicated local computer) or moved to, else the carrier (`assistant`); any other (a mesh member's): the carrier. Only the roster, the adds and the moves decide it, never what a manager reports | `managers.machines` ("Moving a machine or a source"), or the manager's own list ("Each manager's computers") |
| Session | Its computer's manager, always: a manager's own conversations run on its own computers, and moving a computer moves its sessions with it ("Moving a machine or a source") | |
| Pending card | The manager that reports it (`fleet.interaction(s)`), taken only on a computer of its own; one naming no computer is its own | |
| Inbox, todos, knowledge base, model settings, extensions and sources, the assistant page… | The manager the request names, else, for an extension's token, the manager whose extension it is, else the default one | Header `X-Persona-Manager` or `?manager=` (`docs/protocol/protocol.md`, "Per-manager routing"); an extension's token: the manager that knew it (`authorizeExtension`) |

An extension's token acts as its manager, the one that recognized it, and only as it, wherever the request names its target. Refused `403 other_manager` before anything is done:
- naming another manager (`X-Persona-Manager`, `?manager=`): on a route of no object, a merged list, an extension's HTTP or an extension API prefix (`impliedManager`);
- a route about another manager's computer (`/machines/{mid}/…`, `/machines/{id}/…`, any `{mid}` such as a todo's agents), session (`/sessions/{mid}/{sid}/…`), pending card (`/interactions/{id}/…`) or conversation (`/assistant/conversations/{id}/…`), whether the hub serves the route itself or forwards it (`extensionReach`, and `byMachine`, `bySession`, `byInteraction`, `byConversation`);
- another manager's computer or session in the query or body: starting or resuming an agent (`POST /api/v1/sessions`'s `machine_id`, `resume_session_id`), a notification (`POST /api/v1/notify`), a session list (`?machine_id=`).

The hub's own lists show it its manager's things only: `GET /api/v1/machines`, `/api/v1/interactions`, and `/api/v1/sessions` (the paged list and its counts too, over the manager's computers). `TestEveryExtensionRouteIsBounded` keeps every route open to extensions (`extwire.RouteScopes`) said to be one of these. The apps' devices are not limited this way; an app asks for one manager's sessions with `GET /api/v1/sessions?manager=<id>` (feature `sessions_manager`, `docs/protocol/protocol.md` ("One manager's sessions")).

- What a manager reports replaces only its own share: a manager reporting `devices.state` touches only its computers, a full list of pending cards replaces only its cards, and other managers' stay. The app gets computers ordered by manager: the one connecting hub.json's computers first, the rest by id.
- When a hub feature needs the assistant: things tied to a computer or a session (message parameters, renaming, starting an Agent, question cards, read state, the extensions' `agent.finished` / `agent.needs_you`, a computer's claude-dirs, pairing a service computer's connector) go to its manager; the mutes go to each manager for its own computers only, in its hello's answer and with `fleet.mutes`, and redeploying outdated nodes to each manager that carries computers; things that aren't (Siri, shortcuts, the knowledge base, an extension's hub_call) go to the default manager; notices that concern everyone (the app can fill in forms now, a source has something new) go to every connected manager. The admin page's usage sources go to the manager the request names, else the default one. An extension's token is checked with each manager in turn (the default first); whichever recognizes it owns it.
- The hub caches the default manager for 2 seconds (every forwarded request needs it) and reads it again when the roster changes (`managersChanged`). It keeps the roster's identities as long, for the lists the apps keep (`/api/v1/extensions` and the others of `extwire.KeptRoutes`) and `GET /api/v1/managers`, and drops them when the roster changes or the hub makes or revokes a token itself. A read that fails is never kept: with nothing kept, those lists still answer 503. A connection's token is looked up afresh every time (a revoked one stops at once).
- The merged inbox an app asks for after every inbox push is made once for all the apps asking within 2 seconds, until a manager says its inbox changed or a change goes to it (`server/internal/hub/inbox_answers.go`; `docs/protocol/protocol.md` ("Inbox validator")).
- How lists are merged (and why the inbox's paged history, `GET /api/v1/inbox/done`, is not), the `manager` field and what offline looks like are in `docs/protocol/protocol.md`, "Per-manager routing". An offline manager's things get no extra field: the app uses its `online` and `last_seen` in the roster to show "Last synced…".

What the hub keeps of each manager and how a machine or a source moves are in "What the hub keeps of each manager" and "Moving a machine or a source" below.

## Configuration

Each manager's configuration is its own `manager.json` (`docs/operations/config.md` ("manager.json")): whose assistant it is and what it should know (`assistant.owner`, `assistant.notes`), its default machine and launcher (`assistant.machine`, `assistant.launcher`), `agents` (triage, question delegation, launcher health), `inbox`, `kb`, `ai`, `hook_timeout_minutes`, and its connectors, extensions written by hand, bots, mail sign-ins, Lark and usage sources. The hub reads none of these, and says once at start which ones its `hub.json` still has.

- **What the hub's hello still carries** is the hub's: the machines this manager owns and a default machine among them (the hub's own machine when this manager owns it, else its first own one), the launchers `hub.json`'s `machines[].launchers` add for its own machines, `persona_view` / `html_views` (always true, for a manager from before #5509), the push timings, the user's language and the mutes. The manager lays its `manager.json` over that answer, reading the file again at every hello and `manager.updated`; a file that stops reading while it runs leaves it with the sections it last read.
- **`config.own`**: a manager that reads its own `manager.json` names the capability `config.own` in `manager.hello`'s `capabilities` (`docs/protocol/protocol.md` ("Handshake")). For a manager without it the hub logs once that it runs on its built-in defaults, and `GET /api/v1/managers` marks it `"needs_update": true` while it is online.
- **An older manager** (from before 2026-11-06) still connects, but the hello no longer gives it the defaults it used to get from `hub.json` (owner, notes, Agents, knowledge base, models), so it runs on its built-in ones until it is updated, and its knowledge base doesn't open (it waits for the hub's `kb`, which no longer comes). That is acceptable: managers made in the app only exist since 2026-11-06, and the built-in manager is updated together with the hub. The other way round, an older hub still sends its `hub.json`'s sections, and a section the manager's `manager.json` has replaces them.
- **A built-in manager the hub did not start** (`assistant.external`, or one run as a service of its own): the hello used to carry the hub's values of these sections, and its own machine's `hub.json` may be a stub (`personad hub setup` writes placeholders) or a copy. So its start leaves them out of its own move, and the hub hands them over raw in the handshake's answer to it (`legacy_config`: `assistant.owner` / `notes` / `machine` / `launcher`, `agents`, `kb`, `ai`, `hook_timeout_minutes`, and of `inbox` its `triage_ai`, `judge_ai` and `agent.machine`; the rest of `inbox` was always read on the manager's own machine and moves from there, without the two models; the AI twin always ran where that machine's `inbox.agent.machine` said, so it moves too, and the hub's is taken only when it has none). The manager takes each over once: one its `manager.json` lacks is copied in, one it has keeps its value. A later change of the hub's copy is not taken: its `manager.json` is the one to change. If they can't be written, it goes by them as they came (also across `manager.updated`) until they are. Inbox values taken over this way that the extensions read (the AI twin's machine) apply from its next start. The hub's own child took them from the same `hub.json` at its start, and gets no `legacy_config`. Managers made in the app don't get them either: each has its own `manager.json`, empty until it is set.

## A second manager (first half of step 3)

A manager made in the app installs and runs on its own: its own id, directory and database; it connects to the hub, shows in the roster and is online. Its assistant page, conversations and the other assistant endpoints reach it through `X-Persona-Manager: <id>` (or `?manager=<id>`, see "Ownership" above). It may report everything the hub already keeps per manager: computers (`devices.*`), pending cards (`fleet.interaction(s)`, `fleet.interaction_resolved`) and messages for the apps (`ws.broadcast`); it may also call `device.call` and `app.call`. Its snapshot, tools, extensions' report and Live Activity are kept as its own too (below, "What the hub keeps of each manager"); every bus method and event is open to every manager. **It acts only on the computers moved to it**: until one is, it can run nothing on any computer (no Agent, no conversation of its own; `devices.list` lists no computer). Moving a computer or a source to it is in "Moving a machine or a source" below.

### Registering a dedicated local computer

An authenticated administrator can create a local computer for an installed manager in one request to `POST /api/v1/admin/machines`:

```json
{
  "kind": "local",
  "id": "work-local",
  "name": "Work computer",
  "manager": "m-abcdef",
  "config": {
    "codex_discovery": false,
    "codex_homes": ["/srv/persona/work/codex"],
    "claude_config_dirs": ["/srv/persona/work/claude"],
    "claude_global_hooks": false,
    "botmux": false,
    "herdr_autostart": false,
    "usage_windows": false
  }
}
```

`manager` must identify a registered, installed manager other than `assistant`; an offline installed manager may be prepared before connecting. `config` contains the computer's configuration fields; the outer `id`, `name`, `kind` and `icon` determine its identity. These two fields are accepted only for local computers. Ordinary device pairing remains limited to link computers and retains its trust checks.

The hub saves the complete owner map before writing or publishing the new entry. Failed owner persistence publishes nothing; failed configuration persistence attempts to restore the previous owner map. If that rollback also fails, the safe reservation remains and ordinary registration with the same ID is rejected; retry dedicated registration or choose another ID. The entry carries `owner_required: true`, so a missing owner record or a failed ownership read withholds it from every manager, including after a restart. Dedicated computers are withheld while an ownership read has failed; a successful ownership retry restores their assignments. Existing computers keep their cached assignments and normal carrier fallback during such a failure. A dedicated local computer cannot be moved to `assistant`; it can be moved to another explicit manager. Existing computers without the marker retain their normal carrier fallback. Removing its manager leaves the dedicated computer unassigned until it is explicitly assigned to another manager.

Prepare and verify the manager's isolated runtime and node build before registering the local computer: publication immediately allows that manager to start its local node. Creating an ordinary local entry first and assigning it afterwards is unsafe because the carrier can start it between those steps. This registration does not move or reconfigure an existing computer.

If validation fails, stop only the dedicated manager and retain its database and profiles. Do not restart it on a build without session isolation while its local entry is still dispatched. Before rolling the hub back to a build without `owner_required`, remove the dedicated entry through the admin endpoint and apply its required restart in the release lane; verify it is absent from every manager's configuration. Older hubs do not enforce the new marker. Removing the entry from disk alone does not withdraw the live configuration.

### Directory and manager.json

- The default directory is `managers/<id>` in this computer's data directory (`~/.persona/managers/<id>`); `--dir` picks another. The directory is 0700 and its `manager.json` 0600:
  `{id, name, hub, hub_id, token, fingerprint?, database_url?, database_container?}`. `hub` is the address it reaches the hub at; `fingerprint` is the pin of the hub's own TLS certificate (only when it was installed through the hub's TLS port); `database_url` is its database, with its password; `database_container` names the container install made for it (none for a database you gave).
  The same file holds its sections of the configuration (whose assistant it is, its default machine and launcher, the Agents' triage and delegation, the Inbox, the knowledge base, the models, connectors, extensions written by hand, bots, mail sign-ins, Lark, usage sources; "Configuration" above, `docs/operations/config.md` ("manager.json")); joining again with a new code rewrites only who it is.
  The built-in manager (the assistant the hub starts) has its `manager.json` in `managers/assistant`, with the sections only; `personad manager` commands leave that directory out.
  A `manager.json` that doesn't read (not JSON, sections of the wrong shape, a `connector_gate` rule the gate can't use, a broken `moved_from_hub_json`) keeps that manager from starting, rather than running without its gate rules: it says why each time its service starts it again, until the file is fixed (one that isn't JSON at all, or is empty, exits with status 2, which its systemd service doesn't restart on: on Linux, start it again once fixed). Its own Postgres container, when install made one, is started first; the check runs before the manager connects to its database or starts any work. `join` over a file that isn't JSON, or is empty, keeps it beside the new one (`manager.json.unreadable-<time>`) and says so: copy its sections back.
- Switching back to an older build: its `join` and `install` rewrite the whole `manager.json` and drop the sections, its `run` reads them from a `hub.json` in the directory instead, and its `run` / `status` count `managers/assistant` as one more manager (give `--dir`); see `docs/operations/config.md` ("manager.json").
- Its knowledge base (`data/`), `secret.key` and extensions are all under this directory; it never writes to the hub's. While it runs, `PERSONA_HOME` points at it, so the programs it starts use it too.
- Moving to another computer: copy the whole directory, and the same token still connects; or get a new code for it in the app and install it again there (the old token stops working at once).

### Each manager's computers

A manager keeps the computers it connects in its `manager.json` (`machines`, each entry as the hub's hand-over has it; `server/internal/managerconf/machines.go`, `server/internal/devices/ownlist.go`):

- **Taken over from the hub's hand-over.** The first hand-over (`devices` in the hello's answer, then `devices.config`) is written there, and `machines_from_hub` records when it was first taken over, which hub handed it over (`hub_id`), whether the hub was in a mesh group (`mesh`), and the hub's tailcat DERP map. Each later hand-over that differs is written over it: the hub still edits the lists (adding, removing or moving a computer), so an edit by hand lasts only until the next one. An entry that doesn't read (no lowercase `id`, a padded or empty one, an id twice) is left out (the hub writes its own ids, so it shouldn't happen), and a list that doesn't read is written over by the next hand-over; the log says so once. A `manager.json` that is a link (to a volume) is written where it leads.
- **A start without the hub.** A manager whose hub hasn't answered within 20 seconds of its start connects the computers of its list, as the last hand-over had them; a hub that is up answers well within that (the built-in manager is started by its hub), so then nothing connects before the hub's hand-over. Local, ssh and tailcat computers work while the hub is away; Persona Link and connector computers need the hub anyway. It waits for the hub instead when the hub was in a mesh group at the last hand-over (which computers are this hub's to connect, and when, are the group's), and when the list is another hub's (the manager joined another hub since: its `hub_id` differs).
- **When the hub comes.** Its hand-over is the list: a computer it no longer has is let go, a new one connected, one whose entry changed connected again with it, and the hub is reported each entry as it has it. What the early connections couldn't do without the hub is done then: the computers waiting to be confirmed are read again (the managed launchers go out with the hub's part of each connection), a node on another build is offered the hub's, and tailcat makes its tunnels again with the hub's DERP map, at the next dial, when it differs from the one the list had. A computer moved away while this manager was stopped is connected until then, and so is the list of a manager that was installed again elsewhere (its old copy's token no longer works, but it connects its list before it learns that): stop the old copy's service.
- **Its own list as the list** (`machines.own`). A manager names the capability `machines.own` in its hello. The first time the hub hands it `machines_own` in `devices`, the hand-over's `machines` is taken over as its own (over a list taken over before, which may be out of date, or another hub's), and `machines_from_hub` says so (`own`). Another hub's own list (the manager joined another hub, or the hub's id changed with its database made again) is kept beside `manager.json` first (`manager.json.machines-<time>`, 0600) and the log says where. From then on its own list is the list: later hand-overs don't change it, and the hub edits it over the bus (`devices.machines.put`, `remove`, `get`; `docs/protocol/protocol.md`), each edit written to `manager.json` and the computer connected, connected again or let go at once. A list that doesn't read is then never written over: the computers stay as they are (at the manager's start, the hub's hand-over meanwhile) and the log says so until it is fixed by hand. An edit by hand takes effect at the manager's next start, the hub's next hand-over or its next edit. A hub that hands the list again without `machines_own` (an older build switched back to) has its hand-over run, but the own list is kept, not written over, for when a hub hands `machines_own` again; meanwhile the hub's edits are refused.
- **The hub's side** (`server/internal/hub/machines_kept.go`). The hub hands `machines_own` to every manager that names `machines.own`. Once such a manager's report says it holds its list as its own (`devices.state` `own_list`: its `manager.json` list reads, is marked its own and is the one running), the hub moves the `hub.json` machines it reports out of `hub.json`: a copy of them as `hub.json` had them goes beside it (`hub.json.machines-kept-<time>`, 0600), and from then on the hub knows each as kept by that manager (`hub.machines_kept`, beside the owners of `hub.json`'s machines) and by what it last reported of it ("What the hub keeps of each manager": the entry without its secrets). The hub's readers (Persona Link and device-token checks, a member's node streams, the admin page, pairing, trust, mesh records, the warm start) go by `hub.json` plus those. Its hand-over (`devices`) then carries no machines (`null`); the computers waiting to be confirmed and the rest of it, as before. Each new connection counts as holding its list only once its report says so: until then its hand-over carries what `hub.json` stages for it, and edits are staged there. A kept machine its manager's report lacks (its list doesn't read) stays known as last reported.
  - **Edits go to the manager that keeps the computer**: adding one (the admin page, a computer's code) puts it in the carrier's own list when the carrier keeps one and is connected; removing one (the admin page, a rejected computer) and a connector's new address change it there, at once and without a hub restart. With that manager away they are answered `503 assistant_offline`, and nothing changes; an add then goes to `hub.json`.
  - **`hub.json` is where the hub stages what such a manager doesn't have yet**: a computer added while it was away, one moved to it, one edited in `hub.json`, or one an older hub build added while switched back to. Each time it reports, the hub asks it for each of its `hub.json` machines (`devices.machines.get`): one it has as `hub.json` has it moves out; one it lacks, or has otherwise, is put to it as `hub.json` has it (the same entry once), and moves out at its next report. A machine its report names that is no longer its own (moved away while it couldn't let it go) is taken out of its list then. A kept machine its list no longer has (its `manager.json` lost) is said in the log: put it back from a copy beside `hub.json`, or remove it. Nothing is settled before the hub has read who owns what.
  - A kept machine's `trust` (`work`) is its manager's entry's now, as are its other settings.
  - **`hub setup` leaves the emptied list alone.** The `"machines": []` a move-out leaves in `hub.json` is not a hub installed before Claude Code: a rerun adds this computer to `hub.json` only while `hub.machines_kept` names none that a manager on the roster keeps ([onboarding.md](onboarding.md) 6.1).
  - **Removing a manager that keeps computers is refused** (`409 keeps_machines`; `503 owners_unknown` while the hub cannot read who keeps what): their entries (their secrets) are in its `manager.json` only. Move them away first, or remove it with `?drop_machines=1`, which drops them. Removing a machine from `hub.json` forgets an old record of a manager that kept it. The hub's own default computer (a `hub.json` without `machines`) moves like any other, but is not removed (`409 default_machine`): it is in `hub.json` again at every start; set `"machines": []` there to remove it.
  - Downgrades: an older hub build doesn't know the moved-out machines (copy them back into `hub.json` from the copy beside it). A manager switched back to a build without `machines.own` is handed no list at all while it still keeps machines (the hub says so in its log): a build from before would write the hand-over over its `manager.json` and lose them. They are connected again when it is switched forward.
- What the hub knows of each manager's computers in turn is in "What the hub keeps of each manager" below.

### Database

A manager owns its database: a Postgres of its own, never the hub's.

- **By default it gets its own container**, the way `personad hub setup` makes the hub's (`server/internal/pgdocker` is shared by both): `personad manager install` (and the `/i/` script, which runs it) makes the Docker container `persona-mgr-<id>-pg` with the volume `persona-mgr-<id>-data`, its port published on a free `127.0.0.1` port, user and database `persona`, running `postgres:18-alpine` with `-c wal_compression=lz4 -c checkpoint_timeout=15min` (`pgdocker.ServerArgs`, as the hub's; [docker.md](../operations/docker.md) ("Disk writes")), with the manager set of migrations (`docs/server/server.md`, "Migrations"). The password is generated there and kept only in `manager.json` (0600). This holds on the hub machine too: a manager there gets its own container, not a database in the hub's Postgres. `manager run` starts the container again when it runs (after a reboot, say), and makes it when install didn't. If the container's port was taken while it was stopped, it is made again on a new free port, over the same volume and with the same password, and `manager.json` gets the new address. If both the container and its volume are gone, the new database is empty, and the manager says so. A container by that name that publishes no port (one the docker script made) can't be used from the host: install says so.
- **`--database-url postgres://USER:PASSWORD@HOST:5432/DBNAME`** gives it another Postgres instead (its own server, or a separate database and role somewhere). It is used as it is, and the database is created when that server doesn't have it yet. It can't be the hub's own database (refused; every name of the local machine, `localhost`, `127.0.0.0/8` and `::1`, counts as the same host, and a missing port as 5432). Given into a directory whose container install made, that container is no longer used and not removed; join says how to remove it.
- **No Docker and no `--database-url`**: `manager join`, `manager join … --install` and `manager run --join` check this before trading the code (unless `--dir` already has a `manager.json` with a database: joining again after a revoke needs no Docker), print one line saying what to do (install Docker, or add `--database-url 'postgres://USER:PASSWORD@HOST:5432/DBNAME'`), and the install code is not used; `manager join` exits 2, `manager run --join` waits (below, "Commands"). A user who may not use Docker is told the `usermod` line; a Docker that isn't running is a plain error.
- **The hub never hands out its database password**: the join answer has nothing about databases.
- The default manager (the assistant the hub starts) keeps using the hub's database, with nothing migrated.

### Install commands

The answers of `POST /api/v1/managers` and `POST /api/v1/managers/{id}/code` carry `commands`, built from the hub address the app used for that request (https when it came over TLS or through a proxy that says so, with the pin when it came through the hub's TLS port). An `https://` `public_url` (a reverse proxy, a subpath: `docs/operations/network.md`) goes first, its path kept; an `http://` one does not, since every hub writes one for its host name, for the private network only (`docs/operations/config.md`). A request that came through a member hub (whose `Host` is the mesh's, `peer`) uses this hub's own addresses instead, most secure first: its endpoints on its TLS port (pinned), an https `public_url`, its other https endpoints, an http `public_url`, then any other endpoint. The pin goes with an address on the hub's own TLS port:

| Key | Command | For |
| --- | --- | --- |
| `service` | `curl -fsSL <hub>/i/<code> \| sh` (through the hub's TLS port it adds `-k --pinnedpubkey 'sha256//<pin>'`) | Any Linux or Mac, the hub machine included |
| `join` | `personad manager join <hub> <code> --install` | A computer that has personad already |
| `docker` | `curl -fsSL <hub>/i/<code>/docker \| sh` (pinned as above through the TLS port): the script that starts the manager and its own Postgres, two containers on a network of their own (see "Containers") | A computer with Docker; only when the hub knows its image (`PERSONA_IMAGE` or the one it was built as) |

`GET /i/<code>` answers a POSIX sh script. It needs no credential (the code is the credential), and **fetching the script doesn't use up the code**: only the join does. Unknown codes are 404 and count against the source, as at the join; public plaintext requests get 403 `tls_required`, and the code in their path is voided (as at the join). The script looks for this computer's personad (`$PERSONA_HOME/bin/personad`, `~/.persona/bin/personad`, or `personad` on the PATH); if there is none, it downloads it from the hub's release address the way `install.sh` does, and checks it against the sha256 the hub put into the script from the release it last read (`latest.json`; so the checksum comes from the hub, over its pinned TLS port when the command used it, not from the download site), or against the site's `SHA256SUMS` only when the hub knows none. The hub otherwise reads `latest.json` every 6 hours (hub-update.md), so for a script it reads it again first when its copy was read a minute ago or more (only a read that worked counts, not a check that failed; waiting at most 5 seconds, at most once a minute across requests; when that fails the sums it had stay): a release that came out since the last check doesn't fail every install with a checksum mismatch, and getting the command again a minute later gets the new sums. If the download still doesn't match, the script says a release may have come out since the hub last checked and to get the command from the app again. The site serves only its latest release: when that isn't the hub's own version, the script says so. It then runs `personad manager join <hub> <code> --install`. Arguments after `sh -s --` go to the join, e.g. `curl … | sh -s -- --database-url '…'`.

### Commands

- `personad manager join <hub> <code> [--dir D] [--database-url U] [--fingerprint F] [--install]`: first checks that there will be a database (no Docker and no `--database-url`: it stops without using the code, exit 2), then trades the code and writes `manager.json`. A directory that is already another manager's is not overwritten: the new manager goes to its own default directory.
- `personad manager run [--dir D] [--join <hub> <code>]`: runs it. `--dir` can be left out when this computer has only one manager. `--join`: trades the code first when the directory has no `manager.json` yet (a container runs the same command on every start, and from the second start on the join is skipped). Configuration mistakes (no `manager.json`, no database to use) exit 2, which the systemd service doesn't restart (`RestartPreventExitStatus=2`). A container's `--restart unless-stopped` restarts on exit 2 too, so when the join itself can't work (the code was used or expired, a plaintext join was refused, no database it can have) `run --join --dir D` prints one line and waits, polling `D`'s `manager.json` as it does after a revoke (without `--dir` it exits 2: there is no directory to wait on, and it never takes up another manager's). Get a new code in the app, then run the new install command (the docker script makes again a manager container that never joined, see "Containers"), or write `manager.json` into the directory with `personad manager join <hub> <new code> --dir <its directory>`.
- `personad manager install [--dir D]`: first sets up its database (its own container, see "Database"; a database it was given is just used), then on Linux writes the systemd user unit `persona-manager-<id>.service` (`Restart=always`, `RestartPreventExitStatus=2`, with a reminder about linger); on a Mac the launchd agent `com.persona.manager.<id>` (its log is `manager.log` in its directory). The binary it runs is the hub machine's `~/.persona/bin/personad` when there is one (so it upgrades with the hub), else the current one. On other systems, or without a systemd user instance, it says how to keep it running yourself.
- `personad manager uninstall [--dir D] [--purge]`: stops and removes the service and says what happens to the data. Its database container is stopped and **its volume, with all the data, stays**; `install` again picks it up. **`--purge` removes the container and the volume**, so the data is gone and the next install starts with an empty database. A database given with `--database-url` is never touched. The directory stays either way (deleting the manager in the app is what makes the hub stop accepting its token).
- `personad manager status [--dir D]`: this computer's managers, with directory, hub, database (and whether its container runs; Docker not running or missing is said as such) and service state.
- `personad manager search-reindex [--dir D]`: empties the manager's chat search index in its database (its `manager.json`'s, never the hub's), and it reads its chats again from the start: at its next sweep when it runs, else when it starts (`docs/assistant/assistant.md` ("Chat search (#6282)"); the built-in manager's is `personad assistant search-reindex`).

### Containers

A manager in Docker runs the hub's image beside a Postgres container of its own, on a network of their own. `commands.docker` is `curl -fsSL <hub>/i/<code>/docker | sh`: like `GET /i/<code>`, `GET /i/<code>/docker` needs no credential, doesn't use up the code, and counts unknown codes against the source; it answers 404 when the hub doesn't know its image. The script:

- makes the network `persona-mgr-<id>`, the Postgres container `persona-mgr-<id>-pg` (volume `persona-mgr-<id>-data`, not published on the host, started with the same `-c` settings) and the manager container `persona-mgr-<id>` (volume `persona-mgr-<id>-home`), running `manager run --dir /home/persona/.persona/managers/<id> --join <hub> <code>`;
- makes up the database password in the shell that runs it (the hub never knows it) and passes it **only through the environment**: `POSTGRES_PASSWORD` to Postgres and `PERSONA_MANAGER_DATABASE_URL` to the manager (`docker run -e NAME` with no value), never on a command line, where `ps` and the container's `Cmd` would show it. `manager run --join` reads `PERSONA_MANAGER_DATABASE_URL` when there is no `--database-url` (not `PERSONA_DATABASE_URL`: that one is the hub's, which a manager refuses), and keeps it in its `manager.json` on the first start; from the second start on the join is skipped;
- can run again: an existing network or container is kept (a stopped one is started), but a manager container that never joined (no `manager.json` in its `-home` volume: the hub refused its code, and it waits) is removed and made again with the script's code; and an existing database keeps its password, read back from its container, or, when only the volumes are left, from the manager's `manager.json` in its `-home` volume. When the `-data` volume is there and its password can't be found (the `-home` volume was removed), it stops and says to remove the `-data` volume too (its data goes with it).

The manager retries until its Postgres answers (the container restarts it). When the entrypoint sees `manager` it writes no `hub.json` and shows none of the hub's reminders (`deploy/docker/entrypoint.sh`). Don't share the hub's data volume (it holds the hub's keys).

To remove it: `docker rm -f persona-mgr-<id> persona-mgr-<id>-pg && docker network rm persona-mgr-<id>`. The volumes `persona-mgr-<id>-home` (its directory) and `persona-mgr-<id>-data` (its database) stay, and running the script again picks them up; `docker volume rm persona-mgr-<id>-home persona-mgr-<id>-data` removes them with the data.

### Extensions and the hub's API

The built-in manager runs on the hub's machine: its extensions call the hub there (`hub.json`'s `listen`), with a token of the scopes they were granted or, the old way (`hub_api`, the extensions in `manager.json`), the hub's own token (`docs/extensions/extensions.md`, "Permissions"). Another manager has neither: it may run on another computer and reach the hub only at its `manager.json`'s `hub`, across the internet with a pinned key the extensions don't know, and it never has the hub's token. So its extensions reach the hub through it: it is **relayed** (`extmgr` `relayed()`). Every manager but the built-in one is relayed; the built-in one becomes relayed with that one switch once it is a service of its own (step 3), and until then its extensions get exactly what they always did.

- **The token** is made by the manager each time it starts the extension's program, kept in its memory only (nothing written to its directory or any `hub.json`; its database records the token's SHA-256 and what it was for, never the token, and nothing recorded is read back as a credential: `extension_tokens`, `docs/extensions/extensions.md` "Permissions"), and dropped when the extension stops for good, is switched off, upgraded, reconfigured or uninstalled. It opens what the extension was granted and no more: the scopes its manifest asks for and the user agreed to (`permissions.hub`). Only an extension that asks for no scope but for the hub's full token the old way (`hub_api`, and the extensions written in `manager.json`) gets a token of **every scope** instead of the hub's own: every route an extension may be granted (`extwire.RouteScopes`, any `extensions.call:<id>` too) but `agents.permission_mode`'s, which an extension gets only when its manifest names it, none of those open to full credentials only (pairing, tokens, managers, the admin pages, `/api/v1/ws`…; `TestAllScopesOpenNoFullOnlyRoute` goes through every route the hub lists). The manager never hands out its bus token, and a token in a `hub.json` that happens to be in its directory is not read for this.
- **The address** is the manager's relay to the hub (`internal/extension/hubrelay`): it listens on the loopback, on a port the system picks, once an extension needs it, and passes each request (WebSockets too) on to its `manager.json`'s `hub` with its own client, the one that pins the hub's key. It passes on only the hub's API (`/api/…`, no `.` or `..` segment) with a live token of one of its own extensions (the header, else `?token=`, as the hub reads them), as the extension sent it: no cookie, no `X-Forwarded-*`, nothing of the extension's making but the request. Anything else gets 401 or 404 from it and never reaches the hub. While the manager is off the hub's bus (a hub restart, a network blip) it answers `503 manager_offline` with `Retry-After` itself and sends nothing on: the hub could not ask it whose a token is. A hub can also lose the manager before the manager notices (it crashed and came back, the connection is half open: the manager's keepalive finds out within a minute or so). So when the hub's auth layer refuses a token the relay knows (`401`, or `503 manager_offline`), the relay holds its extensions' requests the same way until the manager's next bus connection, or for a minute at most (a refusal that was not about the connection); a refusal of a token that went meanwhile (its extension stopped), or of a request sent on an earlier connection than the manager's now (it came back after a reconnect), holds nothing. The hub's auth layer says it is its own refusal with `X-Persona-Auth-Refused` (`token` on the 401, `manager_offline` on the 503) and takes that header off every other response, a manager's or an extension's passed on included, as the response's head actually leaves (outside gzip, which may hold it back): a `401` that comes from further on (a route whose own upstream refused its token) holds nothing. The extensions get it as `PERSONA_HUB_URL` and in `initialize`'s `hub.url`; the sandbox's egress proxy points `hub.persona.internal` at it.
- **The proof**: on each request the relay adds `X-Persona-Manager-Proof` (`extwire` `SignProof`): an HMAC-SHA256 over the method, the path with its query, the hash of the extension's token, a time and a random nonce, with the manager's id. Its key is made from the manager's bus token (`extwire.ProofKey`: an HMAC of a fixed label keyed by the token); the token itself is never sent. The hub makes the same key from the token as the manager connects and keeps it with that connection, in memory only: it is not the hash of the token the hub's database keeps, so reading the database or a backup forges no proof. An extension never sees it and cannot make one. The proof is set as each request goes out, so a bodiless `GET` or `HEAD` the hub refuses as sent before (`proof_replayed`: the transport may send a request again, nonce and all, on a connection that dropped) is sent once more with a new one.
- **Who it is**: the extensions of a manager other than the built-in one get `PERSONA_MANAGER=<id>` and `initialize`'s `hub.manager`; the built-in manager's get neither, as before.
- **The hub** asks each manager whose a token is, as for any extension's (`extensions.authorize`); the one that knows it is the manager the extension acts as, and only as it ("Ownership" above: `impliedManager`, `extensionReach`). From this machine or the LAN that is all, as before. From the internet (over TLS only, like any credential: `tls_required`) it takes an extension's token only with its manager's proof: one that names that manager, is signed with the key of that manager's **live** bus connection (no lookup), for this request (method, path and query) and this token, within 60 seconds of the hub's clock either way, with a nonce it has not seen. Without a proof the manager signed it is `403 extension_token_local_only`, counted against the source like a bad token: so a token that leaked is no use on its own from the internet, and the built-in manager's extensions, which send no proof, are refused there as ever. Extensions' tokens that fail from the internet (unknown, or without a good proof) count in a bucket of their own, which gates only extensions' tokens: a relayed manager's extensions call from its address, so calls the hub can't place must never lock out the manager's own bus dial, the apps or any other credential from there (an address locked out by other credentials is still locked out for extensions' tokens too). There is nothing to guess in one: it is 32 random bytes, new each start. A proof that names a manager of the roster with no live bus connection here (the hub restarted, and the manager has not noticed) gets `503 manager_offline` with `Retry-After`, not counted and before any manager is asked: without that connection nobody can tell whose the token is, nor check the proof, and a 503 says nothing of the token. That is only within two minutes of the hub's start, or of that manager's bus connection ending here (kept in memory): about the time a manager takes to notice and come back. Outside that window such a proof is counted as any other, or the answer would tell anyone, for free and again and again, which managers are in the roster and off the bus. Whether such a manager is in the roster is kept for 5 seconds (a database lookup at most every 5 seconds per manager named, however many requests), and dropped when the manager is revoked. A manager that does not answer whose a token is (it timed out, or is not ready yet) gives no verdict: the hub answers `503 manager_unreachable` with `Retry-After`, not counted and without `X-Persona-Auth-Refused` (the token is not known to be nobody's); only when every manager asked answered "not mine" is it a `401` that says so. From the internet that 503 is only for a request its manager's proof vouches for (signed with that manager's live key, fresh); anything else is counted as before. A proof naming no manager of the roster, a malformed one, or one failing against a connected manager's key is counted as above. A proof the manager did sign but that is refused is not counted, since the source is the manager's: out of the window is `403 clock_skew` (the manager's computer and the hub need their clocks within a minute of each other; the relay says so in its log when the hub's `Date` is 30 seconds off), sent twice is `403 proof_replayed`, and while that manager has 65536 nonces kept (each until its proof is stale) its proofs get `429 proof_busy` with `Retry-After`, no other manager's. The hub drops the proof before anything else sees the request. The nonces are in memory only: after a hub restart, a proof captured in the minute before it could be taken once more (capturing one means breaking the TLS it came over).
- **Revoked with the manager**: revoking or deleting the manager closes its bus connection, and at once nothing knows its extensions' tokens (no manager answers for them: `401`) nor makes a proof the hub takes (`TestRevokingAManagerEndsItsExtensionsTokens`); its relay, off the bus, answers `503 manager_offline` itself, and the manager stops its extensions once the hub refuses its token. A manager that is stopped or offline is the same until it is back.
- **Never logged**: neither the relay nor the hub logs a token, a proof or its key (the relay says only the method of a request that failed, the hub never logs headers and only fixed paths for refusals), and the token is not in the program's start environment the manager keeps, only in the one it hands the program each start. The tests look for them in every log line.

Not yet covered: the built-in voice extension (off until it is turned on) also calls routes open to full credentials only (`/api/v1/ws`, `/api/v1/channels`, `/api/v1/agents/triage`). Turned on in another manager, those calls are refused.

### After it is revoked

When the hub deletes it (or it was installed again somewhere else), the connection is closed with 4002 and the next dial gets 401 with code `token_revoked`. Only that explicit word counts: a hub that can't look tokens up (its database restarting) answers 503 `store_unavailable`, and a plain 401 is a refusal to retry later; the manager keeps dialing as usual on both. On the explicit word it says once that the hub no longer accepts its token and **stops dialing**; the process stays up, checks `manager.json` every 10 seconds, and every 10 minutes tries the token alone with a bare dial, nothing else of the manager running meanwhile (no bots, connectors, extensions or inbox: those sources may be another manager's now). It starts again only when that dial goes through (a hub restored from a backup may know the token again); a dial that gets no verdict (the hub unreachable, a proxy's answer) is tried again after a minute, never taken for yes. While the hub can't look tokens up it answers 503 for a couple of seconds without asking its database again, and counts none of it against the source. Once you get a new code in the app and `personad manager join … --dir <the same directory>` writes a new token, it restarts itself in place (exec), with nothing to change in the service. The assistant the hub starts is not affected (it doesn't take this path and keeps retrying every minute).

## The built-in manager's database

The built-in manager keeps its data in a database of its own, **inside the hub's Postgres server**: next to the hub's database (`persona`, or whatever its `database_url` names) is a second one named after it with `_manager` (`persona_manager`; `jarvis_manager` on an install whose database is still `jarvis`). Upgrading moves the data there once, by itself ([server.md](../server/server.md) ("The default manager's own database")).

- **One server, two databases.** Removing the hub's Postgres server (its container `persona-postgres` and the volume `persona-pgdata`, `jarvis-postgres` and `jarvis-pgdata` on an install from before the rename, or the system's Postgres) removes the built-in manager's data too: the conversations' state, todos, the inbox, the knowledge base's index, the model providers' and extensions' settings.
- **Back up both.** A backup of the hub must have both databases, `persona` and `persona_manager`: one `pg_dump` of each, or `pg_dumpall` of the whole server. A dump of `persona` alone no longer has the manager's data. Restore both together.
- **Moving the hub.** Move both databases. Its `manager.json` keeps only the second database's name, so it is found again on the new server through the hub's `database_url`.
- **Managers made in the app** are not affected: each has a Postgres of its own (above).

## The built-in manager's own files

The built-in manager (the assistant the hub starts) has its own directory, `~/.persona/managers/assistant/`, beside the ones of managers made in the app. Its `manager.json` is there (docs/operations/config.md ("manager.json")), and so are its keys (`server/internal/managerconf/files.go`):

| File | What it is |
| --- | --- |
| `secret.key` | Seals the manager's secrets in its database: model providers' keys, extensions', connectors' and bots' secrets, mail passwords. On an upgraded install it starts as a copy of the hub's and is rotated to a key of its own once the manager's data is in its own database ("Its own secret.key" below). The hub's own `~/.persona/secret.key` seals the hub's (peer tokens, connector credentials). |
| `tailcat-hub.json` | The identity the computers reached over tailcat trust. The manager dials them; `personad hub tailcat-key` prints this one. |
| `handles.key` | Keys the knowledge base's identity hints of senders. |

- **Upgrading.** The first time the built-in manager starts with this version, it copies each of them from `~/.persona` into its directory, once. `moved_from_data_dir` in its `manager.json` records which files and when. It copies rather than moves: the same bytes open what they already sealed, and an older build switched back still finds them where it looks. A file already in the manager's directory is never replaced.
- **When a copy fails** (a full disk), the manager reads the file where it was and says so at start. Making a new key beside the old one would no longer open what the old one sealed.
- **On a fresh install** there is nothing to copy: the manager makes its keys in its own directory when it first needs them (mail makes `secret.key` at its first start), so the hub's `secret.key` and the manager's differ from the start.
- **Switching back to an older build** keeps working for every key that was copied: the older build reads the same bytes in `~/.persona`, including for what the manager sealed after the copy (and before the move into its own database, whose copy in the hub's database the older build uses). A key that only the manager's directory has (a fresh install, or tailcat or the handles key first used after the upgrade) is not there for the older build. It makes its own, so it cannot open what the manager sealed with its key (model providers' keys, mail passwords, extensions', connectors' and bots' secrets: they are entered again there, and what is entered then does not open after switching forward again), the computers set up for the manager's tailcat key must be set up for the older build's, and identity hints hash differently.
- **Who reads what.** The hub reads none of these files (`TestTheHubOpensNoneOfTheManagersFiles` in `internal/hub`), and the manager doesn't read the hub's `secret.key`. The data directory's `tailcat-hub.json` and `handles.key` are left only for an older build and can be deleted once none will run; `~/.persona/secret.key` stays: it is the hub's own (linked hubs' tokens, the computers' connector credentials). Rotating the tailcat key now means deleting both copies of `tailcat-hub.json`: the next start would copy the one left in `~/.persona` again.
- **The knowledge base** stays at `~/.persona/data`, which the docs, the prompts and the agents that search it go by. `kb_dir` in its `manager.json` moves it (an absolute path, `~/…`, or one relative to the manager's directory); the assistant directory's CLAUDE.md and the daily routine's knowledge hint follow it, the inbox agent's knowledge heading follows it too, and the `kb_search` tool's description names no folder. A manager made in the app keeps its own in its directory.
- **What stays in `~/.persona` for now:** `extensions/`, until extensions are a part of their own (step 5).

### Its own secret.key

On an upgraded install the manager's `secret.key` began as the same bytes as the hub's, so each part could open the other's secrets. Once its data is in its own database ([server.md](../server/server.md) ("The default manager's own database")), the built-in manager rotates to a key of its own, once, at its start, before anything of it reads a secret (`server/internal/assistant/keyrotate.go`):

1. Under an advisory lock in its database (two starts at once: one rotates, the other finds it done), it keeps the key it has in `secret.key.prev` and writes a fresh one to `secret.key.next-<its fingerprint>` (each attempt its own file, so one never overwrites another's).
2. One transaction seals every one of its secrets in its database again with the new key, and records the new key's fingerprint (`sealing_key`; an HMAC that does not tell the key): mail passwords and OAuth tokens, connectors' and extensions' secrets, extension markets' tokens, the model providers' keys, headers and environment, the Lark bot's app secret and the Outlook client ID (`db.sealedTables` and `db.sealedSettings`; guard tests fail for a sealed column or a place that seals which is not listed). A value that opens with no key it has is left as it was, and the log says where. The transaction first checks that the record is still what the rotation read, so a process whose lock was lost cannot seal over another's work.
3. The new key's file replaces `secret.key`.
4. The old key stays in `secret.key.prev`, only for reading, until nothing can still be sealed with it; then it is deleted. That needs three things: ten minutes since the rotation, no other manager process using its database, and no legacy `mail_accounts.json` waiting to be imported. A process started before the rotation (a hub switching versions) may still seal with the old key, and it may have no connection open at the moment it is counted; the ten minutes cover that. The running manager checks every minute, and each start checks too; before deleting the old key, it seals again whatever is still sealed with it. A `database_url` that sets its own `application_name` hides other manager processes from the count; only the ten minutes cover those.

- **Stopping anywhere** (a crash, a full disk, a lost connection) is safe. Before the commit nothing is sealed with the new key, and the next start begins again. After it, the database names the new key, and the next start finishes the rename before anything reads a secret. When the commit's answer is lost, the manager waits until no re-seal is open on the server any more (its COMMIT may still be on the way; an orphaned one is ended within two minutes) and reads the record then: if the commit went through it carries on, and if that cannot be told within three minutes, it keeps the new key's file and does not start. After a connection that broke, the new key's file is never deleted: it goes only once the record names another key. The re-seal runs to its end even when the manager is being stopped. If the rename itself fails, the manager does not start: it would seal with a key the database does not name.
- **Never the hub's.** It rotates only `managers/assistant/secret.key`, never `~/.persona/secret.key` (which the manager still reads when its copy failed: it then does not rotate), and only in a database that does not have the hub's tables. Only the built-in manager rotates: a manager made in the app made its own key.
- **Backups.** From the rotation on, the manager's `secret.key` is the only key that opens its secrets: back up the data directory (`~/.persona`, which holds `managers/assistant/`) together with both databases. A backup of its database from before the rotation is sealed with the hub's key. After restoring one, copy `~/.persona/secret.key` to `managers/assistant/secret.key.prev` and restart: the manager seals those secrets again with its own key and deletes the copy.
- **A key that does not match.** If `secret.key` is not the key the database names (restored from another backup), the manager says so and changes nothing. Those secrets open again once the right key is `secret.key` again, or is added to `secret.key.prev`.
- **What still opens with the hub's key.** The manager's tables the move left in the hub's database keep the secrets as they were then, sealed with the hub's key, until `personad assistant drop-shared-tables` removes them.
- **Switching back.** A build from before the manager had its own key files reads `~/.persona/secret.key` and the hub's database, so it keeps working. So does a build from after the move but before the rotation: it reads the new `secret.key` and opens the secrets sealed again. A build from in between (its own key files, but still on the hub's database) does not: it reads the new `secret.key` against the hub's copy, which is sealed with the hub's key. To switch back to one of those, set the rotated `managers/assistant/secret.key` aside and copy `~/.persona/secret.key` there; put the rotated key back before switching forward again.
- **While the old key goes.** The running manager reads the old keys when it starts and keeps them in memory until it stops, also after the file is deleted. A value one of its services read before and writes back afterwards still opens, and the running manager seals it again within a minute, and once more when it stops. A process started after the file went never has the old key.
- **During a hub switch,** an older manager process still running cannot open what the rotation sealed again (model providers' keys, connectors' secrets): it is about to stop.
- **A legacy `mail_accounts.json` that fails to import** keeps the old key: each start says so, and it is deleted once the file is imported.

## Automatic updates for an independent manager

An independent manager's executable is separate from the Hub and the node. Updating either
of those does not update that manager. Older `manager run` processes have no update command
or RPC. Their first update is driven externally by the existing release publisher, executing
the **new, same-source release artifact** as `personad manager update`. It does not ask the
old process to execute a new command, reinstall or join again.

The existing `scripts/release/hub_release.py` worker accepts an explicit manager scope:

```sh
python3 scripts/release/hub_release.py --config <existing-worker-config> \
  --scope manager --manager-id <manager-id> --commit <full-main-commit>
```

An existing service that supplies no arguments can select the same operation through its
private worker configuration: `scope: "manager"`, `manager_id`, and `manager_commit` (the full
source SHA). Unconfigured workers keep their existing Hub behavior. `manager_targets` maps
that exact ID to a `publish_command` argv array invoking
`scripts/release/publish_manager_release.py --config <private-target-config>`; add `--apply`
only for an authorized activation window. There is no inferred default manager or new timer.
Use `--validate-only` to build and validate without publication.

This manager operation is a pinned, one-shot bootstrap. The existing release service and
timer must stay gated outside its separately scheduled window, including after completion;
selecting manager scope does not enable periodic manager upgrades. The old baseline hash
and bootstrap window are not a continuing health probe. Repeating an obsolete operation
must fail its current preconditions, rather than return a historical deployment success.
Further activation requires a newly reviewed baseline and authorization window.

The worker retains the original `state_dir/lock`, source-branch ancestry checks and full
release validation. `--publish-managers` produces `manager-manifest.json` containing the
same-source Linux and Darwin personad artifacts; it does not publish node packages or
change a node pointer. Each manager has its own `state_dir/manager/<id>/last.json`.
The target configuration's bytes enter the cache identity: a Hub-only success cannot skip
an unfinished manager, and changing an explicit target causes a new publication check.
Validated builds may be reused, but a historical manager success never skips the current
publisher invocation. Validation-only statuses use `manager-release/validation`, separate
from activation's `manager-release/worker` status.
A checked package is not installed. Only a confirmed receipt bound to this run, manager
and source makes that manager operation successful. Consumers must require that success
before resuming application publication.

### Transport and the first update

The manager publisher reuses the original publisher's `credentials_command`, `ssh_proxy`,
`remote_python`, `remote_root` and `release_namespace` configuration and authenticated connection to the Hub.
On the Hub it holds the existing `releases/hub/.publish.lock` for the whole manager operation.
It then uses a configured SSH transport to the target Mac. The new transport is a product
entry point, not a claim that an installation already has the required endpoint or identity.
A Persona Link connection or a reverse SSH connection does not establish this route.

The private publisher configuration adds a `target` object with these required values:

| Values | Meaning |
| --- | --- |
| `manager_id`, `main`, `machine_id` | Exact existing manager and original assistant identity |
| `dir`, `binary`, `uid` | Canonical manager directory, its own `bin/personad`, operating-system owner |
| `unit`, `plist_path` | Original launchd label and existing plist; compatibility labels are accepted |
| `previous_sha256`, `config_sha256`, `plist_sha256` | Read-only baseline hashes for the executable, manager.json and original plist |
| `transport` | `kind: "ssh"`, explicit `host`, `port`, `user`, `identity_file`, `known_hosts_file` on the Hub |
| `freeze`, `activation_enabled`, `bootstrap_authorized`, `bootstrap_window_until` | Explicit activation policy; frozen/disabled is the default |

SSH uses only those selected identity and known-host files, strict host-key checking and
batch mode. No default key, hostname inference, reverse route or trust-on-first-use is used.
Missing transport configuration fails without guessing. Direct SSH (`kind: "ssh"`) and
managed Cloudflare SSH (`kind: "cloudflare-ssh"`) are supported. Cloudflare targets use
the same explicit SSH fields with origin port 22, plus `cloudflared_path` (canonical,
executable absolute path on the Hub) and `cloudflared_sha256` (the installed binary's
verified SHA256). The publisher generates only the fixed proxy command
`cloudflared access ssh --hostname <host>`; arbitrary proxy commands, SSH aliases and
implicit jumps are rejected. The selected managed route and any required noninteractive
Cloudflare Access authorization must already work for the publisher identity. An account
API token or a tunnel management certificate does not establish client authorization.
Install the architecture-matching official client through the existing configuration lane
and record its hash before selecting it; the publisher does not download clients or create
tunnels, DNS records, services, Access policies or SSH authorizations.
Other transports and platforms are rejected. The operator must
provision the intended endpoint, trusted host key and identity reference through their normal
configuration process before checking connectivity. The publisher never provisions them.

Without `--apply`, publication only reads the service and product state and returns `checked`.
It does not create remote staging, rewrite product configuration or operate a service.
The installed executable must support `manager update inventory --plan -`; an older
executable without that read capability fails the check rather than staging a reader.

Applying additionally requires an unfrozen, explicit maintenance window of at most fifteen
minutes. The publisher stages the same-source formal candidate in the existing isolated
transaction directory with no idle digest. It executes that candidate's read-only inventory
CLI before checking or starting activation. The CLI receives only the original manager
identity through stdin, reads persisted assistant identity without migrations, and obtains
two complete, stable local node runtime inventories. Hub REST reads verify online status,
main session and machine ownership; display session lists never attest idleness.
Busy, compacting, pending, incomplete, unsupported or changing runtime evidence refuses
activation. One exact owned machine must be covered; additional machines fail closed.
After candidate checks, the publisher reads authority again and binds the fresh real digest
to the activation plan. A maintenance window alone never establishes idle state.

### Confirmation and recovery

The formal artifact is staged in the manager's own `.manager-updates/<run-id>` directory.
The new CLI checks the release channel, complete clean source identity, platform, native
checksum, size, owner, original loaded service arguments and baseline hashes. Stage/dev
executables cannot activate a formal update. `manager update check --plan <plan>` is read-only.

`manager update start` creates a separate, restartable launchd transaction guardian. It never
rewrites the original plist or its environment, calls install/join, or changes the manager's
configuration, database bindings, node, Hub or other manager. The guardian journals before
replacing the independent executable and restarts only that original validated service.
A crash during activation resumes recovery rather than retrying the candidate.
An unfinished active transaction prevents another run from taking ownership. A recovering
guardian may restore an image only while the active marker still belongs to its exact run
and target; a missing or foreign marker cannot authorize rollback of a later transaction.

The new manager reports readiness only after its stores opened and its authenticated Hub
handshake completed. The guardian checks that readiness against the original service's
actual PID, image, native checksum and unchanged configuration. It then waits for the
publisher to verify the live manager version, scoped assistant's original main/machine and
unchanged node inventory through existing Hub GET routes. `confirm` acknowledges these
checks; only then is the receipt `confirmed`. Roster, machine or main-session resync may
lag the authenticated handshake: the publisher allows at most sixty seconds from the
`start` command's return for these temporary absences to settle. Explicit ownership or
identity conflicts fail immediately.
A health rejection, missing acknowledgement,
startup timeout or interrupted activation restores the verified previous executable and
restarts the same service. An unrelated replacement or changed service identity is never
overwritten. Receipts distinguish `checked`, `applied`, `confirmed` and `rollback`; failures
must not release dependent publication steps.
A rollback receipt proves that the previous executable was restored and the original
service's restart command succeeded; reconnect and service health still require verification.

This path does not change default permissions. After the manager version is confirmed,
permission settings and inheritance require their own explicitly scoped product acceptance.
The presence of `config.own` or an omitted optional `default_permission_mode` field alone
does not prove support or an active runtime approval policy. Existing main conversations and
history remain the acceptance baseline; updating the manager does not send a new turn.

## The built-in manager as its own service

By default the hub starts the built-in manager as its child (`personad assistant`, or `persona-manager assistant` beside a hub run as `persona-hub`) and gives it a new bus token at every start. With `assistant.mode` set to `service` in `hub.json`, the built-in manager is a service of its own instead: the hub neither starts it nor gives it a token. It is bound to the hub once with a one-time code, and hub restarts (blue-green switches) no longer restart it. It runs on the hub's machine (or in a container beside the hub): it shares the hub's data directory, `hub.json` included, as the child does.

- **Setup installs it.** `personad hub setup` (`persona-hub setup`) makes a new install's built-in manager a service of its own when it installs services: on Linux with a systemd user instance (`systemctl --user` works), or on a Mac. It doesn't with `--no-service` or in a container. The new `hub.json` gets `assistant.mode` `service`; a mode written there already stays (`--manager-service` sets `service` over a `child`). With service mode, setup makes a one-time code (as `manager-code` does) and runs `<data dir>/bin/personad manager install --builtin --join http://127.0.0.1:<port>` with the code in `PERSONA_MANAGER_CODE`, not on the command line (any user of the machine can read that while it runs, and the hub trades this code from its own machine without another credential). The manager's program does the rest, so the hub writes none of its files. Setup voids the code afterwards when the program did not trade it. Then it waits up to 90 seconds for the hub to have it on the bus.
  - A failure of the manager's program stops setup with that program's last line, and with the way back (`persona-hub manager-mode child`, then restart the hub's service). When the service does not come online, setup says so (and where its log is) and goes on to the pairing code. A rerun changes nothing that works.
  - **Existing installs:** a `hub.json` a hub has run with keeps its mode, and setup says how to switch. `hub setup --manager-service` does the switch. First `<data dir>/bin/personad` (in an older layout, the binary under its former name; see `docs/protocol/rolling-upgrade-compatibility.md`) must say the service can be installed (`manager install --builtin --check`; an older binary can't: nothing is changed then). Then setup sets the mode, restarts the hub's service, binds and installs. When that fails, setup undoes the switch: it puts the mode back, removes the service as far as it got (`uninstall --builtin`; a binding it made stays) and restarts the hub, which starts its child again. When the service only fails to come online, setup leaves it and says how to go back (`persona-hub manager-mode child`, then restart the hub's service), as it does after every failure of this step. `--manager-service` refuses a hub whose built-in manager runs elsewhere (`assistant.external`) and changes nothing; it can't go with `--no-service`. Step by step, with a check and the way back for each step and for Docker and hubs without a service manager: [upgrade.md](../operations/upgrade.md).
  - **Docker:** the hub image runs the built-in manager (`persona-manager assistant`) beside the hub in the hub's container, under `personad supervise`, which binds it and starts each again when it stops. New installs get service mode; older ones keep the hub's child until switched. It can also run in a container of its own. See [docker.md](../operations/docker.md) ("The hub and the built-in manager in one container").
  - **Service mode without a service:** `hub setup --no-service`, or a container, on a hub in service mode installs nothing. When the built-in manager isn't on the bus, setup reports it as a problem (nothing runs it) and gives both ways out: run it yourself, or `persona-hub manager-mode child` so the hub starts it.
- **Its service.** `persona-manager install --builtin [--join <hub address>]` (`personad manager install --builtin`) installs it on Linux as the systemd user unit `persona-manager-assistant.service`, and on a Mac as the launchd agent `com.persona.manager.assistant` (log: `managers/assistant/manager.log` in the data directory). The unit runs `<data dir>/bin/persona-manager assistant` when that is beside `<data dir>/bin/personad` and its build (`version -v`), else `<data dir>/bin/personad assistant` (the binary updates replace; without one there, the running program); a new agent on a Mac by the same rules, but on a Mac installed with `personad` it stays on `personad`: its own agent ran it, or, before it has one, the hub's agent runs it (Full Disk Access lists `personad` for the node of the hub's computer, and moving would need another program added there); `install --builtin` says so when `persona-manager` is beside it, and says which program Full Disk Access needs when it moves an agent ([server.md](../server/server.md) ("Programs")). Each runs it with `PERSONA_ASSISTANT_DEPLOY=service` and `PERSONA_HOME` set to the data directory. The unit restarts it on any exit but 2 (`RestartPreventExitStatus=2`: not bound, another one running). With `--join` and a code in `PERSONA_MANAGER_CODE` (which it takes out of its environment once read, so `systemctl` and `launchctl` don't get it), it keeps a binding whose token the hub still takes: it checks with a bare dial, which takes nothing over, and leaves the code to run out. Otherwise it trades the code first. Without a working binding and a code it installs nothing (exit 2). No systemd user instance, or another system, stops it before the code is spent; `install --builtin --check` checks just that, changing nothing. The unit is started when it does not run, restarted when it changed or the binding is new, and left alone otherwise. A unit or agent that ran another program is moved to this one, and it says so (`it runs … now, not …`); one under the former name keeps `personad`, and `PERSONA_SPLIT_PROGRAMS=0` in its environment keeps `personad` too, written into the unit or agent until `install --builtin` runs again without it ([server.md](../server/server.md) ("Programs")). On a Mac, `bootstrap` right after `bootout` is tried up to 5 times, a second apart. `persona-manager join --builtin <hub address> [<code>] --install` (the code given, or in `PERSONA_MANAGER_CODE`) always trades the code, then installs it the same way. `persona-manager uninstall --builtin` stops and removes the service; the binding and the data stay. `persona-manager status` lists it too (`status --builtin`: only it).
- **A new binary.** Updates (the hub's self-update swaps `personad` and its programs together) and `install.sh` replace the file the service runs from, and nothing else restarts the service. So the service looks at that file every minute. When another file is there, or this one was written over:
  - **Check:** the new file must be an executable regular file whose `version -v` answers within 30 seconds (one that hangs is killed with what it started). One that doesn't is not used: the service goes on with the code it runs, says so in its log, and doesn't check that file again until another one is there.
  - **Idle:** with a file that runs, it waits until nothing is going on. That means no request being answered (an app's call or an extension's through the hub; an agent's tool call or a write the gate forwarded from a computer), no hub event left to handle, and no request or stream of the extensions' open (a voice call, or a live view such as an extension's log page left open, which holds it up to the 30 minutes below). None of its own conversations may be on a turn (or their machine not answering), no agent's finished turn being looked at, and no scheduled task's message or channel's answer going out. A task agent's start also keeps it busy, counted before its goroutine is launched until linking, failure bookkeeping or entering a retained-tab remedy finishes; normal starts and both retry paths are covered (#3251). A computer's card or question waits on a person and is taken up again after a restart, so it doesn't count. Its outbox doesn't hold it back: what it keeps waits in its database. It logs what it waits for. A check of all this that doesn't answer within 10 seconds counts as busy, and its late answer is dropped. After 30 minutes it goes ahead anyway, saying so.
  - **Restart:** then it stops and starts again in place on the new file, after one more check (as after a refused token, with the same exec).
  - **Failure:** when the check or the exec fails then, it runs again on its old code, and that file isn't tried again. The file that was there when it started isn't started on, not even when that very file is renamed back while it waits. A rollback that copies the old binary back in is a new file, so the service starts again once more, onto the old version. After a refused token it starts again only on a file that passes the same check.
- **Binding by hand.**
  1. `persona-hub manager-mode service` sets the mode in `hub.json`; the running hub takes it at its next start: `persona-hub switch` (or restart its service). The hub then stops starting its child. The built-in manager is offline until step 4.
  2. `persona-hub manager-code` prints a one-time code (10 minutes). It refuses unless the built-in manager is a service here (`assistant.mode` `service`, not `assistant.external`).
  3. `PERSONA_MANAGER_CODE=<code> persona-manager join --builtin <hub address>` (or the code as a second argument, where other users of the machine can see it while it runs) trades the code for the built-in manager's token (`POST /api/v1/bus/join` with `builtin: true`) and keeps the hub's address, the token, the hub's id and any `--fingerprint` in its `manager.json` (`hub`, `token`, `hub_id`, `fingerprint`; its other keys as they were, 0600). It reads that file before it trades the code: one that does not read stops it with the code unspent. The hub never writes that file.
  4. `persona-manager assistant` with `PERSONA_ASSISTANT_DEPLOY=service` runs it on that binding (its service sets the variable; `install --builtin`, or `--install` in step 3, installs the service). It reads no token from stdin, and takes `hub.json`'s manager sections over into its `manager.json` as the hub's child does.
- **What the hub accepts.** A code is traded only by the join of its kind: the built-in manager's only by `join --builtin`, and every other only by a manager's join (`409`). The built-in manager's code is also refused when the built-in manager is not a bound service here (`409`), and from an address the hub does not count as local (`403`; local is its LAN class, [network.md](../operations/network.md): loopback, private ranges, link-local, on-link global IPv6, `security.trusted_cidrs`, the address range of its VPN). A code the hub cannot look up is refused too (`503`). None of these refusals spends the code. A trade gives the built-in manager a new token and hangs up a connection that came with the old one. `persona-hub assistant-token` is refused in service mode: its token would replace the bound one.
- **Not bound** (no token in its `manager.json`, or a `manager.json` that does not read): it does not start and exits 2. Restarting can't fix that, and the service will not restart it.
- **One at a time.** A second `persona-manager assistant` in service mode on the same data directory does not start (exit 2): it holds a lock on `managers/assistant/.service.lock` while it runs. This is Linux and macOS only, as the service is.
- **When the hub refuses its token:**
  - **When it happens:** the code was traded again, `assistant.mode` went back to `child`, or the hub was switched back to a version from before this mode. A hub in child mode, or one from before, starts its own child with a new token.
  - **At start:** it dials the hub once right after reading its binding, before anything else (its configuration, its database, its computers, extensions and connectors). On any refusal, a plain `401` from an older hub included, none of that starts.
  - **While running:** any refusal on a reconnect stops all of it, the hub closing a connection that said no hello in time (4003) too: a hub stalled that long costs the built-in manager up to 10 minutes, until its next try.
  - **Waiting:** it then checks its `manager.json` for a new token every 10 seconds, and tries the old one again every 10 minutes. Once it has a token the hub takes, it starts again in place. A hub that does not answer at start doesn't stop it: it runs as usual, and its bus stops it on a refusal later.
  - **Overlap:** short overlaps remain while a refused service shuts down and a child starts.
- **Going back to child mode:** `persona-hub manager-mode child`, then `persona-hub switch`. The hub starts its child again with a new token, and the service, refused, waits as above. Remove it (`persona-manager uninstall --builtin`), or leave it waiting. To go forward again, `persona-hub setup --manager-service` (or set service mode, switch, and bind with a new code: the old token was replaced by the child's).
- `personad hub manager-mode`, `personad hub manager-code` and `personad manager join|install|uninstall|status --builtin` are the same commands.

## What the hub keeps of each manager

Nothing one manager reports replaces another's (`server/internal/hub/manager_state.go`). The assistant the hub starts (`assistant`) keeps its state where it always did; every other manager gets its own when it first reports, dropped when it is removed (`DELETE /api/v1/managers/{id}`).

| What | Kept | Where the hub needs one |
| --- | --- | --- |
| Snapshot (`manager.snapshot`): conversations, tasks, profile, todo links | By manager | A conversation the snapshot lists counts as the manager's own only on a computer it owns (`conversation`, `mayClaim`); a row naming no computer (an older one) counts for no manager, so a request about it goes to the manager it names, else the default one (as with one manager). A snapshot naming another manager's session, or a session on a computer moved away from it, takes nothing. In the session lists every session carries its computer's manager (`manager: <id>`). |
| Profile (in the snapshot) | By manager in memory; only the assistant's is kept in the database (`hub.assistant_profile`) | The hub reads the user's time zone and the skills machine from the selected manager's profile, falling back to the built-in assistant's profile only when that manager has not reported one. `GET /api/v1/skills` selects the manager named by `X-Persona-Manager` or `?manager=`, else the default. Time-zone reads without a request use the default manager. Every manager's main conversation counts as a main conversation (`isMainOn`), on a computer of its own only. |
| Tools (`assistant.tools`) | By manager | The assistant's are asked for when it connects (as before); another manager's the first time they are needed after it connected. |
| Extensions' report (`extensions.report`) | By manager; only the assistant's is kept across a restart | Merged: features and looks of all, a machine's extras (Cua, ego) from its own manager, an API prefix (`/api/v1/<prefix>/`) served by the first manager that reports it, the assistant's first. |
| Live Activity (`fleet.live`) | By manager | The default manager's, else the assistant's (the Live Activity is one per phone). |
| Pending cards (`fleet.interaction(s)`) | By manager (each card names the manager that reported it) | Answering a card goes to its manager (`interactionOwner`). Removing a manager withdraws its cards: the apps get `interaction_resolved` for each. The push of a card from a manager other than the built-in assistant replaces only that manager's push of the card: its `apns-collapse-id` is `card:` and a hash of the manager and the card id. The built-in assistant's card keeps the card id, unless the id is longer than APNs' 64 bytes, when it gets the same `card:` form. |
| Inbox "Needs you" count (`inbox.needs_you {count}`) | By the manager's connection, in memory: gone when it disconnects, unknown until the new connection says it | The inbox is the manager's; the hub reads none of it. Each manager counts its open items under "Needs you" and tells the hub after each handshake and after every inbox change. The roster gives it as `inbox_needs_you` for the apps' badges (absent while not known), and a number that differs from the one before pushes `{"type":"managers"}` a second later, once for the numbers that change within it (a round's items triaged one by one move it a step each, and the apps reload more than the roster on that push). |
| Machines (`devices.state`) | By manager, in the database (`hub_settings` `hub.machine_entries`, `hub/machine_entries.go`): each of its own entries (from `entries[].cfg`; a manager from before sends none, so the state's `config`, else the entry the hub handed it), the computer as its node last described itself (`info`), and when it was last seen (a machine connected as it is written, or as its manager goes away, is seen then). Secrets stay with the manager: the tailcat address is left out, a proxy's password cut | A hub that restarts without the warm hand-over (a crash, a stop longer than 2 minutes) shows every manager's machines offline as last reported (host name, OS, versions, `last_seen`) until their manager reports them, and a manager that stays away, its machines so. Only the machines the hub hands the manager count; any other id its report names is refused and logged once. Written within a second of a change to an entry or its `info`, when a manager goes away, at the hub's stop, and at least every 10 minutes while reports come. Moving a machine hands its entry to the new manager; removing a machine drops it; removing a manager hands its machines' entries to the carrier, which they go back to. Read at start without the machines and managers that are gone. A mesh record lists each computer as its own manager reaches it (`entries[].avail`, `rtt_ms`), unreachable while that manager is away. |

When several managers report a to-do link for the same machine/session pair, the hub uses the session owner's link (`sessionOwner`: the machine's owner). If that owner has no link, it uses the built-in assistant's link, then the first link encountered from another manager; ties among those other managers have no guaranteed order. Each non-nil report rebuilds the merged links using current ownership. A nil report keeps the manager's previous links, while an empty report withdraws them. A single manager's behavior is unchanged.

A manager going offline keeps its last reported profile in memory. After a hub restart, a non-built-in manager uses the built-in assistant's persisted profile until it reports again. A reported empty or invalid time zone uses the hub's local time zone, as with one manager; it does not borrow another manager's time zone. A selected profile whose skills machine is unavailable keeps the existing skills endpoint error behavior.

There is no gate on the bus by method: every manager may call every method and publish every event. What concerns one machine is taken only from its manager (`ownsMachine`): `devices.state` (below), `fleet.sessions`, `devices.node`, `devices.request`, `devices.connected`, `devices.connector_cred` and `devices.connector_paired`; another manager's are dropped or refused `no_device`. A pending card another manager reported is not replaced by one with the same id. A card (`fleet.interaction`, an entry of `fleet.interactions`) is taken only on a machine of its manager's own: one naming another manager's machine, or a session on one (by its machine; a session id alone by the machine that lists it, or the conversation's manager), is dropped, so it can neither look like that session's question nor get the user's answer. A card naming no machine and no session is its manager's own (`cardAllowed`). **A manager acts only on the machines it owns**: `device.call` goes only to a machine of the caller's own, and on another manager's every method (starting or resuming a session there, its sessions, files, panes, memory, launchers, its session list) is refused `no_device` and never reaches the node. The call about every machine (`devices.list`) lists only the caller's machines (the others' ids are in `others`). The assistant the hub starts is a manager like the others: it has no say on a machine moved away from it. A call checked before its machine moved still reaches only the caller's own node: the hub checks the owner again as it sends it (`withCaller`), so it never lands at the new manager's. So a manager never acts on a machine or a session it does not own, and a manager whose conversations should run on a machine runs them there only once the machine is moved to it.

The other ways a manager reaches the apps and the hub follow the same rule (#5923); what names a session without its machine goes by where the session is (the computers listing it, the manager whose conversation it is: `ownsRef`):

- `ws.broadcast` carries only a manager's own types: the ones the managers send (`managerMessageTypes`: the assistant's feed, views, plans, schedule, todos…, its extensions' manager's inbox, mail accounts, extension events…) and the ones its own running extensions declare for `api.broadcast` (their `events`, in its extensions' report, marked `events_declared`); a manager from before that (its report without `events_declared`, or the old report the hub kept from before a restart) may send any type but the hub's, since its extensions' types are not known; never one of the hub's own (`interaction`, `interaction_resolved`, `machines`, `sessions`, `items`, `error`, `fleet`, `look`, `personas`, `hub_update`… `hubMessageTypes`). `TestBroadcastTypes` reads both from the code (`go/ast`). Every object in the message, at any depth, that has a `machine_id`, `session_id` or `conversation` must name the caller's (strings or null). The hub reads the message with exact keys, as the apps do: a key twice in one object, or a key that differs from `type`, `machine_id`, `session_id` or `conversation` only by case, drops it, and the apps get the message as the hub read it (marshalled again), not the manager's bytes, with top-level `manager` set to the sender's id when it is not the assistant the hub starts (a `manager` the message carried is replaced, or taken out of the assistant's: "Clients" below), and without a top-level `event_seq` of its own: only the hub's event log numbers a message, and an `extension_operation`, which the log does not keep, goes without one. Anything else is dropped.
- `notify.request`: a card's push (`input`) only for a pending card the caller reported, and the hub pushes its own copy of the card, not what the request says of it; any other push (`assistant`, `done`, `reply`, `decide`) only about a computer and session of its own, or none. An extension's push (`hub.push_localized`, `hub.push_background`) likewise names only its own computer and session, and only a pending card of its own (an `interaction_id` nobody has pending is refused too). The rest is refused `no_device`. What goes skips the devices that turned the caller's pushes off ("Clients" below, Push switches).
- `app.call` naming a `machine_id` only on a computer of the caller's; the settings it reads or changes through its extensions (`settings.list`, `persona_settings`) are the caller's, not the default manager's.
- `devices.request` keys are each manager's own: one manager's `devices.request_end` never ends another's request. A card is checked again once kept, so one reported while its computer moved does not stay.

## Directories on a computer

Each manager's assistant runs its conversations in a directory of its own on a computer, so their CLAUDE.md, memory, connectors' command lines and skills are its own:

| Manager | Assistant | Health space |
| --- | --- | --- |
| The built-in one (`assistant`) | `~/.persona/assistant` (as ever) | `~/.persona/health` |
| Another (`m-…`) | `~/.persona/assistant-<id>` | `~/.persona/health-<id>` |

Under a custom `PERSONA_HOME` they are in that root instead of `~/.persona`. The manager names them when it prepares one (`assistant.prepare`, `internal/identity` `AssistantDirName` / `HealthDirName`). The node knows any manager's (`IsAssistantDir`: `assistant`, `health`, and the same with `-m-<hex>`; `assistant-bin` and the like are not), and keeps every manager's health space from the conversations outside it, another manager's health conversations included (a health conversation reads its own space only). The hub and each manager count a conversation as the assistant's only in the directories of the computer's manager (`IsAssistantDirOf`); the hub asks a computer for another manager's skills in that manager's directory. A computer that moved keeps the old manager's directories, which the new one does not read ("Moving a machine or a source").

The node lists an assistant or health conversation in the directory it started in, not where the model's last `cd` left it (#2368: a `cd` into `.claude/skills/<skill>` had one listed as an agent): its start record, else the transcript's first `cwd`, else its own project directory's name. The other way round, an agent whose `cd` landed in an assistant or health directory itself (one started in the home directory) is listed where it started, so only a conversation that started there is ever listed in one. The hub and the managers keep counting only exact directories (`IsAssistantDirOf`), not anything inside them: a conversation the user runs in a subfolder is theirs, not the assistant's. An older node's rows at rest may still drift until the node is updated; health cards are kept off the lock screen and the channels for every node version (the manager places a card of its conversation in the conversation's directory, `placeCard`).

Health reports the user uploads (`POST /api/v1/machines/{mid}/files?dest=health`) go in the health space of the computer's manager, whose health conversations run there: `health/reports/` for the built-in one as ever, `health-<id>/reports/` for another; its Health page lists and deletes those only (`health.reports.*` with its `health_dir`), and its health CLAUDE.md names its own space. Another manager's space needs a node with the `health_spaces` capability that also says, on each call, which space it used (an older one answers 409 `node_outdated` rather than put, list or delete a report in the built-in's space; a delete is asked only after a list of the same space came back saying so). Reports belong to the space they were uploaded to, not to the computer: those uploaded before a computer moves stay in the previous manager's health space on it, the new owner neither lists nor reads them, and they show again if the computer moves back.

These directories keep each manager's assistant to its own files, not the managers apart: managers that run their conversations on the same computer under the same user account can read each other's files (assistant memory, CLAUDE.md, `~/.claude/projects`, the guest directory). Use separate OS users for isolation.

A manager hands its launchers (with their keys) only to its own computers: its list of computers is the hub's `devices.list`, which has no other, and a node connection the hub refuses as another manager's gets none of the manager's own calls nor its extensions' part. Only that answer counts (`devices.connected` → `no_device`, a computer moving away while the manager still has it); with the hub away, or any other error, the connection is configured as before.

## Moving a machine or a source

Moving a machine also gives both managers a new answer to their hello (`manager.updated`): the machines each owns and its default machine among them.

**A machine** (one of the hub's own list, hub.json or added in the admin page, or one a manager keeps in its own list): `POST /api/v1/managers/{id}/machines {"machine_id"}` → `{machine_id, manager, from}`. `id` `assistant` moves it back to the carrier.

- **One its manager keeps** ("Each manager's computers") moves with its entry, secrets too: the hub gets it from the manager that keeps it (`devices.machines.get`), puts it in the new one's own list (`devices.machines.put`), or into `hub.json` for a manager that keeps none, and has the old one let it go (`devices.machines.remove`). With the one that keeps it away, it doesn't move (`503 assistant_offline`). A `hub.json` machine moved away from a manager that keeps its own list is taken out of that list (retried at its next report when that fails), and put in the new one's when it keeps one, before it leaves `hub.json`. A manager that keeps machines in its own list is removed only with `?drop_machines=1` ("Each manager's computers").

- **Its engine choice goes with it.** Each manager keeps its computers' engine choices in its own settings, so before the hand-over the hub reads the choice from the old manager (`devices.engine.get`) and puts it in the new one (`devices.engine.put`); a computer never set stays unset. If the old manager can't answer (offline, removed, an older build) the computer moves without it, logged; if the new one can't store it the move fails, so a change of manager never switches the engine (#3611). A new manager too old for the call takes the computer without it, as before.
- The hub keeps who carries it (setting `managers.machines`, `{machine: manager}`, absent: the carrier), and from then on sends what concerns the machine to the new manager (`moveMachine` in `ownership_moves.go`; who owns it is still decided in one place, `ownership.go`).
- Each connected manager is handed its machines again (`devices.config`, and the hello's `devices` section now goes to every manager with only its own machines): the old one lets it go, the new one connects it. Until the new one reports it, the machine shows offline.
- **Its sessions go with it.** From the move on, every session on the machine is the new manager's: the user's messages, renames and read state, its cards' parameters, `device.call` there. That includes the old manager's own conversations there, its main conversation too: its snapshot listing them no longer counts, and it can no longer reach them. Its pending cards on the machine are withdrawn (`interaction_resolved`), and those naming one of its sessions without the machine; its cards naming nothing of the machine stay. A manager keeps its main conversation on a machine it keeps.
- **Its directories stay, unread.** The old manager's assistant and health directories stay on the computer as they are (its CLAUDE.md, its memory, its conversations' transcripts): the new manager uses its own (below, "Directories on a computer"), never reads the old one's, and its conversations there are no assistant conversations of the new manager's. Delete them by hand if they should go.
- **Its relays are cut.** A Persona Link (and its streams) or a member hub's node stream the hub relays to the old manager is closed with 1013 (try again later): Persona Link dials again and lands at the new manager. A relay is checked again as it is taken, so one handed over while the machine moved does not stay.
- A machine of the hub's own list is taken only from its manager's report (`devices.state`), derived or not: the old one's report while it lets go, or any other manager's, is dropped. A machine not in the list (a mesh member's) is the carrier's: only the carrier is handed the mesh, and any other manager's report of it is dropped.
- Moves are one at a time (read the kept map, keep it, install it), so moves at the same time all stay, and a removal's release holds the same lock. Until the hub has read the kept map (at start; again at the next move when that failed) a move is refused `503 owners_unknown`: it would overwrite it. A move checks under that lock that its target is still in the roster. Reading it drops a machine hub.json no longer has and an owner the roster no longer has; removing a machine from hub.json drops its owner.
- Credentials the hub keeps for it stay with the hub and go only to the machine's manager: a service machine's (`devices.connector_cred`, `devices.connector_paired` from another manager are refused `no_device`), a Persona Link's (the link relay is handed to the machine's manager). An ssh machine is connected with the new manager's own ssh setup.
- **A move does not revoke what the old manager already has.** A service machine's connector credential is not rotated (a new one takes a pair link from that computer): the old manager could have read it while the machine was its own and can still dial the connector with it. To cut it off, pair the connector again after the move (admin page › the machine › pair again: its old credential stops working at once, `docs/operations/link.md`); the new manager does the pairing. An ssh machine trusts whatever ssh keys are set up on it: remove the old manager's key there yourself.
- A mesh member's machines are not movable (`400 not_movable`), nor unknown ones.

**A computer added to a manager** (`add.manager` on `POST /api/v1/auth/pair-codes`, `docs/protocol/protocol.md` ("Computer pairing codes")) is that manager's from the start, never the carrier's first: the hub records its owner (`managers.machines`) before it writes the entry, as for a dedicated local computer (`addMachineTo` in `machines_owned_local.go`), and then hands it over as above: into the manager's own list when it keeps one and is connected, else into `hub.json`, where an offline manager takes it over when it connects. From then on it is a machine like one moved there; removing the manager gives one in `hub.json` back to the carrier, and one in its own list goes with it (`?drop_machines=1`), a computer still waiting to be confirmed as a rejected one goes: its Persona Link credentials, pairing codes and place among the pending too. A pending computer of that name used again (it never connected) is moved to the manager named first.

**A source** (only a mail account so far, `mail:<account id>`): `POST /api/v1/managers/{id}/sources {"source", "from"?}` → `{source, manager, from}`; `from` is the manager that has it (the stamp on its list item), the default when not given.

- The hub asks `from` for it (`extensions.source_export`: the account with its credentials in plaintext, over the bus only; the hub neither keeps nor logs it), hands it to `id` (`extensions.source_import`: sealed again with that manager's own key), then has `from` let it go (`extensions.source_release`: it deletes the account and its secrets; what it already filed stays in its knowledge base). See `docs/extensions/mail.md`.
- Both have to be connected (`503 assistant_offline`); one move of a source at a time. `404 no_source`: `from` does not have it; `409 source_exists` / `source_kind`: `id` has another source by that address, or it is a kind that cannot move yet. When the import worked but the release did not, `502 source_not_released`: both have it. Moving it again releases it: when `id` answers `source_exists`, the hub checks `id` has that very source (it exports it) and goes on to the release.
- When the import does not answer (the link dropped, the time ran out), the hub asks `id` whether it has the source: it does, the release follows; it does not, `from` keeps it; no answer either, `502 source_in_doubt` (moving it again finds out).

**Revoking a manager** (`DELETE /api/v1/managers/{id}`): it waits for the moves to or from it under way, and a move after it gets `404 no_manager`. Its machines go back to the carrier (`assistant`); what the hub kept of it goes: its snapshot, tools, report, Live Activity, its pending cards; every relay it has (Persona Links, node streams, its extensions' requests) is closed, as when its token is replaced. Its sources live in its own database, which the hub cannot reach once it is gone: move them away first (`POST /api/v1/managers/assistant/sources`); the app should say so before it removes one.

## Settings › Managers in the apps

### Shared bot credentials (web)

The web page warns when two or more managers report the same enabled Feishu bot (app ID) or bound, enabled WeChat account. It names the managers and platform and recommends using a separate bot or account for each manager: sharing credentials may disrupt delivery or disconnect clients. This is advisory; it does not stop either manager or change routing. One manager alone produces no warning.

Managers include `bot_identities: [{kind, id}]` in `extensions.report`, with `kind` equal to `feishu` or `wechat`. These are stable account identities, never app secrets or access tokens; a WeChat display name is not an identity. Disabled or unbound bots and standby managers report no corresponding identity. Binding, unbinding and enabling changes refresh the report.

The hub compares each installed manager's latest report, including reports retained while a manager is offline. `GET /api/v1/managers` adds `bot_conflicts: [{platform, managers: [id, ...]}]` only when duplicates exist; raw bot identities are not returned to clients. Changed identity reports push the existing `managers` event so an open page rereads the roster. Removing a manager removes its contribution. Old managers without this report field cannot be checked; other managers' reports remain in memory only and must arrive again after a hub restart, following the existing report retention policy.

For screenshots, `MOCK_SHARED_BOTS=1` on the mock hub adds Feishu and WeChat conflicts between two sample managers.

### Roster and actions

Every client has the same page (web: `docs/web/web.md`, Android: `docs/android/android.md`). On iOS and the Mac it is the **Assistants** row in Settings' server section (`SettingsPage.managers`, `Persona/Views/Settings/ManagersView.swift`; logic and words in `ManagersModel.swift`, tests `ManagersModelTests`):

- The list shows each manager's name, a Default chip, a status dot with Online / Offline · last synced … / Installing · code expires in n min, and where it runs (host · OS · the hub's own / service / container / standalone).
- A manager's page (`SettingsPage.manager(id)`) has its status, where it runs, version, and when it connected or last synced. Its actions are Rename, Make Default, Install Elsewhere (it warns first that the old install stops; a manager still installing gets New Install Code instead), and Delete (confirmed; Cancel Install while installing). Delete is disabled for the hub's own manager and for the default one, and the footer says why.
- New Manager asks for a name, then opens the install code sheet: the code with Copy, an m:ss countdown, and New Install Code once it runs out. When the hub sends `commands`, the sheet adds As a Service and With Docker, each with Copy. Without them it shows the code and a short note.
- The socket asks for feature `managers` in its URL's `?features=` (`LiveConnection.queryItems`; the Apple apps' `client_hello` only carries the locale), and each `{"type":"managers"}` push moves `AppModel.managersRevision`, which makes the open page reread the roster. A hub without the roster (404 without a code) gets a line saying to update the hub.
- DEBUG launch arguments for screenshots: `-tab settings -openManagers YES`, `-openManagerPage <id>`, and `-showManagerCode YES` (makes a manager on the fake hub and opens its code sheet). The fake hub (`scripts/mock/mock_hub.py`) serves the roster; `MOCK_MANAGER_COMMANDS=1` adds the commands.

## Automatic update idle evidence

A checked release candidate is not idle evidence. The original independent
manager settings and the live Node own different parts of the proof. A newer
full `personad` can read both without replacing or restarting that manager:

```sh
personad manager update inventory --plan /absolute/original-plan.json \
  --main ORIGINAL_MAIN --machine ORIGINAL_MACHINE --machine-uid ORIGINAL_UID
```

This command uses the plan only to bind the original manager directory, UID and
config hash. It opens that manager's existing Postgres with read-only startup
parameters and executes one fixed SELECT of the persisted main, machine, row
version and observation time. It does not use the database migration entry point,
write settings, create receipts or activate an update. Connection diagnostics do
not print the DSN. A missing main or mismatched explicit identity fails closed.

The optional Node capability `manager_update_inventory_v1` announces the local
0600 `node.sock` request kind `update.inventory`. The input is an explicit
`{manager, main, machine_id, machine_uid, authority_revision}`. Its schema-1
response binds that identity to the process instance, source revisions, complete
activity rows and completion time. It is a local read-only interface; it does not
add a Hub Link transaction-update adapter or raise the Node protocol floor.
Legacy managers and Nodes remain compatible for ordinary use, but a legacy Node
without this producer cannot furnish this proof.

The producer reads full configured host snapshots, complete loaded Codex thread
pages including ephemeral/child threads, fresh background terminal lists, and
owned stdio app-servers. Starting keys, warm spares, resident processes and
pending interactions cannot be omitted. Retained background/compaction and nested
workflow child metadata remain blockers without explicit completion. It compares
source membership, identity, configuration and the owner's process inventory
again after reading. A cached display row, historical `offline` status, missing
list or old mtime never proves completion. An unloaded persisted main is covered
only after the complete live sources have answered. Snapshot data includes no
prompts, task commands, transcript content or credentials.

An explicitly remote Codex terminal can use the configured app-server's authority.
The supported command form is `codex resume --remote <configured-local-endpoint> <thread-id>`:
the host must report that exact session, its foreground PID must match the owner's
process inventory, and kernel argv must bind that PID to the same endpoint and
thread. Argument boundaries come from `/proc/<pid>/cmdline` on Linux and
`KERN_PROCARGS2` on macOS, never the formatted `ps` command or a title. The endpoint
must already be a configured, connected local app-server; collection neither starts
one nor resumes the terminal. A matching historical thread ID alone is insufficient.
All loaded threads, ephemeral children, background terminals and pending activity
are retained even when the host displays idle. Activity revisions and foreground
bindings are read again before completion. Missing sessions, duplicate bindings,
changed membership and old app-servers without background-terminal reads are refused.

Other terminal forms, live Claude streams without a synchronous background-inventory
barrier, and third-party runtimes without an authoritative inventory contract remain
unsupported for idle attestation. This adapter does not certify existing embedded
or unbound terminals, upgrade a runtime, or establish a new runtime capability.
Herdr's display revision, foreground process list and session snapshot are not a
complete background or child inventory. A future runtime producer must expose a
read-only snapshot for the same live session/process, with an instance/generation,
complete source membership, children, background work, pending interactions,
compaction and revision/freshness evidence. Installing a host adapter after a
session starts cannot manufacture missing lifetime coverage. Their display saying
idle does not remove the blocker. An unreachable source, unresolved retained activity,
missing capability, changing ownership, partial page or clock conflict also fails closed.

#### Preparing terminal maintenance material

`personad manager maintenance` is a separate, read-only preparation utility. It
does not call session close, retire, start or resume, send slash commands or signals,
change update scope, or produce idle evidence. Both native exit and restoration
execution remain **unsupported**: knowing `/exit` and an exact history ID does not
prove persistence, termination of attached background sessions, child completion,
or safe recovery of tools and services. No force-close fallback exists.

An operator can preserve an explicit private record before considering maintenance:

```json
{
  "runtime": "claude",
  "version": "<recorded native version>",
  "session_id": "aaaaaaaa-bbbb-cccc-dddd-eeeeeeeeeeee",
  "pane": "<recorded pane>",
  "pid": 12345,
  "executable": "/absolute/canonical/path/to/claude",
  "cwd": "/absolute/canonical/workspace",
  "profile_home": "/absolute/canonical/profile",
  "history": "/absolute/canonical/profile/projects/project/session.jsonl",
  "environment": {
    "HOME": "/absolute/home",
    "CLAUDE_CONFIG_DIR": "/absolute/canonical/profile"
  },
  "resume_options": ["--model", "<recorded model>"],
  "settings": ["/absolute/canonical/profile/settings.json"]
}
```

For Codex, use `runtime: "codex"`, `CODEX_HOME` and its native rollout. All paths
must already be canonical. Version, pane, cwd, profile, options and session-to-PID
association are supplied observations, not verified runtime claims. Preparation
checks the history's own ID, hashes the executable/history/selected settings, and
brackets file reads with owner/process observations. The process key is only an
OS observation, not a stable producer instance or proof of a session binding.
It deliberately reads no process environments, arguments, credentials or task text
from running terminals. Record only known non-secret settings paths, never tokens,
credential files or message content. Output includes private paths and must stay
local; do not attach the record to a public issue.

```sh
umask 077
personad manager maintenance prepare --record record.json > prepared.json
personad manager maintenance observe --prepared prepared.json --wait 10s
personad manager maintenance recovery-recipe --prepared prepared.json
```

Input JSON must be owned by the current user, private (0600 or stricter), at most
1 MiB and contain no unknown fields. At most 16 distinct selected settings files
are accepted; file read budgets are 512 MiB for the executable, 128 MiB for history
and 4 MiB per settings file. System-installed executables may belong to another
user; private history and settings must belong to the current user. No default
profile, guessed ID or empty-history
fallback is accepted. Only the original ID and explicitly recorded options appear
in the recipe, as an argument vector with no prompt or shell execution. Missing or
conflicting history, a changed executable/settings file, history truncation or a
changed original history prefix refuses the recipe. Same-ID history may append;
each appended row is checked, including a final persistence flush after departure.

Observation waits at most 30 seconds. Unreadable/partial process tables and changed
PID observations return errors; timeout remains an error and never closes anything.
A wait that runs out during a process-table read reports `state: "timeout"`, not an
unreadable table.
`process_absent: true` is only an absence observation, not a graceful-exit receipt:
crash, detach, PID reuse and surviving background work are not resolved by it.
`graceful_exit_confirmed`, `background_complete`, `machine_idle`, `binding_verified`
and `execution_supported` remain false in their respective outputs. A successful
prepare or recipe command means only that its preservation checks passed. It is
not authorization or technical readiness for exit, recovery or manager activation.
The original complete inventory, main identity, transaction lock, guardian, health
confirmation and rollback requirements remain necessary and unchanged.

The native reader performs two complete runtime reads within 30 seconds, compares
payload revisions, and rereads persisted identity after the final runtime read.
Only a successful complete read returns `idle: true` and a SHA-256 digest. Its
`completed_at` starts the evidence lifetime; it does not retimestamp a saved
snapshot. Collect again immediately before the original transaction start after
any transfer/check. The transaction's original lock, fresh plan, guardian,
confirmation and rollback requirements remain in force. An explicit bootstrap
window does not replace missing idle evidence.

The native reader may be newer than the fixed formal manager candidate. The
candidate retains its own source/hash checks and is not rebuilt merely to collect
inventory. A Node-only executable lacking the manager CLI needs the same formal
source's full `personad` reader, not a guessed executable or an installed manager
replacement. Existing publisher HTTP collection (`manager_idle.py`) still refuses
legacy display inventories without its complete scoped metadata; the local
producer does not silently label those HTTP lists authoritative. Hub Link update
transport is a separate capability and is not required for local collection.

## Clients (step 4)

What the hub gives the apps for several managers; each app's pages are in its own docs (web: `docs/web/web.md`, Android: `docs/android/android.md`, iOS and the Mac: `docs/apple/ios.md`). **Once a roster is known (read in this run, or kept from the last launch), web, Android and Apple show the current assistant's identity and switcher, including with one installed manager** (those still installing do not count as installed). The frozen Mac follows Apple's shared sidebar code. A legacy hub without a roster shows no switcher and keeps the client's earlier header and controls; on Apple, the sidebar's title is the persona's name. Product branding and the user's chosen Persona look stay unchanged. On all three clients the behavior gate is still multiple installed managers: with one installed manager or no roster, filtering, badges, extra requests, `X-Persona-Manager`, `?manager=` and `needs_you` reads remain off, and behavior with multiple installed managers is unchanged.

### The current assistant

An app shows one assistant at a time, the **current assistant**, picked in a switcher at the head of its sidebar. The web app, Android and the Apple apps work this way (`docs/web/web.md`, "Settings"; `docs/android/android.md`, "Several managers on the pages"; `docs/apple/ios.md`, "The Persona page's manager" and "The pages show the current assistant"; on the frozen Mac app the switcher is one line in the title row). What still groups by manager on a client (the extensions and connectors pages in Settings) is in "Grouping" below, and its own doc says which.

- **Names**: what people read says assistant (助手, アシスタント): New assistant, Manage assistants…, Settings › Assistants, Default assistant; the settings row for the assistant's own profile is Assistant profile (助手资料). Code, the protocol, `manager.json` and these docs keep `manager`.
- **The pick** is kept on the device, per hub, across launches. A device that never picked follows the hub's default, and a pick whose manager left the roster (deleted, or never installed) goes back to it. Requests name the pick with `X-Persona-Manager: <id>`; with the default current none is sent, so a hub with one manager gets the requests it always got. Until the roster is read after a launch, the kept pick already counts: the pages list its things only and the switcher shows the name the roster last gave it, rather than every assistant's and the hub's own name for a moment.
- **One identity for the default assistant (#6401)**: the default manager is the Persona of the main conversation, so every client shows the chosen look's face in the switcher's head — not the first-letter monogram every other assistant keeps — with the same presence and needs-you corner marks. Changing the look changes that face. Its name is the manager name the hub keeps (`PATCH /api/v1/managers/{id}`), shown in the switcher's head, the main conversation's row, the profile and the composer; on web and Apple the profile edits it directly (a pencil on the name), and every client can rename it from Settings › Assistants. A hub without a roster keeps the look's own name and the earlier header, read-only.

- **The switcher** shows the current assistant's avatar, name and status (Online · its computer, Offline · last synced …). It opens the roster: the installed managers, the default first and tagged Default, the current one checked, an offline one's whole row faded (avatar, name and line) but still selectable (its pages show what the app last read, as below); then the ones still installing (Installing · code expires in n minutes), where choosing one opens its install code and commands instead of switching; then **New assistant** and **Manage assistants…** (Settings › Assistants). With one installed manager, web, Android and Apple show the same switcher and a one-row roster without a Default tag; New assistant and Manage assistants… remain available. New assistant also remains in Settings › Assistants. With two or more installed managers, all three use the switcher above, including offline managers; pending installs alone do not enable it. On Apple, a hub without a roster keeps the persona's name as the sidebar's title; web and Android keep their earlier header and controls.
- **Avatars** are a disc with the first character of the name. The default manager's is the AI purple; any other takes one of five hues by the sum of its id's UTF-8 bytes modulo 5, in the order blue, green, orange, pink, indigo, each client using its own design system's color of that name. A mark at its foot gives its status (online green, offline neutral, installing orange), and on the sidebar's head a mark at its top says another assistant has something waiting. Where a client already shows the user's chosen Persona look, it keeps the look and changes only the name beside it.
- **Counts** (one definition on every client): an assistant's count = its agents waiting for the user + its `inbox_needs_you` from the roster (`docs/protocol/protocol.md`; absent counts as 0). An agent waiting is a session of that assistant that is not a quiet task's, is not muted, and has at least one pending card or is in Needs you; each session counts once. A pending card on no session counts 1 each. The current assistant's row shows no count. The mark on the sidebar's avatar means another assistant's count is above 0. Clients count from the sessions and cards the hub already pushes with their `manager`, and again after every `managers` push. The Apple apps get no session pushes from a hub with bounded lists (`sessions_list`), so there they read the hub's sessions in Needs you for it.
- **Pages**: the assistant page, Agents, computers, the inbox, to-dos, scheduled tasks and the knowledge base show the current assistant's only, with no manager headings. The hub's merged lists and pushes stay whole and the app filters by each item's `manager` (none, or one the roster doesn't know: the default's); the assistant's own routes and its knowledge base (`/api/v1/assistant…`, `/api/v1/kb…`, `/api/v1/kb-search`, `/api/v1/recordings…`) name the pick, and so does a new to-do. The Apple apps ask a hub that can for the current assistant's page of agents (`sessions_manager`, `docs/protocol/protocol.md` ("One manager's sessions")), as their Agents list is paged by the hub, and leave the recordings, and their part of the knowledge base (`/api/v1/kb/recordings…`), with the default: the phone syncs its own in the background, whichever assistant is current. An item opened from a notification or a link opens as itself, routed by its own manager as before, and does not change the pick; nor does anything done to another assistant's item (handing it to Persona, summarizing its chat, the outbox, answering a card): the conversation it starts or uses opens as itself on its own computer (its address names that computer and, when another than the default, its manager, so a reload, a new tab or a link opens it there too), its requests name its manager, and only the switcher, or a pick leaving the roster, changes the current assistant. What a conversation's feed offers (a plan's Start or Don't start, a briefing question's Handled) names the conversation's manager: those routes name no conversation, so the hub would take them to the default. A page that stays where it is when the pick changes shows the new assistant's at once: the lists filter again, and the pages that read the assistant's things themselves (All chats, the profile, scheduled tasks, the knowledge base) read them again, so nothing on screen and no request is the last assistant's; what a client keeps of them (the knowledge base's lists, the to-dos' projects) is kept per assistant. A page about one thing (an entry, an item, a to-do) either closes when the pick changes or keeps writing to the assistant it was read from; a knowledge entry opened by its address (which names no assistant) is read from the current assistant and everything its page writes names that same one. A new mail written on the inbox page is the current assistant's (its mail accounts, sent through it). A to-do made for an agent (Create and link, a project's new to-do) is the agent's assistant's, and the to-dos offered there are that assistant's.
- **Offline is not empty**: the hub's merged lists leave out a manager that doesn't answer, so with the current assistant offline the inbox and the to-dos (and any other page built on a merged list) say "<name> is offline" with when it last synced and that the page updates once it is back ("Last synced <time>. This updates when it's back online."), under its avatar with the offline mark, instead of their empty or first-run page; Android also says it on Agents and Computers when the hub keeps none of that assistant's agents or computers. Only with several assistants and the current one offline; one assistant, or an online one, is unchanged.
- **Add computer** is the current assistant's: a new computer's code names its real id, the default's too (`add.manager`, `docs/protocol/protocol.md` "Computer pairing codes"), once the roster has said which that is (a client waits for it rather than sending a placeholder); a new code for an existing computer names none. When the reply's `manager` is another assistant, or is missing (a hub from before the field puts a new computer under its own assistant), the waiting screen says "This computer was added under <name>." With the current assistant offline nothing is added and the client says why. The list of computers waiting to be confirmed that blocks a new one (the hub's limit of 3) is every assistant's. Apple's sheet follows this for the hub-level group's hub only (`AddComputerModel`): while no roster is known and no pick is kept, Next waits a few seconds for the hub's answer (a hub without a roster answers 404 and is not kept waiting); it shows the hub's `too_many_pending` words and has no list of the computers in the way.
- **Settings** come in three groups, in this order. **"<name>'s settings"** (zh「{name} 的设置」, ja「{name}の設定」): the current assistant's avatar and name with a **Switch** (切换, 切り替え) that opens the same list of assistants as the sidebar (Apple keeps its existing Persona face/name and omits switching with one assistant); rows in this order, those a client has: model providers, model settings, the assistant's profile (助手资料), session triage, connectors, extensions, inbox rules, scheduled tasks, Claude Code / Codex on its computers; each page reads and writes the current assistant only, with no picker of its own, and connectors and extensions list its items only, without manager headings; the line under it says that only its own settings are shown and to switch to change another's. **This device** (这台设备, このデバイス): appearance and layout, notifications, translation, storage, health. **Hub**: the hub, its version, the assistant list (Assistants, 助手, アシスタント), pairing again; the line under it says these two groups are the same whichever assistant is current. A client's other rows go where they belong: an assistant's thing in the first group, this device's in the second, the whole hub's in the third. The avatar, which the hub keeps for every device whichever assistant is current, goes in Hub. The first group shows with one assistant too; web and Android keep the name/avatar/Switch header, while Apple keeps its single-assistant appearance without Switch; a hub without a roster has no assistant to name, so there the group has a plain heading and no Switch or line under it. The default assistant's pages (so one assistant's) name no manager on their requests, as everywhere. With the current assistant offline, the first group's pages say so, as below, rather than look empty or failed. A settings page open when the pick changes either goes back to the settings list or reads everything again for the new assistant; it never shows the new one's name over the last one's content, and nothing it writes goes to the wrong assistant. The health page keeps following the default. Apple combines model providers and model settings in Models, collects Claude Code / Codex / triage in Agent, and moves diagnostics into About and Watch sync into Devices & Pairing; its search and exact entry mapping are in `docs/apple/ios.md` ("Settings by scope (#5236)").
- **Unchanged**: the default manager and what follows it outside the app (Siri, Shortcuts, the watch, widgets, the Live Activity), the health space and the Health page, the hub's routing and its database. CarPlay's voice (Apple) follows the conversation open in the app, else the current assistant's main conversation: it extends the app's screen.

### What the hub gives

- **Badges**: the roster gives each online manager's `inbox_needs_you`, the open items of its inbox under "Needs you" (`docs/protocol/protocol.md`, "Bus"; what the Inbox badge counts of that manager's list). It is absent for a manager that is offline, being installed or from before it reported one: an app then counts only what it knows itself (the agents waiting for the user, from the live pushes). It changes with a `{"type":"managers"}` push (within about a second of the inbox changing), after which the apps read the roster again as they do for any other change of it.
- **Push switches**: a device's `muted_managers` in `PUT /api/v1/devices/{id}/prefs` (`docs/protocol/protocol.md`; an app offers the switch only when the hub's answer has the field, and sends only that field). Whatever a manager asks for skips the devices that muted it, on APNs and as `ws_notify` events alike: `notify.request` from its bus connection (its assistant's reminders, finished turns, reply reminders and cards, from its outbox too), its extensions' `hub.push_localized` and `POST /api/v1/notify` with their token, `POST /api/v1/notify` with another credential that names one of its computers (an id this hub has no computer for leaves it the hub's own), and `personad notify` on one of its computers (the computer's manager). The mute is applied per device where the hub sends (`Pusher.sendFrom`, `notifyWSFrom`), so a push asked for explicitly still goes past Phone Muted and to an open desktop as before (`docs/lessons/server.md`). The Live Activity shows one manager's agents (the default's, else the assistant's: `fleetLiveOf`); on a device that muted that manager it starts without its alert, as in quiet hours. A write of the prefs keeps only managers of the roster, so a removed manager's id takes none of the 64 places. The hub's own pushes (pairing, a computer joining, updates) and an extension's silent `hub.push_background` are no manager's and still come.
- **Live updates**: another manager's `ws.broadcast` messages carry `manager` (`docs/protocol/protocol.md`, "Messages to the App"); one without it is the assistant the hub starts. What names a conversation (feed items, cards, plans) goes by its conversation, whichever manager's it is, so another manager's conversation open elsewhere stays live; only what is about the assistant page itself (`assistant_schedule`) is the shown manager's.
- **An offline manager's computers**: the hub shows them offline with its words for an unreachable assistant (`hub-assistant_link.offline`, no `error_code`). An app with several managers may say instead that the computer's manager is offline (the roster's `online` and the computer's `manager`), and offers no Reconnect, which goes through that manager.
- **Settings › Managers** lists them (`GET /api/v1/managers`, reloaded on `{"type":"managers"}`), with details, new, rename, default, install elsewhere and delete; see "Install codes" and "Revoking" above. Each manager's details have the push switch above. A manager the hub marks `needs_update` (online without `config.own`, "Configuration" above) gets a **Needs update** badge in the list and on its page, which says to update personad where it runs. A never-installed manager's new code that gets `404 no_manager` (it left the roster 7 days after its last code expired) makes it again under the same name.
- **The assistant page is the current assistant's** (a client still on the page switcher: one segment per installed manager at the page's top, the default first and then the roster's order, starting on the default and not kept across launches). Every request on the assistant's routes (`/api/v1/assistant…`) carries `X-Persona-Manager: <id>` for the chosen one; with the default chosen none is sent. Not on one conversation's routes (`/api/v1/assistant/conversations/{id}/…`): those name the manager whose page listed the conversation, or none, and the hub sends them to the conversation's manager (byConversation), which a named manager would override. The health space has no switcher and stays the default's: its list (`?space=health`), the machine it runs on (that list's `machine_id`, not the shown manager's), and a new conversation (`POST …/conversations?space=health`). Sessions (the main conversation's messages, its transcript) need nothing: the hub sends them to the session's manager. Its list of conversations is the chosen manager's (sessions carry their computer's `manager`).
- **An offline manager** is greyed out in the switcher. Its page shows what the app last read of it in this run (the hub answers `503 assistant_offline` for it), the composer is disabled and says "<name> · last synced <time>" from its `last_seen`, and nothing is sent or queued. A conversation of an offline manager opened anywhere else (the inbox, a notification, the Agents list) has its composer off the same way, by the conversation's own manager. Its computers say that their manager "<name>" is offline and that they come back online once it is back, with no Reconnect.
- **Grouping** (on a client still without the current assistant): the machines page, the extensions page and the inbox group their items under each manager's name by the item's `manager` (none, or a manager the roster doesn't know: the default's), the default first, empty groups left out; an offline manager's heading says when it last synced. The inbox keeps its sections inside each manager's group. A request for an item of another manager than the default (its details, done, reply) names that manager (`X-Persona-Manager`), as `docs/protocol/protocol.md` ("Per-manager routing") asks, and so does everything its page reads and sends (its Lark chat, its mail, its connector's thread): named where each request is made, so one that goes out after the page moved on keeps its own, and `?manager=` on pictures and files loaded by URL. An answer about one item comes from its manager unstamped: the item keeps the stamp it had. Bulk actions (Clean up all, a section's Clear all) send one request per manager with its own items; one manager failing leaves the others' done and puts its own items back. An item is its id and its manager (one account in two managers lists the same id in both): the apps keep each copy apart, and a link to another manager's item names that manager. Mutes and rules are each manager's (set from an item with its manager, covering only that manager's items; the lists show each manager's under its name), so is an item's Trail, and an item an extension draws (`inbox_item`) is drawn by its manager's extension, asked for with its name, as are the sections (`machine_section`) of its computers. An extension's page carries its manager (the same id can be under several managers: each one's built-ins), and so do its sign-in updates (`extension_auth`, matched by the event's `manager` and the id), the connectors and channel it contributes (that manager's copies and pages), its upgrade (that manager's catalog, preview, consent and operation; an operation's push says whose with its `manager`, and `GET …/-/operations` is the default's) and its pages. Handing an inbox item to Persona, or summarizing a Lark chat, starts the conversation with the item's manager and opens it (a client with the current assistant leaves the pick as it is, above). A Lark document or Moments post that a link in a chat (an agent's, a conversation, an inbox item's) opens in the app's reader is read as that chat's manager, and so is everything the reader loads for it (comments, summary, pictures and files with `?manager=`, the read-ahead and its cache, kept apart per manager) and every link opened from inside it; a chat of the default's names none. What the pages without a switcher show of a manager's settings (the workflow board's switch, extension badges in the sidebar) is the default's: the others' updates of them are left out.
- **Deleting one** says what goes with it: how many computers it has (the machines stamped with it), which go back to the hub's own manager, and that its sources (mail accounts…) are in its own database and are deleted with it unless moved to another manager first.
- **Move to…** on a computer's page gives it to another manager (`POST /api/v1/managers/{id}/machines`, the menu lists the installed managers, offline ones marked); not for a linked hub's computer (`kind` `hub`, or a `hub_id` other than this hub's: in a mesh every computer names its hub). Its sessions and cards follow it.
- **Mock hub**: `scripts/mock/mock_hub.py` has three installed managers by default (助手 default, 工作 online, 家里 offline) and one installing; computers, sessions, cards and the merged lists carry `manager` as on the real hub (one manager too; a computer never moved is the carrier's, `assistant`; a computer of an offline manager is offline with the hub's words and its sessions are in state unknown; the merged extensions list has the built-ins under every installed manager, as each manager's extmgr adds them; the merged inbox leaves out the offline manager's items, as the hub leaves out a manager that doesn't answer; a hand-off naming 工作 starts 工作's main conversation on its MacBook), 工作's assistant page has no main conversation yet and 家里's answers 503. `scripts/test/test_mock_hub_managers.py` checks this against a running mock. By default 家里 has no computer, so the computers other screenshots count stay as they were; `MOCK_MANAGER_NAS=1` gives it the NAS and the NAS an agent (in state unknown). `MOCK_MANAGERS=1` is one manager, `MOCK_MANAGERS=0` a hub from before the roster, `MOCK_MANAGER_OUTDATED=1` marks 工作 `needs_update`. Device prefs keep `muted_managers`, `POST /api/v1/managers/{id}/machines` / `…/sources` move a computer or a mail account, and each other manager keeps its own inbox mutes and rules (named with `X-Persona-Manager`; an offline one answers 503 `assistant_offline`).
