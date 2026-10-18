---
name: codex-with-chatgpt
description: >
  Use ChatGPT (web) as the planning and review brain for Codex coding sessions,
  while Codex keeps full execution ownership. Use when the user says
  "Use Codex with ChatGPT ..." / "Set up Codex with ChatGPT" / "Plan with ChatGPT",
  when they ask to connect ChatGPT to the current workspace, disconnect it,
  destroy its owned setup, explicitly update this fork, or run a task through the ChatGPT planning loop.
---

# Codex with ChatGPT

ChatGPT thinks. Codex works.

You (Codex) own execution: editing, shell, git, tests, recovery.
ChatGPT owns high-level reasoning: understanding, planning, review, debug strategy.
The C2C Bridge gives ChatGPT read-only MCP access to the current workspace, so
control messages between you and ChatGPT stay tiny (< 1 KB) — ChatGPT pulls
whatever data it needs by itself.

**Golden rules**

1. NEVER paste file contents, diffs, or logs into ChatGPT. ChatGPT reads them through MCP.
2. NEVER show the user technical internals (MCP, OAuth, PKCE, tunnel, ports, localhost).
   Speak in terms of "Connect ChatGPT / Secure connection / Pairing".
   **Setup names and connection choice** may show user-facing names (including tunnel name and hostname),
   and **guided manual ChatGPT setup** may show required settings fields.
   Neither exception exposes internal identifiers or explains internals.
3. The pairing code is the ONLY credential you may ever type into a browser.
   Never touch OAuth tokens, cookies, or session storage.
4. If something fails, run `c2c doctor` and repair silently. Only involve the user
   for the single grouped setup choice below, real configuration conflicts,
   logins, credentials, CAPTCHA, 2FA, explicit consent screens, or **guided
   manual ChatGPT setup** when manual operation was explicitly chosen.
   Read `c2c prefs --json` before ChatGPT configuration:
   - Explicit user preference takes precedence over saved `setupMode`.
   - `setupMode` missing: use automatic setup; after the grouped choice,
     remember it with `c2c prefs set --setup-mode auto --json`. Do not add
     a separate auto/manual question or repeat `setupChoicePrompt`.
   - `setupMode` is `manual`: skip automatic ChatGPT settings. Use guided
     manual from the start (chosen, not a failure).
   - `setupMode` is `auto`: automatic browser setup. Two explicit failures of
     the same configuration step after repair: report the concrete blocker;
     do not silently switch the user to manual setup.
     A browser/js timeout, a page still loading/generating, or waiting for
     user login/2FA does NOT count as a failure. Preserve the saved `setupMode`.
   `developerModeEnabled: true` means skip `#settings/Security` until a
   connector create fails because developer mode is required. Then open
   that page, enable it, and `c2c prefs set --developer-mode --json`.
     These prefs are for this machine, not per workspace. Reuse them on
     reconnect or a second repo.
5. ALWAYS use the built-in in-app browser (iab) for every ChatGPT step.
   Follow **In-app browser (ChatGPT)** below. NEVER Computer Use (no
   screenshot-click). NEVER launch or control a third-party/external browser
   (Chrome, Safari, Edge…), and never use `open <url>` to hand off to one.
   - The ONLY exception: the user explicitly says the Cloudflare login must use
     their own browser session — that single Cloudflare login step may go through
     their browser; everything else stays in the built-in browser.
   - If the user asks to run ChatGPT in their own browser, refuse politely and
     explain: "Codex frequently operates ChatGPT pages and connection settings,
     which may disrupt your normal browsing. Use the built-in browser."
     Only if the user explicitly accepts that disruption may you proceed in
     their browser; otherwise keep ChatGPT in the built-in browser.
6. Conversation reuse depends on `c2c session --json` → `conversation.mode`
   (see Conversation management). Do not invent a second mode.
   - **long-chat** (legacy session file, or the user opted out): ONE ChatGPT
     conversation per workspace. Never silently start a new chat.
   - **project** (new workspaces, or an existing workspace that opted in):
     ONE ChatGPT Project (collection) per workspace. Same Codex conversation
     reuses the ChatGPT chat URL saved in THIS thread. A new Codex
     conversation opens a new chat from the Project collection page — never
     `goto` `https://chatgpt.com/` to create it, and never reuse another
     Codex conversation's chat URL just because `session.url` exists.
   Each workspace also has exactly ONE ChatGPT connector. Do not create a
   second connector for the same workspace. Other workspaces may have their
   own connectors — never edit those.
7. After first-time setup, never ask the user to approve writing C2C's local
   settings directory. Run `c2c sandbox-allow --json` (idempotent). If it fails
   with EPERM / Operation not permitted, request elevated permissions and retry
   ONCE. After `{ "alreadyAllowed": true }` or `{ "added": true }`, stay silent.
8. ChatGPT pages: only the URLs in **In-app browser (ChatGPT)**, except the
   focused Project creation flow in **Bind Project**. Do not hunt other menus.
9. **Doctor gate.** After `c2c doctor --json`, do not `goto` ChatGPT and do not
   send `[C2C]` until local is green — except the reconnect settings pages when
   `chatgptRepair.needed` is true. During reconciliation, the focused
   `workspace_info` verification and `connector bind` are also allowed once
   local bridge/MCP/tunnel checks pass. Not green:
   - `report.bridge.ok` is not true
   - `report.mcp.ok` is not true (unauthenticated local `/mcp` must be 401)
   - `workspaceNameRestartRequired` is true: the display name changed. Run
     `c2c restart -w <ws> --tunnel --json`, then setup/doctor again. The root ID
     and tokens remain valid; repair the connector only if the address changed.
   - sandbox / state-dir write failed (EPERM)
   - this workspace used to have a public URL and the tunnel is down
   - `chatgptRepair.needed` is true (settings + workspace_info + connector bind, then doctor again)
   - `namedRepair.needed` is true (user must log in to Cloudflare, then doctor again.
     Do not Delete the ChatGPT connector — the address did not change)
   - `report.bridge` reports an uncertain state: the local bridge may still be running.
     Do not `c2c start`, do not Delete the connector, do not treat it as
     `chatgptRepair`. Wait and run doctor again.
   If doctor is already green and `chatgptRepair.needed` is false, do not
   `c2c restart`, do not start a second tunnel, and do not Delete the
   connector. ChatGPT/IAB-only errors are not permission to churn the
   public address.
   A ChatGPT-side 401 after a sent message is different: repair then, do not
   treat it as permission to skip this gate next time.
