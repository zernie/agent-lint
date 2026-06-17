# Sandboxing — what's isolated, what's recorded (honestly)

Testing a hook or a third-party plugin means **executing its code with your
privileges**. vigiles confines that under [bubblewrap](https://github.com/containers/bubblewrap)
(`bwrap`) — but it's important to be precise about what that does and doesn't
protect, so you don't trust a boundary that isn't there.

## Tiers (graceful degradation, no Docker)

The sandbox protects the **host** from untrusted code. So the real question is
"is the host already disposable?" — and the answer differs by environment:

| Tier                    | Mechanism                                                                    | When                                                                           |
| ----------------------- | ---------------------------------------------------------------------------- | ------------------------------------------------------------------------------ |
| **A — bubblewrap**      | a fresh user/net/pid/mount namespace: no egress, read-only host, cleared env | a dev machine where unprivileged user namespaces work                          |
| **B — outer container** | `sandbox: false`, trusting an already-ephemeral host                         | CI / cloud agents (the runner is thrown away — the inner sandbox is redundant) |
| **D — refuse**          | run nothing                                                                  | untrusted code, no confinement available, host not disposable                  |

bwrap is the only one that actually confines; Docker/podman-rootless rely on the
**same** unprivileged-user-namespace primitive, so they're not a way around its
absence. The honest non-Docker alternative for hosts where user namespaces are
hard-disabled is [Landlock](https://docs.kernel.org/userspace-api/landlock.html)
(unprivileged FS, and network from kernel 6.7) — a future tier, not shipped.

> **macOS is coming via a native backend, not a VM.** bwrap is Linux-only by
> design (it _is_ Linux namespaces), so Mac confinement comes from a second backend
> — `sandbox-exec` (Seatbelt), built into every Mac — behind a `vigiles/os-isolation`
> port, with the safe-by-default rule unchanged. The decision, the build-vs-adopt
> survey (incl. why not Claude Code's own Bash-only sandbox or Anthropic's `srt`),
> and the enabled/disabled model are recorded in
> [`research/cross-platform-sandboxing.md`](../research/cross-platform-sandboxing.md).

> **`sandboxAvailable()` probes real capability, not just the binary.** `bwrap
--version` succeeding doesn't mean this host can create namespaces (many CI
> runners disable unprivileged user namespaces). We probe an actual `bwrap
--unshare-all … true`, so we never claim confinement we can't deliver. On
> Ubuntu 24.04 runners, unblock it with `sysctl -w
kernel.apparmor_restrict_unprivileged_userns=0` (see `.github/workflows/ci.yml`).

## Why confinement is opt-in, not always-on

The default is: _untrusted_ code is confined (a `plugin`/`pluginDir`, or `runHook`
with `trusted: false`), code you authored runs direct. Forcing the sandbox on
_everything_ is tempting — "why not always be safe?" — but it's the wrong default
for four concrete reasons, each load-bearing:

1. **It isn't always available.** Confinement is Linux + working unprivileged user
   namespaces only, and `sandboxAvailable()` probes the real capability (many CI
   runners ship `bwrap` but disable userns). Force it everywhere and a hook _you
   wrote_ turns red on every Mac and every hardened runner — `decideSandbox`
   returns `throw`, not a run. The unit tier is meant to run **anywhere**.
2. **The sandbox is deliberately hostile.** No egress, `--clearenv` (every host
   var dropped), a fresh empty `$HOME`, a read-only `/`. Exactly right for foreign
   code — but a hook you wrote that legitimately needs an env var, the network, or
   to write outside its work dir now fails for reasons unrelated to its logic, and
   you have to claw each var back via `setenvArgs`.
3. **Trust follows provenance.** Inline code you authored is trusted; foreign
   `plugin`/`pluginDir` is not — committing it to your repo is the same trust
   decision as taking on a dependency. You already made the call when you vendored
   it; the sandbox earns its keep on the code you _haven't_ linted.
4. **Cost.** A direct `spawnSync` is milliseconds — the whole point of the unit
   tier. The confined path stands up an IO dir, a fresh HOME, before/after tree
   snapshots, and a `bwrap` spawn. Paid on every _trusted_ hook, that defeats the
   cheap base of the pyramid.

`sandbox: "strict"` forces confinement even for trusted code when you _do_ want it
(belt-and-suspenders on inline code). It's just not the default, because as a
default it mostly punishes the code you trust on the platforms where it can't run.

## Filesystem (IO) — how good is it against `rm -rf`?

**Against destruction: strong.** Under bwrap the host root is mounted
`--ro-bind / /` (read-only) and only a throwaway work dir is writable. So
`rm -rf /`, `rm -rf ~`, `rm -rf /etc` all fail with `EROFS` — the worst a hook can
delete is its own disposable scratch dir.

**Be honest about two gaps:**

1. **Reading is NOT isolated.** The whole host `/` is mounted read-only, so a
   hook can `cat /home/you/.ssh/id_rsa` or `cat /home/you/.aws/credentials`.
   Environment secrets are cleared (`--clearenv`, so `ANTHROPIC_API_KEY` isn't
   visible), but **secrets on disk are readable**. What saves you is that egress
   is blocked — it can read but can't send. (A future `strictFs` mode would bind
   a minimal rootfs instead of all of `/`, at the cost of compatibility.)
