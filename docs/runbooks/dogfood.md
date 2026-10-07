# Runbook: dogfood Bandwise on this repo

Phase D of ADR-020. Bandwise runs as Claude Code hooks on this repository, with your own TypeSafe key, before anyone else uses it. Every set starts in `shadow`.

## What you get

Three sets from the agent pack, in `.bandwise/sets/`:

| Set | Hook event | In `controlled`, a high band answer... |
|---|---|---|
| `done-check` | `Stop` | sends the agent back when work is left or a claim is unchecked |
| `action-risk-gate` | `PreToolUse` on Bash, Edit, Write, MultiEdit, NotebookEdit | turns the tool call into a permission prompt |
| `model-tier` | `UserPromptSubmit` | adds advice to hand mechanical work to a cheaper subagent |

In `shadow` none of that happens. The hook runs the set, writes a receipt, and prints nothing.

## D0 status (2026-09-30): done

Nick ran D0 from his own shell on Node 22 with his TypeSafe key (NSI-730).

- `pnpm fixtures:record` recorded 9 of 9 typesafe success fixtures against TypeSafe's openapi.json 0.2.0. `noul-near-half` stays hand-authored: live Jev scored its ticket 0.07, not near 0.5, and the fixture exists to test the band edge. The recorder skips any fixture marked `"source": "hand-authored"`.
- `pnpm smoke` passed all 36 checks. `jev-preview` and `jev-latest` both resolved to `jev-1.13.0`. Each model cost $0.000074 (cap $0.001), so the whole smoke cost about $0.0002.
- `bandwise run --live` on `done-check` answered `unverified` in the high band for the turn that claims success without a check, which is the answer the set wants. System One cost $0.000029 for 681 input tokens, latency 287 ms, and the receipt counted $0.000575 saved against claude-haiku-4-5.
- Earlier, the cloud session could not run the SDK path live: its proxy did not replace the placeholder `Authorization` header and every call came back 401. Live runs belong in a shell that holds the key.

To re-record later, from your shell with `TYPESAFE_API_KEY` set:

```sh
pnpm fixtures:record          # rewrites the recorded success fixtures in packages/system-one-client/fixtures/typesafe
pnpm smoke                    # checks jev-preview, jev-latest and jev-1.13.0; prints cost per model
git diff --stat packages/system-one-client/fixtures
```

## Status (2026-09-30)

The three dogfood hooks are wired in this repo's `.claude/settings.json`, all in `shadow`: `done-check` on Stop, `action-risk-gate` on PreToolUse, and `model-tier` on UserPromptSubmit. The risk gate runs with `--drop content_preview`, so file contents stay on the machine. Nick approved them on 2026-09-30. The week of receipts before any set moves to `controlled` (section 3) starts then.

## Hosted mode (D2e)

To move the hooks from your own key to app.bandwise.dev, follow [hosted-dogfood.md](hosted-dogfood.md) in order: migrations, the Vercel env, `bootstrap-internal` for the `internal` org and the `.bandwise/sets/` specs, the minted tokens, the checks, and the rollback plan. It marks which steps need PJ. Hosted mode went live on 2026-10-05: the hooks on this repo call app.bandwise.dev with the run-only hook token, every set still in `shadow`.

## 1. Install

You need Node 22, `pnpm install` done in this repo, and your key in the shell Claude Code starts from. On a Mac, keep the key in the Keychain and load it in `~/.zshrc`, so it never sits in a plain file:

```sh
security add-generic-password -a "$USER" -s TYPESAFE_API_KEY -w     # prompts for the key; add -U to replace an old one
```

Then add this line to `~/.zshrc`:

```sh
export TYPESAFE_API_KEY="$(security find-generic-password -a "$USER" -s TYPESAFE_API_KEY -w 2>/dev/null)"
```

Open a new terminal window and run the live check below. If it answers, the key the hooks will see is the right one. If you only need the key for one window, `read -s "TYPESAFE_API_KEY?TypeSafe key: " && export TYPESAFE_API_KEY` loads it without echoing it or writing it to your shell history.