10. Write code and documentation in English. When editing a source or documentation
    file, translate Chinese text encountered in that file into English, including
    comments, instructions, and user-facing strings. Keep this within the files
    being edited; do not expand the task into a repository-wide translation.

## In-app browser (ChatGPT)

Official skill: `control-in-app-browser`. These C2C rules override defaults
that close the tab, hide the window, or stall on the settings page.

1. **Surface.** Once per Codex session: `setupBrowserRuntime()`, then
   `const iab = await agent.browsers.get("iab")`. Reuse `iab`. Do not re-read
   `documentation()` if it is already bound. Never `getDefault()`, `getForUrl()`,
   or Computer Use.

2. **One tab.** Create the ChatGPT tab once (`tabs.new()`). After that, only
   `tab.goto(...)` to switch URLs. If the tab still exists, claim it — never
   open a second ChatGPT tab. Do not `goto` the URL you are already on.

3. **Foreground + keep (standby).** Right after opening or claiming the tab:
   - `await (await iab.capabilities.get("visibility")).set(true)` — first-time
     setup and ChatGPT chatting stay in front of the user so they can watch.
   - `await tab.markHandoff()` immediately, then again at the start and end of
     every turn. After setup succeeds or the C2C chat is open, also
     `await tab.markDeliverable()`.
   Never close this tab. Finished, waiting for the user, or timed out: leave it
   marked (standby). Do not let default turn cleanup close it.

4. **URLs only** (same tab, `goto` — never hunt menus, except focused Project
   creation in **Bind Project**):
   - Developer mode: `https://chatgpt.com/#settings/Security`
     (skip when `c2c prefs --json` has `developerModeEnabled: true`)
   - Plugins hub: `https://chatgpt.com/plugins`
   - Add connector: `https://chatgpt.com/plugins#settings/Connectors?create-connector=true&redirectAfter=%2Fplugins`
   - New chat (long-chat only, and only if no saved chat): `https://chatgpt.com/`
   - Saved C2C chat: `conversation.chatUrl` / `session.url` (long-chat, or
     the chat already bound in THIS Codex conversation)
   - Saved Project collection: `conversation.projectUrl`
     (`https://chatgpt.com/g/g-p-…/project`)
   Never click Reconnect / Refresh on an existing connector. The old address is
   dead and that page hangs on "This site cannot be reached". When the address
   changed: Delete THIS workspace's `connectorName` only, then create it again
     via the Add connector URL (same name, new Server URL). Do not put that public
   address into Project instructions — write the connector **name** only.

5. **Do not wait for 8 tools** on the settings page. "Connected" / authorize
   success / pairing accepted is enough. Confirm tools in the conversation with
   `workspace_info`.

6. **Batch.** Fill a known form in one Playwright / `js` script when you can.
   After an action, one cheap DOM check. Do not screenshot-poll.

7. **One conversation, Chat mode.** The first ChatGPT chat is the C2C
   conversation. Chat and Work are separate: a Work conversation
   cannot become Chat. On every NEW conversation, if a Chat/Work switcher is
   visible (often top-left), confirm **Chat** is selected before the boot
   prompt. If it is Work, do not continue there — Switch to a new Chat
   conversation (HANDOFF). If no switcher is visible, do not hunt menus; continue.
   Send the boot prompt and the workspace_info check in that Chat conversation.
   Confirm the reply names the current workspace **before** saving or replacing
   the session URL. If validation fails, keep the old saved URL. Do not open a
   throwaway verify chat and later another C2C chat.

   A collection or chat page that shows only `Retry` is a navigation
   error, not generation and not a pairing failure. Reuse the same iab tab.
   Try Retry once. If it stays Retry-only, `goto` the last working chat URL
   from this thread (or `session.url` if that is the only saved chat), then
   click the on-page `Open … project` link — that same-site
   hop is allowed. Do not treat the URLs-only rule as forbidding this link.
   On the collection, require the project chat list and new-chat composer
   before continuing. Keep the old saved URL/checkpoint until the replacement
   chat passes workspace_info. Do not `session clear`. Do not use Computer Use.

8. **Wait for a ChatGPT reply (do not hold one long browser wait).** After you
   send INIT, EXECUTED, boot, or the workspace_info check: `markHandoff`, keep
   the tab foreground, and stay in this same task. Do not `waitFor` 5 minutes
   and do not screenshot-poll. Every 20–30 seconds, one cheap DOM check:
   - still generating → wait again (do not type, do not resend);
   - `STATE: PLAN` / `DONE` / `BLOCKED` / the verify workspace name → read it
     and continue the existing protocol;
   - visible error → repair; do not start a new chat.
   A browser/js timeout is not failure. Claim the same tab, read the page, keep
   standby. If ChatGPT is still thinking, keep polling. Never open a second
   tab and never resend INIT/EXECUTED just because a wait timed out.

## Locations

- The codex-with-chatgpt checkout lives at: `<ACTUAL_CHECKOUT_PATH>`
  (installer/update MUST replace this line in the installed Skill with the user's actual checkout path.)
- Codex home: let `<codex-home>` be a non-empty `CODEX_HOME` when set; otherwise
  use `~/.codex` (`%USERPROFILE%\.codex` on Windows).
- CLI: let `<checkout>` mean the path on the previous line; run
  `node "<checkout>/bin/c2c.js" <command>` (or `c2c <command>` if globally linked).
  All commands support `--json` for parsing.
- If the checkout has no `node_modules` or no `dist/`, first run
  `corepack pnpm install && corepack pnpm build` inside it.
- For commands that act on the user's project (`setup`, `doctor`, `session`,
  `restart`, `start`, `stop`, `status`, `pair`, `unpair`, `disconnect`, `destroy`, `connector bind`, `logs`, `workspace`,
  `record`, `tunnel status`, `tunnel choose`), pass `-w <workspace root>`
  (the project the user is working on, NOT the c2c repo).
