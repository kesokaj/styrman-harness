---
owner: verifier
date: 2026-09-17
---
# Verification guide — sh-agent

The standing procedure for this repo. Written under the rule in `agents/verifier.md`
("What to run"): the first run under a new project writes this guide; later runs cite
it and record outcomes only. Update this file in the same run that changes the steps.

## 1. Go checks (every change, including one that touches only `context/`, `skills/`, `agents/`, `commands/` or `rules/`: the root package's embed tests compare those trees with the binary's embedded copy, so a new file or mode there fails here, BUG-137)

```bash
gofmt -l cmd internal     # must print nothing; NOT `gofmt -l .` — it walks .agents/scratch,
                          # where a stray Go file fails a gate that has nothing to do with it (BUG-048)
go vet ./...
go test -race -timeout 30m ./...   # -timeout 30m: on a one-CPU box (nproc = 1) cmd/sh-agent takes ~13 min under -race,
                                   # past Go's 10-minute default per-package timeout (a larger machine: ~62 s)
```

The suite does not depend on the caller's environment: every test package drops `GIT_*` variables in a `TestMain` (git exports them inside a hook, and they would aim a fixture's git at another repository), and the dream package's also clears `CLAUDE_CONFIG_DIR`. A check for that, when a test helper that runs git or reads a CLI's directory changes: `GIT_DIR=/nonexistent CLAUDE_CONFIG_DIR=/nonexistent go test ./...`.

## 2. Harness self-check (every change to `context/`, `agents/`, or `skills/`)

```bash
go run ./cmd/sh-agent list      # sanity: every skill and agent parses; its section headers print the counts
go run ./cmd/sh-agent render | wc -l   # rendered context/AGENTS.md must stay under 100 lines
go test ./internal/harness/... -run 'TestRenderedContextFitsAntigravityBlock|TestRenderedContextUnderTarget' -v   # a change to context/*.md
  # or rules/*.md must pass this: it renders the real checkout plus every rules/*.md and pins the
  # result under 22,000 bytes, inside Antigravity's 24,000-byte global rules block, and the hand-written part (before the generated `## Installed` inventory) under 15,000 bytes,
  # the harness's own ceiling (goal 14,500; plan audit-fix D2b) (REQUIREMENTS §
  # Known limits, ADR-035); already covered by `go test ./...` in § 1, named here explicitly