Paste commands without `#` comment lines. zsh does not treat them as comments at an interactive prompt unless `setopt interactivecomments` is on.

Check one set live before wiring any hook:

```sh
pnpm bandwise run --live .bandwise/sets/done-check.json \
  .bandwise/states/done-check/example-2-claims-success-without-a-check.json --receipts
```

Print the hook entries:

```sh
pnpm bandwise hooks install --command 'pnpm -s --dir "$CLAUDE_PROJECT_DIR" bandwise'
```

It prints JSON for `.claude/settings.json` and writes nothing. Read it, then merge the `hooks` block into `.claude/settings.json` yourself. Every command ends in `--rollout shadow`. Start a new Claude Code session so the hooks load.

The command runs the CLI from this repo's source, so the hooks use whatever is on `main` and need no global install. One hook run takes under a second before the System One call. Sessions without the key, such as cloud sessions, run the hooks and get a silent no-op.

To confirm the hooks work, send one prompt in a new session and run:

```sh
pnpm bandwise report --since 1h
```

A `model-tier` row means the `UserPromptSubmit` hook ran live. `done-check` appears after Claude's first reply.

What the hook sends to TypeSafe: only the fields the set's input schema names. For `done-check` that is your last request and Claude's final message, read from the session transcript. For `action-risk-gate` it is the tool name, command, file path, the first 2000 characters of new content, and the description. For `model-tier` it is your prompt. Secret-shaped text is replaced before the call:
- API keys, tokens and private keys
- `Authorization` headers of any scheme
- passwords in URLs such as `postgres://user:pass@host`
- values after a name that says key, token, secret, password or credential, in `NAME=value`, JSON, YAML and `--flag value` form

That redaction is pattern based. It catches the common shapes but cannot promise that every private value is gone, so treat whatever a hook reads as something TypeSafe may see. Add `--drop <field>` to a hook command to never send a field at all. For example, `--drop content_preview` keeps file contents on the machine for the risk gate.

What it never does: block or change anything in `shadow`, print the key, write a prompt or tool input into a receipt, or fail a session. A missing key turns the hook off. Any error or a 3 second timeout exits 0 with no output.

## 2. Read the report

```sh
pnpm bandwise report --since 7d
pnpm bandwise report --since 7d --set action-risk-gate --json
```

Per set it shows runs and failures, decisions, the band mix, how often the set would have acted, how often it did act (0 in shadow), System One spend, counterfactual LLM spend, estimated savings and latency.

Read the savings as estimates. The counterfactual prices one comparator LLM call per decision. In Claude Code the real saving is fewer wasted turns and fewer risky actions, and no receipt can price those exactly. What the receipts can tell you for sure is what System One cost and how often each set would have stepped in.

Receipts live in `~/.bandwise/receipts.jsonl`, one JSON line per run. Delete the file to start over.

### Compare launch profiles (NSI-729)

```sh
pnpm bandwise report --since 14d --compare profile
```

Each `Stop` receipt carries the task behind it: time from your request to the stop, agent turns, tool calls (subagent turns not counted), a hash of the session id, and the launch profile used and picked. Counts only, never the prompt or the reply. `--compare profile` groups those receipts by profile used and profile picked. Per group it shows the task count, the median time to stop, turns and tool calls, and how often done-check said `finished`.

How to read it:
- Look at the task count before any time. Medians over a handful of tasks swing a lot.
- Until `bandwise launch` exists (NSI-727), every group reads `profile none, pick none`. That row is the baseline for this repo.
- In `shadow` the session always runs the default, so a row marked "pick differs" shows what the set would have chosen, not what the choice would have changed. Only a stretch in `controlled` can show that.
- No speed or cost claim about launch profiles goes on www or in the docs until two weeks of these numbers back it (ADR-020 Amendment 1, point 14). Write the decision here, next to the numbers.

## 3. Move a set from shadow to controlled

One set at a time, after about a week of receipts, and only when you say so.