- Do not add `-w` to machine-wide commands: `update`, `update-check`, `sandbox-allow`,
  `prefs`, `tunnel login`. They still accept and ignore `-w`, so a leftover
  flag must not fail the command.

## Updates (explicit requests only)

Never check for or install updates at workflow startup. No daily auto-update.
Run `c2c sandbox-allow --json` when needed as before; it is not an update trigger.

Only when the user asks to update, inside the checkout in **Locations**:

1. Run `c2c update --json`. It verifies that the resolved `origin` is exactly
   `hudrucan/desk-c2c-hub` on GitHub before pulling the current branch from
   `origin` with `--ff-only`. A different origin, dirty checkout, or detached
   HEAD stops the update. Never auto-stash, reset, rewrite origin, or pull upstream.
2. `corepack pnpm install --frozen-lockfile`, then `corepack pnpm build`.
3. Copy `skill/SKILL.md` to `<codex-home>/skills/codex-with-chatgpt/SKILL.md`
   and replace the checkout path in that copy with the actual fork checkout.
4. `c2c sandbox-allow --json`, then `c2c restart -w <workspace> --tunnel --json`
   for an active connection. Verify it with doctor and reconcile only if needed.
5. Report the result. The new Skill takes effect in the next Codex session.

`c2c update-check --json` is also explicit-only and checks the same origin.
It does not authorize a pull or trigger an automatic update.

## Setup names and connection choice (before provisioning)

Resolve each name independently, in this order:

1. Values explicitly provided by the user, including earlier in this chat.
2. Existing persisted values for this workspace.
3. Sensible human-readable suggestions from project context: repository folder,
   package/product name, and a domain the user provided or already configured.
4. Fallback defaults only when that context is insufficient.

Use read-only discovery first: `c2c workspace -w <ws> --json`,
`c2c session -w <ws> --json`, and `c2c tunnel status -w <ws> --json`.
Inspect only relevant naming fields in external workspace registration, legacy
`.c2c.json`, and the workspace's saved
endpoint, tunnel and session records under the existing C2C state directory.
Do not print credential files. A stopped bridge, missing session, or expired
temporary URL does not make a persisted setup new. Do not run `setup`,
`tunnel choose`, `start --tunnel`, or a repairing `doctor` before resolving
names; `doctor --no-fix` is available for diagnosis.

For an existing setup, reuse persisted names without a naming prompt. Fill
missing legacy labels from the existing CLI conventions, not a new branding
suggestion. A new explicit value overrides a suggestion; if it conflicts with
an existing deployed name, explain the affected resource and resolve only
that conflict before renaming or replacing it. Disagreement between saved
endpoint/session names or a name already used by another setup is also a real
conflict; never delete a connector merely because its display name matches.

For a new setup with unresolved important names, present ONE compact grouped
choice and wait before provisioning. Keep already specified or persisted
values fixed and label them as such; ask only about the remaining suggestions.
If all applicable choices are already explicit, proceed without asking again.
Use the user's language. For example, when the user supplied `example.com`:

```text
Suggested setup:
- Workspace / Project: desk-c2c-hub
- Tunnel: desk-c2c
- Hostname: code.example.com
- Connector: Desk C2C Hub

Accept the suggestions, or tell me which names to customize.
```

Derive a readable connector title from the project name; use `Codex with
ChatGPT` only as a fallback. Without a known Cloudflare domain, show
`Hostname: temporary address (or provide your Cloudflare domain for a fixed address)`.
That same reply can select temporary/fixed and supply the domain or hostname;
do not ask a second connection-choice question using the CLI's `userPrompt`.
Never provision `example.com` from the example. For Quick Tunnel, the tunnel
name is not applicable and the hostname is provider-assigned; do not ask the
user to name either. Do not ask about workspace hashes, ports, OAuth client
IDs, pairing codes, runtime IDs, or other internal identifiers. Pairing codes
are generated automatically later, never chosen by the user.

### Apply the resolved names using existing support

- **Workspace / Project:** pass `--workspace-name <name>` to setup. It saves
  a local override in external C2C `workspaces/<workspaceId>.json` state; never
  create/edit `.c2c.json` just for naming. Without an external override, the
  existing `.c2c.json` `name` and other project configuration remain readable.
  Use the resolved name for the new ChatGPT Project title too. Do not rename the repo
  directory, package, workspace ID, or an existing ChatGPT Project by inference.
  A running bridge captures the name at startup; changing the file alone does
  not rename it live. Setup/start report `WORKSPACE_NAME_RESTART_REQUIRED`;
  status/doctor expose `workspaceNameRestartRequired`. After an authorized
  name change, restart explicitly and rerun setup; retain the chosen names
  and explain any temporary-address change. Do not revoke tokens or replace
  the root-derived workspace ID.
- **Tunnel:** pass `--tunnel-name <name>` to setup or `tunnel choose --mode named`.
  Explicit values override the persisted `tunnelName`; the hash-based legacy
  name is only a fallback when neither exists. A name already used by a
  different resource returns `TUNNEL_NAMING_CONFLICT`. Resolve the conflict;
  do not append a suffix, adopt an unverified tunnel, or edit state to bypass it.
- **Hostname:** for a fixed address, pass the resolved value explicitly:
  `c2c setup -w <ws> --zone <domain> --hostname <hostname> --tunnel-name <name> --json`.
  Do not let the generated default replace a chosen hostname. For temporary
  addresses, use `c2c tunnel choose -w <ws> --mode quick --json`.