```

The installer also refuses a command or rule whose first line opens a frontmatter block (`---`, also after a byte-order mark or with spaces after it) that cannot be read: such a file was once deployed as written with its keys unchecked (`TestLintRefusesUnreadableFrontmatterInDocs`).

## 3. Scratch-home install and drift check

Never install into the operator's real `$HOME` from a dev session.

```bash
rm -rf .agents/scratch/<slug>-home
mkdir -p .agents/scratch/<slug>-home
go run ./cmd/sh-agent install --home .agents/scratch/<slug>-home
go run ./cmd/sh-agent status --home .agents/scratch/<slug>-home   # must report "drift none"
```

Confirm every `agents/*.md` and its derived Antigravity `agent.md` under
`.gemini/config/agents/<name>/agent.md` in the scratch home carry the same
`## Records` section (exactly one each) when an agent definition changed.

## 3a. Plain-copy install (change touching checkout-vs-mirror rebuild logic)

When a change affects `IsCheckout` / rebuild-decision logic in `cmd/sh-agent` or
`internal/harness/repo.go`, the scratch-home tier above only exercises the checkout
path. Also build the real binary and run it against a read-only, `.git`-less copy:

```bash
go build -o .agents/scratch/<slug>/sh-agent ./cmd/sh-agent
mkdir -p .agents/scratch/<slug>/mirror
for d in context skills agents commands rules; do
  mkdir -p ".agents/scratch/<slug>/mirror/$d"
  rsync -a --exclude .git "$d/" ".agents/scratch/<slug>/mirror/$d/"
done
chmod -R a-w .agents/scratch/<slug>/mirror
.agents/scratch/<slug>/sh-agent install --repo .agents/scratch/<slug>/mirror \
  --home .agents/scratch/<slug>/home2   # must say "plain copy" and not rebuild
ls -a .agents/scratch/<slug>/mirror     # must show no .agents/ created
.agents/scratch/<slug>/sh-agent status --repo .agents/scratch/<slug>/mirror \
  --home .agents/scratch/<slug>/home2   # first line "plain copy"; drift none
chmod -R u+w .agents/scratch/<slug>/mirror   # restore before cleanup
```

Then confirm the checkout path still rebuilds with
`<built binary> install --repo <this checkout> --home .agents/scratch/<slug>/home3 --dry-run`
→ `[dry-run] the binary would be rebuilt from <checkout>`.

## 3b. `report`, the feedback loop back (change to `internal/harness/report.go`, `cmd/sh-agent/main.go`'s report wiring, or `reorder`, which derives the value-taking flags from the verb's FlagSet)

Never run `report` without `--dry-run` from a dev or verification session — it pushes
to the real feedback repository (`git@github.com:kesokaj/styrman-harness-feedback.git`)
and never touch the real `$HOME`.

```bash
go run ./cmd/sh-agent report --dry-run --home .agents/scratch/<slug>-home
```

Must print the destination, the collected/absent files, and the redaction list (what was
caught — it cannot show a miss), and write nothing (`git status` in a real feedback checkout stays byte-identical before and
after). `go test ./cmd/... -run TestReorder` covers a new value-flag registered on
a verb's FlagSet (reorder derives the value-taking set from it); `-run TestReport` alone does NOT run every report test (`TestSendReport`,
`TestResolveFeedbackFailures`, `TestSendReportRefusesRedirectsAndLinks`,
`TestSendReportPushesOnlyToFeedbackURL` don't match that prefix) — use
`go test ./internal/... -run 'TestReport|TestSendReport|TestResolveFeedback'` for
collection, redaction, and the git side, against local bare repositories under
`.agents/scratch/` or Go's own `t.TempDir()`, never the real remote, and confirm with
`go test ./internal/... -list 'TestReport|TestSendReport|TestResolveFeedback'` that it
lists every one of them.
A real end-to-end run against the feedback repository is an e2e-tier check the main
agent runs and logs, not a bare `verifier` dispatch.

## 3c. Verb × place-kind matrix (change to `cmd/sh-agent` or `internal/harness` that touches a verb's behavior or a refusal message)

`.agents/docs/testing/sh-agent-matrix.md` is the reproducible spec: every `sh-agent`
verb run against a checkout clone, a `git archive` plain copy, and a release-stamped
local build, each from a fresh scratch home, driven by `.agents/scratch/matrix/run.sh`
(gitignored; `git clone` of the checkout for the checkout kind, `go build ./cmd/sh-agent`
for the development binary both the checkout and plain-copy kinds run,
`go build -trimpath -ldflags "-X main.version=vX.Y.Y"` for the release-shaped binary,
`git archive HEAD | tar -x` for the plain copy). `report` runs only `--dry-run`; `update`
runs with a PATH holding no `gh`, so nothing reaches the network.

Run it, then update the matrix file's table and its "How the cells were run" line (tree
SHA and date) in the same change. Every cell is `exercised` (ran, output logged),
`refused` (a message naming the cause and the alternative), `n/a` (the verb has no
meaning there), or `remainder` (no machine here can run it) — none blank. Pass means: no
silent cell; every `refused` cell's message names both the cause and the alternative;
and `status` reports drift none from a fresh home on each of the three place kinds.

## 3d. Search index (change to `internal/search`, or to the `search`/`index` wiring in `cmd/sh-agent`)

```bash
go test -race -timeout 30m ./internal/search ./cmd/sh-agent    # unit tests: reconcile, parsing, queries, refusals, the global search index
SH_AGENT_RECALL=1 go test ./internal/search -run 'TestRecall$' -v   # recall measurement over testdata/recall.tsv: prints per-question recall and the means; not a gate
go build -o .agents/scratch/sh-agent ./cmd/sh-agent
.agents/scratch/sh-agent index --rebuild --home .agents/scratch/s   # this checkout: under 10 s
.agents/scratch/sh-agent search --home .agents/scratch/s <words>    # warm, nothing changed: under 100 ms end to end
```

A new or changed verb also gets its rows in `sh-agent-matrix.md` (section 3c). A test written after its code is checked by the mutation protocol (`review-standards` § 2): the mutated code compiles and a named test fails.

## 3e. Memory, dream and the timer (change to `internal/memory`, `internal/dream`, or the `memory`/`dream` wiring in `cmd/sh-agent`)

```bash
go test -race -timeout 30m ./internal/memory ./internal/dream ./internal/search ./cmd/sh-agent
```

- The unit tests put fake `claude`, `agy`, `systemctl` and `launchctl` on PATH; nothing calls a real CLI or manager.
- A real `sh-agent dream` run in development goes against a scratch `--home` (under `.agents/scratch/`) whose search.db indexes only fixture projects — never `--all` against the real home: a real run sends redacted project content and transcripts to a model provider.
- The timer is verified by `systemd-analyze verify` on units rendered through a fake manager. The real `--install-timer` is the operator's step (R6).
- Corpus measurement of the Antigravity reader (a change to `internal/search/dream.go`): `SH_AGENT_CORPUS=<dir of copied Antigravity conversation databases> go test ./internal/search -run TestAgyCorpusLeaves -count=1 -v` prints `corpus: N databases, L prose leaves kept, K with a tool-argument key`. K must be 0. The 2026-09-30 measurement over 95 databases was 971 and 0, before and after the reader change. The copies live under `.agents/scratch/` and are deleted after.
- The kit is in `testing/2026-09-30-verify-parity-memory-dream-phase-4.md`.

## 3f. The Google skills catalog (change under `skills/google-catalog/`, to `internal/harness/catalog_test.go`, or to the listing budget)

- The catalog tests run inside § 1's `go test ./...`: `TestCatalogMatchesChecksums`, `TestCatalogIndexMatchesEntries`, `TestCatalogFilesAreCarryable` (each fails on an empty catalog), `TestCatalogInstallsClean`, `TestRouterDescription`, `TestSkillListingBudget` (names plus descriptions of the skills the model is shown at most 19,500 bytes; a skill with `disable-model-invocation: true` is not counted, the test skips it; a new or longer skill description can therefore fail `go test ./...`, with 160 bytes of room today: 19,340 of 19,500, the `review` description being shorter than it was in v2.2.0), and `TestCatalogNotesNeverAllowQuiet` (a note that names `--quiet` says to leave it out, with no exception in that clause), and `TestRefreshCatalogScript`, which builds local fixture repositories and never reaches the network (it needs `bash`, `git` and `go`; `-short` skips it) and covers the work directory (never `/`, the home directory or the checkout; never nested with `--dest`; a non-empty one needs the script's marker `.refresh-catalog-work` or an `origins.txt`), a leading `//` in `--dest`, and the two source overrides (an `https://` URL without user information or a query string, or an absolute path; no message ever shows such a value, git's own message is not shown either, hidden on all three git steps that carry the value (pointing an existing clone at the source, fetch, clone), and the script turns git's tracing and credential prompts off for its own calls (`GIT_TERMINAL_PROMPT=0` and an empty `GIT_ASKPASS`: no terminal prompt, no askpass program; the three `GIT_TRACE2*` targets set to 0, because they can come from git's config; every other `GIT_TRACE*` variable the caller exports set to 0, except `GIT_TRACE_REDACT`, which is set to 1; `GIT_CURL_VERBOSE` removed, because set to anything it turns curl's trace on); the test asserts it four ways: `GIT_TRACE` and `GIT_TRACE2_EVENT` pointing at files that must not hold the override's value, all three `trace2` targets (`eventTarget`, `normalTarget`, `perfTarget`) in the fixture home's git config, an https fixture server that answers 401 with an askpass stub that must not run (the case also fails if git never reached the server), and the script's text for `GIT_CURL_VERBOSE` (no run shows that one: the calls' output is discarded), each failure named by the source's role; a run that used an override says when it ends that git keeps the value in the work clones under the work directory, to be deleted if the value is sensitive, printed however the run ends after the first clone or fetch (success, a refusal of the script's own, a command that stops it, or a run ended by TERM: the test signals the script's process group while a stub `go` sleeps, and wants exit 143 and the note) and not printed by a refusal before any clone; the test asserts each of these with a pin that does not resolve after the clone, a fetch that fails, a clone whose git config is locked, a destination that cannot be created, and a refused override value; a pin must be a full commit id (40 hex digits) and is refused by shape before any clone ("a pin must be a full commit id (40 hex digits)"), because git checks a tag or branch named like a shorter id out before the abbreviated commit id; the script checks the pin out as `<pin>^{commit}` and compares the checked-out commit with it, because git takes a local branch of that exact name first, and the test has a source whose default branch is named like the pin and points elsewhere (its content must not be vendored); the test refuses a tag named in hex digits, the commit's 7-digit id and its 39-digit id; and the manifest records the upstream repositories' names, never an override); the catalog tests give every subprocess an environment without `GIT_*` variables. `TestScriptsHaveNoEarlyExitPipe` fails on any tracked script under `skills/*/scripts/` or `.agents/docs/testing/` that sets `pipefail` and pipes into an early-exit consumer without ending `|| true`: it cuts each logical line at its unquoted single pipes (a command substitution is code again inside double quotes) and matches each stage: `head`, `grep -q`/`-m`/`-l` and their long forms, a `sed` script with a `q` or `Q` command, an `awk` program with `exit`, `read` (BUG-155, BUG-157).
- A refresh — `bash skills/google-catalog/scripts/refresh-catalog.sh <agents-cli pin> <google-skills pin>` (each pin a full 40-digit commit id), which needs the network — is followed by `git add skills/google-catalog && go test ./...` (an unstaged catalog fails `TestEmbedHoldsOnlyTrackedFiles` with "embedded but not tracked", the same message an ignored path gives), a read of `git diff --cached --stat -- skills/google-catalog`, and a security review of the diff before the commit (`AGENTS.md` § Rules).
- Behaviour on the CLIs is three matrix rows (`skill-matrix.md`: `catalog-no-leak`, `catalog-route`, `catalog-precedence`), run on both from a sandbox home; each is judged from the run's own record (Claude Code's stream-json events, Antigravity's conversation database), not from the model's reply.

## 4. Sandbox start of each CLI (change to `context/`, `agents/`, or `skills/`)

One start of Claude Code and one of Antigravity in the sandbox (paths and flags in
`.agents/docs/testing/2026-09-03-verify-sandbox.md`), each asked a context question
that quotes the new wording, log grepped for parse errors. The full skill-matrix
scenarios are `.agents/docs/testing/skill-matrix.md` — run the matrix in full only
before saying "complete" or "all skills"; a targeted change runs only the matrix row(s)
it affects.
A sandbox home that must be logged in is built under `.agents/scratch/` (gitignored, never
embedded: `go:embed` covers only the five source directories); any credential file copied into
it from the real home is `chmod 600`, lives only for the run, and is deleted by name right
after (security review 2026-09-21). Prefer the real-home smoke checks of § 5 when the change
needs no separate home.

A change that must hold on each kind of machine (R10: Claude Code only, Antigravity only, both)
is checked in three sandbox homes, one per `sh-agent install --home <sb> --vendor claude|agy|all`,
with `HOME=<sb>` for the whole run so every `sh-agent` call the agent makes lands there (BUG-107).
Claude Code runs with `CLAUDE_CONFIG_DIR=<sb>/.claude` and a copy of `~/.claude/.credentials.json`
in it; Antigravity with its token and a settings file written for the run (§ Behavioural runs below).
A vendor setting the session cannot write, such as a project's `.claude/settings.local.json`,
reaches Claude Code through `claude -p --settings '<json>'` instead. Kit and first use:
`testing/2026-09-30-verify-parity-memory-dream-phase-2.md`.

### Behavioural runs (a change to `agents/*.md` or to a `context/` rule that changes what the main agent does)

Moved here from `AGENTS.md` § Testing on 2026-10-01 (plan audit-fix, C17); the project file points at this section.

- A change to `agents/*.md` gets a behavioural run: `claude -p --agents <json built from the working-tree file>` in a scratch clone of a small repository, several runs, with the agent's artifact carrying something only the new definition writes, so the run proves which definition ran. The dispatch text does NOT repeat the changed rule (the definition alone is under test); the prompt goes on stdin because `--allowedTools` is variadic and swallows a trailing argument; `--allowedTools` names the agent's tools or every call is refused at the permission gate and the run proves nothing; the tool-call order is read from the run's subagent transcript under `~/.claude/projects/`; the result is reported as n of N runs, never "works" (BUG-083). A change to `context/` that should change what the main agent does runs the same way with the new text given through `claude -p --append-system-prompt`.
- The real home is never touched. A CLI started from a scratch `HOME` cannot authenticate (credentials live in the real home), so the CLI start of § 4 is the sandbox procedure or the real-home smoke checks of § 5, never `HOME=<scratch> claude -p`. A verification log states what it did not exercise; "complete" or "all skills" is said only after the full matrix in `skill-matrix.md` has run.
- **Every kit sources `kit-preamble.sh` first** (`. .agents/docs/testing/kit-preamble.sh` at the top of the kit script built in scratch, with `KIT_CLONE`, `KIT_HOME` and, when the dispatch states fixture facts, `KIT_ASSERT_GREP` (newline-separated `file:pattern`) and `KIT_ASSERT_COMMIT` (one commit SHA of 7 to 40 hex digits, never a ref name: `HEAD` or a branch would be in every clone's history; checked with `git merge-base --is-ancestor`)). The preamble is the setup proof BUG-087, 090, 091, 106, 107, 115, 116 and 123 each asked for: it asserts every fixture fact before the CLI starts, refuses a clone whose parent is a git checkout (an ancestor `AGENTS.md` would load and an agent resolved the docs root upward into this repository's trail, BUG-106), lists the real `~/.config/sh-agent` before the run and again on exit, and FAILS the kit (exit 1) when it changed (a kit's own `--home` does not reach the agent's calls: `search` registered test clones in the real global index, BUG-107, and a `/distill` probe appended to the real feedback and retro logs, BUG-123), and puts a wrapper first on `PATH` that pins `--home "$KIT_HOME"` on every `sh-agent` call the agent makes. The preamble has a behaviour test, `TestKitPreambleAssertsCommit` (run by § 1's `go test ./...`; `-short` skips it): twelve values of `KIT_ASSERT_COMMIT` (a ref named in hex digits is refused: the value is resolved first and the commit's id must start with it), a home without `~/.config/sh-agent` (BUG-158), and a run that changes a name or a file's contents in the real config (the kit fails; the test's cases are a new file, a new directory and a new looping symlink through a symlinked config directory, and an append to a symlinked file). The fingerprint is exact about links: the config directory itself may be a symlink; a link that points at a regular file is read through; any other link contributes the path it points at, so re-pointing it is seen, and a link to a device or a fifo is never opened; links are not walked. It does not see a rewrite with the same bytes, a `touch` or a `chmod`, a file made and removed again before the run ends, or anything inside a directory it cannot list or inside a subdirectory that is itself a symlink. The test's cases also include a link to `/dev/zero` and a link to a fifo (each must return within 30 seconds), and a link re-pointed at another directory. The preamble's exit check is its EXIT trap and nothing else: a kit never sets an EXIT trap of its own after sourcing it and never ends in `exec <cli>`. The trap prints `kit: real config unchanged` when it ran and found nothing, and a run counts only when its output holds that line or the kit's FAIL line.
- **A behavioural, sandbox or real-home run is recorded so the release gate can count it:** the main agent writes its own log `testing/<date>-verify-<slug>.md` with frontmatter `owner: main` and a `Range reviewed: <base>..<head>` line reaching the head the rows ran on. The log also carries a `## Status: PASS` or `## Status: FAIL` heading and gives each row as n of N against the row's own pass criterion: `/preflight` Step 2 counts a tier only when its rows ran and passed, and a log that shows a row failing blocks the gate whatever its heading. `/preflight` Step 2 counts such a log only for tiers no subagent can run (these rows), never for a verification command, which only a log with `owner: verifier` shows as run.
- A sandbox home for headless agy gets its own `~/.gemini/antigravity-cli/settings.json`, written for the run with the fewest grants the run needs — the grant store knows `command(<name>|*)`, `read_file(*)`, `write_file(*)` and `mcp(*)` only (any other entry is skipped with `ignoring invalid allow entry` in `cli.log`), and a row that dies with "auto-denied" is diagnosed from its conversation database (`strings ~/.gemini/antigravity-cli/conversations/<id>.db | grep -o '"CommandLine":"[^"]*'`: the last command line names what was denied) before any grant is widened (BUG-141) (a `command(<name>)` grant allows every argument of that command) and the scratch clone as its only trusted workspace, and deleted by name with the copied token — never a copy of the real home's file, which approves every tool and trusts real checkouts; a run counts only when its stderr has no "auto-denied" line and its `cli.log` no "invalid allow entry" line.
- A sandbox home is a `HOME` override, nothing more: the CLI under test keeps the operator's uid, environment, Docker socket and reachable checkouts, and rows that need `command(*)` or `--dangerously-skip-permissions` run that way. Accepted as the design on the operator's word (2026-10-01, the v2.0.0 gate's trail-slice finding, "Go with your recommendations"): the kits' guards (fixture asserts, the clone outside every checkout, the fingerprinted real config directory, the `--home` wrapper) are what keeps a run honest, not isolation, and a row that must not reach the machine is not run headless here. That acceptance covers text the harness wrote. A row that loads vendored or third-party text (the `google-catalog` rows, a newly adopted skill) runs with read-only grants — `Read Grep Glob Skill` and the read commands on Claude Code, `read_file(*)` and the named read commands on Antigravity — never `command(*)` (the v2.1.0 gate's trail-slice finding; the Phase 0 probes of the catalog plan predate this rule).
- The must-fail control for a change to `context/` runs in a project that does not contain the harness source, never in a clone of this repository, whose own `context/` carries the new text.
- A run kit separates the RUN from the CHECK (BUG-140): the run saves the CLI's output and leaves the clone as it is; the check re-reads the saved output and the clone from disk and prints the result line, so it can be run again when a process dies or a verdict script has a bug (three result lines were lost on 2026-10-01, cause unknown; two verdicts were re-judged from saved records the same day). A count inside a kit is `grep -c … || true`, never `grep … | wc -l || echo 0` under `pipefail`.
- A headless probe of a working-tree skill passes `--setting-sources project,local`, or first shows the real home has no installed skill of that name: a user-level skill shadows the project link (plan `2026-09-29-dreamer-memory-loop.md` D15).

## 5. Real-home smoke checks (after any install into a real home)

The three checks in `.agents/docs/testing/2026-09-03-verify-real-home.md` (context
questions — including the canary word GANNET that ends the rendered context, which a
truncated file fails (BUG-085) — one skill load, one agent dispatch) from that home, on each
CLI, before the install is called done. The Mac procedure is
`.agents/docs/testing/2026-09-04-verify-mac-real-home.md`.
Run them from a fresh clone of the demo service, never from inside a harness checkout: the
canary word is written in this repo's README and AGENTS.md, so a session started here could
answer it from the project context without the global context having loaded. On Antigravity
the answer counts only with the store check beside it (`strings` the newest
`~/.gemini/antigravity-cli/conversations/*.db`: one `<RULE[...AGENTS.md]>` block, the canary
line inside it, no `<truncated` line). A headless Antigravity check that needs tools uses the
real settings' `permissions.allow` entries; `--dangerously-skip-permissions` only inside a
throwaway clone, and never as the standing way.

After any `sh-agent update`, also run the deploy guides' post-update check from that
home: `hash -r` (bash) or `rehash` (zsh), then `sh-agent version` unqualified and
confirm it matches the version just installed, then `sh-agent status` and confirm it
prints no `shadowed` line (BUG-079). When the version is wrong, `type sh-agent` then
`which -a sh-agent` name which file the shell is still reaching.

The by-hand install chains (README § Install without cloning, `remote.md` § First
install) are exercised only in `.agents/docs/testing/2026-09-17-release-binary-e2e.md`,
not by any tier in this guide — an accepted e2e-only check.

## Full matrix

`.agents/docs/testing/skill-matrix.md` is the reproducible spec of every skill/agent
sandbox scenario. Cite it rather than duplicating rows here; add a row there when a
skill or agent gains new behavior worth an end-to-end check.