1. Run `pnpm bandwise report --since 7d --set <set>`. Look at "would have acted" and the band mix. A set that would have acted on ordinary work stays in shadow: tighten its thresholds in `.bandwise/sets/<set>.json` first, commit, and give it another week.
2. In `.claude/settings.json`, change that set's hook command from `--rollout shadow` to `--rollout controlled`. Commit it with a message that names the set and the receipts you read.
3. In `controlled`, only a high band answer acts. The next report shows it under "acted".

To step back, change it to `--rollout shadow` again. That is never gated.

## Launch profiles (NSI-727, NSI-741)

`model-tier` can only advise inside a session. `bandwise launch` picks before one starts, from `.bandwise/profiles.json`, and starts Claude Code with that profile's `--model` and `--effort`:

```sh
pnpm -s bandwise launch --task "Rename getUser to fetchUser everywhere" --
pnpm -s bandwise launch -- -p "Rename getUser to fetchUser everywhere"
```

- Everything after `--` goes to `claude` unchanged. The task for the pick is `--task`, or else the argument right after `-p`, or else the only argument after `--`. Any other form has no task and starts the default with a notice, so pass `--task` when the prompt is somewhere else.
- It adds only `--model` and `--effort`, and only if you did not pass them yourself. It never touches a permission flag.
- It sets `BANDWISE_LAUNCH_PROFILE` and `BANDWISE_LAUNCH_PICKED` for the session, so its Stop receipts land in `bandwise report --compare profile` (NSI-729).
- Otherwise the session gets exactly the environment `claude` would get if you started it from the same shell. If `TYPESAFE_API_KEY` is set there, the session inherits it, and it has to: the hooks inside the session read it. `bandwise launch` never adds a key and never removes one. Anything the agent's own tools can read in that shell, they can read either way. Taking the key out of the shell entirely, with the hooks reading it from the Keychain, is NSI-742.
- Notices such as "using the default profile" print before the session starts, not when it ends.
- `.bandwise/profiles.json` is the allowlist: `light` (sonnet, low), `standard` (sonnet, medium, the default), `deep` (opus, high) and `deep_review` (opus, high, plus a sonnet review session). Change a model or an effort here, by commit, like a spec. `deep_review`'s second session is reported, never started.
- In `shadow` it always starts the default, and the receipt records the pick. Read the pick mix with `pnpm bandwise report --since 7d --set launch-profile`.
- No key, an error, a timeout or a broken install still starts the session, on the default, with one line on stderr saying why. Only an invalid profiles file stops it.
- `bandwise launch --print` does the pick and prints it as JSON instead, for hosts that start sessions themselves.
- Only `packages/cli/src/live/spawn.ts` may start a program. A boundary rule, a CLI test and the kit's ESLint config enforce it. PJ is the Security reviewer for this path (NSI-741).

## 4. Switch the hooks to hosted Bandwise (D2d)

Once the `internal` org is up on app.bandwise.dev (D2e) with the `.bandwise/sets/` specs imported and each set's production channel published, the same hooks can call the hosted endpoint instead of TypeSafe. Nothing in `.claude/settings.json` changes. The switch is one variable.

1. Get two tokens for the `internal` org, minted as in [hosted-dogfood.md](hosted-dogfood.md) section 4. The hook token is run only, limited to the dogfood sets, and is the only Bandwise token the Claude Code session ever sees, because the hooks can read every variable in that shell. The CLI token is an `sa_live_` agent token with `run`, `sets:read`, `sets:write`, `release:production`, `runs:read` and `usage:read`, and it is loaded for one command at a time. The hook token is a run-only `sa_live_` agent token with role ceiling `viewer` (Nick, 2026-10-01).
2. Keep both in the Keychain and load them in `~/.zshrc` as hosted-dogfood.md section 5 shows:

   ```sh
   export BANDWISE_TOKEN="$(security find-generic-password -a "$USER" -s BANDWISE_TOKEN -w 2>/dev/null)"
   bwa() { BANDWISE_TOKEN="$(security find-generic-password -a "$USER" -s BANDWISE_AGENT_TOKEN -w 2>/dev/null)" pnpm -s bandwise "$@"; }
   ```

   Never export the agent token. `bwa` sets it for the one command it runs. `BANDWISE_BASE_URL` defaults to `https://app.bandwise.dev`. Set it only for a local console, as `http://localhost:3000`. The CLI refuses plain http to any other host, so a token never crosses a network in clear text.