- **Connector:** pass `--connector-name <name>` to setup. Runtime persists
  `desiredConnectorName`; `connectorName` / `boundMcpUrl` remain the last
  verified ChatGPT binding. Setup, restart and doctor do not commit a new binding.
  Use output `connectorName` as the desired title. Before renaming/removing an
  existing plugin, verify its saved plugin ID (when available), name and Server
  URL against `previousConnectorName` / `previousMcpUrl`. Never use its title
  alone as ownership proof. Failed reconcile leaves the bound state unchanged.
  After ChatGPT settings reflect the desired title/URL, call `workspace_info`
  through that exact plugin and verify the root-derived workspace ID. Then run:
  `c2c connector bind -w <ws> --name "<name>" --mcp-url "<url>" --connector-id "<observed-plugin-id>" --verified-workspace "<observed-workspace-id>" --json`.
  These IDs are machine arguments, not questions for the user. Only after bind
  succeeds update Project instructions/session metadata to the new name. A stale
  acknowledgement is rejected; re-read setup/doctor output and reconcile again.
  Never mark bound just because local setup or OAuth succeeded.

Tunnel rename uses the saved UUID in place. Hostname rename cleans the previous
CNAME only if it still points to that UUID. Rename/cleanup requires a scoped
`CLOUDFLARE_API_TOKEN`; do not put it in browser fields or logs. If a
`TUNNEL_ROLLBACK_PENDING` error appears, rerun the named setup request once to
recover before proceeding; do not switch to Quick or manually discard state.
See [lifecycle recovery](../docs/lifecycle.md) for uncertain creation outcomes.

For example, apply the accepted fixed-hostname choice in one command:

```bash
c2c setup -w <workspace> --workspace-name "desk-c2c-hub" --tunnel-name "desk-c2c" --zone "example.com" --hostname "code.example.com" --connector-name "Desk C2C Hub" --json
```

Use the actual resolved values, never the example domain. A rerun needs no
naming flags unless the user explicitly changes a name. For temporary setup,
record the Quick choice and pass only display/connector names to setup.

Honor existing temporary/fixed preferences without reprovisioning a healthy
connection. If fixed-address provisioning needs a domain or authentication,
request only that missing information or human action. Follow Golden rule 5
for browser choice. If the CLI returns `fallback`, report the actual outcome;
an explicit requirement for the chosen fixed hostname is a conflict, not
permission to silently accept a temporary address. Never put credentials in
the project or introduce a new naming configuration format.

After acceptance or complete explicit instructions, carry setup through
connector authorization and file-read verification automatically. Do not add
per-name or per-step confirmations; stop only for real conflicts, human
authentication/credentials, required explicit permission, or an actual blocker.

## Workflow: first-time setup ("Set up Codex with ChatGPT")

1. Detect prerequisites yourself: `node --version` (>= 20), and check `cloudflared`.
   - If cloudflared is missing on macOS run `brew install cloudflared`; on Windows use
     `winget install Cloudflare.cloudflared`. Do this yourself; don't ask.
2. If the c2c repo has no `node_modules`, run `pnpm install && pnpm build` in it.
3. Complete **Setup names and connection choice** before provisioning. Run
   `c2c sandbox-allow --json`, then `c2c setup -w <workspace> --json` with the
   resolved naming flags above. Fixed-hostname setup provisions the chosen
   tunnel and hostname; existing setups reuse persisted values without flags.
   `sandbox-allow` edits Codex `config.toml` only — it adds C2C's state directory
   to `[sandbox_workspace_write].writable_roots` so later chats can write logs
   without elevation. If the write is denied, request approval and retry once.
   → returns `{ mcpUrl, pairingCode, workspaceName, connectorName, ... }`.
   Use the returned, persisted `connectorName` as this workspace's plugin title;
   retain legacy titles on existing setups unless the user explicitly changes one.
   Pairing codes expire in ~5 minutes. Do not mint one until the ChatGPT
   Authorize / pairing form is on screen: run `c2c pair --json` then type
   that code immediately. Doctor does not pre-mint a code.
4. `c2c prefs --json` (this machine, not this workspace).
   - Resolve explicit/saved preferences per Golden rule 4. If `setupMode` is
     null, remember `auto` and continue; no second setup-choice prompt.
   - If they later ask to switch: same `c2c prefs set --setup-mode` command.
     Do not re-ask on a later workspace or on reconnect.
   - `setupMode: "manual"`: skip step 5's automatic ChatGPT settings. Go to
     **Guided manual ChatGPT setup** (chosen). Opening line:
     `We'll use guided manual setup, one action at a time.`
     Do not describe this choice as an automatic-setup failure.
   - `setupMode: "auto"`: continue with step 5. Apply Golden rule 4 on failure.
5. Open ChatGPT on the ONE iab tab (see **In-app browser**). Foreground +
   markHandoff immediately. Same tab, `goto` only:
   - Developer mode: skip `https://chatgpt.com/#settings/Security` when
     `developerModeEnabled` is true. Otherwise open it, enable Developer mode
     if it is off, then `c2c prefs set --developer-mode`.
     Never record it as off. If creating the connector later says developer
     mode is required, open this page, enable it, save `--developer-mode`,
     and retry create — do not skip that recovery.
   - Existing `connectorName`: `https://chatgpt.com/plugins` — check ownership
     and saved endpoint first. Reuse a working setup; replace only when repair
     requires it. Do not delete an unrelated connector with the same title.
   - Missing / just removed: `https://chatgpt.com/plugins#settings/Connectors?create-connector=true&redirectAfter=%2Fplugins`
     Operate ONLY on the resolved and persisted `connectorName` from step 3:
     - If that exact name exists: verify it belongs to this workspace before
       any replacement. An unrelated connector with the same title is a
       real naming conflict. Never Reconnect or open an expired Server URL.
     - If it does not exist: create one with that exact name.
     - Never rename, delete, or edit a connector that belongs to another workspace.
     - Description: `Securely connect ChatGPT to the current Codex workspace for planning and review.`
     - Server URL: the `mcpUrl` from step 3
     - Authentication: OAuth
     Fill the known form in one script when you can. Then Connect / Authorize.
     Only then run `c2c pair --json` and type that code. As soon as it shows
     Connected / authorized / pairing accepted, continue — do NOT wait for 8
     tools on this page.
