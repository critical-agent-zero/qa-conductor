# qa-conductor

A side-by-side PR-QA harness. For a pull request it boots two copies of your app: **base** (what's live now) and **PR** (the branch). Each runs against its own clone of real data, behind proxies that mirror scrolling and navigation between the two panes. A reviewer drives both at once and posts a verdict (a comment plus a label) back to the PR.

The conductor owns the choreography: session state, cancellation, the harness UI and API, the pane proxies and the verdict. Everything about *your* app and infrastructure comes from five adapters you supply, plus an optional sixth, [Exposure](#exposure-optional), through which the conductor publishes itself on a front door such as `tailscale serve`.

> **Status: 0.x.** The interface may still change: a 0.x minor version may break it, and so may a patch release when a fix needs to. Read the migration notes in [CHANGELOG.md](CHANGELOG.md) before upgrading, and to choose when that happens, install with `--save-exact`: the `^` range npm saves by default takes patch releases.

## Contents

- [Try it](#try-it), [Requirements](#requirements), [Install](#install)
- [Quickstart: QA your own app](#quickstart-qa-your-own-app)
- [Use](#use), with the [Entry points](#entry-points)
- [Using the harness](#using-the-harness)
- [Security](#security)
- [The seams](#the-seams): [Types](#types), [Contracts](#contracts-between-the-seams), the built-in [`build-worktree`](#built-in-adaptersbuild-worktree-git-worktree-buildconvention), [`provisioner-process`](#built-in-adaptersprovisioner-process-process-provisioner) and [`provisioner-docker`](#built-in-adaptersprovisioner-docker-docker-provisioner), the [Effect wrappers](#effect-wrappers), and [Exposure](#exposure-optional)
- [Configuration](#configuration): [The env file](#the-env-file), [Sample `.env.qa` files](#sample-envqa-files), [Tokens](#tokens), [Keys](#keys), [A `cfg` built in code](#a-cfg-built-in-code)
- [HTTP API](#http-api-harness-port), [Expose CLI](#expose-cli), [Demo](#demo)
- [Known limits](#known-limits)
- [Contributing](#contributing), [Reporting a vulnerability](#reporting-a-vulnerability), [License](#license)

## Try it

```sh
git clone https://github.com/critical-labs/qa-conductor
cd qa-conductor
npm run demo        # then open http://127.0.0.1:4100/
```

The demo runs the real conductor against fixture PRs and fake adapters, so it needs nothing but Node: no GitHub token, containers or databases. `demo/` is in the repository, not in the npm package. More in [Demo](#demo).

## Requirements

- **Node 22 or later.** The package has no runtime dependencies.
- **Linux or macOS.** Windows isn't supported: the process Provisioner signals process groups and reads `ps`, and the Docker one runs `sh`.
- **The tools each built-in adapter runs**, on the conductor's `PATH`:
  - `adapters/build-worktree`: `git`, with worktree support;
  - `adapters/provisioner-process`: `ps`, and to tell one boot of the machine from the next, `/proc/sys/kernel/random/boot_id` on Linux or `sysctl` on macOS;
  - `adapters/provisioner-docker` and `./docker`: the `docker` CLI and `sh`, and a Docker daemon the conductor's user may use;
  - `adapters/exposure-tailscale` and the [expose CLI](#expose-cli): a `tailscale` CLI no older than the daemon (on macOS, the app's bundled one), run by a user the daemon lets change `tailscale serve` (on Linux, root or the user `tailscale set --operator` names).
- **No TypeScript declarations yet.** The package is plain JavaScript (ES modules); the [Types](#types) below describe what the adapters exchange.

## Install

```sh
npm install @critical-labs/qa-conductor
```

To pin a git tag instead: `npm install github:critical-labs/qa-conductor#v0.3.1`.

## Quickstart: QA your own app

This script is a whole conductor for an app that runs from a checkout with one `node` command and needs no database. It QAs `acme/widget`'s pull requests on this machine: each pane is a git worktree, `main` and the PR head, running `node server.js` on a port of its own. It is this repository's own self-QA, [`qa/self.mjs`](qa/self.mjs), cut down.

1. Create `.env.qa` beside it, readable by you alone, since it holds a token, and keep it out of git:
   ```sh
   (umask 077 && touch .env.qa)
   echo .env.qa >> .gitignore
   ```
   Then put in it a GitHub token for the repository (see [Tokens](#tokens)) and the repository's name:
   ```
   GITHUB_QA_TOKEN=<token>
   QA_REPO=acme/widget
   ```
2. Save this as `qa.mjs`:
   ```js
   import fs from 'node:fs'
   import os from 'node:os'
   import path from 'node:path'
   import { startConductor } from '@critical-labs/qa-conductor'
   import { loadConfig } from '@critical-labs/qa-conductor/config'
   import { createGithub } from '@critical-labs/qa-conductor/github'
   import { createWorktreeBuild } from '@critical-labs/qa-conductor/adapters/build-worktree'
   import { createProcessProvisioner } from '@critical-labs/qa-conductor/adapters/provisioner-process'

   // Panes on loopback: nothing outside this machine reaches them, so no identity gate.
   const cfg = loadConfig('.env.qa', {
     defaults: { QA_BASE_ORIGIN: 'http://127.0.0.1:3101', QA_PR_ORIGIN: 'http://127.0.0.1:3102' },
   })
   const github = createGithub({ token: cfg.githubToken, repo: cfg.repo, qaLabels: [cfg.verdictLabels.accept, cfg.verdictLabels.reject] })
   const cacheDir = path.join(os.homedir(), '.cache/qa-conductor', cfg.repo.replace('/', '-'))

   const conductor = startConductor({
     cfg,
     github,
     fsx: { readFile: p => fs.promises.readFile(p) },
     adapters: {
       // main and each PR head in a git worktree, a PR only once it passes the trust gate
       build: createWorktreeBuild({
         repo: cfg.repo,
         cacheDir: path.join(cacheDir, 'build'),
         github,
         servicesFor: dir => ({ app: dir }),
         install: { cmd: 'npm', args: ['ci', '--ignore-scripts'] },
       }),
       // `node server.js` in each worktree, as a process group on 127.0.0.1
       provisioner: createProcessProvisioner({
         stateDir: path.join(cacheDir, 'state'),
         command: ({ ref }) => ({ cmd: process.execPath, args: ['server.js'], cwd: ref }),
       }),
       seed: { databases: [], seedPane: async () => {} },
       envTransform: { derivePaneEnv: ({ pane }) => ({ app: { PORT: String(pane.services.app.port) } }) },
       auth: { requiresDb: false, establishSession: async ({ pane }) => ({ landingUrl: `${pane.publicOrigin}/` }) },
     },
   })

   for (const sig of ['SIGINT', 'SIGTERM', 'SIGHUP']) {
     process.on(sig, () => conductor.shutdown().then(() => process.exit(0)))
   }
   ```
3. Run `npm install @critical-labs/qa-conductor` beside it, then `node qa.mjs`, open `http://127.0.0.1:3100/qa/`, and open a PR. Ctrl-C tears both panes down.

What the pieces do, and what to change for your app:
- **The trust gate.** A PR boots only when its author has write access to the repository and its head is in the repository or the author's own fork, since booting it runs its code as you. See [`adapters/build-worktree`](#built-in-adaptersbuild-worktree-git-worktree-buildconvention).
- **Install and launch.** The install runs with `--ignore-scripts`. The server must be started directly, not through `npm run` or `npx` (the [launch contract](#built-in-adaptersprovisioner-process-process-provisioner)), and must listen on the `PORT` the EnvTransform gives it, on `127.0.0.1`. It counts as up once `/` answers below `500`.
- **No data, no sign-in.** The Seed clones nothing and the AuthBootstrap lands each pane on `/`. To give each pane its own copy of a database, pass the Provisioner a `database` and write a `seedPane`; to sign the reviewer in, return a sign-in URL from `establishSession`. [The seams](#the-seams) has the contracts.
- **Other devices.** To open the harness from another machine, read [Security](#security), then [Configuration](#configuration)'s tailnet sample.

## Use

```js
import fs from 'node:fs'
import { startConductor } from '@critical-labs/qa-conductor'
import { loadConfig } from '@critical-labs/qa-conductor/config'
import { createGithub } from '@critical-labs/qa-conductor/github'

const cfg = loadConfig('/path/to/.env.qa', { defaults: { QA_REPO: 'acme/widget' } })
const github = createGithub({ token: cfg.githubToken, repo: cfg.repo, qaLabels: [cfg.verdictLabels.accept, cfg.verdictLabels.reject] })

const conductor = startConductor({
  cfg,
  github,
  fsx: { readFile: p => fs.promises.readFile(p) },   // serves the harness UI files
  adapters: { provisioner, build, seed, envTransform, auth },   // and optionally exposure
  readBaseEnv: async () => ({ /* the env the pane env is derived from */ }),
})

for (const sig of ['SIGINT', 'SIGTERM', 'SIGHUP']) {
  process.on(sig, () => conductor.shutdown().then(() => process.exit(0)))
}
```

`startConductor` takes:

| Option | Default | |
|---|---|---|
| `cfg` | *(required)* | the configuration, from `loadConfig` or built in code (see [Configuration](#configuration)) |
| `github` | *(required)* | what the core calls on GitHub: `createGithub(...)`, or anything with the [members the core uses](#effect-wrappers) |
| `fsx` | *(required)* | `{ readFile(path) }`, which serves the harness UI files from `publicDir` |
| `adapters` | *(required)* | `{ provisioner, build, seed, envTransform, auth }`, plus `exposure` if you want one ([The seams](#the-seams)) |
| `readBaseEnv` | `async () => ({})` | the env the panes' env is derived from, such as production's: passed to `derivePaneEnv` as `prodEnv` at each boot |
| `publicDir` | the package's `public/` | the directory with the harness UI's `index.html` and `harness.js` and the panes' `bridge.js` |
| `log` | `console` | where the `[qa]` lines go: `log.log` and `log.error` |

It serves the harness on `cfg.ports.harness` and one proxy per pane on `cfg.ports.base` / `cfg.ports.pr`, all on `cfg.host` (**`127.0.0.1` by default**). It returns `{ servers, stop(), shutdown(), exposure }`:
- `shutdown()` is the graceful exit. It stops the idle reaper and the [exposure loop](#exposure-optional), refuses harness writes from then on (`503`, so no new boot can start), tears the session down (aborting an in-flight boot and tearing down both panes), ends the progress streams, closes every connection and resolves once all three servers are closed. Call it from your signal handlers; calling it again is a no-op.
- `stop()` only stops the reaper and the exposure loop, and asks the servers to close.
- `exposure` is the exposure loop's handle, `{ ready, state(), reconcile() }`. `ready` resolves with the state after the first pass, or as it stands when `stop()` or `shutdown()` begins first (at once with no Exposure adapter). `state()` is the last pass, as `GET /api/exposure` reports it. `reconcile()` runs a pass now, or joins the one in flight; before all three servers listen there are no targets to mount yet, so it returns `ready`.

`cfg.paneOrigins` must be the URLs viewers actually reach the panes at, and `cfg.harnessOrigin` the one they open the harness at (see [Configuration](#configuration)). To reach the harness from anywhere but the machine it runs on, read [Security](#security) first, then either:
- put `tailscale serve --https` on the same host in front of these ports, in tailscale mode (`QA_EXPOSURE=tailscale`, the default for any layout that isn't loopback throughout): every server then answers only the Tailscale logins in `QA_ALLOWED_LOGINS`, and listens on loopback. Pass an [Exposure adapter](#exposure-optional) and the conductor sets up and keeps those mounts itself; or
- put another TLS front door that authenticates viewers in front of them, and set `QA_EXPOSURE=none`.

### Entry points

| Import | Exports | |
|---|---|---|
| `@critical-labs/qa-conductor` | `startConductor` | the conductor: harness, pane proxies, sessions, the exposure loop ([Use](#use)) |
| `@critical-labs/qa-conductor/config` | `loadConfig`, `parseEnvFile`, `defaultExposure`, `defaultHarnessOrigin`, `isExposureInterval`, `EXPOSURE_MODES`, `EXPOSURE_INTERVAL_RULE`, `MAX_EXPOSURE_INTERVAL_MINUTES`, `HARNESS_PATH` | reading `.env.qa` into `cfg` ([Configuration](#configuration)), and the rules it checks |
| `@critical-labs/qa-conductor/session` | `bootSession`, `teardownSession`, `createSession`, `reduce`, `touch`, `isIdle`, `ROLES`, `PANE_STAGES`, `parseEnv`, `renderEnv`, `migrateImageFor` | the boot sequence and session state the conductor runs, and helpers for adapters: parsing and rendering env file text, and the `migrate-<tag>` image beside an app image |
| `@critical-labs/qa-conductor/github` | `createGithub` | the GitHub [effect wrapper](#effect-wrappers) |
| `@critical-labs/qa-conductor/docker` | `createDocker`, `errorLine` | the Docker [effect wrapper](#effect-wrappers), and the line of a docker CLI failure worth showing |
| `@critical-labs/qa-conductor/exec` | `makeExecFileFn` | the `execFile` [effect wrapper](#effect-wrappers) |
| `@critical-labs/qa-conductor/identity` | `normalizeLogins`, `refusalReason`, `isAllowed`, `identityGate`, `isIdentityRefusal` | the [Tailscale identity gate](#security) |
| `@critical-labs/qa-conductor/exposure` | `mountsFor`, `reconcileExposure`, `runExpose` | one [exposure](#exposure-optional) pass, outside a conductor |
| `@critical-labs/qa-conductor/proxy` | `createPaneProxy`, `panePolicy`, `parseSetCookie`, `isAllowedHost`, `requestHostname`, `misdirected` | the pane proxy, and the [Host allowlist](#security) check every server runs |
| `@critical-labs/qa-conductor/verdict` | `formatVerdict`, `postVerdict` | the verdict comment and label |
| `@critical-labs/qa-conductor/data-diff` | `validateRules`, `createMasker`, `sanitizeSnapshot`, `diffSnapshots`, `divergence`, `flagChanges`, `trustOf`, `LIMITS`, `SECRET_NAME` | the [data checks](#data-checks)' engine, with no I/O: what a snapshot keeps and masks, what changed, where the panes differ, and what is destructive. For checking an inspector's snapshots |
| `@critical-labs/qa-conductor/adapters/provisioner-docker` | `createDockerProvisioner` | a Provisioner that runs each pane as containers on the host's Docker daemon |
| `@critical-labs/qa-conductor/adapters/provisioner-process` | `createProcessProvisioner` | a Provisioner for local process groups |
| `@critical-labs/qa-conductor/adapters/build-worktree` | `createWorktreeBuild`, `trustDecision` | a BuildConvention that runs PRs from git worktrees, behind a trust gate |
| `@critical-labs/qa-conductor/adapters/exposure-tailscale` | `createTailscaleExposure` | an Exposure adapter on `tailscale serve` |
| `@critical-labs/qa-conductor/package.json` | *(the manifest)* | |

Each row lists every name its entry point exports, and no other entry point is exported. The package also installs one bin, `qa-conductor-expose`, the [expose CLI](#expose-cli), for operators.

## Using the harness

Open the harness at its origin, under `/qa/`, as startup logs it (`[qa] harness at <origin>/qa/`); anywhere else it shows a banner that links there. Then:

- **Enrolment.** The conductor answers only browsers it has enrolled ([Security](#security)). A browser enrols by itself when it opens the harness while no pull request's code can be running: no session booting, running or ending, and the startup cleanup done. Otherwise the harness says why, with **Try again**. A try waits up to three seconds for a cleanup that is running, and runs one that failed again, at most once every five seconds from when the last one started and from when it ended. With no enrolled browser at hand while a session runs, try again once it ends by itself, `QA_IDLE_MINUTES` after its last interaction. Enrolment lasts until the conductor restarts, which revokes every browser; the harness then enrols again by itself, or says why it can't. An **Open QA** the restart refused is sent again once it has. At most 32 browsers stay enrolled: one more pushes out the one least recently used.
- **Invite** (top right) gives a link that enrols one more browser, once, within ten minutes, even while a session runs. Anyone who opens it gets in, so send it only to a reviewer.
- **Pull requests.** The picker lists the open PRs, at most the 50 most recently opened, with each one's build status: `ready — opens in seconds`, `building…`, `needs build` or `can't boot: <reason>`. **↻** reloads the list and **Open QA** boots a PR. One session runs at a time: opening another PR offers **Resume** for the running one, or **End #N and open #M** to take over.
- **Boot.** The four steps, Building, Preparing data, Migrating and Starting, each timed, with the BuildConvention's messages under the first. **Cancel boot** tears the boot down. A failed boot shows the error and the failing pane's log tail, with **Retry boot**.
- **Mirror** (`m`) replays each click, key and form value from one pane in the other. Its **⌄** menu turns scroll mirroring off and on (`s`).
- **Re-sync →** (`r`) reloads the PR pane at the base pane's path, and its **⌄** menu the base pane at the PR pane's. A dot on it says the panes are at different paths.
- **375**, **768** and **Full** (`1`, `2`, `3`) set both panes' width.
- **auto-end** counts down to the idle teardown, `QA_IDLE_MINUTES` after the last interaction, and turns amber for the last five minutes.
- **End session** (`e`) tears the session down once you click it again within three seconds.
- **The isolation chip** in the header says whether the PR pane can reach the base pane: `isolated`, `not isolated`, `isolation unknown` or `shared host`, with the reasons when you hover it ([Isolation verdicts](#isolation-verdicts)).
- **Each pane's bar** has a dot (amber while signing in, green while the pane's bridge reports, grey after 10 seconds of silence, red when the pane can't be loaded, with the reason as its path), the pane's path, a count of interactions the other pane couldn't replay (click it to clear), and buttons to copy the path, reload the pane at that path and open it in a new tab.
- **Data** (`d`), with an [inspector](#data-checks), opens the data checks. Its badge counts the red flags of both spans: in a trusted session the destructive changes the base didn't make too, in an advisory one every destructive change, and in either a PR pane that couldn't be read.
  - **The chip** says whether the comparison is `trusted` (the session is isolated) or `advisory`, when every destructive change is red.
  - **Snapshot now** compares the panes with their baseline, and **Re-baseline** makes now the baseline.
  - **Session** and **Boot** pick the span. **Divergence**, **Base** and **PR** pick what it shows: the panes side by side, or one pane's own changes. Click a collection for its rows. A span a pane has no data for says it is incomplete, and why.
  - It shows at most 300 collections and 100 flags, the red first, and 50 rows of each kind a collection, with how many more there are, from the answer's whole counts (fields dropped and added included). The collections with a red flag come first, then any that changed or are unknown, so a PR's padding can't push a changed one out of those drawn. One flag can stand for many collections: those only the PR pane has, or those past the ones listed one by one.
  - Values show as the data checks keep them: a secret only as `(secret)` or `(secret, changed)`, in a row's key and inside JSON too, even where a long value is cut, and personal data as a fingerprint. Names and values from the panes are set apart from the panel's own words, and a control, format, line or paragraph separator character in them shows as its code (`\u{202E}`, `\u{2029}`), so none can reorder or break a line.
  - A span whose PR pane couldn't be read says its changes are unknown, red, and the badge counts it, and so does one neither pane could be read for. "Nothing to compare yet" is only for before the first snapshot. A PR pane whose baseline is the snapshot just taken (its ready read failed) says so: take another to see its changes. A span says why it is incomplete: a pane with no data, or windows that differ (a pane's ready read failed), which a Re-baseline fixes for the session span only. A span whose details were too big to list shows its counts and first red flags.
- **Actions** (`a`) opens the [action log](#security): each action the panes reported, newest last, with the requests it most likely set off, by the rule in [`GET /api/actions`](#http-api-harness-port). It reads on every two seconds while it is open and in view, and starts over when the session is another.
- **Verdict** (`v`) opens the drawer: notes, kept in the browser as a draft for each PR, then **Accept** or **Reject**, a preview of the comment and the label change, and **Post to PR #N**. After posting: **End session**, **Keep session open** or **Back to pull requests**.
- **`?`** lists the keyboard shortcuts, which work while the harness, not a pane, has the focus. `Esc` closes the drawer, the panels or the list, or cancels an end-session click. Below 900 pixels wide, the panes become **BASE** and **PR** tabs.

## Security

**The trust gate is the only real boundary between a PR's code and the reviewer's machine.** Booting a PR runs its code. A BuildConvention that checks out and installs PRs must refuse untrusted ones in `ensureBuilt`, before any git call. **Env scrubbing and loopback binding are defence in depth**, not a boundary.

The conductor's own defences in depth:
- **Tailscale identity gate.** In tailscale mode (`QA_EXPOSURE=tailscale`), the harness and both pane proxies answer `403` to any request whose `Tailscale-User-Login` isn't in `QA_ALLOWED_LOGINS` (matched ignoring case), before anything else runs. The gate wraps each whole server, so no route, present or future, runs for such a request, upgrades included, and the `403` still carries the harness frame lock or the pane's frame policy. `tailscale serve` sets that header from the device the request came from, strips any copy the client sent, and sets none for tagged devices, which are refused. An empty allowlist refuses everyone, so `loadConfig` refuses one in tailscale mode (`startConductor` only logs an error). The gate's `403` carries `X-QA-Refusal: identity`, so a client can tell it from any other `403` without reading the body: the [expose CLI](#expose-cli) publishes a port only once that port answers with it, and `isIdentityRefusal(res)` from `./identity` recognises it. The pane proxies drop an `X-QA-Refusal` the pane app sends, so PR code can't make an ungated pane look gated. The pane proxies drop every `Tailscale-*` header before the pane app sees the request. Other front-door headers pass through, such as `X-Forwarded-For`, which `tailscale serve` sets to the viewer's tailnet address: the pane app, PR code included, still sees which device is viewing.

  `QA_EXPOSURE` defaults to `tailscale` when anything the conductor answers to or listens on is off loopback: the harness origin, either pane origin, `QA_PUBLIC_HOST`, a `QA_ALLOWED_HOSTS` entry or `QA_BIND_HOST` (see [Configuration](#configuration)). Loopback layouts, such as `npm run qa` and the demo, stay ungated with no config.

  **The gate trusts the header from anything that can reach loopback on this host.** That is why tailscale mode requires a loopback bind: on any other address, a client could send its own login. It also means the gate keeps out other devices, not code on this one. With `provisioner-process`, the pane processes run PR code on the same host, as the same user, so they can reach loopback and send any login they like: in tailscale mode the gate does not protect against PR code. Containers don't change that everywhere. On native Linux Docker, a container on a bridge network can't reach the host's loopback, but Docker Desktop (through `host.docker.internal`), Podman machine (through `host.containers.internal`) and the Lima-based runtimes, colima, Lima and Rancher Desktop (through `host.lima.internal`), forward to it, and there a container pane can send any login too. Rootless Docker and rootless Podman on Linux don't forward it by default ([Isolation verdicts](#isolation-verdicts)). Such code still meets the [capability](#security) below, which no login gets it past.
- **The per-browser capability.** All three servers answer only a browser the conductor has enrolled. Every `/api/*` route but `POST /api/enrol` needs that browser's token in an `X-QA-Cap` header (the event stream takes it as `?cap=`, since `EventSource` can't send a header), and every pane request, the bridge script included, needs its pane cookie. Anything else gets `403` with `X-QA-Refusal: capability`. The check runs after the identity gate, the `Host` allowlist and the request guards, and before any route, the idle clock or the pane app. So PR code that reaches the conductor on loopback gets nowhere, whatever login, `Origin` or Fetch Metadata it sends.
  - **Enrolment.** `POST /api/enrol` gives a browser its token only while no PR code can be running. That means the session is idle, or failed and torn down. Every boot started, aborted ones included, has settled, and a teardown that began after the last one settled has succeeded: when a cancelled boot settles, the conductor runs that teardown itself. And the startup sweep has succeeded. Otherwise it answers `403 capability` with the reason, which the body names too, beside `refusal: "capability"`, since a front door may drop the header. A failed sweep or a failed teardown keeps enrolment shut until one succeeds: a try to enrol with no session running runs the one that failed again, at most once every five seconds from when the last one started and from when it ended, and waits up to three seconds for a sweep or teardown in flight before it answers. Any number of tries may wait at once: they share one wait on the run. A caller with no token, PR code included, can start that run too, but no more often. So a Provisioner must report a teardown or sweep that leaves anything running, by rejecting; the built-in ones do. Anything that reaches the harness while nothing runs can enrol, a local process included: the window keeps out PR code, not other code on this host.
  - **Invites.** An enrolled browser can ask for an invite (`POST /api/invite`): a link to the harness whose fragment holds a one-time ticket, valid for ten minutes. It enrols one more browser, whatever is running.
  - **The token** stays in the harness origin's `localStorage`, which no pane can read, since storage is per origin, port included. The browser never sends it by itself, so it never rides to another port, as a cookie would.
  - **The pane cookie.** Frames and subresources can't send a header, so the panes take a cookie. To load a pane, the harness asks for a pane-entry link (`POST /api/pane-entry`), for one pane, used once, within a minute. The pane's `/__qa/enter` answers it with a `303` to the pane path, setting `qa-<id>`, or `__Host-qa-<id>` on an https pane, with `HttpOnly`, `SameSite=Strict`, `Path=/`, and `Secure` on https. `<id>` comes from the harness origin, so a conductor nested in another's pane keeps a cookie of its own. Both panes take the one cookie. It lasts one session: when a session is torn down, boots or becomes ready, every browser gets a new one, any pane-entry link not yet used stops working, and the harness enters each pane again. A harness still showing a session that ended, or that was opened again from another browser, notices within a minute and draws it afresh; until then its panes answer `403`. Names starting with `qa-` are the conductor's: `QA_FORWARD_CLIENT_COOKIES` can't name one, so the pane apps never get it. The proxy takes the `"cookies"` type out of a `Clear-Site-Data` the pane app sends, which would wipe it with every cookie on the hostname; the other types still reach the browser, and `"*"` becomes `"cache", "storage", "executionContexts"`. A request a pane page makes without credentials, such as `fetch(url, { credentials: 'omit' })` or a `<link rel="manifest">` without `crossorigin="use-credentials"`, carries no cookie, so the pane refuses it too.
  - **One hostname.** The cookie is `SameSite=Strict`, so a pane framed by a harness on another site never gets it. `startConductor` refuses pane origins on another hostname than the harness origin's, and `/api/pane-entry` answers `409` for ones assigned after start.
  - **A restart revokes** every token and cookie: they live in memory.
  - **What it doesn't close:**
    - what isn't a conductor listener: the base app's own published port (the Docker Provisioner's `hostPorts`), and anything the base pane's containers expose ([Known limits](#known-limits));
    - on plain-http loopback, a PR page and the PR app working together. Cookies ignore ports, so the PR page can make the browser send the pane cookie to a port the PR app listens on, where Docker Desktop publishes it on the host's loopback. The value it lifts admits both panes until that session ends. Over https, the cookie is `Secure` and never goes to plain http;
    - with `provisioner-process`, PR code runs as you, so it can read your browser's profile, the token included: there the capability only raises the bar;
    - PR code that outlives its teardown, such as a process an install script left running under `build-worktree`, which can enrol once nothing else runs. A Provisioner without `sweep` can't clear an earlier run's panes, so enrolment then trusts that none is left;
    - what runs in the reviewer's browser, which holds the capability: the PR pane's app redirecting the harness's frame to a base pane URL (the pane request guard below), and the mirror (the bridge below).

  **The gate works only behind `tailscale serve --https`**, which sets `Tailscale-User-Login` and drops any copy the client sent. Never put Funnel in front of the conductor, which opens it to the internet, nor `tailscale serve --tcp` or `--tls-terminated-tcp`, which pass the client's bytes through unchanged, so a header it writes itself reaches the gate. And never put `tailscale serve` in front of a conductor in none mode (`QA_EXPOSURE=none`): with no gate, every device on the tailnet gets in.
- **The action log keeps no values.** For the ready session, each pane's proxy records what it forwarded to the app: the method, the path, the status, the time it took and the bytes it sent back.
  - **What it never records:** a header, a cookie, a body or a query value.
  - **A query** keeps its keys. A part with no `=`, usually a value itself, goes whole.
  - **A path segment** that looks like a value shows only what kind it was. It is decoded first, up to three times, so a value encoded twice is still seen. The kinds:
    - an email address: anything with an `@`, fullwidth `＠` or small `﹫`;
    - a `key=value` pair, where the key stays;
    - a number: seven digits or more anywhere in the segment, with at most three separators between any two (a phone, a card, an account like `ACCT9876543210`);
    - a token: a JWT, hex, a long mix of letters and digits, or a run of 24 letters or more.
  - **That is a heuristic:** a short code or token, such as six digits or a 15-character key, can slip through.
  - **Refused requests:** what a guard refuses is only counted, by reason, so another page can't write entries.
  - **Marks:** the harness adds a mark for the clicks, submits, changes and Enters a pane reports, mirrored or not: the pane and the kind of action, never the element or what was typed.
    - A mark comes from that pane's own bridge, which PR code can drive, so it says which pane reported it.
    - At most one of each kind a pane every 100 ms, from a budget of 2,000 a pane that refills one a second. So PR code can use up its own pane's marks for as long as it keeps posting, never the base pane's. Each pane keeps its last 8,000 marks.
    - Marks group both panes' requests, since a mirrored action is reported by the pane it happened in only. The reader groups them ([HTTP API](#http-api-harness-port)).
  - **Where it lives:** in memory, behind the capability like the rest of the API, and it goes with its session. Requests and marks are stamped with one clock that only goes forward. Nothing of the log reaches the event stream, the conductor's log or GitHub ([HTTP API](#http-api-harness-port)).
- **Loopback by default.** All three servers listen on `QA_BIND_HOST`, default `127.0.0.1`, and tailscale mode refuses any other address (`loadConfig` and `startConductor` throw). In none mode, anything other than loopback exposes the harness to whoever reaches it: while no session runs, they can enrol, and then use an API that returns pane login URLs and posts verdicts with `GITHUB_QA_TOKEN`. A pane proxy *is* an authenticated pane session for any enrolled browser, because the proxy holds the pane's cookie jar. Widen the bind only in none mode, behind a firewall or an authenticating front door, and have viewers reach the harness and the panes over https (a plain-http origin must be loopback, see the pane request guard below).
- **Host allowlist.** Every server checks the `Host` header before routing (the harness does so before it even parses the request target) and answers `421` unless its hostname (port ignored, `[]` stripped) is `127.0.0.1`, `localhost`, `::1`, `QA_PUBLIC_HOST`, the hostname of the harness origin or of either pane origin, or an entry in `QA_ALLOWED_HOSTS`. This defeats DNS rebinding. A front door must pass the viewer's `Host` through, or rewrite it to a loopback `Host`. A rewritten `Host` that is allowed but not loopback (`qa-conductor:3100` behind nginx, say) clears this check, but every browser `/api/*` call then gets `403 not the harness origin` (see [Same-origin API](#security)).
- **Pane request guard.** The proxy holds each pane's cookie jar, so every request that reaches a pane acts as the reviewer, and the reviewer's browser sends requests for any page they have open. Loopback and the Host allowlist don't stop that. So a pane answers `403` to:
  - a write, a preflight, a CORS read or a WebSocket that doesn't come from the pane's own pages (`sec-fetch-site` `same-origin` or `none`, else an `Origin` whose host is the request's `Host`);
  - a subresource load (`<img>`, `<script>`, a no-cors fetch) from another site;
  - a navigation from another site, into a frame or top-level, unless its `Referer` is the harness origin, as it is for the harness's own iframes and "Open in new tab" links. A redirect the app answers such a navigation with keeps that `Referer` for the next hop, unless the redirect's own `Referrer-Policy` drops it, so the proxy removes that header from a redirect that stays on the pane.

  `same-site` counts as another site: on loopback every other port is same-site, and so is every host in a tailnet. A request the guard admits gets the whole jar.

  The guard works from Fetch Metadata (`sec-fetch-site`, `sec-fetch-mode`, `sec-fetch-dest`), which browsers send only to https and loopback origins. A request without it (curl, an older browser) is judged by its `Origin` alone, and another page's `<img>`, `<iframe>` or link sends no `Origin`. Over plain http on any other host, the guard couldn't tell those from curl, so `loadConfig` and `startConductor` refuse an `http:` harness or pane origin whose host isn't loopback (`127.0.0.0/8`, `::1`, `localhost`).

  **The guard keeps out other pages, not the panes' own apps.** A pane's app sees the harness's navigations, and when it answers one with a redirect, the next hop keeps the harness `Referer` wherever it goes. So the PR pane's app can redirect the harness's frame, or a new tab, to any URL of the base pane, which serves it with the reviewer's session. The trust gate is the boundary against PR code.
- **The pane apps get only their jar's cookies.** A pane proxy keeps the app's cookies in its jar and never passes the app's `Set-Cookie` on to the browser. Nor does it pass the browser's own `Cookie` header on to the app. Cookies ignore ports, so that header carries every cookie for the pane's hostname: another app's on another port, its session among them, and any the other pane's scripts set with `document.cookie`. And the app runs PR code. An app that reads a cookie its own scripts set (a locale, say) gets it only when `QA_FORWARD_CLIENT_COOKIES` names it. The jar's value wins on a name both have, and any page on the hostname, the other pane included, can set that cookie. So such a cookie passes only when its value is an RFC 6265 cookie-value. A browser sends back whatever a page wrote, so a value with a space, a comma, a backslash or a stray double quote could hide another cookie (`locale=fr, sid=evil`) for a lenient parser to read, and the proxy drops it. The jar's cookies come first in the header the app gets. And each jar holds one session's cookies: the conductor gives both panes fresh jars when a session is torn down, when the next one starts booting and when it is ready, and detaches both panes while a session boots, so no PR's app gets the cookies an earlier session's app set.

  **The panes' pages still share the browser's cookies with every app on their hostname.** A pane's scripts (PR code) run there, so they can read that hostname's cookies that aren't `HttpOnly`, and set cookies the browser then sends to every app on it. They can also send those apps requests that carry their cookies, `HttpOnly` and `SameSite=Strict` ones included (a form post, a `no-cors` fetch), because every port of the hostname, and every host in a tailnet, is same-site: PR code can act on the reviewer's session in another app without reading it. Serve the panes on a hostname no other app uses. That stops the cookie sharing, not those requests, so another app the reviewer is signed in to must not rely on `SameSite` alone against the panes.
- **Pane frame lock.** Every pane response, the proxy's own `403`, `421`, `502` and `503` included, carries `Content-Security-Policy: frame-ancestors 'self' <harness origin> <QA_FRAME_ANCESTORS…>` and `X-Content-Type-Options: nosniff`. The policy replaces the app's own `frame-ancestors` directive (its other directives are kept), and the app's `X-Frame-Options` is dropped. A value that isn't an http(s) origin is left out, and so is an IPv6 literal, which a CSP source can't express.
- **The mirror bridge talks only to the harness.** The proxy puts the harness origin on the script tag it injects (`data-harness`). The bridge posts only to its parent frame at that origin, applies replays only from its parent at that origin, and does nothing without one. So a page that frames a pane, the PR pane included, can neither hear nor drive its bridge. **The PR pane's code can still drive the base pane through the harness**, as mirroring does: while the mirror is on, the harness replays in the base pane every interaction the PR pane posts to it (a click, a key or a value on any selector), and PR code can post those itself.
- **Harness frame lock.** Every harness response, errors and refusals included, carries `frame-ancestors 'self'`, `X-Frame-Options: SAMEORIGIN` and `Referrer-Policy: strict-origin-when-cross-origin`. No other page can frame the harness to trick a click that starts a session or posts a verdict, and the harness's frame loads and new tabs always send its origin as the `Referer` the panes check.
- **The harness runs only its own script.** Its policy also has `default-src 'self'; script-src 'self'; style-src 'self' 'unsafe-inline'; object-src 'none'; base-uri 'none'; form-action 'none'; frame-src <pane origins>`. Its Data and Actions panels show names, values and paths PR code controls, and draw them as text. If one ever slipped through as markup, it still couldn't run a script, load from or post to another site, or frame one. With a pane origin that is an IPv6 literal, which a CSP source can't express, `frame-src` is `http: https:`.
  - **A pane can't leave its origin.** `frame-src` holds a pane's frame to its own origin, so a navigation to another one inside the pane (an SSO or OAuth hop, a hosted payment page, a redirect to another host) shows the browser's error page instead. Open the pane in a new tab (its bar's ↗) for such a flow.
- **Open the harness at its origin.** The panes trust exactly one harness origin, `QA_HARNESS_ORIGIN`, which startup logs as `[qa] harness at <origin>/qa/`. Opened anywhere else that reaches it (`localhost` for `127.0.0.1`, or another front-door port), the harness shows a banner linking to that origin, and the panes answer `403`. The harness and both panes share one hostname, on ports of their own, since the pane cookie reaches no other ([the capability](#security)). An IPv6 literal can't be the harness origin, since a CSP source can't name one: with a `::1` bind, set `QA_HARNESS_ORIGIN=http://localhost:<port>` and both pane origins on `localhost` (startup logs an error until you do).
- **Same-origin API.** Every harness `/api/*` request, reads and the progress stream included, gets `403 cross-site request refused` when `sec-fetch-site` is present and isn't `same-origin` or `none`, or, absent that, when `Origin` is present and its host isn't the request's `Host`. Another page can't read the answers, but its writes would run, and each read of `/api/prs` spends GitHub API calls. A browser (a request with either header) must also reach the API at the harness origin's host and port, else it gets `403 not the harness origin` (its body names `harnessOrigin`, for the banner): a page served by another front-door handler that proxies to the harness, such as a stale `tailscale serve` mount on another port, is same-origin with that handler. Loopback `Host`s are exempt from that second check, and non-browser clients, which send neither header, from both. Like the pane guard, this needs Fetch Metadata: over plain http off loopback, another page's `<script src>` GET sends neither header and passes as a non-browser client.
- **JSON bodies.** Every `POST` route (`/api/session`, `/api/verdict`, `/api/teardown`, `/api/enrol`, `/api/invite` and `/api/pane-entry`) requires `content-type: application/json` (else `415`). A cross-site form can't send that type, and a cross-site `fetch()` with it needs a CORS preflight the harness never grants.
- **Inert rendering.** The harness UI renders PR titles, build messages, blocked reasons, errors and log tails as text, and links a build run only when its URL is `https://`.

### Isolation verdicts

Each session gets a verdict on whether the PR pane can reach the base pane. The base pane is what a PR is compared with, so where PR code can reach it, the comparison can't take the base pane's changes for the base's own.

- **The verdicts**, best to worst:
  - `isolated`: the Provisioner's check found no way from the PR pane to the base pane, and nothing about the runtime says otherwise;
  - `unknown`: nothing could tell, or the check failed;
  - `reachable`: the PR pane can reach the base pane's containers, or the host's loopback, where the base app is published;
  - `shared-host`: both panes run as one user on one host.
- **When:** once both panes' databases exist and before either is seeded, so a strict refusal copies no data, and before any migrate or app of the PR's runs.
- **Who decides:** the Provisioner's `isolation` member ([The seams](#the-seams)). The Docker Provisioner probes ([its section](#built-in-adaptersprovisioner-docker-docker-provisioner)), the process Provisioner declares `shared-host`, and a Provisioner with neither is `unknown`. A BuildConvention that runs the PR's code on this host to build it declares `isolation: 'shared-host'` too, as `build-worktree` does with an `install` step: that code runs before any check, as you, so the verdict is never better than `shared-host`.
- **What must run no PR code:** everything before the check, that is a BuildConvention without that declaration (its `resolveBaseImages` and `resolvePrImages`, and so `build-worktree`'s `servicesFor`, included) and the Provisioner's `provisionDatabase`.
- **Same host:** the Docker Provisioner's probe speaks for the host the conductor runs on. A daemon elsewhere (a context or `DOCKER_HOST` that isn't `unix://` or `npipe://`) publishes the pane apps there, so its verdict is `unknown`. A `unix://` socket counts as this host, a forwarded one included (say, an SSH tunnel to another host's socket): don't forward one here.
- **Floors** the conductor applies to whatever the Provisioner says:
  - on macOS, never better than `reachable`: containers run in a VM that forwards the host's loopback (left out for a Provisioner that declares `shared-host`, which runs none);
  - a non-loopback `QA_BIND_HOST`: `reachable`;
  - any loopback bind but `127.0.0.1`, such as `127.0.0.2`, `::1` or `localhost`: at best `unknown`. The pane apps are published on `127.0.0.1`, which a runtime may forward alone, so a probe that misses the conductor elsewhere can't speak for them.
- **Fails closed:** a check that can't run, can't finish, or can't reach even the PR pane's own database gives `unknown`, never `isolated`.
- **Where it shows:** `/api/state`'s `isolation` (`{verdict, reasons, checkedAt}`, `null` until known for this session and again once it is torn down), an `isolation` event on the progress stream, and a chip in the harness header with the reasons as its title.
- **`QA_REQUIRE_ISOLATION=1`** refuses a session that isn't `isolated`, before any of the PR's code runs. When that is known as the boot starts (a declaration, a BuildConvention's, no check, a floor), it refuses before the build. Otherwise it refuses after the check, before either pane is seeded and before any migrate or app of the PR's runs, and the boot fails with the reasons.
  - **It is read from the env file alone.** A variable in the shell doesn't set it, nor does an `export QA_REQUIRE_ISOLATION=1` line, which the file reads as another key.
  - **So it shows:** the conductor logs `QA_REQUIRE_ISOLATION on` at startup, and logs an error when the declarations or floors already refuse every session. `/api/state` carries `requireIsolation`, and the harness's chip adds `· strict`.

What a base-vs-PR comparison can promise, by verdict:

| Verdict | What the PR did (PR-side) | What the base pane shows |
|---|---|---|
| `isolated` | unaffected by the base | the base's own changes, so it can excuse a PR change\* |
| `reachable` | unaffected by the base | advisory: the base pane's changes never excuse a PR change |
| `shared-host` | unaffected by the base | advisory, as above |
| `unknown` | unaffected by the base | advisory, as above |

\*Still subject to what every runtime shares: one base env and the external services both panes use, the mirror, and the PR app redirecting the harness's frame ([Known limits](#known-limits)).

By runtime, from the runtimes' sources and docs. These rows weren't each run end to end here, and the probe and floors decide each session:

| Runtime | Containers reach the host's loopback | The PR pane reaches the base pane's containers | Verdict to expect |
|---|---|---|---|
| Docker Engine on Linux, rootful, default iptables | no | no (each pane has its own network) | `isolated` |
| Rootless Docker on Linux | no, by default (`--disable-host-loopback`) | no | `isolated` |
| Docker Desktop (macOS, Windows) | yes, through `host.docker.internal` | no | `reachable` |
| Podman machine (macOS) | yes, through gvproxy's host address (`host.containers.internal`, `192.168.127.254`) | yes (Podman doesn't isolate networks) | `reachable` |
| colima, Lima, Rancher Desktop | yes, through Lima's host address (`host.lima.internal`, `192.168.5.2`) | no | `reachable` |
| Rootless Podman on Linux | no, by default (pasta and slirp4netns map no host loopback) | yes | `reachable` |
| Docker Engine with `"iptables": false` | no | yes | `reachable` |
| Docker Engine, dual-stack networks, `"ip6tables": false` (the default before 27) | no | yes, over IPv6 | `reachable` |
| Process Provisioner (any host) | yes | yes, as the same user | `shared-host` |

The probe doesn't try the node's `tailscale serve` ports: every way through them ends at a conductor listener, which the [capability](#security) guards.

## The seams

A boot runs these five seams in order: `ensureBuilt` → `provisionDatabase` (both panes) → the [isolation check](#isolation-verdicts) → per pane (`seedPane` → `reserveServices`) → `derivePaneEnv` (+ `runMigrate`) → `launchServices` → `waitHealthy` → `establishSession`. A sixth, [Exposure](#exposure-optional), is optional and outside the boot: it publishes the conductor itself. A seventh, the read-only **Inspector** (`adapters.inspector`), is optional too: right after each `seedPane`, and once `establishSession` is done, it lets the [data checks](#data-checks) read each pane's data. The shapes they pass each other are under [Types](#types).

| Seam | Members | Owns |
|---|---|---|
| **Provisioner** | `provisionDatabase({paneRef, databases, signal}) → {dsn, db}`, `reserveServices({paneRef, services, signal}) → {name: {url, port}}`, `launchServices({paneRef, services, env, reserved, signal})`, `waitHealthy({services, signal})`, `teardown({paneRef})`; optional `runMigrate({paneRef, migrate, env, signal})`, `sweep()`, `logs({paneRef, stage, lines}) → string` (or a promise of one), `isolation` (`'shared-host'`, or `({signal, canary}) → {verdict, reasons}`) | Where panes run: databases, processes or containers, ports, env at rest, cleanup, and whether they are kept apart |
| **BuildConvention** | `migrationStrategy` (`'one-shot-image' \| 'on-boot' \| 'none'`), `ensureBuilt(pr, {signal})`, `resolvePrImages(pr)`, `resolveBaseImages()` → `{services: {name: ref}, migrate?, label?}`; optional `subscribeBuild(cb)` with `cb({runUrl?, runStatus?, runConclusion?, message?})`, `describePrs(prs) → [{number, status: 'built'\|'building'\|'none'\|'blocked', runUrl, reason?}]`, `isolation: 'shared-host'` when it runs the PR's code on this host to build it ([Isolation verdicts](#isolation-verdicts)) | What gets run for base and PR, whether it's ready, and whether it may run at all |
| **Seed** | `databases`, `seedPane({paneRef, db, databases, signal})` | Where each pane's data comes from and how it moves |
| **EnvTransform** | `derivePaneEnv({prodEnv, pane}) → {service: env}` (pure) | Pointing a pane at its own DB and origin, and neutralizing side effects (email, payments, storage) |
| **AuthBootstrap** | `requiresDb`, `establishSession({pane, operator, db?, signal}) → {landingUrl}`; optional `envContributions() → {service: env}` | Getting the reviewer logged in to each pane |
| **Inspector** (optional) | `open({paneRef, db, databases, signal}) → {snapshot({limits, signal}) → Snapshot, close?()}`; optional `rules` | Reading each pane's data for the [data checks](#data-checks), and nothing else |

The optional members degrade gracefully when absent:
- With no `sweep`, nothing is cleaned up at startup, and enrolment trusts that no pane from an earlier run is still up.
- With no `isolation`, every session's [isolation verdict](#isolation-verdicts) is `unknown`.
- With no `logs`, failures show no log tail.
- With no `describePrs`, every PR shows as `none`.
- With no `inspector`, there are no data checks: `/api/state` says `data: {available: false}`, and the boot is as it was.

The one exception: a build that declares `one-shot-image` migrations with a Provisioner that can't `runMigrate` fails the boot with a clear error.

### Types

What the seams pass each other. Any method above may return its result or a promise of it: the core awaits each one.

- **PaneRef**: `{ role, slug, publicOrigin }` during a boot. `role` is `'base'` or `'pr'`, `slug` is `qa-<pr>-<role>`, and `publicOrigin` is the pane's origin from `cfg.paneOrigins`. `teardown` and `logs` get only `{ role }`, since they also run outside a boot.
- **ImageSet**: `{ services: { name: ref }, migrate?: { image }, label? }`, from `resolveBaseImages()` and `resolvePrImages(pr)`. A `ref` is whatever the Provisioner launches, such as an image name or a checkout directory.
- **Reserved**: `{ name: { url, port } }`, from `reserveServices`: where each service will listen. **Only the primary service is proxied**, `app` when there is one, else the first: the pane proxy forwards to `127.0.0.1:<port>` of that service, so it must listen there. Any other service is the app's own business.
- **Pane**: `{ ref, dsn, db, services, publicOrigin, env }`. `ref` is the PaneRef, `dsn` and `db` come from `provisionDatabase`, `services` is the Reserved map, and `env` is the pane's env. `derivePaneEnv` gets the pane before it has an `env`; `establishSession` gets it whole.
- **PaneEnv**: `{ service: { KEY: value } }`, from `derivePaneEnv`. **EnvContributions**, the same shape from `auth.envContributions()`, is merged over it service by service. `runMigrate` and `launchServices` get the result as `env`.
- **SessionResult**: `{ landingUrl }`, from `establishSession`: the URL the harness loads in the pane's frame. The core reads nothing else from it, so a session cookie must reach the pane's jar as a `Set-Cookie` the landing URL answers with (see below).
- **BuildEvent**: `{ runUrl?, runStatus?, runConclusion?, message? }`, what `subscribeBuild`'s callback gets.
- **Readiness**: `{ number, status, runUrl, reason? }`, one per PR from `describePrs`, with `status` one of `'built'`, `'building'`, `'none'` and `'blocked'`.

### Contracts between the seams

- **`db` is opaque to the core.** Whatever `provisionDatabase` returns as `db` is passed unchanged to `seedPane`, to `inspector.open` and (when `requiresDb`) to `establishSession`. Its shape is a contract among a consumer's own adapters.
- **The inspector reads, and never fails a boot.**
  - **When it runs:** `open` is called right after each pane's `seedPane`, with the same `db`, and the probe it returns takes the `seeded` snapshot there, before anything of the PR's runs on that pane. Both probes take the `ready` snapshot once every pane is signed in, before the boot returns.
  - **Read only:** a probe must only read. `close()`, if any, frees what the conductor's side holds, and must never touch the store.
  - **Failures:** an `open` or `snapshot` that throws, returns nothing useful, or takes longer than `limits.timeoutMs` (30 s) fails nothing. Its pane shows why it has no data, and a probe that comes too late is closed unused. The `signal` each call gets aborts at its timeout too, so a call that heeds it stops. A hanging inspector can add up to 150 s to a boot: an open and a seeded read per pane, one after the other, then the ready reads together.
  - **Cancellation:** an aborted boot calls the inspector no more. Teardown, and the next boot, close the probes before the panes go.
  - **Rules:** `rules` are the [data checks'](#data-checks) rules, which `startConductor` checks, throwing on bad ones.
- **Cancellation (`signal`).** Teardown and takeover abort the in-flight boot. An aborted boot never tears anything down, even when the abort lands while its failure log tail is being read: whoever aborted it already did.
  - **Where the core checks it:**
    - between stages;
    - at the top of each pane's provisioning;
    - between `provisionDatabase` and the Seed;
    - before each `launchServices`;
    - before the `waitHealthy` loop;
    - before each pane's `establishSession`.
  - **Who gets it:** `ensureBuilt`, the Provisioner calls that list `signal` (`provisionDatabase`, `reserveServices`, `runMigrate`, `launchServices`, `waitHealthy`), `seedPane` and `establishSession`. So a long wait can stop early, and a Seed or sign-in can stop between its steps.
  - **Adapters may ignore it.** A Seed or sign-in that writes the pane's database should check it before each write. Once the boot is aborted, the next session may own that pane's name.
  - **The Docker Provisioner** checks it before each step that creates or changes something, and its `db.query` refuses once the boot is aborted. It still finishes a wait or a Docker call already running.
  - **The process Provisioner** passes it on to `database.handle`, so a handle whose calls write can refuse too.
- **The isolation check (`isolation`).** A Provisioner whose panes share one user on one host declares `isolation: 'shared-host'`. One that can check is an async `isolation({signal, canary})`, which the core calls once both panes' databases exist, before either is seeded and before any migrate or launch.
  - It resolves to `{verdict, reasons}`, with `verdict` one of `isolated`, `unknown`, `reachable` and `shared-host`, and `reasons` saying why for anything but `isolated`. A throw, or anything else, counts as `unknown`. A check must fail closed: one that couldn't show it can reach anything isn't `isolated`.
  - `canary` is `{port, path, expect}`: while the check runs, the harness, on `port` (the harness port, on the conductor's bind address), answers a `GET` of `path`, and only that, with `expect`, before the identity gate. A probe from the PR pane's side that gets `expect` there has reached this conductor, so it reaches the host's loopback.
  - The core raises the result to its floors and records it ([Isolation verdicts](#isolation-verdicts)). `bootSession` takes the call as `deps.checkIsolation({stage, signal})`, with `stage` `'start'` before the build and `'panes'` at this point; a throw fails the boot.
- **Startup sweep.** The conductor calls `sweep()` once, at startup. A boot started before it settles waits for it before `ensureBuilt`, so the sweep can't remove the new session's panes. While it waits, the harness shows `waiting for startup cleanup…` under the first boot step, then `startup cleanup done`, and counts the wait in that step's time and the boot's. There is no timeout. A failed sweep is logged and doesn't block boots, even one that throws synchronously or rejects with something other than an `Error`, but it keeps enrolment shut until it succeeds: it runs again when a browser tries to enrol with no session running ([Security](#security)). A sweep, like a `teardown`, must reject when it leaves anything running. A teardown or takeover during the wait cancels the waiting boot, as it would at any other point.
- **Build progress.** `subscribeBuild(cb)` payloads are `{runUrl?, runStatus?, runConclusion?, message?}`. The harness shows `message` (plain text, e.g. `installing dependencies for #12 (abc1234)…`) under the first boot step, else a summary of the run's status that names a `completed` run's conclusion when it isn't `success` (`Build ended: failure`), and links the run when `runUrl` is `https://`. `/api/state` returns the latest as `buildRun: {url, status, conclusion, message}`. A boot that fails at `ensuring-image` with an error that carries `run: {url, status, conclusion}`, as `awaitPreviewImage`'s does, gets that run as its last build event before the error, so `buildRun` and the error's run link show the run that failed. Only string fields are kept, and only when there is a `url` or a `status`.
- **`blocked`.** `describePrs` may report a PR as `blocked`, with a plain-text `reason` (for example, an untrusted author or a head branch in someone else's fork). The picker shows it as `can't boot: <reason>`. Opening the PR is still allowed, because `ensureBuilt` is the real gate. `describePrs` receives `listOpenPrs()` items, or for `/api/build-status` an item built from `github.prInfo(pr)` (`{number, headSha, author, authorAssociation, headRepo, headOwner}`), falling back to `{number, headSha}` from `prHead` when `github` has no `prInfo`.
- **Display `label`.** `resolveBaseImages` / `resolvePrImages` may return a `label` string, used as the pane's tag instead of the primary service's ref (`app`, else the first service). The label appears in the harness header and in the **public** verdict comment. Consumers whose service refs are local paths or objects must set one, so no path or object leaks into the PR. It must not contain `:`.
- **Failure log tails.** When a boot fails at a pane stage (`cloning`, `migrating`, `starting`), the core calls `logs({paneRef: {role}, stage, lines: 40})` for the failing pane *before* tearing the panes down, and attaches the result to the error as `err.logTail` (with the pane's role as `err.failedRole`). An error that already carries a string `logTail` keeps it, so a BuildConvention can attach its own tail to an `ensuring-image` failure (for example, installer output). The harness shows the tail under the error.
- **Landing flows stay on the pane origin (AuthBootstrap).** The harness loads each `landingUrl` through a one-time pane-entry link, which sets the pane cookie and then redirects there ([Security](#security)). So a `landingUrl` must be on its pane's origin, or relative to it: one elsewhere isn't loaded, and the pane's bar shows why. The bridge learns the harness origin from the proxy, not from the URL. A pane serves a navigation from another site only when its `Referer` is the harness origin, so a sign-in step on another site, such as an external identity provider's form, comes back with that site's `Referer` and is refused. Keep landing flows on the pane origin. Redirects within it are fine, whatever their `Referrer-Policy`: the proxy drops that header from a redirect that stays on the pane, so the next hop still carries the harness `Referer`.
- **Sessions live in the jar (AuthBootstrap).** The pane app gets the cookies its own responses set this session, which the proxy keeps, and not the browser's. So the session must reach the jar in a `Set-Cookie`: have the `landingUrl`, or a redirect it makes, set it server-side. A session cookie the app's scripts write can't be kept apart for two panes on one hostname, `QA_FORWARD_CLIENT_COOKIES` or not. Cookies ignore ports, so both panes' pages write the same browser cookie, whichever pane signs in last overwrites it, and both proxies would pass that one value on: one pane's app would get the other pane's session (see [Security](#security)).

**Reference consumers:** this repository's self-QA ([`qa/self.mjs`](qa/self.mjs): `build-worktree` and `provisioner-process`, described in [CONTRIBUTING.md](CONTRIBUTING.md#qa-this-repos-own-pull-requests)), the demo's fake adapters ([`demo/fake-adapters.mjs`](demo/fake-adapters.mjs)), and agent-identity's [`packages/qa`](https://github.com/critical-labs/agent-identity/tree/main/packages/qa), a 0.2-era consumer that seeds each pane's DynamoDB Local from a redacted snapshot.

### Data checks

The data checks compare snapshots of each pane's data. They show what a pane's data did between two snapshots, and where the PR pane's changes depart from the base pane's. They also flag the destructive ones. Both panes start from one seed and get the same mirrored actions, so a PR-only change is the PR's. The engine is [`@critical-labs/qa-conductor/data-diff`](#entry-points): pure functions with no I/O.

With an [inspector](#the-seams), each session takes these snapshots of each pane, in memory only:
- **`seeded`:** right after its seed, before anything of the PR's ran on it. `seeded` to `ready` is the **boot** span: what migrations and the sign-in did.
- **`ready`:** once both panes are signed in, before the reviewer's first request. It is the baseline. A pane whose ready read failed keeps its `seeded` snapshot, and its first later snapshot is its baseline, so its boot span still shows; why its ready read failed stays in `errors.boot`. That pane's spans then cover another window than the other pane's: they say so (`aligned: false`), are incomplete, and nothing in the base pane excuses a PR change there. A boot span is aligned only when both panes' baselines came from the ready read itself: when both ready reads failed, both panes' boot spans run on into the session, so they are unaligned too. `baselineAt` is the ready read's time only when a pane's baseline came from it. A Re-baseline aligns the session span again; the boot span stays as it was.
- **`now`:** on **Snapshot now** (`POST /api/data/snapshot`). The baseline to `now` is the **session** span: what the reviewer's actions did. A pane whose read failed has no session span, rather than an old one.

**Re-baseline** (`{rebaseline: true}`) makes now the baseline, after a manual sign-in, say: both panes, or, when either read fails, neither. `GET /api/data` gives both spans: each pane's diff, their divergence, and the PR's flags, `trusted` or `advisory` by the session's isolation verdict. A span whose PR pane couldn't be read (a read that failed or hung, which PR code can cause with a lock) has a red `unreadable` flag: its changes are unknown, never none. So does one neither pane could be read for, once a snapshot was taken, and one whose PR pane's snapshot just became its baseline (its ready read failed), which has nothing yet to compare with. The flag's `reason` says which: `failed`, `neither` or `baseline`. It never reaches the event stream, a log or GitHub. The event stream says only `{kind: 'capture', pane, phase, ok}`, for the `seeded` and `ready` phases.


- **A snapshot** is `{ collections: { name: Collection } }`. A **Collection** is `{ key, rows, count?, truncated?, fields? }`:
  - `rows` are plain JSON objects;
  - `key` names the identity fields from the store's own schema (a primary key, a `KeySchema`), or is `null`, and the rows are then compared as a multiset;
  - `count` is the true row count. A truncated collection shows only a net change in it: a fall reads as deletes, a rise as inserts, and what happened past the cut can't be seen. A collection with fewer rows than its `count` is truncated, and one marked `truncated` with no `count` is a problem;
  - `fields` are its declared columns, so a dropped column shows. Leave it out for a schemaless store.
- **Rules** (`validateRules(rules)`) are plain data. Every list is optional, and a collection name in a rule matches exactly or with `*` globs:
  - `exclude: [name]`: never kept or shown, such as migration history or sessions;
  - `volatile: [{collection, fields, mode?}]`: fields such as timestamps that change on their own. `ignore` (the default) drops them; `presence` keeps only whether each is set;
  - `classify: [{collection, fields, as}]`: `as` is `secret` or `pii`. It names top-level fields only. A value inside JSON is masked when its key looks secret, but `classify` doesn't reach it;
  - `softDelete: [{collection, field}]`: a field whose being set counts as a delete. It is never masked, and `null`, `false`, `0` and `''` count as not set;
  - `destructive: [{collection, maxChanged?, allowDeletes?}]`: a collection's own mass-change threshold, or deletes it expects. A rule that names the collection exactly wins over a glob.

  An entry with a field no rule has, such as `allowDelete`, is refused.
- **What a snapshot keeps** (`sanitizeSnapshot(raw, {masker, rules, limits})`, with `createMasker({key, rules})`):
  - at most `LIMITS.maxRows` (10,000) rows a collection, `LIMITS.maxBytes` (32 MB) in all and `LIMITS.maxCollections` (1,000) collections. The bytes are shared fairly: the collections with the fewest rows go first, each with at most an equal share of what is left, so one big collection, a PR's padding say, can't starve the others. A collection cut short is `truncated`, and only its count is compared. The bytes are the kept rows' JSON: they bound neither the heap the rows take nor the work of reading them ([Known limits](#known-limits));
  - past `maxCollections`, the collections with the most rows are kept, so many small ones can't push a real one out. The rest are kept as their counts alone (`truncated`, with no rows), up to ten times as many, and only past those is one left out. `problems` names both;
  - a collection's `key` and declared `fields` count against its share of the bytes, like its rows. A collection whose name is over 200 characters is left out. A key of more than 32 fields is dropped, and the rows are compared without one. A collection with more than 2,000 declared fields, or whose key and fields don't fit its share, is kept as its count. `problems` says each;
  - it returns `{collections, problems, omitted}`. `omitted` counts the collections given but not kept (left out, or unreadable), or is `null` when the snapshot couldn't be read at all. Those left out for a name over 200 characters don't count: no collection the diff sees can be one of them;
  - each value as it is, except:
    - **a secret** is `{t: 'secret', d}`: only whether it changed shows. That is a field whose name matches `SECRET_NAME`, or one `classify` marks `secret`. `SECRET_NAME` matches, in any case:
      - `pass`, `pwd`, `secret`, `token`, `salt`, `hash`, `otp`, `private`, `session`, `card`, `cvv`, `cvc`, `ssn`, `iban`, `authorization`, `bearer`, `jwt`, `cookie`, `credential`, `signature`, `dsn`, `mnemonic`, anywhere in the name;
      - `api_key`, `access_key`, `signing_key`, `client_key`, `encryption_key`, `master_key`, `ssh_key`, `database_url`, `mongo_url`, `redis_url`, `amqp_url`, `postgres_url`, `mysql_url`, `connection_string`, `seed_phrase`, `recovery_code`, `backup_code` and `pin_code`, with `_`, `-` or nothing between the words (`apiKey`, `api-key`), and `uri` for `url`;
      - `pin`, `pw` and `psk` as words of their own (`pin`, `user_pin`, `user_pw`, `wifi-psk`), and `auth` or `_auth` as the whole name (Docker's and npm's base64 `user:password`), in text after an escape too (`%26pin%3D…`, `\n_auth=…`).

      A secret-looking name stays secret whatever `classify` says;
    - **personal data** that `classify` marks `pii` is `{t: 'pii', fp, type, len}`: an 8-hex fingerprint, the type and the length;
    - `d` and `fp` are HMACs under `key`, which the conductor makes for each session and never sends anywhere. So equal values match across the panes, and say nothing past the session. A secret's digest is its field's, so equal secrets in two fields don't match;
    - an object or array is `{t: 'json', s}`, its JSON, and so is a string that holds one. A string that holds a JSON string holding one (JSON encoded twice) adds `enc: 2`, so re-encoding a column shows;
    - a value under a secret-looking key inside JSON is masked too, with a digest of its collection's and field's. So is every value of a name and value pair whose name looks secret: `name` or `key` with `value`, all lower case or all capitalized, whatever else the object holds (`{name: 'Authorization', value}`, a HAR cookie, AWS's `{Name, Value}`, an SSM Parameter); and the looser spellings, `field` or `k` for the name and `val` or `v` for the value, in any case, in an object of at most six keys. Any of its name-like keys may name it (`{key: 'mail.smtp', name: 'Password', value}`). A row shaped as such a pair, as in a settings table (`{id, key: 'smtp_password', value}`), has its value fields masked the same way. So is the string after a secret-looking one in a list of strings (Node's `rawHeaders`). JSON held in a string inside JSON is read too, up to three deep, and so is JSON encoded twice, which keeps its outer string form, and NDJSON line by line. Bytes inside JSON show only their length, and a `Set` or `Map` its entries;
    - text that isn't JSON, or is over 256 KB, but shows a secret-looking key is masked whole: `[text with a secret-looking key, <length>, <digest>]`. A key counts at a word's start, or right after a percent-escape (`x%3dpassword=…`), quoted or not (an escaped quote, one HTML-escaped in any case, one percent-encoded, or a backtick), or in brackets, then up to 32 spaces and `:` or `=` or their percent-encodings (`"password": …`, `\"password\": …`, `&quot;password&quot;: …`, `` `password` = … ``, `api_key=…`, `user[password]=…`, `password%3D…`), and as a tag, with a namespace, whatever its attributes hold (`<password>`, `<wsse:Password Type="…">`, `<password hint="a<b">`). So do a command-line flag whose name looks secret (`--password …`, `--db-token=…`), a MySQL client's `-p<password>`, and a PEM or PGP private key. The first 256 KB are read: a cell shows at most its first 200 characters;
    - in text, these are replaced by a digest, the rest kept:
      - a URL's password (`postgres://app:<secret>@db`, with an empty user too, and up to the last `@` before the host), or a token alone as its userinfo (16 characters or more). The user too when it looks like a token, or has an empty password or GitHub's `x-oauth-basic` beside it (`https://<token>:x-oauth-basic@github.com`);
      - the value after `Bearer`, `Basic` or `Token`, in any case, when it looks like a token: a digit in it, or 16 characters, or for `Basic`, base64 (`dXNlcjpwYXNz`). So prose such as "Basic introduction" is kept;
      - a Go DSN's password, up to its last `@` (`user:<secret>@tcp(…)`, `@tcp6(…)`, `@unix(…)`, `@cloudsql(…)`, any network, or `@/`), and a JWT;
      - the `value` of an element whose `key`, `name`, `id` or `type` looks secret, quoted either way or not (`<add key="DbPassword" value="…"/>`, `<input type=password value=…>`);
    - **what masking misses.** It is best-effort: a PR controls its own data, and can always hide a value from a name or a shape. It matters for the seeded data the Data panel shows. In text, a secret with no key, scheme or shape listed above shows: SQL's `INSERT … VALUES` by position, a password alone on a line, a `-p` flag outside a MySQL client, a URL password with a raw `/`, a DSN password with a `:` in it, an element's value holding a `>`. So does a field whose name `SECRET_NAME` doesn't match, such as `key` alone, which is often a row's own key, and a pair under other names, such as WordPress's `{option_name, option_value}`. Name such fields in `classify`;
    - a string or JSON over 200 characters is `{t: 'long', s, len, d}`, cut;
    - bytes are `{t: 'blob', len, d}`;
    - a value that isn't set (`null`, `''`, `[]`, `{}`, or an empty `Set` or `Map`) is kept as it is, whatever its field, so clearing a secret shows. A `Set` or `Map` with entries is masked like any other value.
  - Anything malformed, or that throws as it is read, is listed in `problems`, never thrown. A key that a row lacks, or that two rows share, is dropped.
  - Collection and field names are the store's, any string: `__proto__` and `constructor` are names like any other.
- **`diffSnapshots(before, after)`**: per collection, `{status, key, inserted, updated, deleted, fieldsDropped, fieldsAdded, countBefore, countAfter, truncated, keyLost, omitted, fieldsBefore}`. `fieldsBefore` is the before snapshot's declared fields, or `null`. `keyLost` says the after snapshot no longer bears out the key the before one had, for example because two rows share it.
  - `status` is `same`, `changed`, `added` or `dropped`, or `unknown` for a truncated collection whose count didn't change: it never claims nothing changed.
  - A collection missing from a snapshot that left some out (its `omitted` isn't 0) may only have been left out. It is `unknown` and truncated, never `added` or `dropped`, with `omitted` saying which side (`before` or `after`, else `null`) and that side's count `null`.
  - `inserted` and `deleted` are `[{key, row}]`, and `updated` is `[{key, fields: [{field, before, after}]}]`. A `key` is the JSON of the row's key values. The collection's `key` is the one the diff used: `null` when the rows were compared as a multiset, as they are when either snapshot has no key, or a different one.
  - A field that the declared `fields` gained or lost is named once, not as an update to every row, with a key or without.
- **`divergence(baseDiff, prDiff)`**: per collection, `{status, truncated, changes, counts}`.
  - Each change, by key, is `{kind, key, status, base, pr}`, plus `field` for a schema change. Its `status` is `both`, `pr-only`, `base-only` or `differs`.
  - Without a key both panes share, and for a truncated collection, only the schema's changes and the `counts` of inserted, updated and deleted rows are compared.
  - The collection's `status` sums its changes up: `same` when there are none, or `unknown` for a truncated collection whose counts show nothing, one truncated in one pane only, whose count can't be set beside the other's rows, one a pane's snapshot may have left out, or one the PR pane's diff lacks while the base pane's has it.
  - A collection one pane dropped or added while the other changed it `differs`.
- **`flagChanges(baseDiff, prDiff, rules, {trusted})`**: the PR pane's destructive changes, each `{collection, kind, severity, shared, pr, base, field?, count?, fields?}`. `pr` and `base` are how many of that kind each pane made, on any rows. `shared` says the base made the same change.
  - **The kinds:**
    - `delete`: rows gone, or a `softDelete` field newly set;
    - `emptied`: a collection whose count fell to 0;
    - `dropped`: a collection gone;
    - `column-dropped`: declared fields gone, one flag a collection, with their number in `count` and the first five in `fields`: first those the base pane's before snapshot declares too (the seeded ones, how many in `seeded`), then the PR's own. So padding columns the PR added can't hide a seeded one it dropped. It is shared only when the base dropped every one of them;
    - `mass-change`: more than 20 rows updated or deleted, or more than 20% of a collection of at least 5 rows, or past a rule's `maxChanged`;
    - `key-lost`: a collection whose key the PR's rows no longer bear out, so its rows were compared without one, and updates read as deletes and inserts;
    - `unverified`: a collection the PR pane's snapshot cut short where the base pane's didn't, a cut-short one whose count changed, one a PR snapshot may have left out, or one the base pane's diff has and the PR pane's lacks. What happened past the cut can't be seen, so it is never taken for nothing. One cut short in both panes with no change in count is listed too, `amber` whatever the trust. Those only the PR pane has (the base pane's diff lacks them) are one flag, `{collection: null, kind: 'unverified', severity: 'red', collections, names, …}`: how many, and the first five names;
    - `cleared`: a value set before, now `null`, `''`, `[]` or `{}`.
  - **Severity:** `amber` when the base made the same change (`shared`) and `trusted` is `true`, else `red`. The same change means the same rows (by key, or as a multiset without one), with the same fields changed to the same values, the same field, or for two cut-short collections the same change in count. A count stands for rows only when both panes have only counts. Unless `trusted` is `true`, the base's changes excuse nothing: every flag is `red` but `cleared`, which is `amber` at most, and `unverified` for a collection cut short in both panes with no change in count, which is `amber`. `allowDeletes` turns off a collection's `delete` flags, but not `emptied` or `key-lost`.
    - Since the same change means the same values, a field the app writes with the time or a random value differs between the panes even when both did the same thing. Declare it `volatile` with `mode: 'presence'`, so only whether it is set compares, and a shared action stays shared.
  - **The order:** `red` first. Within a severity, the collections the base pane has come before those only the PR pane has. Then what loses rows, a collection or its key (`delete`, `emptied`, `dropped`, `key-lost`, and the `unverified` flag of a collection the PR pane's snapshots may have left out, which can hide a drop or a wipe) comes before `column-dropped` and `mass-change`, and those before other `unverified` flags and `cleared`. Then by collection, kind and field. So a cap on a list keeps what matters to the base pane's data, and a PR's padding, such as many dropped columns, can't push a delete out.
- **`trustOf(isolation)`**: `trusted` only when the session's [isolation verdict](#isolation-verdicts) is `isolated`, else `advisory`. While the PR pane may reach the base pane, what the base pane did can't excuse what the PR pane did. Pass it on as `flagChanges(…, {trusted: trustOf(isolation) === 'trusted'})`.

### Built in: `adapters/build-worktree` (git-worktree BuildConvention)

A BuildConvention for apps that run a PR from its source rather than from CI-built images. It fetches the base branch and the PR head into a bare repository, checks each SHA out into its own git worktree, optionally installs dependencies, and hands each worktree directory to your Provisioner through `servicesFor`.

```js
import os from 'node:os'
import path from 'node:path'
import { createWorktreeBuild } from '@critical-labs/qa-conductor/adapters/build-worktree'

const build = createWorktreeBuild({
  repo: 'acme/widget',
  cacheDir: path.join(os.homedir(), '.cache/qa-conductor/acme-widget'),
  github,                                          // needs prInfo(num) and authorPermission(login)
  servicesFor: (dir, { role, sha }) => ({ app: dir }),
  install: { cmd: 'pnpm', args: ['install', '--frozen-lockfile', '--ignore-scripts', '--ignore-pnpmfile'] },
})
```

| Option | Default | |
|---|---|---|
| `cloneUrl` | `https://github.com/<repo>.git` | must not contain credentials (construction throws); for a private repo, configure a git credential helper |
| `install` | `null` (no install) | `{ cmd, args, env? }`, run in the worktree. With one, the convention declares `isolation: 'shared-host'`, even with `--ignore-scripts`: an install can still run the PR's code on this host (a package manager the PR picks, its config) before the [isolation check](#isolation-verdicts), so every verdict is `shared-host` and `QA_REQUIRE_ISOLATION=1` refuses. A wrapper that spreads the convention, `{ ...createWorktreeBuild(opts), describePrs }`, keeps the declaration; one that copies members by hand must copy `isolation` too |
| `baseRef` | `'main'` | the branch the base pane runs |
| `trust` | `{ logins: [], associations: ['OWNER', 'MEMBER', 'COLLABORATOR'], requirePush: true, allowForks: true }` | see below; omitted keys keep their defaults. `logins` and `associations` must be arrays of strings (split a comma-separated env value first); anything else throws at construction |
| `keep` | `6` | the newest `keep` builds survive pruning; the two SHAs just built are never removed, even when they fall outside that number |
| `migrationStrategy` | `'on-boot'` | |

How it works:
- **`servicesFor` runs before the isolation check**, in `resolveBaseImages` and `resolvePrImages`, so it must run none of the PR's code: it may read the checkout, never run anything from it.
- **Layout under `cacheDir`.** The bare repository is `repo.git`, created on first use, and each checkout is `worktrees/<sha>`. Markers live at `built/<sha>.json`, outside the checkouts, so a PR's committed files can't supply one. A marker records a fingerprint of the install command, args and env keys. If it doesn't match, or the checkout is gone, the marker is dropped and the SHA is rebuilt from a clean checkout.
- **The cache must be yours alone.** `cacheDir`, `built/` and `worktrees/` are created `0700`. Each build refuses to run unless each of them is a real directory (not a symlink), owned by the current user, and not writable by group or others: anyone who can write there can plant a marker and a tree for the base SHA.
- **One build at a time** per instance. A second caller waits, then runs its own build, re-checking the markers.
- **Progress** goes to `subscribeBuild` as `{ message }` (`fetching acme/widget…`, `installing dependencies for #12 (1a2b3c4)…`, `#12 (1a2b3c4) already built`). Each `ensureBuilt` reports to the subscriber that was current when it was called, and says nothing more once its signal aborts. An install failure's error carries a `logTail`: the last 40 lines of its output, at most 8 KB.
- **`resolvePrImages` / `resolveBaseImages`** return `servicesFor(dir, …)`, `migrate: null`, and a `label` such as `#12@1a2b3c4` or `main@9f8e7d6`, which never contains a path.
- **`describePrs`** reports `blocked` (with a reason) for a PR that fails the trust gate, then `building`, `built` or `none`.
- **Pruning** runs after each build and is best-effort. The newest `keep` builds are kept, and the two SHAs just built are never removed, even when they fall outside that number. Every other checkout is removed, including ones whose build never finished.

**Security.** This adapter checks out and installs a PR's code on the reviewer's machine, as the reviewer, and your Provisioner then runs it. **The trust gate is the only real boundary between a PR's code and the reviewer's machine. Env scrubbing and loopback binding are defence in depth.**
- **The trust gate.** `ensureBuilt` refuses a PR, before any git call, unless all of these hold:
  - its author is in `trust.logins`, or has an association in `trust.associations` **and**, when `requirePush` is set (the default), `write` or `admin` permission on the repo;
  - its head repository still exists;
  - its head branch is in the repo itself or in the author's own fork, not in someone else's fork. With `allowForks: false`, only the repo itself.
- **Association isn't access.** `author_association` alone is not an access check. `COLLABORATOR` includes read-only outside collaborators, and `MEMBER` includes org members with no push access. That's why `requirePush` defaults on.
- **The gate vouches for the author, not for every commit.** It checks who opened the PR and where its head lives, not who pushed the head commit. Anyone with push access to the author's fork (collaborators they added, bots or Actions with write access to it) can move the head, and the moved head passes as the author's. Set `allowForks: false` to require heads in the repo itself, where everyone who can push has write access to the repo.
- **Only the gated SHA runs.** Only the exact SHA that passed the gate is ever checked out or installed. If the head moves between the check and the fetch, the new SHA is gated again, or the build fails with `head moved during fetch; retry`.
- **It fails closed.** Any error while checking (a GitHub error, a missing field) refuses the PR, and a malformed `trust` config throws at construction.
- **Defence in depth, not a sandbox.**
  - The installer's environment is exactly `PATH`, `HOME` and `install.env`, so credentials in environment variables (such as `GITHUB_QA_TOKEN`) don't reach it. Files under `HOME` do: it can read `~/.npmrc` tokens, `~/.config/gh`, `~/.git-credentials` and `~/.ssh`.
  - git runs with hooks disabled and prompts off.
  - A PR that passes the gate still runs with the reviewer's full user access. Code it runs (install scripts, a package manager it selects, the server your Provisioner launches) can rewrite this cache, including markers and other checkouts such as the base, like anything else the reviewer can write.
- **Skip install scripts.** Install with `--ignore-scripts` (with pnpm, also `--ignore-pnpmfile`) so dependency lifecycle scripts and pnpmfiles don't run.

### Built in: `adapters/provisioner-process` (process Provisioner)

A Provisioner for local processes. It runs each pane's services, and optionally a per-pane database, as process groups on `127.0.0.1`, with a scrubbed env, a pidfile and a start-time-checked orphan sweep. Its launch contract is below.

```js
import net from 'node:net'
import os from 'node:os'
import path from 'node:path'
import { setTimeout as sleep } from 'node:timers/promises'
import { createProcessProvisioner } from '@critical-labs/qa-conductor/adapters/provisioner-process'

const ddbDir = '/opt/dynamodb-local'   // where DynamoDBLocal.jar is unpacked

// Resolves once something accepts connections on the port.
async function waitForPort(port, { signal }) {
  while (!signal.aborted) {
    const open = await new Promise(resolve => {
      const socket = net.connect(port, '127.0.0.1', () => { socket.end(); resolve(true) })
      socket.on('error', () => resolve(false))
    })
    if (open) return
    await sleep(250)
  }
}

const provisioner = createProcessProvisioner({
  stateDir: path.join(os.homedir(), '.cache/qa-conductor/acme-widget'),  // holds pids.json
  // `ref` is the service's entry from the BuildConvention, e.g. a checkout directory
  command: ({ name, ref, port, env, paneRef }) => ({
    cmd: path.join(ref, 'node_modules/.bin/tsx'),
    args: ['packages/api/src/dev.ts'],
    cwd: ref,
    env: { HOST: '127.0.0.1', PORT: String(port) },
  }),
  database: {                                  // optional: one per pane
    command: ({ paneRef, port }) => ({ cmd: '/usr/bin/java', args: ['-jar', 'DynamoDBLocal.jar', '-inMemory', '-port', String(port)], cwd: ddbDir }),
    ready: ({ port, signal }) => waitForPort(port, { signal }),
    handle: ({ paneRef, port }) => ({ dsn: `http://127.0.0.1:${port}`, db: { endpoint: `http://127.0.0.1:${port}` } }), // also gets the boot's signal
  },
  healthPath: '/ui/',                          // or (serviceName) => path; default '/'
  healthy: status => status === 200,           // default: status < 500
})
```

The other options are `healthTimeoutMs` (60000, per service), `host` (`127.0.0.1`: the address in reserved urls, health checks and the free-port lookup), `graceMs` (5000, from SIGTERM to SIGKILL), `logLines` (200 per pane) and `log` (`console`). Every effect is injectable: `spawnFn`, `killFn`, `freePortFn`, `fetchFn`, `fsx`, `psFn`, `pgroupFn`, `bootIdFn`, `sleepFn`, `nowFn`, `onExitFn` and `baseEnv`.

**Launch contract.** `command` and `database.command` must start the server binary **directly**, never through a package manager (`pnpm dev`, `pnpm exec`, `npm run`, `npx`). The child has no TTY and only `PATH` plus the env you declare, and the package manager on that `PATH` may not be the one that ran `install`: pnpm 10 and later verify dependencies before run/exec and, with no TTY, fail or reinstall. So use, for example, `{ cmd: join(dir, 'node_modules/.bin/tsx'), args: ['packages/api/src/dev.ts'], cwd: dir }` or `{ cmd: process.execPath, args: ['demo/server.mjs'], cwd: dir }`. The process you start is the server: if it exits, the pane has failed.

- **Env.** A service gets exactly `{ PATH, ...env[name], ...spec.env }`: the conductor's `PATH`, the pane env from your EnvTransform, then the command's own `env`. The database gets `{ PATH, ...spec.env }`. Nothing else is inherited: no credentials, and no `HOME` unless you declare it.
- **Ports.** `reserveServices` picks a free port per service on `host`, and never hands out a port another pane or service still holds. Nothing starts until `launchServices`. Your command must make the server listen on that port, bound to `host`.
- **Health.** `waitHealthy` polls `<url><healthPath>` until `healthy(status)`, for up to `healthTimeoutMs`. A process that exits first fails the boot at once, with its log tail. `healthy(status)` gets the service's own response status: redirects aren't followed (an app often redirects to its public origin, the pane proxy, which answers `503` until the boot is done), so under the default `status < 500` a `3xx` counts as up. A strict predicate such as `status === 200` needs a `healthPath` that doesn't redirect.
- **Logs.** Each pane keeps its last `logLines` lines of stdout and stderr, prefixed `[name]`, and `logs()` returns the tail. The buffer survives teardown, and resets when the pane's next boot starts.
- **Teardown** signals process **groups**, never bare pids, because a wrapper may exit at once while its server lives on. Services go first, then the database: SIGTERM, then SIGKILL after `graceMs`. A group that survives SIGKILL, or a pid teardown can't check, is logged and left for the next sweep, and teardown then rejects, naming it, once it has stopped the rest; so does a sweep that leaves one running. Once a leader has exited, its pid can be reissued, so teardown checks it with `ps` first: a pid held by another process means our group is gone, and it isn't signalled.
- **Isolation.** It declares `isolation: 'shared-host'`: both panes run as you on one host, so each can reach the other's ports, files and processes, and every session's [isolation verdict](#isolation-verdicts) is `shared-host`. A base-vs-PR comparison is advisory with it.
- **Crash cleanup.** Each process is recorded in `<stateDir>/pids.json` with its start time from `ps` and the boot it ran in. The directory must be a real directory owned by you and not writable by group or others (it's created `0700`; one that others could write to is refused, since its contents may be planted), and `pids.json` must be a regular file owned by you (written `0600`). `sweep()`, which the conductor runs at startup, kills the groups a previous run left behind. It skips any pid that now belongs to another process, drops entries from an earlier boot without signalling anything, and leaves in place entries it can't check (no start time). Give each conductor its own `stateDir`. A `process.on('exit')` hook SIGKILLs every live group; signals don't run it, so call the conductor's `shutdown()` from your signal handlers.
- There's no `runMigrate`: process consumers migrate on boot.

**Security.** A PR's code runs as your user, on your machine. The trust gate is the only real boundary between a PR's code and the reviewer's machine: the BuildConvention must refuse to build a PR it doesn't trust. Env scrubbing and loopback binding are defence in depth. The Tailscale identity gate is no boundary against PR code either: a pane process can reach the conductor on loopback and send any `Tailscale-User-Login` it likes (see [Security](#security)).

### Built in: `adapters/provisioner-docker` (Docker Provisioner)

A Provisioner that runs each pane as two containers on the host's Docker daemon, a postgres one and an app one. It writes each pane's env to an owner-only file for `docker run --env-file`, logs in to the registry, runs one-shot migrations, and at startup removes the containers, networks and env files an earlier run left behind.

It keeps the panes apart:
- **A network per pane.** Each pane's containers join a network of their own. On Docker Engine with its default iptables rules, the PR pane's containers can then neither resolve nor reach the base pane's. The conductor needs no shared network: it reaches the apps through their host ports and the databases through `docker exec`.
- **No raw sockets.** Each pane container runs with `--cap-drop NET_RAW`, so PR code can't send crafted packets, which on some setups reach ports published on the host's loopback. Tools that need raw or packet sockets don't work in the panes, such as `tcpdump`, `arping`, `traceroute -I` or `-T`, and `nmap -sS`. `ping` usually still works (Docker 20.10 and later let it use ICMP datagram sockets), unless the image's `ping` carries the `cap_net_raw+ep` file capability.
- **A database password per pane, drawn for each boot,** unless you set `postgres.password`. Only that pane's `dsn` carries it. So a PR that reached the other pane's database still couldn't sign in. That holds for an image that sets its database up from `POSTGRES_PASSWORD` and `POSTGRES_HOST_AUTH_METHOD`, as the official `postgres` image does. `createDocker`'s `postgres.image`, under [Effect wrappers](#effect-wrappers), says which don't.

Its limits, below, say what the networks and passwords don't separate, and [Known limits](#known-limits) what no Provisioner separates.

```js
import fs from 'node:fs'
import { createDocker } from '@critical-labs/qa-conductor/docker'
import { makeExecFileFn } from '@critical-labs/qa-conductor/exec'
import { createDockerProvisioner } from '@critical-labs/qa-conductor/adapters/provisioner-docker'

const provisioner = createDockerProvisioner({
  docker: createDocker({ execFileFn: makeExecFileFn() }),
  fsx: fs.promises,
  workDir: '/var/lib/qa-conductor',
  registry: { user: 'acme-bot', token: cfg.ghcrToken },
})
```

| Option | Default | |
|---|---|---|
| `docker` | *(required)* | a `createDocker(...)` ([Effect wrappers](#effect-wrappers)) |
| `fsx` | *(required)* | `{ writeFile, unlink }`, such as `fs.promises`: writes the env files, mode `0600`, and removes them at teardown and at startup |
| `workDir` | *(required)* | the directory the env files go in, as `.env.qa-base` and `.env.qa-pr`. The `docker` CLI reads them by path, so it must see the same directory |
| `network` | `'qa-session'` | each pane's Docker network: a prefix, so `qa-session-base` and `qa-session-pr`, or `{ base, pr }` to name both. A network name must be letters, digits, `_`, `.` and `-`, and not lowercase hex digits alone, which Docker would also read as the start of a network id. Two panes on one network, or one of Docker's or Podman's own networks or modes (`host`, `bridge`, `none`, `default`, `ingress`, `docker_gwbridge`, `podman`, `private`, `pasta`, `slirp4netns`, `podman-default-kube-network`, `container:<name>`), throw |
| `postgres` | `{ user: 'qa', db: 'postgres' }` | the superuser in the `dsn` it returns, and the database `db.query` uses by default: match `createDocker`'s `user` and `db`. Keys you leave out, or set to `undefined`, keep these values. Leave `password` out, and each pane's database gets its own, 48 random hex characters drawn for each boot. A `password` you give must be a non-empty string with no control characters. Both panes use it, so the PR pane's `dsn` also opens the base pane's database, and only the networks keep them apart. Either password holds only with an image that enforces it: see `createDocker`'s `postgres.image` |
| `hostPorts` | `{ base: 3111, pr: 3112 }` | the loopback host port each pane's app container is published on |
| `registry` | `null` | `{ user, token }`: log in to `ghcr.io` before pulling, and again before each retry |
| `probeTimeoutMs` | `30000` | how long the isolation probe's `docker run` may take in all, after which the docker CLI is killed (`SIGKILL`), the probe container removed, and the verdict is `unknown`. A teardown or takeover during the probe stops it too |

For each pane:
- `provisionDatabase` creates the pane's network, pulls the postgres image if it's missing, and starts `qa-pg-<role>` on the network, with the pane's password. It waits until the database answers twice in a row, creates each of the Seed's `databases`, and returns the `dsn` `postgresql://<user>:<password>@qa-pg-<role>:5432`, with the user and password percent-encoded, and a `db` of `{ dsn, query(sql, { database }) }`, which runs `psql` in the container. A pane network left over from an earlier run is reused.
- `runMigrate` runs `migrate.image` once as `qa-migrate-<role>`, on the pane's network, with the pane's `app` env (else its first service's), and removes the container after.
- `launchServices` pulls each image that's missing (three tries), then runs it as `qa-app-<role>` on the pane's network, with its port `3000` published on `127.0.0.1:<hostPorts[role]>`.
- `waitHealthy` polls `http://127.0.0.1:<port>/api/health` until it answers `200`, for up to a minute.
- `logs` tails the app container at `starting`, else the postgres one.
- `isolation` checks whether the PR pane can reach the base pane, once both databases exist and before either is seeded ([Isolation verdicts](#isolation-verdicts)).
  - **The runtime:** `docker version` naming Podman (the podman-docker shim included), whose networks don't keep the panes apart, makes it `reachable` at once. So does `docker info` naming Docker Desktop, which forwards the host's loopback. A daemon that isn't on this host (the current context's endpoint, which `DOCKER_HOST` sets, isn't `unix://` or `npipe://`) makes it `unknown`.
  - **The probe:** `qa-probe-pr`, a throwaway container from the postgres image, on the PR pane's network, labelled, with no capabilities, ports or mounts.
    - **What it needs:** `bash` with `/dev/tcp`, `timeout` that takes its seconds first (GNU coreutils, or a BusyBox from 1.30), `grep` and `cat`, as the official Debian-based `postgres` images have. It checks the tools first, and stops if one is missing or different.
    - **What it tries:** it asks this conductor's harness port for the canary at each address a runtime gives the host: `host.docker.internal`, `gateway.docker.internal`, `host.containers.internal`, `host.lima.internal`, `host.rancher-desktop.internal`, `192.168.65.254`, `192.168.65.2`, `192.168.127.254`, `192.168.5.2`, `10.0.2.2`, `169.254.1.2`, `172.17.0.1`, and the PR network's gateway. It also connects to the base pane's database at each of its addresses, IPv6 ones included: on a dual-stack network with `ip6tables` off (the default before Docker Engine 27, or `"ip6tables": false`), Docker doesn't isolate IPv6 between networks, and a probe of IPv4 alone would miss that. Each address family's misses count only once its own control hit over that family.
    - **Its positive control:** the PR pane's own database, which it must reach over each address family the base database has: an IPv4 hit says nothing of IPv6.
    - **Timing:** all at once, each in at most 3 seconds. The `docker run` gets `probeTimeoutMs` in all (default 30 s), after which the docker CLI is killed and the probe container removed. A teardown or takeover stops it too.
  - **The verdict:** a canary answered, or the base database connected, makes it `reachable`, saying where, even in a run that then failed or ran out of time. It is `unknown` when the probe didn't run (a tool missing, say), didn't finish, or didn't reach its own pane's database, or when the runtime, the daemon's endpoint or the addresses weren't found. Else it is `isolated`.
- `teardown` removes the pane's containers (a migrate run still in flight, and the PR pane's probe, among them) and their volumes, then its network and its env file. A name already gone is fine, in Docker Engine's words or Podman's (through its own CLI, the podman-docker shim or its Docker-compatible API, after any warnings it writes first), but when docker fails otherwise (no daemon, a container it can't kill, a network still in use), `teardown` rejects with that error once it has tried every step. So does `sweep`.
- `sweep` removes both env files, which hold an earlier run's env and passwords, then every container with `createDocker`'s `label` and both panes' networks. When `network` is a prefix, it also removes the network of that very name, which both panes shared in 0.3.1 and earlier, but only if it carries the label, as that network did. It leaves the name alone when it is one of Docker's or Podman's own, or lowercase hex digits alone.

The provisioner also has `networks`, `{ base, pr }` (frozen): the two network names.

Its limits:
- **One service per pane.** Every service would run as `qa-app-<role>` with the same env file.
- **Fixed names and ports.** The containers, the networks and the host ports are the same on every run, so run one conductor per Docker host.
- **The host's loopback.** The panes' apps are published there, and the conductor listens there by default. Where a container can reach the host's loopback (Docker Desktop, through `host.docker.internal`, Podman machine, through `host.containers.internal`, and Lima-based runtimes such as colima, through `host.lima.internal`; rootless Docker and rootless Podman on Linux don't by default), the PR pane's app can reach all of them:
  - the base pane's app, on its host port, with no session but the base app's own;
  - the base pane's proxy, which signs every request in as the operator, and the harness API. Both answer it `403`, since it holds no enrolled browser's capability ([Security](#security)). That holds over https. On plain-http loopback, a PR page working with the PR app can lift the pane cookie through the browser, which then admits it to the base pane's proxy until that session ends; the harness API still needs the token ([Security](#security)).

  It still can't reach the base pane's database directly: that has no host port.
- **A conductor off loopback.** With a non-loopback `QA_BIND_HOST` (none mode only), a container on any runtime, native Linux Docker Engine included, can reach the harness and the base pane's proxy through its network's gateway or the host's address, unless a host firewall drops that traffic. Both refuse it the same way.
- **Other runtimes.** The networks keep the panes apart because Docker Engine's default iptables rules isolate one network from another. A daemon run with `"iptables": false` doesn't, nor do Podman's networks, which it creates without `isolate=true`. On a dual-stack network, a daemon with `"ip6tables": false` (the default before Docker Engine 27) doesn't keep IPv6 apart either. There, PR code can reach the base pane's containers by address, though not by name. The per-pane password still keeps it out of the base pane's database, unless you set `postgres.password`, or the image doesn't enforce it (see `createDocker`'s `postgres.image`).
- **The app's side:** listen on port `3000` in the container, and answer `GET /api/health` with `200`.
- **The registry login is to `ghcr.io` only.**
- **`signal`.**
  - Each step that creates or changes something (the network, a container, an env file) first checks `signal`, so an aborted boot stops there.
  - `db.query` refuses once the boot is aborted, so a Seed or sign-in still running can't write through it. A Seed that copies with `createDocker`'s `cloneDb` or `pipeDump`, or runs a container of its own, isn't gated by it: it should check `signal` before each step.
  - A teardown doesn't wait for a Docker call already running, such as a pull: the aborted boot stops at its next step once that call returns.
  - A `docker run`, or a `docker exec` query, that had already started can, rarely, still land in the next session's pane of the same role.

### Effect wrappers

**`github`.** The core calls only these, so anything that has them will do:
- `listOpenPrs()` → `[{ number, title, headSha, headRef, author, authorAssociation, headRepo, headOwner }]`, for the picker;
- `prInfo(num)` → `{ number, headSha, author, authorAssociation, isDraft, headRepo, headOwner }`, or without it `prHead(num)` → `headSha`, for `/api/build-status`;
- `postComment(num, body)` → the comment's URL, and `setQaLabel(num, label)`, for the verdict.

`adapters/build-worktree` also needs `prInfo` and `authorPermission(login)`. `createGithub(options)` makes one on GitHub's REST API:

| Option | Default | |
|---|---|---|
| `token` | *(required)* | every call but the package listing ([Tokens](#tokens)) |
| `repo` | *(required)* | `owner/name` |
| `qaLabels` | `['qa-approved', 'qa-changes-requested']` | the accept and reject labels, `[cfg.verdictLabels.accept, cfg.verdictLabels.reject]`: `setQaLabel` adds one and removes the other |
| `packagesToken` | `token` | the GHCR package version listing only (`cfg.ghcrToken`) |
| `packageName` | `null` | the container package the GHCR helpers read; they throw without it |
| `rcTagPattern` | `/-rc\.\d+$/` | which tags `latestRcTag()` counts as release candidates |
| `previewWorkflow` | `'pr-preview.yml'` | the workflow `dispatchPreviewBuild(num)` runs, with the input `pr`, and whose runs `findPreviewRun(num)` and `awaitPreviewImage` read |
| `previewRef` | `'main'` | the ref that workflow is dispatched on |
| `fetchFn` | `fetch` | |

- `listOpenPrs()` returns at most the 50 most recently opened PRs: it reads one page.
- `headRepo` (`owner/name`) and `headOwner` are `null` when the head repository was deleted.
- `authorPermission(login)` returns the login's `admin`, `write`, `read` or `none` permission on the repo, and throws on a non-2xx response. `author_association` alone is no access check: `COLLABORATOR` includes read-only outside collaborators.
- The GHCR and preview-build helpers are for a BuildConvention that runs CI-built images: `ghcrTagExists(tag)`, `latestRcTag()`, `listPrImageTags()`, `awaitPreviewImage(num, sha, { timeoutMs, pollMs, signal, migrate, onRun })`, `dispatchPreviewBuild(num)` and `findPreviewRun(num)`. They read a package that the token's own user owns, not an organization's.
- `awaitPreviewImage` polls every `pollMs` (15000) for up to `timeoutMs` (900000) for the tag `pr-<num>-<the sha's first 12 characters>`, and with `migrate: true` for its `migrate-<tag>` companion too, then resolves with the tag.
  - **The dispatched run.** The first wait for a PR that starts after this client's `dispatchPreviewBuild(num)` resolves also looks up the run that dispatch started, on each poll that misses a tag. The wait claims the dispatch as it starts, so the dispatch arms no other wait. If that run completes with any conclusion but `success`, the wait rejects at once with `preview build failed (conclusion: <conclusion>): <run url>`, and the error carries the run as `err.run`. A `success` keeps the wait polling, since GHCR can lag the run.
  - **Which run is the dispatch's.** Only `workflow_dispatch` runs created in or after the second the dispatch was accepted count, so a run created in an earlier second never does. The time comes from the dispatch response's `Date` header (GitHub's clock), else the local clock. Of those runs, the dispatch's is the earliest whose `run-name` names the PR. Failing that, it is the only one, if that run has no `run-name`, since its title is then just the workflow's name. A workflow whose `run-name` holds the PR number, such as `run-name: Preview #${{ inputs.pr }}`, lets the run be told apart even when other dispatches run at the same time.
  - **Otherwise it just polls GHCR.** That happens while the run can't be told apart, after a failed lookup, and in every other wait for the PR, such as one for a build this client didn't dispatch.
  - **`onRun(run)`** hears the run, in `findPreviewRun`'s shape `{url, status, conclusion, startedAt}`, each time the run taken for the dispatch's changes, or its status or conclusion does. A throw or rejection in `onRun` is ignored. Pass `onRun` on to the `subscribeBuild` callback as `runUrl`, `runStatus` and `runConclusion`, and `buildRun` follows the run while the wait lasts. Without it, the core still shows a failed run, from `err.run` (see [Build progress](#contracts-between-the-seams)).

**`docker`.** `createDocker({ execFileFn, label, postgres })` runs the `docker` CLI for the Docker Provisioner, and for a Seed that copies databases between containers:

| Option | Default | |
|---|---|---|
| `execFileFn` | *(required)* | `makeExecFileFn()` from `./exec`. Your own must pass `opts.env` on to the child, since `login` and `runPg` put secrets there. It must also reject with docker's stderr in the error's `message` or `stderr`, as `makeExecFileFn` does: that is how the Docker Provisioner tells a pane network that already exists from a real failure |
| `label` | `'qa-conductor-session'` | put on every container and network it creates; `sweepQaContainers()` removes whatever carries it |
| `postgres` | `{ image: 'postgres:16', user: 'qa', password: 'qa', db: 'postgres' }` | the pane database containers; keys you leave out, or set to `undefined`, keep these values. The image's entrypoint must set its database up from `POSTGRES_USER`, `POSTGRES_PASSWORD` and `POSTGRES_DB`, and write `POSTGRES_HOST_AUTH_METHOD` into `pg_hba.conf`, as the official `postgres` image's does. An image whose data directory is already initialised ignores them all, and keeps its own password and `pg_hba.conf`: set the provisioner's `postgres.password` to that password, which both panes then share. If that `pg_hba.conf`, or the entrypoint, lets TCP connections in without a password (`trust`), the panes' passwords protect nothing |

`runPg(name, network, { password })` starts a database container, with `password` as its superuser's. `postgres.password` is only the default for a call that passes none: the Docker Provisioner always passes its own. The password reaches `docker run` through the CLI's environment (a bare `-e POSTGRES_PASSWORD`), never its argv, which other local users can read. A password that is empty or not a string throws.

It also passes `-e POSTGRES_HOST_AUTH_METHOD=md5`. That overrides an image's own `ENV`, which may say `trust` (as `cimg/postgres`'s does), and the official entrypoint writes it into `pg_hba.conf` for TCP connections. `md5` uses SCRAM where the stored password is SCRAM, as it is by default from postgres 14 on.

Its members are `run(argv)`, `login(user, token)` (to `ghcr.io`, with the token in the environment, never in argv), `imagePresent`, `ensureImage(image, { retries, relogin })`, `ensurePgImage(opts)` (the same, for `postgres.image`), `runPg`, `waitHealthyPg`, `createDatabase`, `pipeDump(from, to, db)` and `cloneDb(from, to, db)` (a host-side `pg_dump | psql` between two containers), `runMigrate`, `runApp`, `waitHealthyApp`, `psql`, `rmForce` and `rmNetwork` (which reject unless docker says only that what they remove is already gone), `createNetwork`, `rmLabelledNetwork(name)` (only a network of exactly that name that carries `label`), `sweepQaContainers`, `inspectImageOf`, `logsTail`, and for the isolation probe `runtime()` (`{version, os, osError}`, from `docker version` and `docker info`; a failing `info` leaves `os` null and its error in `osError`), `endpoint()` (the current context's daemon endpoint), `networkGateways(name)`, `containerAddresses(name)` (IPv4 and IPv6) and `runProbe(name, network, script, args, { timeoutMs, signal })` (default 30 s, then `SIGKILL`; `signal` stops it too). The module also exports `errorLine(err)`: the first line of a docker CLI failure that says something of it, past the podman-docker shim's banner and Podman's logger warnings. `runPg`, `runMigrate` and `runApp` run their containers with `--cap-drop NET_RAW`. `login`, `createDatabase`, `pipeDump`, `cloneDb`, `logsTail` and `runProbe` throw on a name that isn't letters, digits, `_` and `-`.

**`exec`.** `makeExecFileFn({ maxBuffer })` returns an `execFileFn(cmd, args, opts)` that runs `execFile` with `maxBuffer` (default 64 MB, which `opts` can override) and resolves `{ stdout }`. It rejects with an Error whose message is `<cmd> <first arg>: <execFile's message>`, then, on the next line, up to 2000 characters of stderr. The original error is its `cause`, and it also carries the whole `stdout` and `stderr`, the exit `code`, and `killed` and `signal`, so a caller that set a `timeout` can tell a child killed for it. A call aborted through `opts.signal` rejects with the name `AbortError`.

### Exposure (optional)

An Exposure adapter publishes the conductor's three servers on a front door, such as `tailscale serve`, and reports when they drift. It is optional, and **the core never constructs one**: a platform builds it and passes it as `adapters.exposure`, as it does the other adapters. Only a gated conductor may have one: in none mode, `startConductor` throws `adapters.exposure needs QA_EXPOSURE=tailscale: an ungated conductor must not publish itself`.

```js
import { createTailscaleExposure } from '@critical-labs/qa-conductor/adapters/exposure-tailscale'
import { makeExecFileFn } from '@critical-labs/qa-conductor/exec'

const conductor = startConductor({
  cfg,                                                  // in tailscale mode
  github, fsx, readBaseEnv,
  adapters: { provisioner, build, seed, envTransform, auth, exposure: createTailscaleExposure({ execFileFn: makeExecFileFn() }) },
})
const state = await conductor.exposure.ready          // { mode, managed, ok, checkedAt, drift, added, error }
```

**The reconcile loop.** With an adapter, the conductor owns its mounts:
- It reconciles once all three servers listen, so the targets are the bound ports, then every `QA_EXPOSURE_INTERVAL_MINUTES` (`cfg.exposureIntervalMinutes`, default 5) on an `unref()`ed timer. Each pass derives the mounts afresh with `mountsFor`, since `cfg.paneOrigins` may be assigned after start, then runs `reconcileExposure`.
- One pass runs at a time. A tick while a pass is still running, on a hung CLI say, starts nothing, so CLI processes never stack.
- Once `stop()` or `shutdown()` begins, no pass runs and the timer is cleared. Neither waits for a pass in flight. Nothing ever removes a mount, so after a stop the front door answers `502` until the conductor is back.
- Nothing a pass does takes the conductor down. Each mount it writes is logged as `[qa] exposure mounted <port><path> -> <target>`, or `restored` when this conductor had it in place before. `[qa] exposure failed: …`, `[qa] exposure drift remains: <port><path>, …` and `[qa] exposure ok` are logged only when they change.
- `GET /api/exposure` and `conductor.exposure.state()` report the last pass as `{ mode, managed, ok, checkedAt, drift, added, error }`. Neither calls the front door. The mounts in `drift` and `added` are copied from what the adapter returned, keeping only the Mount type's values: a field that isn't a string (for `port`, an integer), such as a `URL` object as the `target`, is reported as `null`.
- So a deploy needn't touch the mounts: the restarted conductor's first pass restores any that are missing or wrong.

In tailscale mode without an adapter, the mounts are someone else's, such as a deploy script's: startup logs `[qa] exposure: tailscale serve mounts are managed outside the conductor`, and `/api/exposure` reports `managed: false`. In none mode it reports `managed: false` too.

To run a pass yourself, outside a conductor, use the [expose CLI](#expose-cli) from a shell, or from code:

```js
import { mountsFor, reconcileExposure } from '@critical-labs/qa-conductor/exposure'

const exposure = createTailscaleExposure({ execFileFn: makeExecFileFn() })
const result = await reconcileExposure(exposure, mountsFor(cfg), { checkOnly: true })   // { ok, checkedAt, drift, added, error }
```

The contract:
- **`Mount = { name, host, port, path, target }`**, one each for `harness`, `base` and `pr`.
  - `host` and `port` are the mount's public side: the hostname and port of its own origin (`cfg.harnessOrigin`, or the pane's in `cfg.paneOrigins`). A port-less https origin means `443`.
  - **`host` is not `cfg.host`.** `cfg.host` is the address the conductor binds, and only `target` uses it.
  - `path` is `/qa` for the harness and `/` for each pane.
  - `target` is `http://<cfg.host>:<listen port>`, with brackets for IPv6.
- **`Drift = { mount, actual }`**: `actual` is the proxy target the front door serves at that mount over https now, or `null` when there is none: nothing at that path, no https on the port, or a handler that isn't a proxy. A mount also drifts once for each other handler that takes some of its requests, and `actual` then names that handler, as `<path> -> <target>` or `<path> (not a proxy)`.
- **`ensure(mounts) → Promise<{ added: Mount[], ok: Mount[] }>`** creates the missing or mismatched mounts, and only those: `added` lists the mounts it wrote, `ok` the ones already in place. **`check(mounts) → Promise<{ ok: boolean, drift: Drift[] }>`** changes nothing. Either rejects on failure. An `ensure` that fails part way may list the mounts it did write on its error, as `added`.
- **An adapter owns exactly the `(port, path)` pairs it is given**, and never touches another handler.

`mountsFor(cfg, { ports = cfg.ports })` derives the mounts from the origins viewers open, so the URL a viewer sees and the mount behind it can't disagree. Pass the bound ports when `cfg.ports` holds `0`. It throws on a layout no front door can publish:
- no harness origin;
- a missing or unparseable pane origin;
- an origin that isn't https, or is on port `0`;
- two mounts on one port, which would share an origin;
- a listen port that isn't an integer from 1 to 65535.

`reconcileExposure(exposure, mounts, { checkOnly })` runs `ensure` then `check`, or only `check` with `checkOnly`. It resolves `{ ok, checkedAt, drift, added, error }` and never rejects, whatever the adapter throws: a failure comes back as `ok: false` with its message in `error`, and `added` still lists what `ensure` wrote. It doesn't check that the targets are gated, so to publish a conductor from outside it, call `runExpose`, which does.

`runExpose({ cfg, exposure, checkOnly = false, log = console, fetchFn, probeTimeoutMs = 5000 })` is the [expose CLI](#expose-cli)'s pass: `mountsFor(cfg)` then `reconcileExposure`, printed through `log`, resolving the CLI's exit code (`0`, `1` or `2`). A `cfg` without `exposure` or `harnessOrigin` resolves both as `startConductor` does. Without `checkOnly`, it first asks each target whether it is a gated conductor, and writes nothing unless all three are (see the [expose CLI](#expose-cli)). It gives each target up to `probeTimeoutMs`, a whole number of milliseconds from 1 to 2147483647 (anything else returns `2`).
- **`fetchFn`** takes fetch's arguments and must return fetch's `status`, `headers.get` and `body.cancel`. It defaults to plain HTTP over `node:http`, because `fetch` refuses some ports (`6000` and `10080`, among others) that a conductor may listen on, and may read a proxy from the environment.
- **The conductor's own loop doesn't ask:** it publishes only itself, and only in tailscale mode.

**Built in: `adapters/exposure-tailscale`.** `createTailscaleExposure({ execFileFn, bin = 'tailscale', socket = null, timeoutMs = 30000 })` drives `tailscale serve` on the host it runs on:
- `check` runs `tailscale serve status --json`. A mount is in place when its port serves https and its path proxies to its target (one trailing `/` ignored). It reads the status entry for the mount's `host:port`, else the first entry on that port.
- tailscaled hands a request to the deepest handler path that holds it, so a handler under a mount's path takes some of its requests: `/qa/` or `/qa/api` beside the harness's `/qa`, or any other path on a pane's port. `check` reports each one that doesn't proxy to the mount's target as drift.
- `ensure` reads the same status, then runs `tailscale serve --bg --https=<port> [--set-path=<path>] <target>` for each mount whose own handler is missing or points elsewhere, and only those. `--set-path` is left out for `/`. A handler that shadows a mount stays drift until you remove it: `ensure` never writes or removes it. A mount that fails doesn't stop the others, and `ensure` then rejects, naming each failure, with the mounts it did write as the error's `added`.
- Every call goes through `execFileFn` (`makeExecFileFn()` from `./exec`) with a `timeoutMs` timeout. With `socket` set, `--socket=<socket>` comes before the subcommand, for a CLI whose daemon's socket is somewhere else, such as one mounted into a container.
- `bin` is the CLI to run, and it should be no older than the daemon. On macOS, the `tailscale` on `PATH` may lag behind the app's daemon: use the app's bundled CLI, `/Applications/Tailscale.app/Contents/MacOS/Tailscale`.

**What it never touches.** It never runs `tailscale serve reset` or `off`, so it never removes a handler, and it never changes one at a `(port, path)` it wasn't given:
- Another app's `/` handler on the harness's port stays beside the harness's `/qa`, since `tailscale serve` keeps a port's other paths. Give the harness a port of its own all the same: that app's pages would share the harness origin, so the panes and the harness API would take them for the harness.
- The flip side: a declared `(port, path)` is the conductor's. A pane origin on a port where another app serves `/` replaces that app's handler.
- **A changed origin or port leaves the old handler behind.** It keeps proxying to the conductor until you remove it with `tailscale serve --https=<old port> [--set-path=<path>] off`. Until then, browsers that reach the harness through it get `403 not the harness origin` from its API (see [Same-origin API](#security)), but the old URL still answers.

## Configuration

`loadConfig(path, { defaults, required = [] })` reads an env file, `.env.qa` by convention, into `cfg`. File values override `defaults`, and the raw map is returned as `cfg.env` so a platform can read its own keys. `required` lists extra keys the platform insists on (a platform may re-require `QA_OPERATOR_EMAIL`, say); it can't waive the core's.

### The env file

- One `KEY=value` per line. Blank lines, lines that start with `#` and lines with no `=` are skipped. Spaces around the key and the value are dropped, and a later line wins.
- A value in a matching pair of double or single quotes loses them. Nothing is unescaped or expanded, quoted or not: `$HOME` stays `$HOME`.
- No `export`: `export KEY=value` sets a key named `export KEY`, which nothing reads.
- No comment after a value: a `#` after a space or a tab in an unquoted value throws, naming the file, the line and the key, and so does a `#` after a quoted value's closing quote (`KEY="value" # note`), with a space between or not. Put the comment on a line of its own. A value with a space or a tab before a `#` needs quotes (`KEY="a # b"` is `a # b`), and inside them a `#` mustn't follow the quote character, which would read as the closing quote.
- **It holds a token.** Keep it out of git (`echo .env.qa >> .gitignore`) and readable by you alone: create it with `(umask 077 && touch .env.qa)`, or `chmod 600` it.

### Sample `.env.qa` files

On one machine, with everything on loopback and no identity gate:

```ini
GITHUB_QA_TOKEN=<token>
QA_REPO=acme/widget
# With both pane origins set, QA_PUBLIC_HOST isn't needed.
# The harness is at http://127.0.0.1:3100/qa/.
QA_BASE_ORIGIN=http://127.0.0.1:3101
QA_PR_ORIGIN=http://127.0.0.1:3102
```

On a tailnet, behind `tailscale serve` on the conductor's machine, `qa-box.tail1234.ts.net`:

```ini
GITHUB_QA_TOKEN=<token>
QA_REPO=acme/widget
# The harness is at https://qa-box.tail1234.ts.net:8444/qa/, the panes at :8443 and :10000.
QA_PUBLIC_HOST=qa-box.tail1234.ts.net
# Who may open them: Tailscale logins, as tailscale whois shows them.
QA_ALLOWED_LOGINS=alice@github,bob@example.com
```

That layout is tailscale mode: every server listens on loopback and answers only those logins (see [Security](#security)). The platform's [Exposure adapter](#exposure-optional) mounts the three servers on `tailscale serve`, or you do, with `tailscale serve --bg --https=8444 --set-path=/qa http://127.0.0.1:3100`, `tailscale serve --bg --https=8443 http://127.0.0.1:3101` and `tailscale serve --bg --https=10000 http://127.0.0.1:3102`.

### Tokens

`GITHUB_QA_TOKEN` reads the open PRs and posts each verdict, as the token's owner. Use a fine-grained personal access token with:
- **Repository access:** only the repository under QA.
- **Pull requests: read.** The PR list, and each PR's head and author.
- **Issues: read and write.** The verdict comment and label.
- **Metadata: read**, which GitHub grants with any other permission. It also covers the author's permission, which the trust gate checks.

Some built-ins need more than this token:
- `adapters/build-worktree` fetches with plain `git` over https, so a private repository needs a git credential helper that can read it.
- `createGithub`'s GHCR helpers list container package versions, which a fine-grained token can't. Set `QA_GHCR_TOKEN` to a classic token with `read:packages`, and pass `createGithub` the `packageName`.
- A BuildConvention that dispatches preview builds with `createGithub`'s `dispatchPreviewBuild`, and reads their runs with `findPreviewRun` or `awaitPreviewImage`, needs Actions: read and write.

### Keys

| Key | `cfg` | Default | |
|---|---|---|---|
| `GITHUB_QA_TOKEN` | `githubToken` | *(required)* | PR list, head and trust lookups, verdict comment + label ([Tokens](#tokens)) |
| `QA_GHCR_TOKEN` | `ghcrToken` | `GITHUB_QA_TOKEN` | for `createGithub({ packagesToken })`, with its `packageName`: the GHCR package version listing, which a fine-grained token can't call (use a classic PAT with `read:packages`), and a platform's registry login |
| `QA_REPO` | `repo` | *(required)* | `owner/name` |
| `QA_OPERATOR_EMAIL` | `operatorEmail` | `null` | the reviewer, passed to `establishSession` |
| `QA_PUBLIC_HOST` | `publicHost` | *(required unless both pane origins are set)*, else `null` | default host for the harness and pane origins; always an allowed `Host` |
| `QA_BIND_HOST` | `host` | `127.0.0.1` | the address all three servers listen on (`[::1]` is read as `::1`); must be loopback in tailscale mode (see [Security](#security)) |
| `QA_ALLOWED_HOSTS` | `allowedHosts` | *(none)* | extra comma-separated hostnames (no ports) the servers answer to |
| `QA_EXPOSURE` | `exposure` | `tailscale` if any address the conductor answers to or listens on is off loopback (see below), else `none` | `tailscale`: fronted by `tailscale serve --https` on this host, so the identity gate is on and the bind must be loopback. `none`: no gate (0.2's behaviour), for loopback or another authenticating front door. Anything else throws |
| `QA_ALLOWED_LOGINS` | `allowedLogins` | *(none)* | comma-separated Tailscale logins (as `tailscale whois` shows them, e.g. `alice@github`) allowed in when the gate is on; trimmed and lowercased. Required in tailscale mode |
| `QA_EXPOSURE_INTERVAL_MINUTES` | `exposureIntervalMinutes` | `5` | minutes between [exposure](#exposure-optional) reconcile passes, when the platform passes an Exposure adapter. Above `0` and at most `35791`, the longest a timer can wait (above it, Node would fire every millisecond); fractions are fine |
| `QA_TAILSCALE_BIN` | *(only `cfg.env`)* | `tailscale` | the tailscale CLI the [expose CLI](#expose-cli) and this repository's self-QA run, for an env file they read. On macOS, use the app's `/Applications/Tailscale.app/Contents/MacOS/Tailscale` when the one on `PATH` is older than the daemon. The conductor never reads it: a platform passes `bin` to `createTailscaleExposure` |
| `QA_HARNESS_PORT` / `QA_BASE_PROXY_PORT` / `QA_PR_PROXY_PORT` | `ports.harness` / `ports.base` / `ports.pr` | `3100` / `3101` / `3102` | listen ports |
| `QA_HARNESS_ORIGIN` | `harnessOrigin` | `https://<QA_PUBLIC_HOST>:8444`, else `http://<QA_BIND_HOST>:<QA_HARNESS_PORT>` on a loopback bind | the origin viewers open the harness at (any path dropped); the page is under `/qa/`. Required on a non-loopback bind with no public host. On port `0` the conductor derives it from the bound port. Not an IPv6 literal: on a `::1` bind, set `http://localhost:<port>` |
| `QA_BASE_ORIGIN` / `QA_PR_ORIGIN` | `paneOrigins.base` / `paneOrigins.pr` | `https://<QA_PUBLIC_HOST>:8443` / `https://<QA_PUBLIC_HOST>:10000` | the origins viewers reach the panes at |
| `QA_FRAME_ANCESTORS` | `frameAncestors` | *(none)* | extra comma-separated origins allowed to frame the panes, for a harness nested in a pane (self-QA's inner demos). CSP only: they pass no `Referer` check, and the bridge never talks to them |
| `QA_REQUIRE_ISOLATION` | `requireIsolation` | `0` | `1` (or `true`): refuse a session whose PR pane isn't `isolated` from the base pane, before the PR's code runs, a BuildConvention's install step included, as long as everything before the check runs none ([Isolation verdicts](#isolation-verdicts)). `0`, `false` or empty: report the verdict only. Anything else throws |
| `QA_FORWARD_CLIENT_COOKIES` | `forwardClientCookies` | *(none)* | comma-separated names of the browser's own cookies the pane proxies pass to the pane apps, beside each pane's jar, whose value wins on a name both have. Unset, the apps get only the jar's cookies (see [Security](#security)). Each must be a cookie name (an RFC 6265 token); `*` and other wildcards throw. A single quote is part of a name, so quote the whole list or nothing, never each name: `'a','b'` names `a'` and `'b`. Any page on the panes' hostname can set these cookies, the other pane's scripts included, so a value that isn't an RFC 6265 cookie-value (one with a space, a comma, a backslash or a stray double quote) isn't passed. On one hostname both pane apps get the browser's one value of each, so name only cookies both panes may share, such as a preference, never a session. A name starting with `qa-` (in any case, after `__Host-` or `__Secure-` too) throws: those are the conductor's own pane cookies |
| `QA_LABEL_ACCEPT` / `QA_LABEL_REJECT` | `verdictLabels.accept` / `verdictLabels.reject` | `qa-approved` / `qa-changes-requested` | verdict label pair |
| `QA_IDLE_MINUTES` | `idleMinutes` | `30` | idle sessions are torn down |

Every origin key must be an http(s) URL with a plain hostname. It is normalized to an origin (lowercased, a default port and any path dropped), and anything else throws. An `http:` harness or pane origin must be loopback (`127.0.0.0/8`, `::1`, `localhost`): browsers send the `Sec-Fetch-*` headers the request guards rely on only to https and loopback origins (see [Security](#security)). The harness and the two panes must be three different origins: a page that is same-origin with another could act for the reviewer there.

Unset, `QA_EXPOSURE` is `none` only when all of these are loopback, and `tailscale` otherwise: the harness origin (as derived above; when none can be derived, on a loopback bind on port `0` with no `QA_HARNESS_ORIGIN` or `QA_PUBLIC_HOST`, it adds nothing), both pane origins, `QA_PUBLIC_HOST` and every `QA_ALLOWED_HOSTS` entry (both widen the `Host` allowlist), and `QA_BIND_HOST`. So a non-loopback bind alone makes the mode `tailscale`, which then refuses that bind: behind another authenticating front door, set `QA_EXPOSURE=none`. In tailscale mode, `loadConfig` throws on a non-loopback `QA_BIND_HOST` and on an empty `QA_ALLOWED_LOGINS`, and each error says why the mode is `tailscale`.

### A `cfg` built in code

A platform that builds `cfg` in code instead of with `loadConfig` must set `ports`, `paneOrigins`, `verdictLabels` and `idleMinutes`, in the shapes the table's `cfg` column shows. Without `idleMinutes`, the idle reaper silently never ends a session. The core never reads `githubToken`, `ghcrToken`, `repo` or `env`: they are for the platform's own `createGithub` and adapters. `readBaseEnv` is optional too (see [Use](#use)).

It can leave out `operatorEmail`, `publicHost`, `host` (loopback is the default), `allowedHosts`, `harnessOrigin` (derived as above), `frameAncestors`, `forwardClientCookies` (none: `false` or an array of cookie names), `exposure`, `allowedLogins`, `exposureIntervalMinutes` (`5`) and `requireIsolation` (`false`). Without `exposure`, `startConductor` resolves the mode as `loadConfig` does, with `defaultExposure({ harnessOrigin, paneOrigins, publicHost, allowedHosts, host })` from `./config`, where a missing or unparseable pane origin counts as off loopback. The mode is fixed at start, so a `cfg` whose non-loopback origins are assigned after start must set `exposure` itself. `startConductor` refuses an unknown `exposure`, a `host` in brackets (write `::1`, not `[::1]`), tailscale mode on a non-loopback `host`, a `harnessOrigin` or `frameAncestors` entry that isn't an http(s) origin, an `http:` harness origin or pane origin (set at start) whose host isn't loopback, a harness origin equal to a pane origin, an `exposureIntervalMinutes` that isn't a number above `0` and at most `35791`, a `forwardClientCookies` that isn't `false` or an array of cookie names, or that names one starting with `qa-`, a pane origin (set at start) on another hostname than the harness origin (known at start), and an `adapters.exposure` in none mode. Two equal pane origins count as placeholders and aren't checked against the harness origin until the harness enters a pane, when `/api/pane-entry` answers `409` for one on another hostname. Startup logs whether the gate is on and, for a defaulted mode, what made it `tailscale`. In tailscale mode with no `allowedLogins` it logs an error, and every request is refused. The core reads `cfg.paneOrigins` per request, so it may be assigned once the proxies are listening.

## HTTP API (harness port)

| | |
|---|---|
| `GET /` | harness UI |
| `GET /api/state` | session status, tags, `buildRun: {url, status, conclusion, message}`, pane login URLs + origins, `harnessOrigin`, `isolation: {verdict, reasons, checkedAt}` ([Isolation verdicts](#isolation-verdicts); `null` until known for this session), `requireIsolation`, `data: {available}` (whether there is an inspector) |
| `GET /api/prs` | open PRs with build readiness (`imageStatus`, `runUrl`, `reason`) |
| `GET /api/build-status?pr=N` | `{pr, status, exists, runUrl}`, plus `reason` when `status` is `blocked` |
| `GET /api/exposure` | the last [exposure](#exposure-optional) reconcile pass: `{mode, managed, ok, checkedAt, drift, added, error}`. Read-only: it never calls the front door. With no adapter, `managed` is `false` and `ok` and `checkedAt` are `null` |
| `GET /api/progress` | server-sent boot progress (`step`, `build`, `isolation` with `verdict` and `reasons`, `ready` with `isolation`, `error` with `logTail`, `torn-down`) |
| `POST /api/session` `{pr, takeover?}` | boot a session (one at a time; `takeover` replaces the current one) |
| `GET /api/verdict/preview?verdict=accept\|reject&notes=` | the comment + labels that would be posted |
| `POST /api/verdict` `{verdict, notes}` | post the verdict comment and set the label |
| `POST /api/teardown` `{}` | tear down the session (cancels an in-flight boot) |
| `POST /api/enrol` `{invite?}` | `{token}` for a new browser: while no PR code can be running, or with an invite's ticket at any time. The only `/api/*` route that needs no token |
| `POST /api/invite` `{}` | `{url, expiresAt}`: a link to the harness that enrols one more browser, once, within ten minutes. `409` with no harness origin to link to |
| `GET /api/actions?after=N&limit=M` | the ready session's [action log](#security): its requests and marks after sequence number `N` (default `0`), `{active, log, seq, more, requests, marks, dropped, refused, marksDropped}`. One sequence numbers requests and marks alike, in the order they were recorded (a request when it ended). A read gives the next of them, at most `M` together (default and most 2,000), in that order; `more` says there are others, and `seq` is where to read on from. So a reader that reads on until `more` is `false` has had everything still kept, once: `seq` is dense, so a gap in it means items were dropped. `log` names the log: a new session's starts its `seq` again, so when `log` changes, or `active` is `false`, discard what you have and read from `0`. A request is `{seq, pane, at, method, path, status, ms, bytes, aborted}`, and a mark `{seq, pane, at, type}`. **Grouping is the reader's:** a request most likely came from, of the marks no more than 300 ms after it started (`at`), its own pane's nearest within 300 ms either side, else the nearest; the earlier (then the lower `seq`) on a tie; none when no mark is that early (the landing). A mark can come after the requests it set off, so a reader groups again as marks come. Each pane keeps its last 5,000 requests, counting those `dropped`, and its last 8,000 marks; `marksDropped` counts the marks refused or no longer kept. `refused` counts what its guards refused, by reason. With no session ready, `active` is `false`, `log` is `null` and the lists are empty. Reading it is no activity |
| `GET /api/data` | the ready session's [data checks](#data-checks): `{available, active, trust, baselineAt, baselines, rebaselined, comparedAt, errors, problems, problemsCount, boot, session}`. `available` is `false` with no inspector, and `active` is `false` with no session ready. `baselines` is each pane's baseline time. `boot` and `session` are each `{complete, aligned, flags, flagsCount, base, pr, divergence}`, or `null` before a snapshot (`boot`: before the ready read). `base` and `pr` are each pane's diff, `null` for a pane with none; a span with neither has a red `unreadable` flag. `aligned` is `false` when the panes' windows differ (one's ready read failed); `complete` is `false` in either case. **The answer is bounded, at about 4 MB (in bytes, as UTF-8):** a diff lists at most 1,000 collections, with `collectionsCount`: those with a red flag first (in the order of their first flag, so the base pane's collections, and what lost data, come first), then those with changed rows, then those with an amber flag, then any other change, so a PR's padding, flagged or not, can't push a seeded one out. Each has 50 rows of each kind, 50 dropped and 50 added fields, with whole `counts`; a divergence has 50 changes a collection (`changesCount`), ranked the same way. A span has at most 500 flags, red first in the engine's order, with whole `flagsCount` (`{red, amber}`); past 20 red `unverified` flags of named collections, the rest are one flag in their place, `{collection: null, kind: 'unverified', folded: true, collections, names}`. Each pane has at most 50 `problems`, with `problemsCount`, and an error's text is cut at 500 characters. The flags first, then the PR pane's diff, the divergence and the base pane's diff by rank across all three (every list's red-flagged collections, then every list's changed ones, and so on), each collection's own entry (its name, key and counts) included, share 2 MB a span; a collection the budget cut says `cut: true`, and so does a diff or divergence whose listing it stopped. **Its time isn't bounded:** it is built on the event loop that serves the panes, and a PR's data within the limits can hold that loop for seconds ([Known limits](#known-limits)). An answer still too big to build is built without its lists: each span then has `unlisted: true`, no `base`, `pr` or `divergence`, a red `unlisted` flag and its first 20 red flags (in the engine's order, so what loses data in the base pane's collections first), and `flagsCount` counts the `unlisted` flag too. `errors` says, per pane, why one has no data: `boot` for the open, seeded and ready reads, each reason kept, and `session` for the latest read. Values are masked where they may be secret. The answer is built once for each state and trust, and one that fails to build even without its lists fails again at once until the state changes. `no-store`, and reading it is no activity |
| `POST /api/data/snapshot` `{rebaseline?}` | Snapshot now, or with `rebaseline: true` make now the baseline; answers as `GET /api/data`. Concurrent calls of one kind share a snapshot; one of the other kind meanwhile is `409`. `400` for a `rebaseline` that isn't `true` or `false`, `409` with no inspector or no session ready, and when the session ends while the snapshot runs. Activity |
| `POST /api/actions/mark` `{pane, type}` | `{recorded}`: a mark for an action a pane reported, `pane` `base` or `pr`, `type` `click`, `submit`, `change` or `enter` (`400` for anything else). At most one of each kind a pane every 100 ms, from a budget of 2,000 a pane that refills one a second: `recorded` is `false` past them, counted per pane in `marksDropped`. `409` with no session ready. No activity |
| `POST /api/pane-entry` `{role, to?}` | `{url}`: a one-time link, for one minute, that loads `role`'s pane (`base` or `pr`) at `to`, a path or URL on that pane (default `/`), and sets its pane cookie on the way. `400` for another role, or a `to` that leads off the pane; `409` while the pane has no origin, or one on another hostname than the harness's |

Every path also answers under a `/qa` prefix. In tailscale mode, a request to any of the three ports without an allowed `Tailscale-User-Login` gets `403` before anything else, a plain `curl` from the host included: a script on the host can't read `/api/exposure`, so it runs the [expose CLI](#expose-cli) with `--check` instead. Every `/api/*` request must come from the harness page itself, and a browser must reach it at the harness origin's host and port (`403`, see [Security](#security)). Every one but `POST /api/enrol` must then carry an enrolled browser's token, in `X-QA-Cap` (or, for `GET /api/progress` only, as `?cap=`), else it gets `403` with `X-QA-Refusal: capability`; so must every request to a pane, in its pane cookie. A script on the host enrols like a browser, while no session runs. POSTs must be `application/json` (`415`), with a body of at most 64 KiB (`413`, and the connection closes), and a request to any of the three ports with an unrecognised `Host` gets `421`. A request target the harness can't parse as a URL gets `400`, and once `shutdown()` has begun every harness write gets `503`. While no session is ready, the pane proxies answer an enrolled browser `503`. Each pane also answers `GET /__qa/enter?t=<ticket>`, the link `/api/pane-entry` gives, and `GET /__qa/bridge.js`, the mirror bridge; the pane app never sees either path.

## Expose CLI

```sh
npx qa-conductor-expose --check   # report drift on the conductor's tailscale serve mounts; change nothing
npx qa-conductor-expose           # put any missing or wrong mount back now
npm run expose -- --check        # in this repo: self-QA's .env.qa, through self-QA's loader
```

`qa-conductor-expose` runs one [exposure](#exposure-optional) pass from a shell, through the built-in tailscale adapter. **It is a tool for operators and debugging.** The conductor's reconcile loop owns the mounts: it sets them once its servers listen and restores them every `QA_EXPOSURE_INTERVAL_MINUTES`. So a deploy only restarts the conductor, and runs neither this CLI nor `tailscale serve`. Use the CLI to see drift, or to restore a mount now instead of at the next pass.

**A plain run publishes only a gated conductor.** Before it writes anything, it sends each target a request over loopback with no `Tailscale-User-Login`: `GET /qa/api/state` on the harness port and `GET /` on each pane port.
- **What passes:** a conductor in tailscale mode answers each with its identity gate's `403`, marked `X-QA-Refusal: identity`. The CLI checks that header, not the body text.
- **What fails:** a target that answers anything else, such as a conductor in none mode, the demo, another server, another `403`, or a redirect (which isn't followed). So does one that doesn't answer within 5 seconds, or a port where nothing listens.
- **All or nothing:** if any target fails, the CLI writes no mount, runs no `tailscale` command and exits `2`, with a line for each failing target and one saying what to do:

```
qa exposure: 127.0.0.1:3101 (base) is not a gated conductor (got 403 without X-QA-Refusal: identity); refusing to publish it
qa exposure: 127.0.0.1:3102 (pr) is not a gated conductor (nothing listens there); refusing to publish it
qa exposure: nothing was mounted. Start the conductor in tailscale mode on these ports first, or use --check to only report drift
```

**What the check doesn't cover:**
- **Other processes on this host.** It guards against a wrong env file or a stopped conductor, not against another process on this host, which could answer with the same header.
- **Which conductor, or which role.** It checks that each target is gated, not that the harness port holds a harness or that all three belong to one conductor.
- **Later takeovers.** It holds only at the moment the CLI writes. Neither the CLI nor the conductor ever removes a mount, so once the conductor stops, its mounts publish whatever listens on those loopback ports next, with no identity gate.
- **`--check`.** A `--check` run sends no requests to the targets.

```
qa-conductor-expose [--check] [--env FILE] [--config MODULE[#export]] [--tailscale BIN] [--socket PATH] [--help|-h]
```

- **One code path.** It runs `runExpose({ cfg, exposure, checkOnly, log })` from `./exposure`, which is the conductor loop's own pass: `mountsFor(cfg)` on the configured ports, then `reconcileExposure`, which runs `ensure` then `check` (`check` alone with `--check`). Only the check of the targets above comes first, without `--check`. So the CLI and the loop can't disagree about what should be mounted. Like the loop, it never removes a handler. It targets `cfg.ports`, so a conductor on port `0` can only be mounted by its own loop.
- **`--env FILE`** is the conductor's own env file: by default `$QA_ENV_FILE`, else `./.env.qa`. The CLI loads it with `loadConfig`, as the conductor does, so the file needs `GITHUB_QA_TOKEN` and `QA_REPO` even though exposure ignores them.
- **`--config MODULE[#export]`** loads `cfg` with a platform's own loader instead, for an env file that leans on the platform's `defaults`. It imports `MODULE`, a file path from the working directory, and calls `export` (by default, the default export) with the env file's path. For example, `--config qa/self.mjs#loadSelfQaConfig` reads this repo's self-QA `.env.qa`, and a platform's container can pass its own loader the same way. In this repo, `npm run expose` passes self-QA's loader, since self-QA is the repo's only conductor; a `--config` after `--` overrides it, since the last one wins.
- **`--tailscale BIN`** is the CLI to run: by default `QA_TAILSCALE_BIN` in the env file, else `tailscale` on `PATH`. On macOS, use the app's `/Applications/Tailscale.app/Contents/MacOS/Tailscale` when the one on `PATH` is older than the daemon. **`--socket PATH`** passes `--socket=PATH` before the subcommand, for a daemon whose socket is elsewhere, such as one mounted into a container.
- **`--help`** or **`-h`** prints the usage and exits `0` before loading anything.

It prints a line for each mount it writes (`qa exposure: mounted <port><path> -> <target>`), and one for each mount still wrong (`qa exposure: drift <port><path>: want <target>, have <actual|nothing>`). A handler under a mount's path that takes some of its requests is named as one to remove, since the CLI never removes it. Then it prints any tailscale error, and finally `qa exposure: ok (harness <origin>/qa/)` once all three mounts are in place. In none mode it prints `qa exposure: QA_EXPOSURE=none, nothing to do`, since an ungated conductor must not publish itself. Drift and errors go to stderr, everything else to stdout.

| Exit | |
|---|---|
| `0` | every mount is in place (after writing any that weren't), or `QA_EXPOSURE=none`, or `--help` |
| `1` | drift remains, or tailscale failed |
| `2` | a bad flag or a config that doesn't load, with the usage on stderr; or, as one `qa exposure:` line, a mode, bind host or mount layout the conductor can't publish, such as an unknown `QA_EXPOSURE` from a `--config` loader, tailscale mode on a bind host that isn't loopback, an `http:` origin, two mounts on one port or a listen port `0`; or, without `--check`, a target that isn't a gated conductor, with a line for each and nothing mounted |

## Demo

```sh
npm run demo            # then open http://127.0.0.1:4100/
```

Open it at `127.0.0.1`: the panes trust only the harness origin, so at `localhost` the harness shows a banner and the panes stay blank.

Demo mode runs the real conductor with fixture PRs and fake adapters, so you can try the whole harness with no GitHub, containers or databases. Everything listens on `127.0.0.1`: the harness on `PORT` (default `4100`), and the pane proxies and the two in-process pane apps on free ports. The demo is always ungated (`exposure: 'none'`), whatever its harness origin: it binds loopback, and nested in self-QA it sits behind the outer conductor's gate. It starts idle, so the browser that opens it enrols by itself ([Using the harness](#using-the-harness)), and so does one after a restart. `QA_DEMO_SPEED` scales the fake build and boot delays (default `1`; `0` makes them instant). Ctrl-C (or SIGTERM/SIGHUP) stops it.

- **#101, #102** are built and open in seconds. **#103** is mid-build. **#104** builds, then its app crashes at *starting*, with a log tail. **#105** is refused by the trust gate (its head is in someone else's fork). **#106**'s *Empty cart* deletes the saved carts too, which the [data checks](#data-checks) flag: add something to the cart in both panes, empty it, and take a snapshot.
- The PR pane is visibly different from the base: a new heading, a purple accent and an extra sort control on *Products*. Both panes have several pages, forms and long pages, for trying mirroring.
- Verdicts go to an in-memory GitHub fake and are printed to the console. Nothing leaves the machine.

`demo/` is not published with the package. From code, `startDemo({ port, speed, log, harnessOrigin, frameAncestors })` in `demo/index.mjs` returns `{ stop(), ports }`. Without a `harnessOrigin` the core derives `http://127.0.0.1:<port>`. `QA_HARNESS_ORIGIN` and `QA_FRAME_ANCESTORS` set the last two from `npm run demo`.

## Known limits

- **One page of PRs.** The picker lists at most the 50 most recently opened PRs.
- **Mounts outlive the conductor.** Nothing removes a `tailscale serve` mount, so once the conductor stops, its mounts publish whatever listens on those loopback ports next, with no identity gate. The expose CLI refuses to write a mount for a target that isn't a gated conductor, but nothing stops another process taking the port later ([Expose CLI](#expose-cli)).
- **The panes' pages share the browser's cookies with every app on their hostname**, and can send those apps same-site requests that carry them. Serve the panes on a hostname no other app uses ([Security](#security)).
- **The identity gate keeps out other devices, not PR code** on the same host: a pane process, or a container pane outside native Linux Docker, can send any login. The capability keeps such code out of the harness and the panes, but not everywhere ([Security](#security)):
  - on plain-http loopback, a PR page and the PR app can lift the pane cookie through the browser, since cookies ignore ports, for as long as that session lasts;
  - a process pane runs as you, and can read the token from your browser's profile;
  - PR code that outlives its teardown can enrol once nothing runs.
- **The harness and both panes share one hostname.** The pane cookie needs them on one site, and with no public suffix list to tell which hostnames are, the conductor accepts only one hostname: `startConductor` refuses another layout, even one that is one site, such as `qa.example.com` with `base.example.com`. So in self-QA on a tailnet, each inner demo's panes, on this machine's loopback, no longer load ([CONTRIBUTING.md](CONTRIBUTING.md)).
- **A harness that shares an origin with another app** shares its trust. Give the harness a port of its own.
- **Browsers without Fetch Metadata** are judged by `Origin` alone, which is why an `http:` origin must be loopback.
- **An IPv6-literal harness origin** can't be named in `frame-ancestors`: on a `::1` bind, set `QA_HARNESS_ORIGIN=http://localhost:<port>`, and both pane origins on `localhost`.
- **`X-Forwarded-For` reaches the pane apps**, so PR code sees which tailnet address is viewing.
- **The Docker Provisioner** runs one service per pane, with fixed container names and host ports, and logs in to `ghcr.io` only ([its section](#built-in-adaptersprovisioner-docker-docker-provisioner)). **The GHCR helpers** read packages a user owns, not an organization's.
- **The PR pane can still reach parts of the base pane.**
  - **Each session says which.** Its [isolation verdict](#isolation-verdicts) is `isolated` only when a check found none of these paths, and a base-vs-PR comparison is advisory otherwise.
  - **With the Docker Provisioner,** each pane has its own network and its own database password, so on Docker Engine with its default iptables rules PR code can't reach the base pane's database directly. These gaps remain ([its section](#built-in-adaptersprovisioner-docker-docker-provisioner)):
    - where containers can reach the host's loopback (Docker Desktop, Podman machine, and the Lima-based colima, Lima and Rancher Desktop), PR code can still reach the base pane's app, on its published port. It reaches the base pane's proxy, which signs it in as the operator, and the harness too, but they answer it `403` without an enrolled browser's capability;
    - with a non-loopback `QA_BIND_HOST`, it can reach the harness and the base pane's proxy on any runtime, which answer it the same way;
    - without Docker Engine's default iptables rules (`"iptables": false`, or Podman), it can reach the base pane's containers by address, and over IPv6 on a dual-stack network with `"ip6tables": false` (the default before Docker Engine 27);
    - where the networks don't keep the panes apart, PR code can sign in to the base pane's database when the provisioner's `postgres.password` is set, since both panes use it, or when the image doesn't enforce the password ([`createDocker`'s `postgres.image`](#effect-wrappers)).
  - **With the process Provisioner,** both panes' processes run as your user on one host. So PR code can reach the base pane's database and app on loopback, and its files and processes. Its proxy and the harness answer only with the capability, which PR code can read from your browser's profile.
  - **With either:**
    - **One env:** both panes get the same `readBaseEnv` env, unless the EnvTransform gives each pane its own.
    - **One set of auth contributions:** `envContributions()` runs once per boot, and its values win over the EnvTransform's.
    - **What follows:** the PR pane holds the base app's secrets, and the address of any service the Provisioner doesn't create, such as a cache or a bucket. Through a service both panes use, PR code can change what the base pane reads. Give each pane its own value for every secret and stateful service you can.
    - **The mirror:** while it is on, PR code can drive the base pane through the harness ([Security](#security)).
  - The base pane is what the PR is compared with, so code that changes it, by mistake or on purpose, skews the comparison. The trust gate is still the boundary against PR code ([Security](#security)).
- **Hostile PR data and the conductor's responsiveness.** The data checks' engine runs on the conductor's event loop. PR-controlled data within the limits can stall the panes, the harness and every request for seconds, and for minutes in the worst shapes measured (32 MB of text lines that look like JSON but aren't took about 4 minutes):
  - masking works through the raw data a PR's store holds, not just what is kept: every cell is read, and text that looks like JSON is parsed, before the budget is checked;
  - the data answer (`GET /api/data`) diffs both panes' snapshots, flags them and lists them on each build, once for each state and trust: 200 PR tables of 10,000 rows took about 7 to 9 s a build, and the ready read 18 s;
  - the 32 MB budget counts the kept rows' JSON, not the heap they take: 1,000 collections of 10,000 empty rows, 29 MB of JSON, took about 600 MB of heap for one snapshot, and the data answer keeps several;
  - this is accepted. PR authors have passed the trust gate ([Security](#security)), and a stall shows no masked value and hides no destructive change: it only slows that PR's review. Tearing the session down ends it.
- **Linux and macOS only, and no TypeScript declarations yet** ([Requirements](#requirements)).

## Contributing

To work on qa-conductor itself, read [CONTRIBUTING.md](CONTRIBUTING.md): how to run the tests, the commit style, how to QA a pull request in the conductor's own harness (`npm run qa`), and how a release is cut.

## Reporting a vulnerability

Please report it privately, as [SECURITY.md](SECURITY.md) describes, never with its details in a public issue.

## License

[MIT](LICENSE)
