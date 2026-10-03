<!-- SYNCED FROM AI-Handbook — do not edit in a consumer repo. Local edits are overwritten by the next sync and their reasoning is lost; change the handbook instead. -->

# Finding which test actually failed in CI — and why the obvious route is blocked

**The problem.** `mcp__github__get_job_logs` returns the **tail** of a job's
log, and this repo's `Test` job ends with the Postgres service container
dumping its own output — hundreds of lines of expected
`relation "stripe.…" does not exist` noise from tests that deliberately
exercise failure paths. The `not ok N - <test name>` lines are in the middle,
and the tail never reaches them however large you make it. `get_check_run`'s
`output.text` is empty for this job, and `failed_only: true` returns the same
drowned tail. **There is currently no MCP method that surfaces the failing
assertion for this job.**

**The archive route works but is NOT available to you.** The run's full log
archive (`actions_get` → `get_workflow_run_logs_url`, then download + `grep -rh
"not ok [0-9]* - "`) does contain it, and the signed
`results-receiver.actions.githubusercontent.com` URL is a blob host rather than
`api.github.com`. But downloading it needs `curl`/`wget`, and
The handbook's former shell guard **refused those categorically** — no exception for
argument shape or host (see `github-rest-api-blocked-from-bash.md`). Do not
plan around this by reaching for the fetch anyway.

**What to do instead, in order:**

1. **A repo script is no better off.** The shell guard that used to refuse a
   directly-typed `curl` is gone (#89 cut), but nothing changed for this note:
   the refusal was never what blocked the fetch — **the agent proxy is**, and it
   answers a script's `curl` exactly as it answers a typed one. If this recurs,
   the right fix is still a small committed script, and it still needs a
   transport that works. That does not exist yet.
2. **Otherwise ask David** when an ad-hoc fetch is genuinely needed.

**Before concluding "unrelated flake": trace imports, don't grep the file.**
A zero direct-reference count proves nothing. Most integration tests here import
`createApp` from `app.ts`, which pulls the `routes` barrel, whose top-level
imports include `videos.ts` and `videoJobs.ts` — so a video-pipeline change is
reachable from a test that never names it, and an import-time or shared-state
regression would look "unrelated" by grep. Follow the actual import chain from
the failing file until it either reaches a changed module or bottoms out in
leaves. (Worked example: `cliJobPoller.test.ts` imports only
`lib/cliJobPoller.js` plus db/schema/drizzle — genuinely shallow, no barrel, so
that one *was* unrelated. Which the grep also said, but for no good reason.)

A test failing twice on different commits is not automatically your regression,
but it does end the flake explanation until you can point at a mechanism (a thin
timing margin, a shared fixture) rather than a shrug.

**Reproduce with the runner's real invocation** — `node --import tsx/esm`, per
`run_files` in `scripts/lib/test-db.sh`. Without it you get
`ERR_MODULE_NOT_FOUND`, which renders as a test failure and is not one. That
produced a "5/5 failed under load" result that meant nothing.

**Reference:** PR #498, issue #508, PR #509 round 1 (which caught that the
download step this note originally prescribed is blocked).