6. Same tab: open the first C2C chat per **Conversation management**
   (Project collection for a new workspace; `https://chatgpt.com/` only
   in long-chat). Confirm Chat mode per **In-app browser** §7 (if it is Work,
   open a new Chat conversation instead). Send the boot prompt from
   `docs/protocol.md` §Boot Prompt, then (same chat) send:
   `Use the "<connectorName>" connector: call workspace_info and read hello-style top-level file. Reply with the workspace name.`
   Confirm the reply matches `workspaceName` (wait per **In-app browser** §8).
   Run `c2c connector bind` as described above after verification.
   Only then save the chat URL with `c2c session set` (see Conversation
   management). If the name does not match, do not save. markDeliverable.
7. Report to the user exactly in this shape (no internals):

```
Codex with ChatGPT

✓ Project detected
✓ Workspace Bridge started
✓ Secure connection established
✓ ChatGPT connected
✓ File read test passed

Ready.
```

If a login wall appears (ChatGPT, Cloudflare): stop, tell the user the ONE thing
to do ("Please log in to ChatGPT and tell me when you're done"), then continue.

### Guided manual ChatGPT setup

Enter this path only when the user explicitly chose manual operation, directly
or in saved preferences. An automatic-setup blocker is not permission to
silently switch modes. A browser/js timeout without a visible error, a page
still loading/generating, or login / 2FA / CAPTCHA waiting is not a failure.

Stop automating ChatGPT settings. Keep the current local C2C state and the
current `mcpUrl`, `pairingCode`, `workspaceName`, and `connectorName`. Do not
silently fall back to Codex-only execution and do not permanently disable C2C.
Preserve the saved `setupMode` unless the user requests a change.

Opening line:

- `setupMode: "manual"`: `We'll use guided manual setup, one action at a time.`

Then guide ONE action at a time, waiting for the user to say "done" before the
next action:

1. If `developerModeEnabled` is not true: ask them to open
   `https://chatgpt.com/#settings/Security` and enable Developer mode. After they
   say "done", `c2c prefs set --developer-mode`. If it is already remembered,
   skip this step.
2. Ask them to open `https://chatgpt.com/plugins`. If the exact `connectorName`
   exists, verify ownership before any required replacement; reuse a working
   setup and resolve unrelated name collisions. Never ask them to touch another
   workspace's connector.
3. Ask them to open
   `https://chatgpt.com/plugins#settings/Connectors?create-connector=true&redirectAfter=%2Fplugins`
   and create the exact `connectorName` with:
   - Description: `Securely connect ChatGPT to the current Codex workspace for planning and review.`
   - Server URL: the current `mcpUrl`
   - Authentication: OAuth
4. Ask them to Connect / Authorize. Then run `c2c pair --json` and give them
   only that pairing code. If it expires before they finish, run pair again.
5. When they report Connected / authorized / pairing accepted, resume the normal
   setup/reconnect flow at its ChatGPT verification step. If automatic browser
   verification then hits the same explicit failure twice, stop and report the
   exact failed step; do not loop indefinitely and do not continue without C2C.

## Conversation management

`c2c session -w <ws> --json` → `{ session, conversation }`.
`conversation.mode` is the only switch. Missing / legacy files with a chat URL
and no Project stay **long-chat**. Do not ask those users to migrate. If they
later say they want a Project, run **Bind Project**. A brand-new workspace
(no session file) is **project**.

Never match a Project or a chat by display name. Never upload the repo to
Project sources. Never click Share. Do not rename ChatGPT chats.

### long-chat (do not rewrite this path)

ONE ChatGPT conversation per workspace. Same as before.

- **Find it**: if `conversation.reuseSavedChat` and `conversation.chatUrl`,
  `goto` that URL (foreground + markHandoff) and continue there.
- **Save it**: after boot + workspace_info, and the reply names this workspace,
  `c2c session set -w <ws> --mode long-chat --url <url> --title "C2C <workspace name>"`.
  If the name does not match, do not overwrite a previously saved URL.
- **Update it**: after each EXECUTED/DONE,
  `c2c session set -w <ws> --task <id> --iteration <n> --state <STATE>`
  plus checkpoint flags from the coding workflow (`--protocol-state`,
  `--waiting-for`, `--goal`, `--next-step`, `--known-issues`, or
  `--clear-checkpoint` on DONE). Do not put logs or diffs in those fields.
- **Switch it** ONLY when (a) the user asks for a new chat, (b) the current
  chat visibly lags, or (c) this conversation is Work. Then:
  1. Same iab tab: `goto` `https://chatgpt.com/`, confirm Chat mode
     (**In-app browser** §7), then send the boot prompt.
  2. Send a HANDOFF (`docs/protocol.md`) — goal, progress, state, issues,
     next step. Never paste files.
  3. workspace_info check; only then `c2c session set --url`. On failure,
     leave the old saved URL unchanged.
- Saved chat 404s: treat as a switch. Reconstruct HANDOFF from
  `session.checkpoint` (goal, progress, issues, next step). If there is no
  checkpoint, use `task` / `iteration` / `lastState` and `execution_summary`
  metadata only. Never paste logs or output bodies.

### project (new workspaces)

One ChatGPT Project per workspace. Mapping:

1. Same Codex conversation (this thread still has context) → same ChatGPT
   chat URL. `goto` that URL directly. Do not open the collection first.
2. Same workspace, a **new** Codex conversation → new ChatGPT chat from the
   collection page (`conversation.projectUrl`). Ignore `session.url` unless
   you already saved it earlier in THIS Codex thread.
3. Different workspace → different Project and different connector.

**Open a chat in this Codex thread**

- If you already saved a ChatGPT chat URL earlier in THIS Codex conversation:
  `goto` that URL. Continue. No new chat. No HANDOFF.
