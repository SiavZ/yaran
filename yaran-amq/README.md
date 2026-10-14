# yaran-amq overlay

Setup scripts that wire **Yaran** (this repository's fork of `patrickdappollonio/dux`) together with **AMQ** (file-based agent-to-agent messaging from `avivsinai/agent-message-queue`) on a Linux VM with a persistent disk. Until the first Yaran release, the overlay's download fallback remains pinned to this fork's actual historical `dux-amq-v0.1.1` archive and checksum. Prefer building Yaran from source and placing `yaran` on PATH first.

This directory does **not** modify yaran source. It sits alongside the yaran Rust source in this fork so I can keep both pieces under one fork while still pulling upstream.

## What you get

- **Worktree-per-agent UI** (yaran) for parallel Claude/Codex/Gemini sessions
- **Yaran peer router** so agents use `yaran peer send` instead of choosing AMQ vs Claude Peers themselves
- **File-based message bus** (AMQ) so agents on the same VM have a durable cross-provider fallback
- **Automatic identity**: each yaran pane's AMQ handle is the worktree directory basename, lowercased + sanitized to `[a-z0-9_-]` (typically the original branch name at worktree creation; stable across branch renames inside the worktree)
- **Spot-VM survival**: yaran config + sessions, AMQ queue, and Claude session JSONLs all live on a persistent disk (default `/data/state/`)
- **Past-chat resume** in fresh worktrees via `--continue --fork-session` (bypasses deferred-tool blocks)
- **YOLO is opt-in** (audit02 P0-A): `CLAUDE_AMQ_YOLO=1` / `CODEX_AMQ_YOLO=1` enable the per-pane `--dangerously-*` flag. See [Permission model](#permission-model).
- **Per-session system prompt** (audit03 §15): the yaran session-settings modal can set a custom prompt for one specific session without touching `CLAUDE.md` or global config. yaran exports `YARAN_SYSTEM_PROMPT` in the per-PTY env at spawn time; `claude-amq` translates it into `claude --append-system-prompt <text>`. `codex-amq` and `gemini-amq` warn-and-drop because their upstream CLIs have no equivalent system-prompt flag today; Yaran injects non-Claude Orchestrator policy after startup instead of changing provider launch semantics.
- **Orchestrator mode policy**: sessions marked Orchestrator automatically receive a built-in policy that tells them to coordinate through `yaran peer send`, avoid hands-on implementation, and proactively poll workers. `[amq.orchestrator]` also runs a Yaran-side checkpoint watchdog so Codex and Claude orchestrators get periodic peer-routing nudges instead of waiting passively.
- **AMQ registry refresh on Yaran boot**: Yaran reconciles AMQ's `meta/config.json` and Yaran-owned source markers from `sessions.sqlite3` when it starts, and `yaran peer sync-amq` can run the same refresh manually.

## Upgrade compatibility

`YARAN_*` settings take precedence over matching legacy `DUX_*` settings, including an explicitly empty new value. Wrappers accept both brands' installer sentinels and source markers, but write the established `.dux-amq-source` marker for interoperability. Existing persistent state is reused rather than moved or overwritten.

The queue and shared secret retain the durable `${XDG_DATA_HOME:-$HOME/.local/share}/dux-amq` namespace. An explicit `YARAN_AMQ_QUEUE_DIR` (or legacy `DUX_AMQ_QUEUE_DIR`) overrides the queue path, and an empty canonical override disables queue delivery. Signed messages continue to emit `DUX2`, while the verifier accepts both `DUX2` and preview `YARAN2` using their own MAC domains. The replay cache remains `${XDG_RUNTIME_DIR:-/tmp}/dux-amq` so upgrading cannot replay an already accepted message.

## Layout

```
yaran-amq/
├── install.sh                         # one-shot installer (idempotent)
├── wrappers/
│   ├── claude-amq                     # wraps `claude` with AMQ co-op + history seed
│   ├── codex-amq                      # wraps `codex` with AMQ co-op
│   ├── gemini-amq                     # wraps `gemini` with AMQ co-op
│   └── jcode-amq                      # wraps `jcode` with AMQ co-op (--no-update forced)
├── scripts/
│   └── finalize-claude-migration.sh   # moves ~/.claude + ~/.agents onto /data
├── config/
│   ├── bashrc-additions.sh            # env vars + amq shell-setup eval
│   ├── claude-md-additions.md         # global CLAUDE.md fragment teaching AMQ usage
│   ├── yaran-config.sed                 # the provider edits install.sh applies to yaran's config.toml
│   └── yaran-config-changes.toml        # the same end state in config form (validated by crates/yaran/tests/overlay_config.rs)
└── vscode/
    └── settings-additions.json        # VSCode Remote-SSH terminal Ctrl-G fix
```

## Quickstart

Prerequisites:
- Linux VM with a persistent disk mounted at `/data` (tested on GCE)
- `claude` CLI on PATH (Anthropic Claude Code)
- `git`, `curl`, `tar`, `rsync`, `npx`
- `sudo` access (only for the persistent-disk migration step)

Install:
```bash
git clone https://github.com/SiavZ/yaran.git
cd yaran/yaran-amq
./install.sh
exec bash -l
```

Optional one-time migration of an existing `~/.claude` onto `/data` (run **after** closing every running `claude` process):
```bash
/data/state/scripts/finalize-claude-migration.sh
```

Launch:
```bash
yaran
```

YOLO mode for that session (legacy `CLAUDE_YOLO=1` still works for both panes):
```bash
CLAUDE_AMQ_YOLO=1 CODEX_AMQ_YOLO=1 yaran
```

## Permission model

YOLO is **opt-in** as of audit02 phase 01. The wrappers default-deny on tool
execution; you must explicitly export an env var per pane to bypass prompts.
The Anthropic 2025–26 CVE wave (CVE-2025-59536, CVE-2026-21852,
CVE-2026-25723, CVE-2026-33068, CVE-2026-35020/35021/35022) all exploited
credential exfil through prompt-injected paths — default-deny is the single
biggest mitigation.

| Pane     | Env var to enable YOLO              | What it does                                         |
|----------|-------------------------------------|------------------------------------------------------|
| claude   | `CLAUDE_AMQ_YOLO=1`                 | passes `--dangerously-skip-permissions`              |
| codex    | `CODEX_AMQ_YOLO=1`                  | passes `--dangerously-bypass-approvals-and-sandbox`  |
| (legacy) | `CLAUDE_YOLO=1`                     | enables BOTH for backwards compat                    |

When YOLO is active, the wrapper prints a one-line stderr banner so it's
visible in the yaran pane header. If you previously exported the deprecated
`CLAUDE_AMQ_SAFE=1` opt-out, the wrapper now prints a transitional warning;
the variable is otherwise ignored — unset it from your shell rc.

## Session seeding

Cloning the parent worktree's Claude session JSONLs into a fresh worktree
is **opt-in** (audit02 phase 01). Set `CLAUDE_AMQ_SEED_FROM_PARENT=1` to
enable.

Trade-offs to weigh before turning it on:

- **Disk amplification**: rsync clones the parent's full Claude history.
  ~100 MB per worktree on heavy repos; multiplies by N worktrees.
- **Token billing**: a long inherited history pushes new sessions toward
  the 1M-context tier earlier than a clean start would.
- **Cross-worktree info leak**: the parent's transcripts may carry secrets
  or PII from a different feature; seeding makes them readable from the
  new pane.

If you enable seeding, pair it with `resume_args = ["--resume"]` in yaran
config so the picker actually shows the seeded chats. Avoid combining with
`--continue`: the latest parent session may carry a deferred-tool marker
that `--continue` refuses.

## Architecture sketch

```
┌─────────────────────────── yaran (TUI on persistent disk) ───────────────────────────┐
│                                                                                    │
│  ┌──────────── pane 1: alice ───────────┐    ┌──────────── pane 2: bob ─────────┐ │
│  │   claude-amq (wrapper)               │    │   claude-amq (wrapper)           │ │
│  │     ↳ amq coop exec --me alice ─────────────┐                                │ │
│  │       ↳ claude --continue --fork-session    │   ↳ same                       │ │
│  └──────────────────────────────────────┘   ┌─┘                                  │ │
│                                             │                                    │ │
└───────────────── /data/state/amq (file-based queue) ───────────────────────────────┘
                          │
              alice's mailbox  ←→  bob's mailbox  (Maildir-style)
```

- yaran creates a git worktree per pane; each pane gets its own CWD and Claude session storage.
- The `claude-amq` wrapper sets `AM_ME = <branch>`, ensures `--no-init`, and uses the shared `AMQ_GLOBAL_ROOT` queue. It safely recovers a dead exact-owner claim before `amq coop exec --require-wake`; AMQ refuses recovery when the recorded owner is still live, and the wrapper refuses to launch if wake is unavailable.
- `--continue --fork-session` lets a worktree pick up the parent repo's most-recent chat as context, forking off cleanly so deferred-tool markers don't block resume.
- Agents should use `yaran peer send <peer> "..."`. The router uses Claude Peers for Claude targets and AMQ for non-Claude targets. If Claude Peers is unavailable for a Claude target, the send fails loudly instead of silently falling back to AMQ.

## Kernel compatibility (TIOCSTI)

`amq wake` injects messages into agent panes via `ioctl(TIOCSTI)` by default. Linux 6.2 (Nov 2022) made `CONFIG_LEGACY_TIOCSTI` default-off, and Ubuntu 24.04 LTS / Debian 12+ ship the option built out entirely. On those kernels, `--inject-mode raw` silently fails — every wake notification is dropped before reaching the agent.

`install.sh` detects the kernel state by reading `/proc/sys/dev/tty/legacy_tiocsti`:

| Procfs value | Meaning                                | Sentinel `$STATE_ROOT/yaran/.tiocsti-state` |
|--------------|----------------------------------------|-------------------------------------------|
| `1`          | TIOCSTI compiled in AND enabled        | absent (raw mode)                         |
| `0`          | Compiled in but disabled at runtime    | present (via mode)                        |
| (file absent)| Compiled out — no runtime toggle helps | present (via mode)                        |

When the sentinel is present, the wrappers pass `--wake-inject-via "$LOCAL_BIN/yaran-amq-inject-bridge"` to `amq coop exec`. The bridge then runs end-to-end as:

```
amq send → AMQ inbox → wake daemon → bridge auto-drain → file queue → yaran drainer → agent PTY
```

Each step is described in the subsections below.

### Bridge: verify mode

1. **Skip mode (default)** — byte-safely decodes a `YARAN2\t...` envelope when present (and retains YARAN1 compatibility for already queued messages), while treating plain `amq send` bodies as raw. No HMAC check. Per the trust model in [SECURITY.md](../SECURITY.md), same-UID peers share `$HOME` and can read the HMAC secret directly, so verification doesn't add a defensible boundary against peers — insisting on it just silently dropped every legacy unsigned message in production.
2. **Strict mode (opt-in)** — set `[amq.inject].verify_envelope = true` in yaran's `config.toml`. yaran exports `YARAN_AMQ_VERIFY=1` to spawned PTYs at bootstrap; the bridge calls `amq-receive-verify`; unsigned, replayed, stale, or MAC-mismatched envelopes are dropped silently. Outside yaran, set `YARAN_AMQ_VERIFY=1` directly in the shell that runs `amq wake`. Reserved for environments that genuinely cross a trust boundary (e.g. proxying wakes across hosts).

### Bridge: delivery strategy

After unwrap (or verify), the bridge drops raw Ctrl+C interrupt transport bytes and then picks one of three strategies for the body:

| Condition | Strategy |
|-----------|----------|
| `$YARAN_PANE` set (running under yaran) and `AM_ROOT`/`AMQ_GLOBAL_ROOT` set | Run `amq drain --include-body --root "$root" --me "$AM_ME"` and write that output to `~/.local/share/dux-amq/inject-queue/<receiver>/<ts>.msg` |
| `$YARAN_PANE` set but no AMQ root env | Write the wake body itself to the same file queue |
| No `$YARAN_PANE` but `$TMUX` set + `tmux` on PATH | `tmux send-keys -- "$body" Enter` against current pane (or `$YARAN_TMUX_TARGET`) |
| Otherwise | Write to the same file queue; an operator can recover the body manually |

The auto-drain step is deliberate: yaran should inject the actual unread AMQ content, not a reminder that depends on the model choosing to run `amq drain`. The bridge appends a short instruction to act on the drained messages and strips unsafe control bytes before queueing so the Rust drainer will not reject peer-authored bodies.

`<receiver>` is the sanitised `$AM_ME` exported by the wrapper (`[a-z0-9_-]` only). The wrapper derives `$AM_ME` from `basename($PWD)` of the yaran worktree directory, falling back to the symbolic Git branch then `<provider>-<pid>`. When sanitisation collapses to empty, the bridge writes to the reserved `.unrouted/` subdirectory; the drainer routes those messages to the currently-selected yaran session with a status warning. A real `_unrouted` handle remains an ordinary routable identity.

### Drainer (`crate::amq_inject` in the yaran source)

The drainer is a tick-driven worker inside the yaran process. It owns the queue and is responsible for landing each body in the right agent PTY at the right time.

- **Receiver→session mapping** (see `match_receiver` in the inject runtime, formerly `src/app/inject_runtime.rs`) mirrors the wrapper's identity-derivation priority: try `sanitise(basename(worktree_path))` first, then `sanitise(branch_name)`, then exact session id. This is necessary because yaran sessions can change `branch_name` after worktree creation while the directory name is fixed — without basename matching, every queued message for those sessions would orphan in `.inflight`.
- **Idle detection.** Before delivering, the drainer scans the last `[amq.inject].busy_scan_lines` rows of the agent's PTY (default 5) for any of `[amq.inject].busy_markers` (default `["esc to interrupt", "ctrl+c to interrupt"]`). If a marker matches, the body stays queued. The same `InputTarget::Agent` guard the watch engine uses also applies, so a user typing in a session is never interrupted.
- **Two-phase delivery.** Once idle, the drainer sends the body in **phase 1** and a discrete `\r` in **phase 2** after the configured delay. Claude and Codex receive the body as explicit bracketed paste so rapid-input heuristics cannot strip or capture it; Gemini and custom providers keep Alt-Enter (`\e\r`) encoding for interior newlines. The separate `\r` then submits the complete prompt.
- **Auto-clear and auto-compact collaboration guard.** Worker-mode `auto_clear_on_task_done` and `auto_compact_on_compact` never fire while that agent shows a busy marker, has unread AMQ mail, pending outbox drafts, pending yaran inject files, or recent AMQ inbox/outbox/receipt activity. The recent-activity window is `[amq.inject].auto_clear_collaboration_quiet_secs` (default 1800 seconds) for both. This keeps back-and-forth collaboration threads from losing context between replies; orchestrator and attended modes still never auto-clear or auto-compact.
- **Atomic claim.** On scan, each `<ts>.msg` file is renamed to `.inflight.<ts>.msg` before reading. Once delivered, the inflight file is unlinked. This pattern is the read-side mirror of the bridge's own `mktemp + mv -f` write pattern, and the shared `.inflight.` prefix means a single scan filter excludes both sides' in-flight files.
- **Crash recovery with expiry.** At drainer startup (see `reclaim_stale_inflight_with_max_age`), fresh `.inflight.<ts>.msg` files left behind by a prior yaran instance are renamed back to `<ts>.msg`. Files older than `[amq.inject].max_message_age_secs` (default 600 seconds) are moved to the receiver's `.expired/` directory instead of being replayed into restored agents. Plain `.msg` files older than the same TTL are also expired before the startup scan, so messages accumulated while yaran was offline do not flood sessions on reboot. Set the value to `0` to restore replay-all behavior. Bridge-format `mktemp .inflight.XXXXXX` files (no `.msg` suffix) are skipped on purpose — they may belong to a concurrent in-progress write.
- **Validation.** Files larger than `[amq.inject].max_message_bytes` (default 64 KiB) are rejected after claim and moved to `.rejected/` for operator inspection. Symlinks are refused. Receiver subdirectories that don't match `[a-z0-9_-]+` are rejected without a claim.
- **Polling fallback.** A 5-second polling thread (configurable via `[amq.inject].poll_interval_ms`) requests a scan in addition to the `notify` watcher, so filesystems where inotify is lossy (NFS, virtio-9p, some FUSE mounts) still drain.
- **Worker-mode postscript** (audit03 phase 01). When the receiving session has `SessionSettings.mode == Worker` (set via the yaran session-settings modal), the drainer appends a sentinel-required note to the wake body before typing it: `[Orchestrator note] When this task is complete, end your reply with the literal token [task-done] so the orchestration layer knows to clean up.` The token is `crate::watch::builtin::TASK_DONE_SENTINEL`. The matching auto-clear watch rule (also opt-in per session) waits for the agent to emit `[task-done]`, then types the provider's clear command (`/clear` for claude/gemini, `/new` for codex). Postscript injection is yaran-side rather than in the bash bridge — the bridge stays stateless and has no SQLite access, so the lookup of "is this receiver's session a worker?" happens at the yaran drainer where `git.sessions` is in scope.
- **Worker-mode auto-compact.** A second built-in watch rule, also opt-in per session (`auto_compact_on_compact`), waits for the literal `[compact]` (`crate::watch::builtin::COMPACT_SENTINEL`) and types `/compact` followed, on one line, by the text of the compact instructions file: the session's own `compact_instructions_path`, else `[amq.inject].compact_instructions_path` (default `~/.claude/compact-instructions.txt`). The file is read on a worker thread, re-read every 30 seconds, capped at 8 KiB, and stripped of control characters; when it is missing, empty, too big or unreadable the rule types a bare `/compact` and logs why. Once either built-in types its reset the session's watch rules pause for 10 seconds and then absorb whatever is still on screen, so a reply carrying both sentinels, or one echoed after the reset, never fires the other. `[compact]` never clears a session and `[task-done]` never compacts one.

### Operator overrides

```bash
YARAN_AMQ_INJECT_MODE=raw    # force TIOCSTI even on locked-down kernels
YARAN_AMQ_INJECT_MODE=via    # force bridge mode (e.g. for testing)
YARAN_TMUX_TARGET=<pane>     # specific tmux target for the bridge (default: current pane)
YARAN_AMQ_VERIFY=1           # opt into strict HMAC verification at the bridge
```

Inspect at runtime: `cat $STATE_ROOT/yaran/.tiocsti-state` (absent → raw mode active) and `amq doctor --ops`. Wake stderr lands in `$AMQ_GLOBAL_ROOT/agents/<me>/.wake.log` — verify-drop reasons are visible there. Drainer activity is in yaran's main JSON log under `target: "yaran::amq_inject"`; grep for `delivered AMQ wake to session` for a per-message audit trail.

A native upstream fix (HMAC envelope + stdin piping inside AMQ itself) is tracked in `docs/plans/audits/audit02/artifacts/13-upstream-issue.txt`. Upstream AMQ v0.34.0 also added `--defer-while-input` / `--input-quiet-for` flags that gate TIOCSTI on terminal activity heuristics — a coarser version of what yaran's drainer does with PTY-snapshot scanning.

## Trade-offs

- **No native yaran hook** for worktree-create lifecycle, so seeding past-chat history (when enabled) is done in the wrapper (one-shot, on first launch).
- **Seeded worktrees get their own snapshot** of past sessions on first launch (~100 MB for a heavy repo). They diverge afterward — by design. See [Session seeding](#session-seeding) for the disk/billing/leak trade-offs.
- **Identity collisions are possible** if two worktrees normalize to the same handle. Pick distinct branch names.
- **Compaction risk** (when seeding is enabled): on repos with a heavy session history, `--fork-session` inherits all of it, which can push fresh sessions toward 1M-context billing tier earlier. If that bites, leave `CLAUDE_AMQ_SEED_FROM_PARENT` unset (the default) or revert `resume_args` to `["--continue"]`.

## Diagnostics

`yaran-amq doctor` (audit02 phase 20) prints a self-check dump that
operators can attach to a support thread. Same output is reachable
via `yaran doctor`, which adds a Rust-side `sessions.sqlite3` integrity
section on top of the bash-script bundle.

```bash
yaran-amq doctor              # human-readable
yaran-amq doctor --json       # machine-parseable; pipe to `jq`
yaran-amq doctor --anonymize  # redact $HOME, branch names, agent IDs
```

It reports: AMQ binary integrity (sha256 vs the pin in
`bashrc-additions.sh`), kernel `dev.tty.legacy_tiocsti` value,
`sessions.sqlite3` `PRAGMA integrity_check`, encryption posture of
`$STATE_ROOT`, AMQ queue depth and oldest-message age, the
`~/.claude` symlink target, free disk space, and the currently-running
yaran PID/uptime/RSS. Each external call is wrapped in `timeout 5`, so
the tool never hangs even when the underlying piece is broken.

The HMAC envelope (audit02 phase 08) lives at the path pointed to by
`AMQ_SECRET_PATH` (default `${XDG_DATA_HOME:-$HOME/.local/share}/dux-amq/amq-secret`,
mode 0600). To rotate, `rm` the file and restart every pane —
rotation invalidates every in-flight signed envelope by design.
`yaran-amq/scripts/amq-secret-init.sh` regenerates it idempotently on
the next install.

## Production setup

The default deployment relies on the cloud provider's at-rest
encryption (GCE PD, EBS, Azure Disk). That covers physical-disk
theft but **not** a compromised cloud IAM principal who can attach
the persistent disk to another VM and read agent transcripts /
queues in plaintext.

For stronger isolation, see the operator playbook at
[`docs/operations/encryption-at-rest.md`](../docs/operations/encryption-at-rest.md).
It covers two paths:

- **gocryptfs** — file-level FUSE encryption, no reformat, ~5% IO
  overhead. Recommended for single-user spot VMs. An opt-in helper
  is shipped at [`scripts/install-gocryptfs.sh`](scripts/install-gocryptfs.sh)
  and is **not** invoked by `install.sh`.
- **LUKS** — block-level, requires reformatting the persistent
  disk. Recommended for long-lived shared hosts.

Either path is layered on top of, not in place of, the cloud
default. See also `SECURITY.md` for the broader threat model.

## License

The wrappers and scripts in this directory are MIT-licensed (matching the yaran license in the parent repo).