3. Check the CLI token and the sets before any hook uses them:

   ```sh
   bwa spec diff .bandwise/sets/done-check.json
   bwa report --remote --since 1d
   ```

   `spec diff` exits 0 when the server draft matches the file, 2 when it differs, and 1 with one line that names the problem (for example `error unauthenticated (HTTP 401)` with "check BANDWISE_TOKEN").
4. Open a new terminal, start a new Claude Code session, send one prompt, then run `pnpm bandwise report --since 1h` for the local receipts and `bwa report --remote --since 1h` for the server's runs. Both should show `model-tier`.

Two run-only tokens now make hosted runs: `nick-hooks` from this Mac and `sims-hooks` from cloud sessions on another repo. To tell them apart, run `bwa report --remote --since 1d --token nick-hooks` (or `--token sims-hooks`), or pick a token under "Made by" on `/runs` and `/savings` in the console. Each run row and each run page shows the token that made it.

What changes in hosted mode:
- The hook sends `POST /api/v1/sets/<slug>/run` with the token. The slug is the spec file name (`done-check`, `action-risk-gate`, `model-tier`), or `--remote-set <slug>` on the hook command. It does not need `TYPESAFE_API_KEY`: the server runs the model with the platform key.
- The local spec file still decides which fields leave the machine, with the same redaction, and `--drop content_preview` still keeps file contents local for the risk gate.
- The server's rollout stage decides whether a hook acts, and `--rollout` on the hook command is ignored. Moving a set to `controlled` becomes `bwa rollout done-check controlled --reason "a week of clean shadow receipts"`, and stepping back is `bwa rollout done-check shadow --reason "..."`, with no settings change and no new session. `paused` and `inactive` never act. A move that needs a person exits 3 and prints the approval id and the console link.
- Editing a question or a threshold is: edit `.bandwise/sets/<set>.json`, `bwa spec push .bandwise/sets/<set>.json`, read the lint lines, `bwa publish <set> --changelog "..."`. The next hook call uses the new version. `bwa rollback <set>` restores the previous one.
- Receipts keep landing in `~/.bandwise/receipts.jsonl` with `provider: "bandwise"` and a `remote` field (host, version, channel, run id), so the local report still works. They never hold the token.
- Any error answer, a timeout (3 seconds by default) or a server that cannot be reached ends the hook with exit 0 and no output, and writes a receipt with the error code as its status (`unauthenticated`, `set_not_live`, `network_error`, `timeout`).

To go back to live mode with your own key, `unset BANDWISE_TOKEN` (or remove the export from `~/.zshrc`) and start a new session.

## 5. Remove the hooks

Delete the Bandwise entries from `.claude/settings.json` (or the whole `hooks` block if nothing else is in it) and start a new session. Live mode stays opt-in behind `--live` and an environment key, and hosted mode behind `BANDWISE_TOKEN`, so nothing else runs.

## Checks CI runs

- Every spec in `.bandwise/sets/` validates and runs with status ok under `bandwise run --local` on each example and borderline state in `.bandwise/states/` (`packages/cli/src/local/dogfood-sets.test.ts`).
- Only `packages/cli/src/live/transport.ts` imports the SDK transport, only `packages/cli/src/live/key.ts` reads a key variable, and only `packages/cli/src/remote/credentials.ts` reads `BANDWISE_TOKEN` (the boundary lint and `packages/cli/src/live/live.test.ts`).
- The hosted commands and the hosted hook never print the token or write it to a receipt, even when a server echoes it back (`packages/cli/src/remote/remote.test.ts`, `packages/cli/src/live/hook-remote.test.ts`).
- `bandwise hooks install` prints every dogfood set in `shadow`.