- Else if `conversation.projectReady`: `goto` `conversation.projectUrl`.
  On that page, use the on-page composer ("New chat
  in …"). Do not use the sidebar and do not `goto` `https://chatgpt.com/`.
  Confirm Chat mode (**In-app browser** §7). Boot prompt, then workspace_info
  with the **exact** `connectorName`. After the reply names this workspace,
  `c2c session set -w <ws> --mode project --project-url <collection> --url <chat> --connector-name "<connectorName>" --title "C2C <workspace name>"`.
  If this Codex thread is continuing a previous C2C task, send HANDOFF right
  after the boot prompt.
- Else: **Bind Project** first.

**Update it**: same `c2c session set --task / --iteration / --state` as long-chat.

**Wrong collection**: do not guess another Project. Tell the user the expected
workspace name, ask them to open the right collection, then say "found it".
Also offer "Continue with long-chat". If they pick long-chat:
`c2c session set -w <ws> --mode long-chat` and use the long-chat path.
If the collection 404s or the new chat is not inside the Project, same choice.

**Saved chat 404s** (this thread): `goto` the collection, open a new chat
there, boot + HANDOFF from `session.checkpoint` (no logs) + workspace_info,
then save the new chat URL. Keep `--project-url`.

### Bind Project (use the resolved display name)

Do this for a new workspace, or when an existing user asks to switch to
Project. Reuse an explicitly supplied or saved collection URL; do not match
an existing Project by display name or rename it just to match a suggestion.

1. In automatic setup, create the collection in the same in-app browser tab
   using the resolved Project display name and project-only memory. This
   focused creation flow is the exception to the URLs-only rule; use visible
   DOM controls, never Computer Use. Do not ask for the name again or hand
   routine creation clicks to the user. If manual setup was explicitly chosen,
   guide creation using that same resolved name. Stop for human authentication
   or explicit consent when required; report an actual capability blocker.
2. Verify the collection URL in that tab looks like
   `https://chatgpt.com/g/g-p-…/project`, then:
   `c2c session set -w <ws> --mode project --project-url <url> --connector-name "<connectorName>"`.

3. On that same collection page only, open the top-right **… → Project settings**.
   Do not click Share. Do not add sources / files.
   - Memory: project-only. Leave Library access disabled.
   - Instructions: paste **Project instructions** below (fill `{{…}}` from
     `workspace_info` / setup). Use the resolved and persisted `connectorName`.
     Never write the public / temporary address into Instructions.
   Save and close settings.

4. Still on the collection page, create the first chat with the on-page
   composer, then boot + workspace_info as in setup step 6. Save the chat URL.

### Project instructions (paste into Project settings → Instructions)

```
You are the planning and review layer for one local workspace. Codex executes.

This Project is bound only to:
- Workspace name: {{workspace_name}}
- Kind: {{project_type}} ({{languages}} / {{frameworks}})
- Connector (use this one only): {{connector_name}}

When you call tools, use ONLY that connector. Do not use any other
Codex with ChatGPT connector. If workspace_info names a different
workspace, stop. Do not plan. Do not use this Project's memory.

Read code, git, diffs, and any released command output through that
connector. Never ask anyone to paste file bodies, diffs, or logs. After
EXECUTED, call execution_output (list, then read) when a readable item
exists; if status is restricted, review from git instead. Never upload
the repo into this Project's files or sources.

When facts conflict, trust this order:
1. Current code from the connector
2. A HANDOFF in this chat (this task's goal, progress, next step)
3. These instructions
4. This Project's memory (durable architecture only; stale memory loses)

This Project's memory is only for this workspace. On HANDOFF, trust the
brief, re-read code through the connector, and resume at NEXT_EXPECTED_STEP.

Be substantive: why, which file, what to test. No empty one-liners and
no 40-step epics. Use C2C control messages.
```

## Workflow: coding task ("Use Codex with ChatGPT to implement XXX")

Protocol states sent to ChatGPT: INIT → PLAN → EXECUTING → EXECUTED → REVIEW → (PLAN | DONE | BLOCKED).
Local checkpoint states (session only, never a ChatGPT `STATE:` line):
`INIT`, `PLAN_RECEIVED`, `EXECUTING`, `EXECUTED_LOCAL`, `EXECUTED_SENT`, `DONE`, `BLOCKED`.
Do not invent `STATE: RESUME`. If the original chat is gone, send HANDOFF.
All control messages start with `[C2C]`. Keep Codex→ChatGPT messages under 1 KB.
ChatGPT's replies are expected to be substantive (see step 3). Docs: `docs/protocol.md`.

0. `c2c tunnel status -w <workspace> --json`. Before any new provisioning,
   follow **Setup names and connection choice**. Existing setups reuse their
   saved names and connection preference without another naming prompt.
   Then `c2c doctor -w <workspace> --json` (auto-repairs). **Doctor gate:** if local
   is not green, do not open ChatGPT and do not send INIT. If
   `namedRepair.needed` is true, tell the user `namedRepair.userMessage`, run
   `c2c tunnel login --json` (their browser; Cloudflare exception), then doctor
   again. If `chatgptRepair.needed` is true, tell the user `chatgptRepair.userMessage`
   (one paragraph, no internals), run **Workflow: reconnect after address
   reclaim**, then doctor again and only continue when the gate is green.
   Generate task id: `c2c_` + 4 random hex chars — unless a checkpoint already
   has one (reuse that id; do not mint a second task).
1. `c2c session -w <workspace> --json`. Open ChatGPT on the same iab tab
   per **Conversation management** for `conversation.mode` (foreground +
   markHandoff). long-chat: saved chat, or `https://chatgpt.com/` if none.
   project: this thread's chat URL, or the collection page for a new chat,
   or **Bind Project** if `projectReady` is false. On a NEW conversation
   confirm Chat mode (**In-app browser** §7), then send the boot prompt from
   `docs/protocol.md` §Boot Prompt and the workspace_info check (name the
   exact `connectorName`). Confirm the reply names the current workspace
   before saving the session URL. Do not use the browser to re-read code MCP
   already provides. After sending a control message, wait per
   **In-app browser** §8.

   **Resume from `session.checkpoint` before any INIT.** Missing checkpoint
   (legacy session): continue as a normal new/continued loop. A browser/js
   timeout is not a lost task — claim the original tab; do not INIT, re-run,
   or resend EXECUTED just because a wait timed out.
   - `EXECUTED_SENT` + `waitingFor=GPT_REVIEW`: do not INIT, do not re-run,
     do not resend EXECUTED. Stay on the saved chat and wait for review. If
     that chat 404s: HANDOFF from checkpoint fields (no logs), then wait.
   - `EXECUTED_LOCAL`: local work is done; only send EXECUTED (record first
     if this iteration has no record yet). Do not re-run.
   - `EXECUTING`: not finished. Continue the current PLAN if you still have
     it; otherwise HANDOFF and ask ChatGPT to restate the last PLAN. Do not
     treat it as done and do not INIT a new task.
   - `PLAN_RECEIVED`: execute that plan. Do not INIT.
   - `INIT` / `waitingFor=GPT_PLAN`: claim the tab and wait. Do not resend INIT.
   - `DONE`: summarize to the user if needed; `c2c session set --clear-checkpoint`.
   - `BLOCKED`: surface ChatGPT's reason; do not INIT.
   Never re-pair, never recreate the connector, and never rewrite Project
   instructions just to resume.
2. Send INIT with the user's goal (skip when the checkpoint says not to):

```
[C2C]
STATE: INIT
TASK_ID: c2c_f81a
ITERATION: 0

GOAL:
<user's goal, one paragraph>

INSTRUCTION:
Inspect the connected workspace through the Codex with ChatGPT MCP connector.
Produce a C2C PLAN message.
```

   Confirm the INIT message is visibly in that ChatGPT conversation (one cheap
   DOM check). If the page is Retry-only, recover per **In-app browser** §7
   first. Do not write the waiting checkpoint, and do not wait for PLAN, until
   that message is visible.
   Then:
   `c2c session set -w <ws> --task <id> --iteration 0 --state INIT --protocol-state INIT --waiting-for GPT_PLAN --goal "<short goal>" --next-step "wait for PLAN"`
3. Wait for ChatGPT's `STATE: PLAN` reply (**In-app browser** §8 — short DOM
   checks, same tab; do not treat a 5-minute browser timeout as failure).
   Read GOAL/ACTIONS/TESTS/SUCCESS_CRITERIA.
   A good PLAN also carries RATIONALE and concrete natural-language edit
   suggestions (which file, what to change, why). If the reply is a bare
   one-liner with no rationale or file-level guidance, ask once:
   "Please expand the plan with rationale and concrete per-file suggestions."
   Then:
   `c2c session set -w <ws> --protocol-state PLAN_RECEIVED --waiting-for none --next-step "execute PLAN"`
