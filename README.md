# Amabie

**Amabie is an independent verification layer for coding agents.**

The agent builds. Amabie verifies.

> **NO PROOF, NO DONE.**

A coding agent saying "done" is not evidence. A green test suite is useful
evidence — but if those checks **cannot tell your change from the code that was
already there**, they prove nothing about it, and Amabie says `NOT PROVEN`.

> *"Cool diff. Prove that it actually made the project better."*

**Amabie 2.0.0 release candidate:** start with the [Quickstart](QUICKSTART.md).
The current capability is **LOCAL**: deterministic checks and signed records,
with the worker and verifier still running as the same OS user. It is not an
activated HARDENED boundary. Claude Code completion hooks can block; Codex hooks
need your explicit trust; other agents receive advisory results.

## What Amabie does

Install it once in a repository. Then use your coding agent exactly as you
already do.

- It **finds your project's own checks** — the `test` / `typecheck` / `build`
  scripts you already declare, or your ecosystem's own test command — and writes
  nothing you have to maintain.
- When the agent says it is finished, Amabie **runs those checks itself**, outside
  the agent's context.
- If they fail — **or if they are green for a reason that has nothing to do with
  the change** — it **blocks the completion** and hands back one short, actionable
  message.
- It also **answers the agent directly** (an MCP tool, registered for you) when the
  agent wants to know whether it is done, so it does not have to re-run your suite
  to find out.

There is no Amabie command in the ordinary loop, and you do not have to learn
Amabie's vocabulary to use it.

> **Why you may see one approval prompt — and how to skip it.** Amabie registers its
> agent tools at *project* scope, i.e. a `.mcp.json` in this repository. That is what
> triggers the prompt: a project-scoped server arrives from a file that a clone or a
> branch can change without you acting, so Claude Code holds it at `Pending approval`
> until you approve it once — `claude mcp list` reports
> `amabie: …\main.js mcp - ⏸ Pending approval (run \`claude\` to approve)`. Approve it
> once and the tools are there. Amabie says the same thing at the end of `setup`.
>
> **The prompt is about the optional tool server, not about verification.** The
> completion gate is the `Stop` hook in `.claude/settings.json`, which `setup` installs
> and which decides every completion; the MCP entry is what lets the agent *ask* Amabie
> a question. So an unapproved entry never means an ungated repository.
>
> If you would rather have **no prompt at all**, register the same server at *local*
> scope instead: it lives in your own Claude Code configuration, which nobody else can
> write, so no consent gate applies.
>
> ```sh
> claude mcp remove amabie -s project
> claude mcp add -s local amabie -- amabie mcp
> ```
>
> Both scopes are measured with the real CLI
> ([`tooling/probes/v13-mcp-scope.mjs`](tooling/probes/v13-mcp-scope.mjs)): project →
> `pending-approval`, local → `connected`. The trade-off is real: project scope gives a
> teammate the tools from a clone (each of them approves once), while local scope means
> each developer runs `amabie setup --yes` themselves — which is the documented model
> anyway. [`tooling/probes/v13-agent-integration.mjs`](tooling/probes/v13-agent-integration.mjs)
> measures the state rather than assuming it.

**Why isn't this just "run the tests"?**

| A green suite can be green because… | Amabie's answer |
|---|---|
| the same checks were already green **before** the change, so they say nothing about it | proof must **discriminate**: the check has to fail without the change and pass with it, measured against the sealed base commit |
| a **stated requirement** is covered by no check at all | every authorized requirement needs a **sealed proof binding** (`amabie bind`), or it stays `NOT PROVEN` |
| "prettier" / "feels faster" was never machine-checkable | subjective duties are a **separate, human act** (`amabie accept`, in a terminal) — they can never become a fake technical `PASS` |
| the only evidence is a test **the worker just wrote** | Amabie says so out loud, in the verdict (worker-authored-evidence caveat) |

## Install

```bash
npm install -g ./amabie-cli-2.0.0.tgz
amabie --version                             # amabie 2.0.0
amabie --version --verbose                   # runtime, CLI path and executable SHA-256
```

Amabie 2.0.0 is a **local release candidate**, not a published npm version. The
prepared tarball has package identity `@amabie/cli` and **zero runtime dependencies**.
Require Node.js 22+, npm and Git. Verify its supplied `.sha256` before installing:
`Get-FileHash ./amabie-cli-2.0.0.tgz -Algorithm SHA256` in PowerShell, or
`sha256sum --check amabie-cli-2.0.0.tgz.sha256` on Linux. Do not substitute the
historical Amabie checksum for the current Amabie artifact.

Start with the runnable [Quickstart](QUICKSTART.md), including a passing change,
an intentional regression and an uncovered change that stays `NOT PROVEN`.
The installed package includes the same guide and its three-file example.

