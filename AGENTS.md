# Instructions for AI agents

For AI coding agents (Claude Code, Codex, Copilot and others) working on this repo for a contributor. Humans: this is also the short version of the project rules. `CLAUDE.md` has the project background and hard constraints; read it too.

## Read first

1. `PLAN.md`: "Resume here" (state, results, open items) and "Next, in order". It is the source of truth; docs can be older.
2. `CLAUDE.md`: goal, hard constraints (32-bit exe, single-threaded sim), tooling.
3. The doc for the area you touch (`docs/04-re-findings.md` for findings, `docs/15-native-patches.md` for ts3native, `mods/ts3fixes/README.md` for the player mod, `docs/TESTING.md` before any game run, `docs/BUILD.md` before building).

## Rules

- **No EA files in git, ever:** no game binaries or packages, no extracted DLLs, no decompiled C# or native decompiles, no saves, dumps, traces or captures. Keep them in `game-copy/` or `probe-out/` (git-ignored). Quote at most an address, a method name or a few instructions needed to explain a finding, in your own words.
- **No personal data:** no user names in paths (`C:\Users\<name>`), machine names or emails in commits, docs or logs. Use placeholders: `<SteamLibrary>`, `<Documents>`, `<repo>`.
- **Verified vs inferred:** mark every claim `[verified]` (disassembly, decompiled code, measurement), `[community]` or `[inferred]`. Confirm an inferred claim before code depends on it. Do not treat earlier AI-written notes as verified; check the source they cite.
- **One change at a time**, measured against the baseline (docs/TESTING.md). Prefer in-load A/B with runtime switches over separate runs.
- **Newest design first:** when a new, potentially better design exists for a feature, test it first; drop pending timing runs of older designs once the new one shows big gains (keep the old design only as a ladder baseline arm).
- **Measurement smoke:** before any timing queue over ~1 h, a short smoke job must prove the measurement works (per-arm split, heavy tools off, switch values read back); `tools/harness/queue.ts` runs it automatically (`--no-smoke` for correctness-only queues).
- **Crash-triage builds:** crash-triage logging/fix builds start as soon as the running job ends: `node tools/harness/hold.ts on <reason>`, `node tools/harness/hold.ts wait-job-end`, build, `node tools/harness/hold.ts off`; other builds use correctness windows.
- **Repro per fix:** every fix and every bug gets a trigger action in the agent and an entry in `tools/harness/repros.json`. Do not wait for a problem to happen in play.
- **Hitch fixes are judged by a hitching repro:** when the cause of a hitch is known, do not re-run the fix in natural play. Repro the scenario so the off arm hitches (>= 300 ms) and compare on vs off there. A repro whose off arm does not hitch proves nothing: fix the repro first. Natural play is the last resort, only when a repro is too hard. Releases are exempt: long natural soaks and bundle pairs still back the release claims. A soak with no gain does not turn a repro-verified fix off (rare events cannot show in soaks); it only limits what the release notes claim. Only a clear regression blocks shipping it on. Clear regression = any of: (1) a crash, new stuck Sim or watchdog firing in an on arm that the off arm does not have; (2) at >= 300 or >= 1000 ms, the pooled on/off ratio's 95% CI lies wholly above 1 (`hitch-ab.ts` exact Poisson; "no clear difference" or "not enough events" is not a regression); (3) sim it/s down > 2% in the pooled pair mean, in both orders; (4) a new cause leading >= 1 s hitches in on arms only (`hitch-ab.ts --causes`), traced to the fix's own code.
- **Stuck Sims are log-only:** record possible cases in `docs/data/stuck-log.md`; no research or fix unless a case repeats often or one of our fixes caused it.
- **Stop on obvious errors:** stop a run when it shows an error or the code under test changed; fix, then rerun. Triage every crash against the change ledger (`crash-ledger.ts triage`).
- **Crash cause before fix:** a crash or hang on a build of ours is our code's fault until proven otherwise. Find the actual cause (fault address and instruction from the `[Crash] Log=1` exception lines or the EA xcpt report, then the disassembly of that path) before changing code or blaming the game. A list of "possible reasons" is not a cause. If no fault was captured, rerun to reproduce it with logging on; call it fixed only after **at least two clean runs** of the same job on the fixed build. Before calling any game function from our code, check its argument count, calling convention (`ret N`) and the alignment its data needs (e.g. `movaps` = 16 bytes) in the disassembly (2026-10-17: two design D crashes were our wrong argument count and an 8-byte aligned copy).
- **Crash investigation order:** (1) static analysis first: fault sites and stacks from the logs, the disassembly of each path, which of our hooks or features can reach it; (2) add logging around the sites: checks that log a bad pointer before the game faults, plus a ring of our own lifetime and memory events dumped at the crash (`[CrashForensics]`, docs/157 §11.7, docs/186); (3) rerun the crash with that logging; (4) investigate what it caught; if the log is not enough, add more logging and rerun. Each round keeps every earlier round's log lines and checks (add, never replace), and triage never assumes a single cause: one crash can have several races or causes, so every round reports all bad pointers it caught, not only the first. Avoid bisect runs (feature on/off loads): they cost a lot of game time and rarely name a cause; run one only when Rodney says "ok bisect" (no other option left). A rare crash gets its logging added to normal runs, so the next natural crash is caught.
- **Light crash forensics:** timing runs keep `[CrashForensics] Light=1` (queue.ts sets it in every job); heavy guards (`Enabled=1` with Guards, DbIndexLog, SceneTreeGuard, Draw/Effect/ObjRes) only in crash reruns and correctness runs (docs/67 §18).
- **Every new switch defaults off** until measured in game; anything that changes save data stays opt-in.
- **Community code:** mods without a license (NRaas, simler90, MonoPatcher, S3SS) are read for behaviour only. Write a behaviour spec in your own words, implement from the spec, credit the author. Never port their code line by line.
- **Times:** use UTC in shared logs, tables and commit messages. Older entries in `PLAN.md` and `docs/` use PHT (UTC+8), the maintainer's local time; do not convert them, but do not add new local times.
- **Main agent orchestrates, sub-agents do the work:** in a long session (night chains, test-triage-fix cycles, release work) the main agent only checks queue state, decides what comes next, briefs sub-agents and relays their verdicts. Triage (reading job logs, `hitch-ab.ts` and `run-verdict.ts` output, shadow and crash data), static analysis, fixes (code, build, self-tests, commit) and queue + docs work go to sub-agents with a full brief: goal, inputs (log paths, commits), what is already ruled out, files not to touch, commit rules, and a short report format. Its own work stays at a few short status commands per step, so its context lasts the whole cycle. Exceptions: a one-line fix or a status check that costs less than writing the brief.
- **Game runs are serial;** research and code can run in parallel sub-agents, but never edit `mods/` or `tools/setup/` while a `cycle.ts --restart` or installer step may run (it rebuilds the mods from source).
- Update `PLAN.md` ("Resume here") in the same commit as each fix or result.
- **Reserve shared numbers first:** before writing a new `## N.` section in `docs/51-inference-ledger.md`, run `node tools/registry.ts reserve ledger --for "<topic>"` and use the § it prints (parallel agents collided on § numbers); counters likewise (`reserve native|fixes`, docs/registry.md). `tools/agent-merge.cjs` renumbers a colliding incoming section past reserved numbers and fixes its `ledger §N` / `docs/51 §N` references.
- Scripts are TypeScript run with `node script.ts` (Node 22.18+, no npm dependencies) unless they need Windows-only features.

## Picking work

1. Look at the GitHub issues (labels such as `good first issue`, `needs-measurement`, `research`) and at `PLAN.md` "Next, in order".
2. Comment on the issue that you (or your agent) take it, so two people do not run the same experiment.
3. Good first tasks without deep RE: run the milestone or tests B-E on your machine and report (docs/TESTING.md §8); run an untested opt-in switch on your saves; improve a harness script.

## Branches, commits, pull requests

- Branch from the default branch (`master`): `feature/<issue#>-kebab-summary` (`bugfix/`, `docs/` alike), e.g. `feature/42-water-jps-verify`.
- Commit message: `<gitmoji> <summary>`, a blank line, the detail (what changed, why, how it was measured), then `Closes #<issue>`. One logical change per commit.
- Gitmojis: ✨ feature, 🐛 fix, ⚡️ performance, ♻️ refactor, ✅ tests, 📝 docs, 🔧 config, 🔥 remove, 🥅 error handling, 🔊 logs, 👷 CI.
- PR title = commit summary. The PR body has the measurement table (docs/TESTING.md §8): build hash, settings, machine, baseline vs change.
- Before committing: `git status` shows no EA files, saves, `probe-out/` or `game-copy/` content, and no personal paths in the diff.