4. Execute the plan yourself with your own harness (your tools, your judgment;
   ChatGPT does not micro-manage tool calls).
   Before you start:
   `c2c session set -w <ws> --protocol-state EXECUTING --waiting-for none --next-step "finish PLAN then record"`
5. Record the execution so ChatGPT can read it via MCP. Metadata always:
   `c2c record -w <ws> --task c2c_f81a --iteration 1 --changed-files "src/a.ts,src/b.ts" --tests "27 passed" --exit-status ok`
   If this iteration ran a **test / build / lint / typecheck** command, also
   pass that command's output. Write stdout/stderr to a local temp file first,
   then:
   `c2c record … --command "pnpm test" --output-file <temp> --exit-code <n>`
   Record both success and failure. Do not record shell history, `.env`,
   keys, or unrelated dumps. Never paste that file (or any log) into ChatGPT.
   If the CLI says the output was not released, still send EXECUTED; ChatGPT
   reviews from git. Then:
   `c2c session set -w <ws> --iteration 1 --state EXECUTED --protocol-state EXECUTED_LOCAL --waiting-for none --next-step "send EXECUTED"`
6. Send EXECUTED (no diffs, no logs). Tell ChatGPT to use MCP, including
   `execution_output` when a readable item exists:

```
[C2C]
STATE: EXECUTED
TASK_ID: c2c_f81a
ITERATION: 1

RESULT:
Execution finished.

CHANGED_FILES:
4

TESTS:
27 passed

Please independently inspect the workspace and current git diff through MCP.
If execution_output lists a readable item for this iteration, list then read it.
If status is restricted, ignore it and review from git_diff.
```

   Then:
   `c2c session set -w <ws> --protocol-state EXECUTED_SENT --waiting-for GPT_REVIEW --next-step "wait for PLAN or DONE"`
7. ChatGPT reviews via MCP (`git_diff`, `read_file`, `test_status`,
   `execution_output`) and replies DONE / PLAN (next iteration) / BLOCKED.
8. Loop. Respect maxIterations (`.c2c.json`, default 12). At the limit, pause and ask
   the user: "We've completed 12 iterations and some issues remain. Continue?"
9. On DONE: summarize the result to the user in plain language.
   `c2c session set -w <ws> --state DONE --clear-checkpoint`
10. On BLOCKED: read ChatGPT's reason, fix what you can, or surface the single
    decision the user must make.
    `c2c session set -w <ws> --protocol-state BLOCKED --waiting-for USER --known-issues "<short reason>"`

## Workflow: ChatGPT-generated media

The connector remains read-only. It can view supported PNG/JPEG/GIF/WebP/SVG
files with `read_image`, but it cannot write into the repository or retrieve a
browser download by itself.

When the user asks ChatGPT web to generate an image or video:

1. Generate it in the workspace's saved ChatGPT conversation using the same
   built-in browser tab and connector rules above.
2. Activate the finished asset's actual Download control through the visible
   ChatGPT UI. Browser screenshots are navigation evidence only; never save,
   crop, rename, or import a screenshot as the requested asset.
3. Import the original download through the local execution harness:
   `c2c asset import -w <ws> --from <downloaded-file> --to <new-workspace-relative-path> --json`.