> **Version note.** Amabie 2.0.0 is being prepared from the published Amabie v1.5.0 baseline. The latest
> published artifact is **v1.5.0**, under its original Amabie name, in the
> [historical release](https://github.com/criptofn/Canary/releases/tag/v1.5.0).
> Installing that package does not install Amabie 2.0.0. For a source checkout,
> run `npm ci` and `npm run build:force`, then use `node apps/cli/dist/src/main.js`;
> building does not put `amabie` on PATH. Prepare an installable local package
> with `node tooling/pack.mjs`, then install `./pack/npm/amabie-cli-2.0.0.tgz`.
> The `amabie` executable remains as a compatibility alias for existing v1.5 hooks and scripts.
> v1.3's own bytes are described in [`docs/RELEASE-1.3.md`](docs/RELEASE-1.3.md).

## Use your coding agent normally

```bash
cd your-repo
amabie setup --check    # optional read-only preflight; runs no project checks and writes nothing
amabie setup --yes      # detect the project, seal its checks, wire your agent
```

Claude Code also receives a short completion workflow when a session starts or
resumes: the test command Amabie will run, the installed repair command, and the
instruction to finish normally so the Stop hook runs the full checks. Startup
guidance runs no checks and certifies nothing. Re-run setup once to add it to an
existing installation; unrelated startup hooks are preserved.

If your checks launch Java, Python, Git or another external tool, name it during
setup: `amabie setup --yes --toolchain java --toolchain python`. Amabie finds each
named tool on your shell PATH and seals its executable directory. This authorizes
the directory, including other executables in it; repository directories are
refused. You can still specify a directory with `--toolchain-dir "<absolute path>"`.
`--clear-toolchain-dirs` revokes the previously sealed directories.

`setup --check` reports the checks and toolchains it can see without running
project commands, writing files, or authorizing tool paths. It cannot discover
every tool a project script may launch; actual setup still runs the checks.
`setup` prints the checks it found, smoke-runs them once, and ends in `READY` —
or tells you exactly what it could not do. It wires Claude Code automatically
(merging with, never overwriting, your existing hooks) and registers Amabie's
four everyday MCP tools. At the start of every new project request, the agent
registers that request with `amabie_task`, copying explicit acceptance criteria
verbatim or passing an empty list when none were stated; generic placeholders are refused.
This is untrusted input: it adds obligations but cannot bind checks or prove
completion. Claude Code's `PreToolUse` hook blocks shell, write, delegation and
MCP calls until task registration succeeds; after registration, unbound
objective criteria do not stop implementation. They stay `NOT PROVEN`, and the
completion hook reports the operator binding hint. Subjective-only duties can
continue to human acceptance. The hook protects the normal Claude Code tool
path; `LOCAL` still runs under the same user identity, so a same-user process
can change the local config or hooks. Add
`--mcp-profile expert` for isolated `work` / `finish` operations or the MCP
integration inventory; `amabie agents` remains available on the CLI.

Setup checks all managed config files before writing hooks. If a later write fails,
Amabie restores earlier hook and MCP files when their bytes still match the changes
from that setup attempt; a file changed in the meantime is left alone and reported.

Then ask your agent for the change. It can implement and test while criteria
remain unbound; Amabie keeps them `NOT PROVEN` until an operator binds proof.
The completion hook runs the planned checks and reports any remaining gap.

## What Amabie actually catches

This is the behaviour the whole product exists for, and it is measured end to end
by [`tooling/probes/v13-journey-baseline.mjs`](tooling/probes/v13-journey-baseline.mjs)
(section F), which drives the real completion hook:

| your agent changed… | what Amabie does |
|---|---|
| behaviour, and some check **fails without the change and passes with it** | allows the completion — the checks are evidence about this change |
| behaviour **no declared check can see** (suite green on both sides) | **blocks** it: `Amabie blocked completion: NOT PROVEN — the sealed checks pass on the base commit too, so they carry no evidence about this change (greeting.cjs)` |
| only prose, licences or docs | allows it — no behaviour moved, so nothing is asked to discriminate itself |

That middle row is the point. A green suite that cannot tell your change from the
base is not evidence about your change, and Amabie will not let it be reported as
if it were.

## Two minutes, end to end

```bash
cd your-repo
amabie setup --yes
```

```
repo: /home/you/your-repo
package manager: npm (package-lock.json found)
verification plan (from what this project already declares — Amabie runs only your own checks; change them in their own files):
  ✓ tests: npm run test
harness: Claude Code — hook installed into this project
harness: OpenAI Codex CLI — Stop hook installed into this project (.codex/hooks.json) — Codex runs a project hook only after you review and trust it once (/hooks), so an untrusted hook gates nothing
Claude Code will run Amabie automatically when the agent finishes a turn here.
OpenAI Codex CLI will run Amabie when a turn ends here — the Stop hook is in .codex/hooks.json.
  Codex will NOT run it until you review and trust it once: run `codex` in this project, then `/hooks`, and trust the Amabie Stop hook. Until you do, a Codex completion is NOT gated.
both harnesses are wired here: Claude Code gates completions as soon as this setup ends; Codex gates them once you trust the hook above.
agent tools: registered in .mcp.json — your agent can now ask Amabie whether it is done, instead of guessing. Your other MCP servers are untouched; `amabie uninstall` removes exactly this entry.
  Claude Code asks you to approve a project's MCP server once — run `claude` there and approve it; until then the server is listed but its tools are not available.

smoke test (running your own project scripts):
✓ tests: npm run test (exit 0)

note: no task acceptance criteria are registered. READY means these checks and hooks are set up; Amabie cannot assess requirements it was never given.
  for task-specific proof, register measurable criteria before handing off with `amabie task --requirement "<observable behavior>"`, then bind them to a sealed script with `amabie bind <plan-script> --requirement "<same text>" --reseal`.
Objective requirements need a matching sealed check. Human acceptance applies to subjective
requirements only; approving one subjective part never waives a separate measurable requirement.

READY — Amabie is active here: it will run these checks whenever the AI agent says it is done, and will interrupt the human only when something needs them.
next: try it: break a test on purpose and let the agent finish — Amabie will say so. doctor: amabie doctor
```

Then ask your agent for the change, and let it finish. Three things can happen:

1. **Everything is fine** → you hear nothing. Amabie is silent when there is
   nothing to say, and the agent's completion is allowed.
2. **A check fails** → the agent is blocked once and told exactly what failed, in
   one short message that names the check and the failing test — with the full
   runner output left **on disk**, not pasted into your conversation.
3. **The change is real but nothing checks it** → blocked as `NOT PROVEN`, with the
   one thing that would prove it. See
   [What Amabie actually catches](#what-amabie-actually-catches).

At any point, `amabie doctor` answers "is Amabie really protecting this repo, and
do the checks run?" with `READY` / `NOT PROVEN` / `NEEDS ATTENTION` / `UNSUPPORTED`
and the one command that fixes it. `amabie status` answers the same question about
**state** without running anything, and `amabie result --json` gives an agent the
same answer compactly and for free.

Running `amabie` without a command shows compact read-only connection status and
points to `amabie result` for the last verification and `amabie --help` for the
full command list. Its existing no-command exit code remains 3.

`doctor` also reports how many task requirements were registered and how many
proof obligations are met, unproven, or unmet. `result` shows the same scope for
the historical run, including evidence caveats; older records without it say
that the proof scope was not recorded. Passing checks alone do not establish
acceptance criteria that were never registered.

When one check fails, doctor prints its sealed check id and a focused recheck command.
Use `amabie doctor --check <id>` while repairing that check; it returns `PARTIAL` and
does not update the completion checkpoint. Run `amabie doctor` for the full gate.

For an unproven regression, add a test that fails against the project's starting
commit and passes with your change. Amabie runs that comparison automatically;
keep working on this branch.

## Expert mode — when a change must be *proven*, not just green

Not part of the ordinary loop, and **measured to cost more than the everyday path**
(see [the arm map](#what-the-benchmarks-actually-show): the `work` → `finish`
ceremony ran at **177.8 %** of a plain agent's tokens, where the everyday shape ran
at **92.7 %** in the **historical v1.3** measurement, with identical correctness).
That 92.7 % is **historical and superseded** — the v1.5 everyday figure is
**withdrawn**, so no current everyday percentage exists. Reach for the candidate path
when a change needs evidence rather than a green suite — for example when someone
else's work must be verified before it reaches your branch.

```bash
# operator, BEFORE the handoff — declare each stated requirement, then bind it
amabie task "make the dialog prettier" --requirement "the button is #D94141"
amabie bind e2e --requirement "the button is #D94141"   # attach it to a sealed check
amabie setup                                            # re-seal: the binding becomes frozen authority

# worker
amabie work fix "make the dialog prettier" --kind ui    # register + open an isolated candidate
#   ...work only inside the candidate directory printed above, then commit THERE...
amabie finish fix                                       # verify from outside; promote only if the proof holds
```

**Bind the requirements before you hand off — measured, not stylistic.** In one
benchmark, five requirements that were *declared but never bound* cost the
guarded run **1.5–1.7M tokens and 41–45 turns**, because the worker was left
pursuing a duty only the operator could close. The same five requirements
**bound** to sealed checks came out **cheaper than the unprotected arm** at 100%
delivered correctness (see [what the benchmarks actually show](#what-the-benchmarks-actually-show)).

**What you get after that single command:**

- *automatic* — the agent finishes → Amabie runs your checks → all pass:
  total silence (you are not interrupted); a check fails: the agent is
  blocked once and sent back to repair it, and if it still fails, you are
  told in plain words. The automatic hook checks the configured plan; task-aware candidate
  completion also requires registration and isolation.
- *self-healing* — re-run `amabie setup` any time; it repairs its own wiring,
  never duplicates a hook, never destroys your edits.
- *reversible* — `amabie uninstall` removes exactly Amabie's own changes
  (identified by recorded command strings, never by guesswork) and keeps every
  other settings entry (content preserved — re-serialization may reformat
  whitespace). If cleanup can't fully succeed it keeps its ownership record so
  the advertised retry actually works.

**Supported today.** Amabie discovers the checks your project already declares —
and it never invents one:

| Project | Discovered from | Checks |
|---|---|---|
| Node / JS / TS | `package.json` (+ its lockfile) | `test`, `typecheck`, `build`, `bench`, `e2e` scripts |
| Python | `pyproject.toml`, `setup.py`, `setup.cfg`, `tox.ini`, `requirements*.txt` | `pytest`, `tox`, `unittest`, plus `mypy` / `pyright` / `ruff` |
| Rust | `Cargo.toml` | `cargo test`, `cargo check`, `cargo build` |
| Go | `go.mod`, `go.work` | `go test ./...`, `go vet ./...` |
| **Any other command-driven project** | the executable truth you already declare — CI workflow commands, `Makefile` / `Taskfile` / `justfile` targets, CMake+CTest or Meson, a shipped `gradlew` / `mvnw`, `pom.xml`, `build.gradle*`, `*.sln` / `*.csproj`, `Package.swift`, `build.zig`, `phpunit.xml`, `composer.json`, `Rakefile`, `mix.exs`, `shard.yml` — or your own `amabie.project.json` (argv arrays, never a shell line) | those commands, **sealed and pinned** to absolute paths, verified as **UNIVERSAL**: the command really ran, with that exit status, bound to the candidate's bytes — but the runner's internals were **not** observed |

Agents are reported by what they can actually do, not by what we wish they could:

| Agent | Capability |
|---|---|
| Claude Code | **GATED** — `amabie setup` installs completion and pre-tool hooks; failing checks block completion, unregistered tasks block project changes, and unbound objective criteria remain `NOT PROVEN` |
| OpenAI Codex CLI | **GATED, after one trust step you take** — `amabie setup` installs a `Stop` hook into this project's `.codex/hooks.json` that runs the same checks; Codex runs a project hook only once you have reviewed and trusted it (`/hooks`), so until then the file is written and gates nothing |
| Any other command-line agent | **ADVISORY** — the machine-readable protocol (`amabie result --json`, `amabie doctor --json`) tells the agent what Amabie knows, and cannot block it. `amabie agents install <id>` adds a marked, removable block to `AGENTS.md` saying so |

`amabie agents` prints that table for the repository in front of you. Security
capability is reported the same way: **`LOCAL`** is what this build can honestly
claim today, and `HARDENED` is not available yet
([why](docs/CAPABILITY-LEVELS.md), and
[what a real boundary would require](docs/TRUST-ARCHITECTURE.md)). **`LOCAL`
proof is same-user and operator-selected**: the caller who runs `amabie setup
--yes` chooses the plan and the starting commit that are checked, and nothing
checks that the caller is not the worker — so a worker with your authority can
re-run `setup` and complete against a plan and baseline it sealed itself.
`HARDENED` is the worker-independent path (a broker with a different OS
identity), and it is not available in this build. Full matrix,
including what is deliberately *not* supported:
[docs/COMPATIBILITY.md](docs/COMPATIBILITY.md). Upgrading an existing
installation: [docs/MIGRATION-1.0-TO-1.1.md](docs/MIGRATION-1.0-TO-1.1.md).

**What `READY` means — and what it does not.** READY is printed only when
Amabie's wiring was verified to exist *and* your detected checks were
actually executed and passed in that run. Nothing executed → NEEDS
ATTENTION, never a fake green. This auto-watched plan runner is the everyday
path; the much stronger **attested proof pipeline** (`amabie prove` /
`amabie check`, below) is a separate, different promise for release-grade
claims. If the only check that distinguishes a change uses assertions the worker
added or rewrote, `doctor` prints an evidence caveat: the check is change-sensitive,
but its contents are not independent authority.

## What the benchmarks actually show

> **What it costs, in one paragraph.** There is **no supported everyday token-saving figure** — the
> one this release published is withdrawn, and the corrected data cannot resolve an effect. What can
> still be said is narrower and it is stated with its own limit below: on short, well-bounded
> **confined** tasks in our replicated experiments, measured savings ranged from roughly **27 % to
> 87 %** (best pairing, not typical, not universal).
>
> On the everyday workflow, this release **WITHDRAWS its token-saving figure**. The v1.5 candidate
> published `83.21 % of Plain (-16.79 %)`; an independent audit found the aggregate pooled a cell
> measured by the **fallback estimator** rather than the declared provider-native ledger, and this
> closure found the same class of defect again in the follow-up run (a tree edited mid-measurement).
> Under the corrected accounting there are now **two COMPLETE runs and they disagree in sign**:
> **80.74 % (-19.26 %)** and **102.91 % (+2.91 %)** - a **22.17-point spread** against a **44.3 %
> drift in the plain arm alone**. Pooling them gives 89.81 % (-10.19 %), which is **smaller than the
> spread between runs of the identical configuration**; the aggregate probe prints that warning
> itself. **No saving claim is supported, and none is made.** The standing MCP payload IS now inside
> the measurement and costs ~438 tokens (measured, not derived), so the **accounting** is fixed -
> the **saving** is not supported. See
> [`docs/BENCHMARK-EVERYDAY-1.5.md`](docs/BENCHMARK-EVERYDAY-1.5.md).
>
> **The qualification, which is part of the claim, not a footnote to it:**
>
> - those confined measurements are **experimental** — the fixtures were authored and validated for
>   the `guarded` (everyday) arm, so a confined run is a like-for-like experiment *outside* that
>   configuration, which the harness itself prints on every such run (full caveat below);
> - **87 % is not typical and not universal.** It is the best pairing in a 3×3 replication of the
>   single most favourable cell, not an average, and the long stateful task is repeatedly *more*
>   expensive than Plain under confined transport;
> - **Amabie does not always save tokens.** The ≤75 % aggregate target was not met (the best measured
>   everyday aggregate is **withdrawn** and no current figure is claimed), and this release makes no such claim;
> - per task, the **withdrawn** generation was not uniform: it ranged from **43.8 % MORE expensive to
>   38.7 % cheaper**, and on the smallest fixture Amabie cost more in **both** of those runs. Those
>   per-cell observations stand as observations; the **aggregates** built from them
>   (**−19.3 %** and **−13.4 %**) are **superseded**, because that dataset is the one the audit
>   disqualified. The corrected pair of COMPLETE runs is **−19.26 %** and **+2.91 %** — read those,
>   not these.
> - **the standing payload is now accounted for — and it was overstated before.** The tool server
>   `setup` registers is re-advertised on **every turn** — measured from the real server over the real
>   transport at **5,726 bytes** (1,475 B of instructions + 4,251 B of tool definitions), of which
>   **1,923 B (33.6 %) is expert-only ceremony** (`amabie_work` / `amabie_finish`) that an everyday user
>   never calls ([`tooling/probes/v13-standing-context.mjs`](tooling/probes/v13-standing-context.mjs)).
>   Its cost is **~438 tokens per session, MEASURED provider-natively** — **not** the ~1,432 that
>   `bytes ÷ 4` implied, which overstated it **3.3×**. v1.5 now passes `--mcp-config` in the benchmark,
>   in the measurement (proven in-session), so the accounting is now right; the historical 92.7 % did not
>   include it. The v1.5 saving figure is nevertheless **withdrawn** — see the corrected data above.

**The arm map — which Amabie *shape* costs what.** Same three fixtures, same
model, same starting bytes, same hidden oracle. **`plain` means not using Amabie at
all**: `amabie setup` runs for the protected arms only (`run-trial.mjs:254`, and the
harness says so again at line 803 — "the plain arm HAS no Amabie"), so every ratio
below is Amabie against genuine plain, not two Amabie configurations differing by a
prompt. (An earlier version of this README said setup ran for *every* arm and that
the arms differed by "one paragraph of instruction". That was wrong, and it
understated the result: the `plain` arm was never gated.)

| task | plain agent | **everyday shape** | ceremony (`work`→`finish`) | confined transport |
|---|---|---|---|---|
| bound-requirements | 126,977 | **105,255** | 200,565 | 20,472 |
| bug-sum | 70,070 | **70,083** | 153,178 | 26,970 |
| stateful-replay | 212,777 | **204,454** | 374,821 | 595,419 |
| **total** | **409,824** | **379,792 — 92.7 %** | **728,564 — 177.8 %** | **642,861 — 156.9 %** |
| correctness | 12/12, 15/15, 406/406 | *same* | *same* | *same* |

*(The table above is the HISTORICAL v1.3 measurement and is kept as a record. It is not Amabie's
current footprint — see the bullets.)*

Read it this way, because it is the only reading the numbers support:

- **HISTORICAL (v1.3, one recorded run per cell): 92.7 % of Plain, −7.3 % in aggregate**, at equal
  measured correctness with no false done. Per task that run measured **17.1 % lower to essentially
  parity (+0.02 %)**. **It is historical, and it understates Amabie's cost:** that run launched the agent
  **without** the MCP server, so it excluded a standing payload of 5,726 bytes per turn.
- **CURRENT (v1.5): NO TOKEN-SAVING CLAIM IS MADE. The earlier v1.5 figure was withdrawn.** The
  candidate published `83.21 % of Plain (-16.79 %)`. An independent audit showed the aggregate pooled a
  cell whose tokens came from the **fallback estimator** instead of the declared provider-native ledger;
  this closure then found the same class of defect in the replacement run, whose **six cells carry five
  different instrument digests** because the tree was edited while it measured. Under the corrected
  contract (`tooling/benchmark/eligibility.mjs`) a cell counts only if its run completed on the declared
  ledger, and a run counts only if every cell is eligible **and all cells share one instrument**;
  anything else is reported **INCOMPLETE** and contributes no ratio at all.
  What the corrected data shows: there are **two COMPLETE runs and they disagree in sign** —
  **−19.26 %** (80.74 %) and **+2.91 %** (102.91 %, Amabie *more* expensive) — a **22.17-point spread**
  against a **44.3 % drift in the plain arm alone** (376,688 → 543,518) on identical configuration.
  Pooling them gives **−10.19 %**, which is **smaller than the spread between runs of the identical
  configuration**, and the aggregate probe prints that warning itself. The post-closure run `r4` is
  also the only one whose tree was **frozen** while it measured, so it is the only one whose six cells
  are unambiguously one experiment.
  **This benchmark, at n=1 per cell on Amabie-authored fixtures, cannot resolve an effect of this size
  in either direction.** Method, every cell and every limit:
  [`docs/BENCHMARK-EVERYDAY-1.5.md`](docs/BENCHMARK-EVERYDAY-1.5.md).
- **The standing payload costs ~438 tokens per session, MEASURED — not the ~1,432 that `bytes ÷ 4`
  implied.** JSON tool schemas tokenise far better than four bytes per token, so the derived figure
  overstated the payload by **3.3×**. `bytes ÷ 4` must not be quoted as tokens.
- **The ceremony costs more than it saves** (+77.8 %) with identical correctness,
  which is why it is documented here as expert mode rather than the ordinary path.
- **The confined transport is a trade, not a win**: 2–6× cheaper on short,
  well-specified changes, and much more expensive on the long one. (The column
  above is measured WITHOUT the opt-in per-batch check; see the full benchmark
  below for what that flag does.)

**The ≤75 % token target is not met — and since the v1.5 withdrawal there is no current everyday figure
at all.** The historical 92.7 % excluded the standing payload, and the v1.5 replacement was withdrawn
(see above), so the everyday path currently has **no supported aggregate number**.
A full benchmark of the confined path with the opt-in per-batch check puts it at
**86.8 % of plain by median, 110.5 % by mean** — about parity, not a saving — with equal correctness on every
cell that could run at all. Per cell the picture is sharper and more favourable: on the two short bound cells
it beats the target in **all six replicated runs** (**13.1-36.5 %** and **54.0-73.3 %** of plain), and the
long stateful cell is the whole reason the aggregate stays above it (120-260 %). Both numbers are stated
because either one alone hides the other.

> **Where the confined numbers come from, and how far they may be quoted.** All three benchmark fixtures
> declare `benchmarkConfig: {"arm": "guarded"}`, so every `plain` and confined run above is — in the
> benchmark harness's own printed words — *"an experiment outside the configuration the fixture was
> authored and validated for; do not present it as that fixture's measurement."* That applies to **both**
> arms equally, so the ratios are like-for-like, but no absolute confined figure here is a fixture's
> validated measurement. The everyday/`guarded` numbers were the exception in *design*: `guarded` **is**
> the arm those fixtures were authored for. That design advantage did **not** survive measurement — the
> everyday aggregate is **withdrawn** and no current figure is claimed — so the historical **92.7 %** is
> quoted only as history, never as the stronger current measurement.

Short version, with the full ledgers linked below — and stated the way the
evidence supports it:

**This corpus did NOT demonstrate a general correctness advantage for Amabie.**
On the consolidated 13-fixture matrix the plain model already hit a ceiling:
**36/36 delivered correct**, with zero false dones and zero false greens in
*both* arms. What the measurements do show is a **token** effect that depends
entirely on whether the operator bound the requirements:

| Configuration (one benchmark, one model, one host) | Measured result |
|---|---|
| 13 fixtures, **no declared proof** (`bench-final`) | plain **36/36** correct · `guarded` **33/33** correct · 0 false dones, 0 false greens in both arms · `guarded` **+40.2%** tokens |
| requirements declared **and BOUND** to sealed checks (`bench-r11`) | plain 125,369 tokens → `guarded` **100,812 (−19.6%)**, `invisible` 91,439 (**−27.1%**) · **5/5 correct in every arm**, 0 false dones, 0 false greens |
| requirements declared and **NOT bound** (`bench-r9`) | `guarded` **1.5–1.7M tokens over 41–45 turns** — the worker pursuing a duty only the operator can close |

**The safe claim is exactly this:** *in one bound-requirement benchmark, Amabie
reduced model-token use by 19.6% while maintaining 100% delivered correctness.*
It is **not** "Amabie saves 19.6% of tokens", it is **not** a correctness claim,
and it is **not** a universal result. An earlier configuration measured −58.5%
tokens with correctness unchanged (`bench-r6`); that is a **historical
configuration result**, not the v1.1 headline. A −56.4% configuration
(`bench-r5`) is explicitly **rejected as a default** because it lost one
delivered-correct result and produced a false green. **Reliability outranks
token savings.**

Numbers, denominators and the counter-examples: [`tooling/benchmark/RESULTS.md`](tooling/benchmark/RESULTS.md) ·
what the set can and cannot tell you: [`tooling/benchmark/BENCHMARKS.md`](tooling/benchmark/BENCHMARKS.md) ·
the consolidated matrix and its three corrected defects: [`docs/V1.1-STATUS.md`](docs/V1.1-STATUS.md) ·
**v1.2's false-done corpus and its result — which is that no correctness advantage was demonstrated**:
[`docs/V1.2-BENCHMARK.md`](docs/V1.2-BENCHMARK.md).

> **The v1.2 result, in one line, so it cannot be missed:** five fixtures were authored for the failure
> classes v1.1 had no coverage of. In the configuration the harness accepts, the guarded arm was
> **correct on all seven fixtures measured** — the completion path works end to end — and it cost **more
> than the bare agent on every one of them**, by an amount that depends heavily on the task: **+3.2% to
> +408.7%**, with four paired fixtures totalling **+115.1%** (539,419 → 1,160,170 tokens). **The plain
> agent was correct in every trial; no correctness advantage was demonstrated, and Amabie's own KPI
> reads FAILS THE TOKEN REQUIREMENT.** The three measured reasons the corpus cannot show an advantage,
> and the caveats that limit each number, are in that document.

### v1.5 release and post-release evidence

> **Post-release native pilot (2026-10-01, unpublished improvements).** Twelve Claude Code
> sessions on three projects using local `qwen3.5:9b` produced 6/6 correct solutions without
> Amabie and 4/6 with Amabie after an explicitly post-pilot H1 check. Four Amabie sessions
> passed their actual completion hook; native token use was 3.95× the plain arm. This small
> pilot supports no token-saving claim. [Results, artifact identity and limits](docs/POST-V15-NATIVE-PILOT-COMPLETE-2026-10-01.md).

The subsequent unpublished correction accepts sufficient imported `*-test.js` checks,
including uncommitted files, and retains baseline failure logs. Its H3 controls reject
weak tests and the old faulty implementation. [Repair and evidence](docs/POST-V15-IMPORTED-CHECK-REPAIR-2026-10-01.md).
Its next native H3 pair completed correctly in both arms; Amabie's actual Stop
hook passed with the worker-test provenance caveat retained. The Amabie session
used 28 turns versus four without Amabie, so this remains a completion improvement
without an efficiency claim. [Native follow-up](docs/POST-V15-IMPORTED-CHECK-NATIVE-2026-10-01.md).

> **v1.5 status: the token-saving headline is WITHDRAWN.**
> The v1.5 candidate published `83.21 % of Plain (−16.79 %)` for the everyday path. An
> independent audit found that aggregate pooled a cell measured by the **fallback estimator**
> rather than the declared provider-native ledger, and the replacement run measured a tree
> that was **edited while it ran**. Under the corrected rule
> ([`tooling/benchmark/eligibility.mjs`](tooling/benchmark/eligibility.mjs)) the **two COMPLETE
> runs disagree in sign** — 80.74 % (−19.26 %) and 102.91 % (**+2.91 %**) — and their spread is
> larger than any delta pooled across them. **v1.5 therefore claims no token-saving percentage
> at all**: not a smaller one, not a different one. What survives is a measured **cost**, not a
> saving: the standing MCP payload is genuinely inside the guarded sessions (6/6 guarded
> advertised it, 0/6 plain) and costs **~438 provider-native tokens** per session — **not** the
> ~1,432 that a `bytes ÷ 4` derivation implied. One intermittent Windows containment-sweep
> failure is **open and unexplained** (recorded as open, not re-rolled until green). Provenance of
> the gates that have run: **`e51b6fc` is the last product-source change** — the audited product
> fixes and the local release batteries belong to it — while the **latest fully CI-tested candidate
> is `d3f6a9c`, all six legs green in run
> [`36168541720`](https://github.com/criptofn/Amabie/actions/runs/36168541720)** (Windows core
> terminal success: 1,211 tests, 1,206 pass, 0 fail, 5 skipped). Evidence:
> [`docs/AUDIT-KIT-1.5.md`](docs/AUDIT-KIT-1.5.md) ·
> [`docs/CLAIM-EVIDENCE-MATRIX-1.5.md`](docs/CLAIM-EVIDENCE-MATRIX-1.5.md) ·
> [`docs/POST-AUDIT-CLOSURE-1.5.md`](docs/POST-AUDIT-CLOSURE-1.5.md) ·
> [`docs/BENCHMARK-EVERYDAY-1.5.md`](docs/BENCHMARK-EVERYDAY-1.5.md).

## Known limitations

What Amabie does **not** claim is as much a part of the product as what it does.

- **`LOCAL` is not an OS isolation boundary.** A same-UID worker can replace the
  local root of trust, **or simply re-run `amabie setup --yes`** and make a
  different plan and starting commit the ones that are checked — `setup` never
  checks the caller's identity, so this is expected onboarding behaviour at
  `LOCAL`, not a defect. Those limits are documented, not papered over
  ([`docs/CAPABILITY-LEVELS.md`](docs/CAPABILITY-LEVELS.md)).
- **`HARDENED` is not available in this release.** The provider/broker
  architecture exists and refuses to serve without a proven separation, but
  `HARDENED` is only ever produced by a boundary **measurement** in which every
  control is observed present (`amabie provider status`).
- **A bound check is declared proof coverage inside Amabie's model — not
  semantic truth.** Binding a requirement to a sealed check says the plan
  measures something for it; Amabie does not thereby *understand* the
  requirement.
- **Confined mode can only run work whose requirements are bound.** Of the **20**
  benchmark fixtures this repository maintains, only **5** have every declared
  requirement bound to a sealed check (`bound-requirements`, `bug-sum`,
  `impossible-test`, `stateful-replay`, `version-bump`). The other 15 are
  **refused before any model is started** — measured **0** worker launches,
  **0** worker tokens spent, and **no** delivered-correctness credit. A refusal is
  not a result, and no binding was invented to raise the count.
- Amabie does **not** claim to "never fail open" universally, nor that every
  promoted change is independently **semantically** proven.
- Claim strength is tiered: only the observed runners (`mocha`, `node --test`,
  `pytest`, `unittest`) bound to an authority can carry a strong verdict; an
  unknown runner is `INCONCLUSIVE_ONLY` by construction, and printed text never
  upgrades a verdict.
- `NOT PROVEN`, `NEEDS ATTENTION`, `UNSUPPORTED`, `INCONCLUSIVE` and `BLOCKED`
  are first-class outcomes — and **a skip is not a pass**.
- **On the everyday path agent edits are not confined to an OS boundary.** The
  Claude `PreToolUse` hook requires task registration before matched shell,
  write, delegation and MCP calls run. Unbound objectives remain `NOT PROVEN` at
  completion, and those tools still run with the user's normal authority. The
  confined executor exists (see [`docs/TRUST-ARCHITECTURE.md`](docs/TRUST-ARCHITECTURE.md))
  and is driven by Amabie itself, not by your editor.
- **A completion is blocked at most once per stop.** Amabie will not fight the
  harness in a loop: after one repair attempt it reports honestly and lets the
  turn end, so a stubborn failure reaches you instead of spinning.
- **Amabie sends nothing anywhere.** There is no telemetry and no network
  dependency; the only measurements are local ones you can read
  (`AMABIE_METRICS=<file>` writes one local record per invocation; `AMABIE_METRICS` remains a legacy alias).
- **Cursor is not a claimed integration.** Cursor documents importing Claude Code
  hooks — including `Stop`, honoured as an automatic follow-up — which would make
  the hook `setup` installs effective there. This project has **not reproduced
  that on a real Cursor install**, so `amabie agents` reports Cursor as
  **`UNMEASURED`** rather than as protection. Cursor also documents no way to
  remove its native tools, so Amabie cannot put Cursor's own edits inside an OS
  boundary. Reading the table: `GATED` means measured and blocking, `ADVISORY`
  means the agent is told and may ignore it, `UNMEASURED` means the mechanism is
  documented and nobody here has checked it.

Full list: [`docs/RELEASE-1.1.md`](docs/RELEASE-1.1.md) ·
[`docs/V1.3-PRODUCT-AUDIT.md`](docs/V1.3-PRODUCT-AUDIT.md).

---

## For the proof-minded: what Amabie fundamentally is

Amabie takes a **baseline** state and a **candidate** change, runs relevant
deterministic checks against both in disposable, sanitized (process/env-boundary
enforced) workspaces, reproduces any divergence, and emits a
**machine-readable Evidence Bundle** with a **deterministic classification**.
Only after that may an LLM explain the evidence — the LLM can never render the
verdict.

```
Classification ∈ PASS | CONFIRMED_REGRESSION | PRE_EXISTING_FAILURE
                 | FLAKY | INFRASTRUCTURE_FAILURE | INCONCLUSIVE
```

Amabie is an orchestrator, not a re-implementation of your toolchain: real
test frameworks are the evidence engines (RepoWise, Semgrep, CodSpeed,
Playwright, … may later feed evidence behind optional adapters — the core
runs with zero integrations).

## The dependency proof pipeline

A controlled, historical verification domain: the dependency update
**axios 0.27.2 → 1.0.0**, judged by a *real* downstream project's *real*
test suite — `ctimmerm/axios-mock-adapter` pinned at commit
`b8804442` (its own devDep was exactly `axios ^0.27.2`).

What Amabie reproduces on demand, from scratch each time:

```
baseline  axios 0.27.2  →  128 passing, 0 failing        (exit 0) ×2
candidate axios 1.0.0   →  125 passing, 3 failing        (exit 3) ×3 unanimous
tree drift              →  confined to axios subtree     (2 entries, verified; re-derived from retained npm-ls snapshots)
normalized output       →  byte-identical per arm, across rounds AND runs ON THE PROOF HOST (host-exact assertions
                           are gated on the actual runtime; off-host the proof honestly reports INCOMPLETE)
classification          →  CONFIRMED_REGRESSION (rule 5) — pure function, no LLM
failing tests           →  "can pass headers to match to a handler" (AxiosHeaders),
                           "handles baseURL correctly" (URL resolution) — genuine
                           axios 1.0.0 behavior changes this project depended on
```

Reproduce it:

```bash
npm ci            # lockfile-exact, reproducible install
npm run build
npm test          # 1191 tests / 0 failures, 4 host-bound skips (measured 2026-09-20; a skip is never a pass)
npm run prove     # fresh end-to-end run; PASS requires the committed proof host (36 assertions
                  # executed, zero skips). On any other runtime it honestly exits 2 (INCOMPLETE):
                  # the 22 portable assertions must all hold, the 6 host-exact ones are skipped,
                  # never silently passed.
npm run report    # no args: renders the latest run's evidence. Exit 0 means SELF-CONSISTENT:
                  # byte + run-identity + tree-snapshot + classification re-derivation checks
                  # passed ON THIS MACHINE — it does NOT mean the committed proof was consulted
                  # (that is prove/check; round-4 F1). Otherwise NOT SELF-CONSISTENT, exit 3.
```

Also demonstrated by this fixture: **Amabie does not manufacture
regressions.** An earlier candidate (axios-cookiejar-support @ f1e045d4)
came back PASS — honestly reported, ledger in
[`fixtures/axios-0.27-to-1.0/README.md`](fixtures/axios-0.27-to-1.0/README.md).

## CLI

The two tiers share one binary; `amabie` below is the linked command, or
`node apps/cli/dist/src/main.js` straight from a checkout.

**Everyday** — what an ordinary user actually types:

```bash
amabie setup --check [--json] # read-only preflight: plan, visible toolchains, managed-file conflicts
amabie setup     [--yes] [--mcp-profile everyday|expert] # install + smoke-run; everyday is default
amabie doctor                # full gate: READY / NOT PROVEN / NEEDS ATTENTION / UNSUPPORTED
amabie doctor --check <id>   # one sealed diagnostic check; PARTIAL, never completion proof
amabie status                # read-only state, runs nothing: CONNECTED / NEEDS ATTENTION / NOT CONNECTED
amabie result    [--json]    # the same state as ONE compact JSON object — free, for agents and scripts
amabie agents    [install|uninstall <id>]   # which agents work here, and at what capability
amabie mcp                   # MCP server on stdio: the same operations as tools, for any MCP client
amabie uninstall             # remove exactly Amabie's own changes (recorded strings, never guesswork)
```

**Expert** — the isolated-candidate lifecycle and the proof obligations. Measured
to cost **more** than the everyday path (see the arm map above), and only needed
when a change must be *proven* rather than merely green:

```bash
amabie task "<intent>" [--requirement "…"]  # declare the parts that must be proven separately
amabie bind <script> --requirement "…"       # the OPERATOR's act: attach a stated requirement to a sealed check
amabie work <name> "<intent>"  # register the intent + open an ISOLATED candidate in one step
amabie finish <name>         # verify the candidate from outside it, then promote only if the proof holds
amabie accept <name>         # close a SUBJECTIVE duty — in a terminal, by a human
amabie isolate <name> [--verify|--promote|--list|--remove]   # the primitives work/finish delegate to
amabie provider <sub>        # status | install-plan | uninstall-plan | serve | call — the HARDENED provider lifecycle
amabie checkpoint            # harness-internal: runs at the agent's completion boundary (Stop hook)
```


`amabie provider status` MEASURES the boundary rather than asserting it: which
account this process is, whether the store can be written by a worker identity,
whether a broker service exists and as which account, and what a restricted
runner could actually be jailed with. `HARDENED` appears only when every one of
those controls is observed available. `amabie provider install-plan` prints the
exact privileged steps (creating the identities, installing the service,
rewriting the store's ACL, and the rollback) and executes none of them — routine
Amabie use after activation needs no elevation, because the service holds the
privileged identity, and the broker never executes candidate code with it.

`amabie mcp` speaks the Model Context Protocol on stdio so a generic agent can
drive Amabie without a bespoke integration. It is a **transport, not a second
authority**: every tool runs the same CLI and relays its verdict and exit code
unchanged, no tool takes an argument that could influence a verdict, and
`amabie accept` is deliberately not exposed — acceptance is a human act in a real
terminal, so a machine channel must not be able to reach it.

### More than one ecosystem in one repository

A repository whose checks live in subdirectories — `web/` Node, `backend/`
Python, `service/` Go — declares them once, at the root:

```json
{ "schema": "amabie-scopes/1",
  "scopes": [ { "path": "web", "ecosystem": "node" },
              { "path": "backend", "ecosystem": "python" },
              { "path": "service", "ecosystem": "go" } ] }
```

`amabie.scopes.json` is **sealed** by `setup` like every other declaration. What
is declared is what counts: nothing is discovered by walking, so an undeclared
`vendor/`, `archive/` or `examples/` tree can never add a check to your plan. A
declaration Amabie cannot honour stops setup instead of shipping a partial plan.

### Any language — the universal project contract

Amabie is **language-agnostic at the project contract level**. It does not need to
know your build system to verify your repository, and you do not need to know
Amabie's adapter model to use it:

```sh
cd your-repo && amabie setup
```

`setup` reads the project's **existing, executable truth** — the commands in your CI
workflows, your `Makefile` / `Taskfile` / `justfile` targets, a configured
CMake+CTest or Meson build tree, a shipped `gradlew`/`mvnw` wrapper, `pom.xml`,
`build.gradle*`, `*.sln`/`*.csproj`, `Package.swift`, `build.zig`, `phpunit.xml`,
`composer.json`, `Rakefile`, `mix.exs`, `shard.yml` — and proposes the plan those
artifacts anchor. Every proposed check says which artifact anchors it. Nothing is
guessed: a command with no anchor is not proposed (setup reports `NEEDS ATTENTION`
instead of inventing one), and if two equally-anchored interpretations exist, Amabie
asks **one** concise question rather than picking for you. The plan is then pinned
(every program sealed to an absolute path), sealed and drift-checked exactly like a
native one.

If discovery cannot see your commands, state them yourself — argv arrays, never a
shell line:

```json
{ "schema": "amabie-project/1",
  "scopes": [ { "path": ".",
                "checks": [ { "name": "build", "kind": "build", "argv": ["cmake", "--build", "build"] },
                            { "name": "tests", "kind": "tests", "argv": ["ctest", "--test-dir", "build"] } ] } ] }
```

`amabie.project.json` refuses a project-supplied environment and a per-check `cwd`
(a working directory is a declared scope, which is validated and sealed), refuses
shell wrappers, and can never name Amabie's own `$` tokens.

**What that buys, stated exactly.** Four levels, reported separately:

| Level | Meaning |
|---|---|
| **UNIVERSAL** | Any command-driven project: the command really ran, at the authorized absolute path, in the authorized sealed directory, with that exit status, bound to the candidate's bytes — **and the runner's internals were not observed**. |
| **NATIVE** | Amabie has ecosystem-specific discovery and toolchain handling: **node**, **python**, **rust**, **go**. |
| **OBSERVED** | Amabie watched the runner's own lifecycle from inside the process: **mocha**, **`node --test`**, **pytest**, **`unittest`**. Printed text becomes refutable. |
| **STRONG** | A strong verdict may rest on it: the observed runners above, each bound by an authority (a repo pin, the verifying runtime itself, or an operator-sealed identity). |

An unknown runner is `INCONCLUSIVE_ONLY`, by construction — so a universal check can
verify a build, a lint or a test command honestly and can **never** turn printed
output into a strong verdict. Amabie does not claim to understand every language; it
claims to verify any command-driven project honestly about what it proved. See
[`docs/COMPATIBILITY.md`](docs/COMPATIBILITY.md).

Every command accepts `--json`: the human prose moves to stderr and stdout
carries exactly one versioned object (`{"schema":"amabie-status/1", …}`). Exit
codes and status words are identical with and without the flag — asking for JSON
never changes a verdict, and the envelope names the files evidence lives in
instead of pasting logs into an agent's context.

`setup` / `doctor` never print READY without having executed the detected
checks and seen them pass *in that same invocation* — `doctor` runs the plan
every time it is called, so a stored or hand-edited record can never produce a
green answer; re-running `setup` heals its own wiring idempotently; nothing
about this tier claims the attested-proof strength of the commands below — it
is a transparent plan runner over *your* scripts.

**A green plan is not a proven task.** `doctor` answers `NOT PROVEN` (exit 2)
and the Stop hook blocks the completion in two cases the old READY hid: when a
stated objective requirement is registered but no sealed check covers it (bind
it in `package.json` `amabie.proofs`), and when
the sealed checks pass on the base commit too — i.e. they cannot tell your
change from no change, so they carry no regression evidence for it. The repair
is to make the proof discriminate: a check that fails without the change and
passes with it. The repair message links the baseline output so you can inspect
what actually ran without the change. A passing baseline is not a passing current
verification. `amabie accept` closes only subjective candidate duties, in a
terminal; it cannot close either of these objective proof gaps.

Release-grade proof pipeline:

```bash
amabie run    <spec.json>   # execute, write evidence
amabie prove  <spec.json>   # re-run + assert expectations
amabie check  <spec.json>   # assert last run's evidence
amabie report [evidence.json] [out.html]  # defaults: latest run
amabie version
```

### Installing, updating and removing Amabie

For an Amabie 1.5 upgrade, first record the repositories using its hooks and back
up their integration settings and local state. Stop active agent sessions before
replacing the installed CLI. Do not use `npm --force` to overwrite a conflicting
`amabie` executable. Once you have reviewed the prepared Amabie artifact, remove
the old `@canary-rn/cli` npm installation, install `@amabie/cli` from its local
tarball, and rerun `amabie setup` in each recorded repository. Setup is an
operator reseal: inspect its declared checks before accepting them. Run
`amabie doctor --json` afterward and review the verdict rather than assuming the
upgrade passed. Existing untracked `.amabie` state is migrated when safe; legacy
signed records retain their historical serialized field names. Do not delete
the old trust store or evidence directories as part of the upgrade.

Three ways to get it, in increasing order of what you must already have:

| You have | Use | Result |
|---|---|---|
| Node.js 22+, npm and Git | verify the supplied checksum, then `npm install -g ./amabie-cli-2.0.0.tgz` | self-contained `@amabie/cli` bundle, zero runtime dependencies |
| A source checkout with Node.js 22+ | `npm ci`, `npm run build:force`, then `node tooling/pack.mjs` | local npm tarball under `pack/npm/`; building alone does not install a command globally |
| A source checkout with Node.js 25.5+ | `npm run standalone` | experimental executable for the current host; a build is not proof of a working first-run workflow |

`tooling/standalone.mjs` builds for **the host it runs on** and then executes the
artifact's version and read-only state with Node removed from `PATH`. Those are
smoke checks, not full installation or verification evidence. It writes the artifact,
its sha256 and the observed runs under `pack/standalone/`. `--build-sea` embeds
the running `node` binary, so a Linux or macOS artifact must be built and executed
*on* Linux or macOS; no other target is claimed from here. Prefer the npm tarball
for this release candidate. Native provider sidecar assets are not included in
the standalone executable, and unavailable provider boundaries must remain LOCAL.

To use a prebuilt standalone on a machine without Node, first obtain an artifact
built and exercised on that exact operating system. Running `npm run standalone`
is a build instruction for a machine that already has Node, not an installation
instruction for a machine without it.

- **Install**: copy the single executable into a directory of its OWN and put it
  on `PATH`. The directory matters: Amabie fingerprints its own bytes as the
  verifier's code, and under a single-executable build that is the file itself —
  a directory shared with unrelated files would make unrelated edits look like
  verifier tampering.
- **Update**: replace the executable, then re-run `amabie setup --yes` in each
  wired repository. The plan and its seal are re-derived; nothing about the old
  binary is trusted afterwards. Upgrading an existing 1.0 installation is
  documented separately in [`docs/MIGRATION-1.0-TO-1.1.md`](docs/MIGRATION-1.0-TO-1.1.md).
- **Uninstall**: `amabie uninstall` in each wired repository removes exactly
  Amabie's own recorded changes (hook entries, config, its own ignore line) and
  refuses to delete `.amabie` while candidates exist; then delete the executable.
  Both directions are exercised end to end by the feature smoke.

Note what a standalone build does *not* change: a **Node project's** checks still
need that project's own Node/npm to run, because Amabie runs *your* scripts. The
standalone build removes Node as a requirement for **running Amabie** — which is
what makes Amabie usable on a Python, Rust or Go project that has no Node at all.

Exit codes: `0` proof holds fully (on the committed proof host) / regression
confirmed / self-consistent report / onboarding READY · `1` a proof assertion
diverged (or `run` classified PASS) · `2` other classification / infra /
proof INCOMPLETE (this runtime is not the proof host — host-exact assertions
unverifiable, never a PASS pretense) / onboarding NEEDS ATTENTION or
UNSUPPORTED · `3` misuse, refused bundle, or a NOT-SELF-CONSISTENT report.

## Security contract — enforced at the process/env boundary, tiered elsewhere

Every downstream repository is **untrusted**. Enforced by
`@amabie/support` + `@amabie/workspace` on every run
([`docs/SECURITY.md`](docs/SECURITY.md), which tiers every claim):

- content fetched **by pinned 40-hex commit SHA** only (tarballs, no git auth)
- **pre-execution audit gate**: refuses repos with install lifecycle hooks
  or shipped `.npmrc`/`.yarnrc` (case-insensitively, recursively) —
  registry-injection vectors
- **allowlisted child environment** — Anthropic/GitHub/cloud credentials,
  `NODE_OPTIONS`, SSH agents, user npm auth are *structurally invisible*
  to external processes (deny-by-omission); Windows session-identity vars the
  OS loader injects are *neutralized* so observed == declared (proven by test)
- `--ignore-scripts` on every install — semantically un-losable: package
  managers run only through **closed allowlists at three levels** (executable,
  subcommand, and since round-4 RB-1, exact option spellings — npm's
  abbreviations, negations and last-wins ordering make textual denylists
  bypassable, so Amabie's isolation flags are appended as the argv *suffix*
  and npm's own last-wins makes them the effective config); raw
  `npm`/`npm-cli.js` forms, wrapper-mediated execution and `--`-bypass shapes
  are rejected (audits B5/B5.1, round-4 RB-1); disposable workspace under
  `.amabie-runs/`; caches and HOME redirected inside
- **evidence is bound to reality, not just self-consistent** (audit B1–B4,
  round-4 RB-2/M-1, independent-audit A+B): failing-test identities are suite-qualified
  (no leaf-title collapse); a zero-test / no-summary / infra-at-exit-0 run can
  never become PASS; **suite collapse is never a verdict** — strong verdicts
  require stable-across-repetitions and comparable-across-arms test-execution
  coverage, and "comparable" includes failing-set containment (a candidate
  failure the baseline never saw fail is never "pre-existing"; classifier
  rules 12/13 + an independent validator gate); **a
  strong verdict additionally requires that Amabie WATCHED the execution** —
  a byte-pinned runner with an Amabie-injected in-process observer, whose
  private-channel lifecycle counts agree with the text summary on every round
  (rule 14; `node -e "console.log('128 passing (1s)')"` → INCONCLUSIVE, never
  PASS — [docs/EXECUTION-AUTHORITY.md](docs/EXECUTION-AUTHORITY.md)); every
  artifact path is derived from its round (traversal/ownership rejected) and
  confined to the run dir; a manifest digest makes single-field rewrites
  detectable; the bundle's structural floor and the published JSON schema are
  **one generated contract** (`packages/evidence/schema/src/contract.ts`);
  and `prove`/`check`/`report` re-derive each round's summary, counts,
  failing-test identities and execution observation **from the artifact
  bytes**, so the bundle cannot lie about what it recorded — and what it
  recorded can only carry strength if the observation channel backs it
- no publish, no push, no external auth, ever
- if a *Tier-A (code-enforced)* bound can't hold: `INFRASTRUCTURE_FAILURE`,
  before executing

**What 1.0 does NOT claim** (read the tiered section): there is no filesystem
jail and no network egress allowlist — a fixture's own test code runs with the
operator's OS permissions. The evidence manifest is tamper-*evidence* /
cross-field integrity, **not authenticated provenance** (no signing key /
external trust root); a forger who controls the whole file recomputes it, which
is exactly why the byte re-derivation, the execution-observation channel (an
integrity bound, not a trust root — its exact ceilings are stated verbatim in
docs/EXECUTION-AUTHORITY.md §7–8) and the committed proof do the real binding.
Isolation is real at the process/environment boundary and a deliberate
best-effort convention beyond it.

## Layout

```
apps/cli/                       run / prove / check / report
packages/core/                  planner · comparator · classification (pure, tested)
packages/runner/                executor · workspace · environment (security + isolation)
packages/evidence/              normalizers · hashing · schema · report
packages/registry-npm/          (reserved — npm resolution adapter, next milestone)
packages/github/                pinned-SHA tarball fetch
packages/ai/                    optional explain-only adapter (noop shipped)
fixtures/axios-0.27-to-1.0/     golden fixture: spec + committed proof expectations
schemas/evidence.schema.json    published evidence contract (GENERATED from packages/evidence/schema/src/contract.ts — the single source of truth)
docs/                           ADR-001 · PLAN · SECURITY · EXECUTION-AUTHORITY · RELEASE-1.1
                                V1.1-STATUS · CAPABILITY-LEVELS · TRUST-ARCHITECTURE
                                AUTHORIZATION-1.0 · COMPATIBILITY · MIGRATION-1.0-TO-1.1
                                TEST-COUNTING · SPEC-FORMAT
tooling/benchmark/              BENCHMARKS (method) · RESULTS (per-configuration ledgers)
archive/python-golden-prototype/ superseded first prototype (concepts preserved in TS)
archive/prototype-scripts/      superseded M0/ladder harnesses (now the CLI)
```

## License

Apache-2.0 — see [LICENSE](LICENSE).