2. **Only Tier A.** With `sandbox: false` / trusted-inline, the hook runs with
   **full host access** — `rm -rf ~` really deletes your home. That's by design
   (it's code you wrote), but it means the protection above applies only to
   _confined_ runs.

**Record what it wrote.** A confined `runHook` also reports the files the hook
touched in its work dir (`r.filesWritten`, relative paths) — so you can assert a
hook stayed in its lane:

```ts
import { assertWroteOnly, assertNoWrite } from "vigiles/harness-assert";

const r = runHook(thirdPartyHookCmd, event, { trusted: false });
// r.filesWritten → [".omc/state/ultrawork-state.json"]
assertWroteOnly(r, [/^\.omc\//]); // only its own state cache
assertNoWrite(r, /\.(env|pem|key)$/); // never a secret-shaped file
```

Dogfood: `src/run-hook.test.ts` confines oh-my-claudecode's `keyword-detector`
and asserts it writes **only** under `.omc/` — its keyword-state cache, nothing
else.

## Network — block, and (optionally) record

**Default: deny-all, and it's a real wall.** Under bwrap the net namespace has
loopback only and no external route, so nothing a hook does reaches the network.
The scripted mock is co-launched _inside_ the namespace, so it stays reachable
while real egress is blocked.

**`recordEgress` — record what it tried to reach, while still blocking it.** A
deny-all wall tells you nothing about _what_ a hook wanted. For the supply-chain
question — "what does this skill phone home to / which registry would its install
hit?" — turn on recording:

```ts
import { runHook } from "vigiles/run-hook";
import { assertNoEgress, assertEgressOnly } from "vigiles/harness-assert";

const r = runHook(thirdPartyHookCmd, event, { recordEgress: true });
// r.egress → [{ host: "registry.npmjs.org", port: 443, ts }]   (recorded)
assertNoEgress(r); // a hook that should phone home to nothing
// or: assertEgressOnly(r, ["registry.npmjs.org", /\.pypi\.org$/]);
```

`recordEgress` confines the hook (it needs the namespace) and runs a recording
proxy on the sandbox loopback; `HTTP(S)_PROXY` points proxy-honoring tools (npm,
pip, curl, fetch) at it. The proxy **records each `host:port` and refuses it** —
so the attempt is captured and nothing leaves.

**Honest limits of `recordEgress`:**

- It records what **proxy-honoring** tools attempt. Raw-socket egress bypasses
  the proxy — but the netns still **blocks** it hard, so it can't get out; it
  just won't appear in the record. _The block is the boundary; the record is
  best-effort observability over it._
- `curl` / `npm` / `pip` honor the proxy on every Node version; capturing
  Node's own **`fetch()`** needs `NODE_USE_ENV_PROXY`, which only takes effect on
  **Node 22+** (on older Node a `fetch()` is still blocked, just not recorded).
- It still **blocks**. So a skill that needs a _real_ `npm install` to succeed
  won't work in this mode — that's `egress: { allow }`, below.

## Network — allowlisted real egress (`egress: { allow }`)

**Let it actually reach the network, but only the hosts you list.** When the
question is "does this skill install cleanly, and _only_ from the registries I
expect?", a wall (record or not) can't answer it — the install has to succeed.
`egress: { allow }` lets traffic out to an allowlist and **drops the rest at the
packet layer**:

```ts
import { runHook } from "vigiles/run-hook";

const r = runHook(installHookCmd, event, {
  egress: { allow: ["registry.npmjs.org"] },
});
// r.egress       → [{ host: "registry.npmjs.org", allowed: true, packets, bytes }]
// r.egressDropped → { packets: 0, bytes: 0 }   // nothing reached off the allowlist
```

How it works (proven in `research/spikes/sandbox-network-allowlist.sh`):
[`slirp4netns`](https://github.com/rootless-containers/slirp4netns) `--configure`
attaches a tap to the bwrap netns (rootless egress via a userspace TCP/IP stack);
an `nft` ruleset **inside** the netns is a `policy drop` output chain that accepts
only the allowlist's resolved IPs (plus loopback + DNS) and `log`+`drop`s the
rest; the per-rule `counter`s read back what was reached and what was dropped.

**Why the boundary is `nft`, not a proxy.** A `recordEgress`/`HTTP_PROXY`
allowlist only constrains tools that _honor the proxy_ — a raw socket ignores the
env and goes straight out. The `nft` wall is at the packet layer, so a raw
`bash /dev/tcp` to an off-list host is **dropped too**. Needs Linux + bubblewrap +
`slirp4netns` + `nft`; it **refuses** (rather than running unconfined) if they're
absent.

**Honest limits:**

- The allowlist is **resolved to IPs at launch**. A host whose DNS rotates
  outside the run's window could hand the hook an IP that wasn't pre-resolved (and
  so gets dropped). The dynamic, resolver-pinned set — a DNS resolver in the netns
  that authorizes each answer's IPs just-in-time — is the next layer (see
  [`research/sandbox-network.md`](../research/sandbox-network.md)).
- The record **names the allowlisted hosts that were reached** and **counts** how
  much off-list traffic was dropped, but does not yet **name the dropped hosts**
  (that needs the in-netns DNS-query log). `r.egressDropped.packets > 0` tells you
  the hook tried to leave the allowlist; the DNS-log layer will say where to.

## Dogfood — a real finding about a real plugin

The egress recorder runs against the **real, vendored** `oh-my-claudecode` plugin
in the gate (`src/run-hook.test.ts`, skips where bwrap can't confine):

- its `keyword-detector` (UserPromptSubmit) hook → `assertNoEgress` (it phones
  home to nothing, while still doing its job);
- its `session-start` (SessionStart) hook → it `fetch()`es
  `registry.npmjs.org` for an **update check on every session start**. The
  recorder captures it (Node `fetch` via `NODE_USE_ENV_PROXY`), blocks it, and
  `assertEgressOnly(r, ["registry.npmjs.org"])` proves it phones the npm
  registry **and nowhere else**.

That second one isn't a toy curl — it's a genuine supply-chain/privacy property
of a popular plugin, asserted from its actual code.

The same `session-start` hook is dogfooded a second time under `egress: { allow:
["registry.npmjs.org"] }`: this time the update-check `fetch()` **succeeds** to
the registry (`r.egress` records it `allowed: true`) and `r.egressDropped.packets`
stays `0` — proving, through the allowlist path, that it reaches the npm registry
**and nothing else**.

## See also

- [Safety model](safety.md) — the front-door overview: this confinement plus
  preventing a real model's tool side effects (`interceptTools`/`notTool`), and
  the one safe-by-default rule that ties them together.
- [Testing your harness](harness-testing.md) — the three tiers + the sandbox boundary.
- [`src/sandbox.ts`](../src/sandbox.ts) — `decideSandbox` (the pure policy), `bwrapArgs`, `parseEgressLog`.
- [`src/egress.ts`](../src/egress.ts) — the `egress: { allow }` allowlist: ruleset builder, counter parser, the pure seams.
- [`research/sandbox-network.md`](../research/sandbox-network.md) — the allowlisted-egress design + the next (resolver-pinned) layer.