4. The destination must be new and project-relative. The importer validates
   PNG/JPEG/GIF/WebP/SVG/MP4/MOV/WebM content, rejects active SVG and path
   escapes, and never overwrites an existing file. Include the imported path in
   EXECUTED/review.

## Workflow: disconnect ("Disconnect ChatGPT")

Run `c2c disconnect -w <workspace> --json`. This revokes access and stops the
bridge, retaining connector, DNS, tunnel, names and session for reuse. Doctor
respects the disconnected marker; an explicit setup/start/restart reconnects.
Do not delete remote resources for a disconnect request. `unpair` remains the
backward-compatible token-revocation-only command.

## Workflow: destroy / deprovision (explicit user request only)

1. Run `c2c destroy -w <workspace> --json` for its read-only plan. It verifies
   local workspace binding, Cloudflare UUID/name and the exact CNAME target.
   Resolve incomplete legacy bindings or ownership conflicts before any deletion.
2. In the same IAB tab, verify the bound plugin's exact ID, name and Server URL
   against `plan.connector`, then delete that plugin only. Never delete by title
   alone. For legacy state without plugin ID, first verify workspace_info and
   acknowledge the existing binding with `connector bind`. If the plugin was
   already removed, verify absence of that exact ID instead of recreating it.
3. If `plan.desired.needed` with a URL, also inspect the pending desired title/URL.
   Remove only a matching owned partial plugin, or verify it is absent. Do not
   leave a partially created desired connector behind. A title collision with a
   different URL is a conflict; do not delete it.
4. Run `c2c destroy -w <workspace> --confirm --connector-removed <bound-plugin-id> --json`.
   Include `--desired-connector-absent` only after step 3. Omit the bound-ID flag
   if the plan has no bound connector. These are receipts of observed UI actions,
   not a substitute for the checks. Do not fabricate them.
5. Runtime revokes/stops, rechecks/deletes owned DNS and tunnel, then removes
   only this workspace's local state. A failed cleanup retains its receipt and
   state for `destroy --confirm` retry; do not start/reconfigure during destroy.
   Shared Cloudflare credentials, other workspaces, repository configuration,
   shared prefs and ChatGPT Project/chat history remain intact.

See [lifecycle recovery](../docs/lifecycle.md) for partial failures and credentials.

## Workflow: reconcile connector (name or address changed)

`setup` / `doctor` output separates desired `connectorName` / `mcpUrl` from
`previousConnectorName` / `previousMcpUrl` and the saved plugin `connectorId`.
Local green does not imply ChatGPT-side reconciliation succeeded.

1. Check local bridge/MCP/tunnel health. Keep the saved conversation and bound
   record until verification succeeds. Reuse the saved automatic/manual preference.
2. Same IAB tab: inspect only the owned plugin identified by the previous
   ID/name/URL. For a name-only change use the visible rename setting if supported;
   otherwise recreate only that owned plugin. For an address change use delete +
   create with the desired name/URL, OAuth and pairing. Never follow a dead URL's
   Reconnect page. If an exact desired plugin already exists, verify ownership
   before reuse; a different URL is a conflict. No suffixes or duplicate plugins.
3. Once Connected, open the saved chat and attach the desired plugin. Request
   workspace_info. Verify workspace ID and name, then `c2c connector bind` with
   the observed plugin ID, desired name and URL. On failure stop after the normal
   bounded retry rule; leave binding pending, never edit endpoint JSON.
4. Run doctor again; pending reconciliation must now be cleared. Save the session
   and update connector-name references in Project instructions after bind only.
   If the old chat cannot access the new plugin, use a new chat in the same
   Project (or the long-chat switch flow), boot + HANDOFF from checkpoint and
   verify there before changing the saved URL. Do not upload files or logs.

## Workflow: repair（anything looks broken）

1. `c2c doctor -w <workspace> --json`. Doctor gate: do not open ChatGPT / send
   `[C2C]` until local is green, except reconnect settings pages.
2. If `namedRepair.needed`, tell the user `namedRepair.userMessage`, run
   `c2c tunnel login --json`, then doctor again. Do not Delete the connector.
3. If `chatgptRepair.needed`, follow **reconcile connector (name or address changed)**, then
   doctor again.
4. Otherwise apply the recovery map. Only involve the user for login / 2FA /
   CAPTCHA — one action.

## Recovery map

| Symptom | Action |
| --- | --- |
| Bridge not running | `c2c start` (doctor does this automatically) |
| Tunnel dead / URL unreachable / connection lost after shutdown | `c2c doctor` → if `namedRepair.needed`, login to Cloudflare and doctor again (do not Delete). If `chatgptRepair.needed`, tell the user the message, then **Delete** THIS workspace's connector only (`connectorName`) and create it again. Never Reconnect. After recreate, re-check `workspace_info` in the saved chat; if it still fails, new chat in the same Project (or long-chat switch) + HANDOFF. |
| Collection page shows only Retry | Same iab tab: Retry once, then open the last working chat and click its Project link. Do not write INIT/EXECUTED waiting checkpoints until the message is visible. |
| ChatGPT says tool call failed / 401 | token expired or revoked → re-pair (new pairing code + authorize) |
| Pairing code rejected/expired | `c2c pair --json` for a fresh code |
| Same explicit ChatGPT setup/reconnect browser configuration step fails twice after repair | Report the actual blocker and preserve the saved setup mode. Use guided manual only if the user explicitly chose it. Do not count browser/js timeout, loading/generating, or login/2FA waiting as failures. |
| Port conflict | handled automatically; never surface to the user |
| Every new chat “repairs” / cannot write the log or settings directory | `c2c sandbox-allow --json` (once). Do not ask the user. |
| cloudflared missing | install it yourself (brew/winget), then retry |
| Sidebar has no Projects | In automatic setup, hover Chats, click the …, choose Organize by project; guide these actions only in explicitly chosen manual setup. |
| Collection page is the wrong Project | Ask the user to open the correct collection and say "found it", or accept long-chat |
