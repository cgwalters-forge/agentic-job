# Safe outputs

> This text is LLM generated.

The agent has no forge write credential. It writes down what it wants done
outside the sandbox, one JSON object per line: open a
pull request with this change, post this comment, or report that it did
nothing or lacked a tool. Those are *safe outputs*. The idea, the format
and the type names are
[gh-aw's](https://github.github.com/gh-aw/reference/safe-outputs/).
The collector is a compatible Rust implementation. GitHub apply uses
gh-aw's pinned handlers or opt-in native handlers. Forgejo and GitLab use
native publishers. This page explains what comes from gh-aw,
what is added, and what gh-aw's scripts need.
[workflow.md](workflow.md) describes how a caller uses the result; the
requirements behind it are
[R7](requirements.md#r7-what-leaves-the-sandbox-is-checked-data) and
[R16](requirements.md#r16-the-agents-writes-are-capped-checked-outputs-applied-elsewhere).

The [run contract specification](../specs/run-contract-spec.md) names the
enforced requirements and their checks.

The applying job's `SAFE_OUTPUTS_PAT` is our equivalent of gh-aw's
`safe-outputs.github-token` for
[cross-repository safe outputs](https://github.github.com/gh-aw/reference/cross-repository/#cross-repository-safe-outputs).
See [the token mapping and setup](workflow.md#the-apply-job-and-its-token)
for repository bounds, job-token limits and default-branch environment storage.

## Standalone CLI

The extracted workspace component also builds a Linux CLI, independent of
`agentic-job`, secure-host, an agent run, checkpoints, Actions and credential
brokers:

```sh
cargo build --locked -p safe-outputs --bin safe-outputs
target/debug/safe-outputs check --context context.json --input outputs.jsonl --checked checked.json
# In a separate trusted process/job, after obtaining its credential:
target/debug/safe-outputs apply --context context.json --input outputs.jsonl --checked checked.json
```

The threat is a producer redirecting a privileged write, or changing its content
after check. The caller supplies trusted JSON bounds/context, outside the
producer's control. All operations are off unless explicitly listed, and total
and per-type counts are checked. This is a small standalone context, not the
agentic-job workflow's TOML bounds file. For example:

```json
{
  "repo": "cgwalters-forge/agentic-job",
  "item": 64,
  "max_outputs": 1,
  "outputs": { "add_comment": { "max": 1 } }
}
```

`repo` is one exact repository and `item` one positive issue/PR number, never a
producer-selected target. `max_outputs` defaults to zero and cannot exceed 1000;
`outputs` defaults to empty and uses the library's existing per-type limits.
Optional trusted `api_url` defaults to `https://api.github.com`; comment apply
requires HTTPS except for literal loopback HTTP publishers used by tests.
Check does not validate that URL. It is a credential destination:
never accept it from the producer. Unknown context keys refuse.

The input is unchanged gh-aw JSONL, for example
`{"type":"add_comment","repo":"cgwalters-forge/agentic-job","item_number":64,"body":"Deterministic proof."}`.
Check reads no-follow regular files, caps input at 1 MiB/1000 lines and context at
64 KiB, runs the existing collector and policy checks, and creates a new receipt
only on success. It will not overwrite a receipt. It does no network I/O and
does not obtain credentials. Validation diagnostics omit request text.

Apply uses the same bounded, no-follow regular-file reader for input and
context, and caps the receipt at 4 KiB. Standalone comment CLI tests cover exact
byte limits and refusal of missing, symlinked, directory and oversized artifacts,
including replacements after a successful check. Refusals make no HTTP requests;
the exact-limit controls publish only to a loopback fixture. This tests file
admission, not the CI artifact provenance required below.

Transfer the exact input and receipt through the trusted check job's artifact
channel. The receipt binds both input and trusted context bytes with SHA-256;
it is **not a signature** or a replacement for CI artifact provenance. A producer
who can replace both input and receipt can forge a check. Apply independently
recollects/revalidates the input under its own trusted context, compares both
digests, and rejects the entire unsupported batch before acquiring credentials
or writing. A changed context requires a new check, even if only whitespace
changed. The receipt is an internal CLI format, not a new safe-output wire format.

For a fixed-destination digest caller, this also prevents an otherwise valid
comment from moving to another repository, item or credential destination between
check and apply. The standalone CLI regression tests change each of those context
fields, output bounds and whitespace after check and require refusal before any
HTTP request to either the original or replacement publisher. Each replacement
context passes a fresh check; the refusal tests receipt binding, not invalid
configuration. This does not authenticate a receipt supplied by the producer.

### Native operations and the pinned adapter

By default standalone apply supports **new GitHub issue/PR comments only** (`add_comment`),
plus non-writing `noop`, `missing_tool` and `missing_data`. Comments may contain
only `type`, `body`, `repo`, `item_number`, `pr` and `pr_number`; any supplied
destination must match the context. Edits, replies, temporary IDs and other
comment semantics refuse rather than silently becoming a new comment. Mentions
receive the existing last-mile notification filter. Repeated apply posts again:
there is no standalone idempotency marker, transaction or rollback; a network
failure can leave an uncertain or partially published batch. Do not blindly retry.

The standalone GitHub CLI tests publish digest-like text to a loopback forge
and assert the exact JSON body: prose user/team mentions receive a zero-width
break, while inline/fenced code and email addresses stay intact. This pins the
last-mile filter against producer-selected notifications from quoted upstream
text; it does not test GitHub's live notification behavior or caller deployment.

Standalone GitHub CLI loopback tests pin that failure boundary: redirects,
authorization/rate-limit errors and server errors stop the batch at the failed
POST, without automatic retry or a request to the redirect destination. Earlier
successful comments are not rolled back. Diagnostics omit the server response,
which may reflect credentials or submitted prose. These tests cover first and
later POST failures, not live-service delivery or recovery after a lost response.
Separate cases receive a complete POST, then return HTTP success with malformed
JSON or close before the advertised response body ends. Both stop without retry,
later posts or response text in diagnostics. Even the last attempted comment may
already exist: inspect the destination before replaying any part of the batch.
These tests establish conservative failure handling, not delivery reconciliation.

Check can validate other non-patch operations under explicit output bounds, but
standalone GitHub apply refuses them, including a batch with a supported comment before
an unsupported operation. Patch operations are not a standalone GitHub CLI interface.
The library and `agentic-job publish` have additional native handlers; that does
not make them standalone CLI handlers. The existing pinned gh-aw adapter in
`apply.yml` remains the path for the broader GitHub vocabulary. Neither that
workflow's nor `check.yml`'s interfaces change. No full native GitHub coverage is
promised here.

### Other CI systems and deterministic proof

On Jenkins, GitLab CI or another CI system, build/pin this binary from trusted
source, run the producer without a write credential, and run check in an
unprivileged job with caller-owned context. Transfer only the JSONL and receipt
from that job to a separate trusted apply job. Do not execute artifact scripts
or binaries. Obtain a narrowly scoped token only in apply and expose it as
`SAFE_OUTPUTS_TOKEN` through the CI secret/environment facility, never command
arguments, JSONL, receipts or logs; do not enable shell tracing. No ambient
`GITHUB_TOKEN`, PAT fallback or Actions metadata is read by the CLI. The CI
operator owns job isolation, artifact provenance and token issuance.

The GitHub and GitLab CLI regression tests run check without credentials, then
require comment publication to refuse a missing, empty or whitespace-only
`SAFE_OUTPUTS_TOKEN` before any HTTP request, even with ambient forge tokens set.
The same checked comment publishes to the loopback fixture once that explicit
credential is supplied. Reporting-only batches (`noop`, `missing_tool` and
`missing_data`) need no credential and make no HTTP requests in either phase.
These tests cover token selection, not CI secret isolation or live token scopes.

#### Standalone GitLab CI

The threat is a producer redirecting GitLab writes or substituting patch bytes
after check. Select `--forge gitlab` explicitly in **both** jobs; the default
remains GitHub. GitLab uses the same collector, checker, planner and publisher as
`agentic-job apply --forge gitlab`, including its whole-batch refusals and
pre-write checks. All output kinds listed under [publishing to GitLab](#publishing-to-gitlab)
are available under explicit policy bounds: notes, issues, labels, closing,
inline findings, fork-pushed Draft MRs and head-leased updates, including
caller-accepted own branches. Caller status/summary lifecycle flags are not
safe-output kinds and are not part of this standalone interface.

The standalone CLI's loopback tests exercise issue creation through check and
apply, including exact project routing, allowed labels and publisher provenance.
A policy-allowed label missing from the live project's label list refuses the
whole batch before any write, including an earlier valid note: GitLab must not
implicitly create it. This is local API-contract coverage, not live-service or
CI artifact-provenance proof.

Standalone inline-review loopback tests also cover LEFT/RIGHT and context-line
positions, the checked MR head and SHA triple, mention/quick-action filtering,
and MR-only routing. A stale head, foreign target, missing diff refs, unavailable
or truncated diff, or absent line refuses the entire batch before writing an
earlier valid finding. Check refuses inline output without explicit bounds, a
merge-request target and a trusted review head. These tests exercise the CLI
through the shared publisher; they do not prove live GitLab or caller activation.
The same suite (`cargo test --locked -p safe-outputs --features test-support
--test cli_gitlab_inline`) changes each member of the diff SHA triple between
the target reads around diff retrieval. Apply refuses before any write, including
when an earlier finding has already passed preflight. This guards against posting
a finding with a position computed from a diff that changed while it was read;
it does not make publication atomic with subsequent changes on GitLab.

Diff-pagination regressions in `cli_gitlab_inline` require a complete listing
even after finding the requested file. They cover a match on the short twentieth
page and an early match followed by an empty page. Twenty full pages refuse
without requesting page 21; a duplicate match on a later page, an oversized
page or a non-array response also refuses before any write. These tests pin
the existing bounded scan against incomplete or ambiguous inline positions;
they add no permission or caller setting and do not prove snapshot consistency
across GitLab API requests.

Standalone close-operation loopback tests keep an issue and merge request with
the same number distinct, even when the trusted default comment target is the
issue. They check the closing note's mention and quick-action neutralization,
the subsequent state change and the returned item URL. A locked merge request
refuses the entire batch before an earlier valid issue note can be posted.
These tests cover the CLI-to-publisher contract, not live-service publication
or CI credential isolation.

GitLab's trusted context has a different shape: `policy` is the existing full
effective policy JSON (the same object `agentic-job policy` emits), `server` is
the forge origin, and `run_url` is the trusted CI run page. Optional `item` and
`item_kind` (`issue` or `pull-request`) must appear together. Inline findings
also require trusted `review_head`, bound to that MR. Do not derive these from
producer artifacts. For a single deterministic note, a minimal context is:

```json
{
  "policy": {
    "forge": "gitlab",
    "contract": 1,
    "repo": "example/team/project",
    "clone_url": "https://gitlab.example/example/team/project",
    "base": "main",
    "kind": "analysis",
    "max_outputs": 1,
    "max_patch_bytes": 1048576,
    "safe_outputs": { "add_comment": { "max": 1 } }
  },
  "server": "https://gitlab.example",
  "item": 7,
  "item_kind": "issue",
  "run_url": "https://gitlab.example/example/team/project/-/pipelines/123"
}
```

For patch operations, put the existing `base.json` and `aw-BRANCH.patch` beside
the input JSONL. Check and apply read each as a bounded no-follow regular file
(one patch, at most 1 MiB and the policy's limit; base at most 64 KiB). The
receipt binds their exact bytes as well as forge, context and JSONL. Transfer
these files through the trusted check artifact channel too. Patch policy uses
the existing protected paths, author, fork/own-branch bounds and pinned push
head, not a second standalone policy implementation. Nested group paths work.
Apply reads only `SAFE_OUTPUTS_TOKEN`, never `GITLAB_TOKEN` or agent credentials.
No automatic retry, transaction or rollback is added.

Standalone patch-file regressions (`cargo test --locked -p safe-outputs --test
cli gitlab_patch_files_are_bounded_regular_inputs_at_check_and_apply`) exercise
both MR creation and branch updates. Check accepts the exact caller patch-byte
bound and the 64 KiB base-metadata bound; check and apply refuse the first byte
over either bound, missing files, directories and symlinks to identical bytes.
Apply is tested with a previously valid receipt, and every refusal precedes any
forge request. This is local artifact-admission coverage, not successful git
transport, live GitLab or CI artifact-isolation proof; no caller setting changes.

Standalone label-operation regressions (`cargo test --locked -p safe-outputs
--features test-support --test cli_gitlab_labels`) cover issue/MR routing with
colliding numbers, incremental label changes and replay without another write.
They also prove that a missing project label or an implicit scoped-label
replacement refuses the whole batch before an earlier valid note can publish.
Pagination cases find a label on page 19 and require an empty page 20 to
complete the listing. A nonempty page 20 refuses the entire batch without
requesting page 21, even when the requested label was already found. This
preserves the existing bounded scan rather than trusting an incomplete label
inventory that could conceal label side effects.
Revalidation cases change live labels after successful batch preflight: a
deleted project label or newly conflicting scoped label refuses publication
without a write, while an already completed addition or removal returns the
typed item's URL without another mutation. This check narrows the race window;
it is not an atomic guarantee against changes after the final read.
These are loopback CLI-to-publisher tests, not live GitLab or CI isolation proof;
they introduce no new permission or caller setting.

Standalone push-preflight regressions (`cargo test --locked -p safe-outputs
--features test-support --test cli_gitlab_push`) exercise a checked patch behind
an earlier valid issue note. A moved head, changed source project or branch,
deleted source project, non-open MR or mismatched MR identity refuses the whole
batch before either the note or git transport runs. These loopback tests prove
CLI-to-publisher refusal, not successful pushes, git leases or live CI isolation;
they add no permission or caller setting.

Minimal GitLab CI jobs, on separate isolated runners, using a pinned binary
already installed by the operator and caller-owned `/trusted/context.json`:

```yaml
stages: [check, apply]
check:
  stage: check
  script:
    - safe-outputs check --forge gitlab --context /trusted/context.json --input outputs.jsonl --checked checked.json
  artifacts:
    paths: [outputs.jsonl, checked.json]
apply:
  stage: apply
  needs: [check]
  environment: safe-output-apply
  rules:
    - if: '$CI_COMMIT_BRANCH == $CI_DEFAULT_BRANCH && $CI_COMMIT_REF_PROTECTED == "true"'
      when: manual
  script:
    - safe-outputs apply --forge gitlab --context /trusted/context.json --input outputs.jsonl --checked checked.json
```

Supply the deterministic JSONL before check, for example
`{"type":"add_comment","body":"Deterministic GitLab proof."}`. GitLab numbers
issues and MRs separately: notes use the caller's fixed item/kind, not
`item_number` in the request. Store the token as a masked, protected variable
named `SAFE_OUTPUTS_TOKEN`, **environment-scoped to `safe-output-apply`**, so
check and the producer cannot read it. Protect that environment and the CI
configuration; do not run apply on untrusted refs. Pin context/run identity
outside producer control and do not execute transferred content. This example
does not provision runners, produce agent output or prove live GitLab CI job
isolation; the disposable local GitLab test covers publication, not deployment.

The [CLI proof workflow](../.github/workflows/safe-outputs-cli.yml) uses
the existing e2e destination, issue 64 in `cgwalters-forge/agentic-job`, and
runs apply in the existing `agent-apply` environment. A push to this repository's
`main` that changes the workflow file, or a dispatch on `main` with
`publish: true`, constructs a fixed non-agent comment, checks it after
secure-host without write permission, and uploads the request and receipt as
one digest-bound file. Apply, a
[trusted artifact consumer](workflows-check.md#trusted-artifact-consumers) on a
separate runner, verifies that digest, builds the CLI and reads the context
from the run's own `main` commit outside its workspace, and reads the artifact
only as data. No target or revision input and
no pull-request event is accepted. Its fixed
[caller context](../.github/agentic-job/e2e/safe-outputs-context.json) allows only
one comment. Apply publishes with its issue-write job token and never reads
`SAFE_OUTPUTS_PAT`: the build's dependencies run beside that token without
secure-host, so the job holds nothing stronger. It creates no repository and
uses no new secret. Manual `publish: false`, PR events, forks and other branches
cannot run either job; manual publication remains off by default.

The concrete duplicate threat is competing attempts, including a rerun after a
lost POST response. All attempts share a fixed, non-cancelling concurrency group.
Immediately before apply, a read-only guard inspects at most 100 comments on
issue 64 (30 seconds, 8 MiB). A full page, failed/malformed lookup, multiple
matches or a matching phrase without the exact body and GitHub Actions bot/App
identity fails closed. An existing exact comment is linked and reused, never
posted again. Absence permits publication only on a run's first attempt; a rerun
without a comment refuses and requires inspection of issue 64 and prior apply
logs. This is not a general CLI idempotency feature. No automatic POST retry is
added. Successful apply reads the comment back and links it in the summary;
an ambiguous POST failure stops before that step. Do not dispatch again to work
around a refusal without inspecting the actual outcome.

Live proof still requires the merged workflow on `main`, environment approval
if configured, and an accessible issue 64. As of the latest pre-change inspection,
the workflow has no runs and issue 64 has no standalone proof comment. Merge is
only the trigger, not completion: observe the actual `check` and `apply` jobs and
logs, verify the resulting comment, then link both the successful non-agent run
and comment back to #2397 through safe outputs. If publication fails, inspect the
failing step and reproduce/fix it without weakening these boundaries. Keep #2397
open while waiting for merge/run or investigating failure; offline tests and PR
CI are not credentialed publication evidence.

## Stacked proposals: library groundwork only

The experimental `safe_outputs::check::stack` library module checks an ordered
proposal with one issue, title, body and single-commit mail patch per step.
It does **not** enable stacked hand-backs or publish pull requests. The CLI,
artifact format and one-PR limit are unchanged. No production caller should
enable stacks yet; this is library groundwork for #3438.

Bounds may set experimental `[github.outputs] stack-steps` (default zero,
at most ten, only alongside `create_pull_request`). Policy compilation carries
it as `safe_outputs.stack_max_steps`, taking the lower of both bounds files;
omission in either disables policy-based stack checking. `check_policy` uses
that ceiling and `policy.max_outputs` together, plus the policy's patch byte,
path, file-count and pinned-author rules. It refuses secondary, external or
advisory publication contexts. This field is stripped from gh-aw's handler
configuration and never increases its ordinary one-PR limit. No workflow
consumes a stacked proposal yet.

The concrete threats are unbounded publication fan-out and a forbidden edit
hidden by a later revert. The trusted library caller must explicitly pass a
`max_steps` of 1–10 (zero refuses); the entire JSON envelope is capped at 1 MiB
before parsing. Each step gets its own existing patch path/type/protection,
file-count and pinned-author checks, plus a caller-supplied patch byte limit.
Titles are capped at 128 bytes and bodies at 48,000 bytes. Issue numbers are
distinct positive integers no greater than 2,147,483,647. The caller must supply
a read-only inspection callback for its secret scan and other content checks;
the library does not acquire credentials or scan secrets itself.

The strict JSON envelope has `base_commit` and `steps`; each step has only
`issue`, `title`, `body` and `patch`; duplicate fields are refused before they
can be collapsed by JSON value decoding. The root commit must match the trusted
caller's full commit ID. Patches are plain `git format-patch --stdout
--no-signature -1` mails, without a base header, describing only their own step's
diff. As for a replacement series, each needs exactly one valid `Date` header,
so that rebuilding a step gives the same commit. The checker supplies the root
provenance header to the existing patch reader; it does not itself apply the
mails. Invalid envelopes refuse the whole
proposal. A step refusal returns the accepted prefix and the first refused
position (one-based), never inspecting steps above it. No accepted prefix is
itself a publishable receipt.

The experimental `safe_outputs::apply::stack` module builds the accepted steps
in the caller's repository, one commit per step on its predecessor, with
`git am` and the fixed committer a [replacement series](#pushing-to-a-pull-requests-branch)
uses, so the same mails on the same base are the same commits. Each commit must
change exactly the paths check read for its step. For a fix round, `restack`
rebuilds the whole stack from its checked steps with the fixed one replaced by
its checked fix: the steps below are the same commits as before, and every step
above is rechecked by being built again on the fix. Nothing is replayed from a
branch check did not read. A step that does not apply,
or changes other paths, stops the stack at its position with a fixed reason, so
a conflict never drops a step silently. Neither function pushes or publishes.

Remaining slices must wire the producer, per-step secret scan and both library
modules into digest-bound check/apply artifacts, then push each step's branch
with a lease and open its PR against its
predecessor, appending that step's closing line. Publication must stop on
refusal without removing earlier PRs. The publisher must keep the stack rebased
after parent changes/merges with `restack`, not rely on PR retargeting to
rewrite git history. Those publication paths, their end-to-end tests, per-step
PR receipts and the series' total cost report are not implemented yet.

## Caller-bound publisher roles

The threat is credential substitution: a comment operation borrowing the
fork-push credential, or a missing role secret falling back to a stronger PAT.
The optional trusted workflow input `role-bindings` prevents that on GitHub,
and the same `APPLY_ROLE_BINDINGS` environment variable does so for
`agentic-job apply --forge` ([below](#forgejo-and-gitlab-roles)). Neither
requests nor agent output can set a role, token name, actor ID or App ID.

| Operation | Fixed role | Secret |
| --- | --- | --- |
| Run-status comment | `status` | `STATUS_TOKEN` |
| Review or result comment, inline review, push-result comment | `review` | `REVIEW_TOKEN` |
| Fork creation, disabling fork Actions, git push | `fork_push` | `PUSH_TOKEN` |
| Upstream PR publication, issue/label/close metadata | `publication` | `PUBLICATION_TOKEN` |

An empty mapping preserves today's single `SAFE_OUTPUTS_PAT`/job-token fallback,
including the PAT supplied as `STATUS_TOKEN` in policy/apply. A nonempty mapping
must bind all four roles. Missing credentials, wrong authenticated numeric actor
IDs or wrong App IDs refuse; there is no fallback. Apply checks all credentials
before its first fork/write. Each status job checks only its own credential.
Roles may deliberately share a credential, but doing so loses separation.

Configured GitHub App roles require an authenticated GraphQL viewer with the
configured numeric `actor_id`. GraphQL declares viewer as `User`, not `Bot`;
REST `GET /users/LOGIN` must independently confirm the same ID and `type: Bot`.
The authenticated login must end in `[bot]`; its App is resolved through
`GET /apps/SLUG` and must match `app_id`. Unsupported viewer queries fail closed.
Rerun/ownership detection requires both the actor ID and REST
`performed_via_github_app.id`, never login text alone. User App tokens with an
`app_id` are not supported: `/user` or viewer identifies the user, not which App
issued that user's token. Fork-push still needs a user's credential and `/user`
to find its fork. Plain user bindings omit `app_id`; their owned objects must
have no App provenance. Ownership lookups use the operation's own role token,
including the review token for comment rerun detection and reply validation.

Role mode requires every writing request to use a supported `native_handlers`
entry. Legacy-only handlers and replacement-series pushes refuse before the
first write. No App, key storage, minting or refresh is added.
Live installation-token viewer behavior and App provenance proof await operator
provisioning; offline tests do not establish them.

### Forgejo and GitLab roles

`agentic-job apply --forge forgejo|gitlab` reads the same JSON from
`APPLY_ROLE_BINDINGS` and the same four `*_TOKEN` variables, set by the
caller's apply job only. Without a mapping it uses `FORGEJO_TOKEN` or
`GITLAB_TOKEN` as before; with one, it never reads that token, and a
missing role token refuses rather than falling back. Each op goes to a fixed
role by its kind, as in the table above: the caller's commit status to
`status`; `add_comment` and inline review comments to `review`;
`push_to_pull_request_branch`, including its reads of the pull request and
fork, to `fork_push`; and issues, labels, closing and new pull requests to
`publication`. A new pull request is pushed to `--push-repo` over git with
`PUSH_TOKEN` and opened through the API with `PUBLICATION_TOKEN`, so the
upstream identity never holds a credential that can push. The publication
identity must still be able to read the fork, and on GitLab, which opens a
merge request on its source project, to open one there.

Before the first write, apply reads each token's authenticated user (Forgejo
`GET /api/v1/user`, which needs the `read:user` scope; GitLab `GET /api/v4/user`,
a project or group access token's bot user) and refuses unless its numeric `id`
is the bound `actor_id`. An `app_id` refuses: these forges have no Apps, so it
could only claim a provenance nothing checks. The only rerun detection these
publishers have is GitLab's commit status read-back, which in role mode takes an
identical status as already set only when its numeric `author.id` is the status
role's `actor_id`, never by username. Each publisher scrubs every form of the
tokens it holds from its errors, and apply also removes every role's raw token,
should a forge echo one role's token in another's answer.

## What is gh-aw's, and why

One script is run as gh-aw ships it: its handlers
(`safe_output_handler_manager.cjs`), which act on the requests. They
come from the action `github/gh-aw/actions/setup`, pinned at commit
`462ed682857c4ab64d40f2c85e3738fa27834839` (v0.91.12-7) in every place
that uses it. Nothing from gh-aw is copied into this repository. Its
collector (`collect_ndjson_output.cjs`), which validates and sanitizes
the requests, is reimplemented as [`collect`](#off-github), held to it
by fixtures gh-aw's collector wrote at that commit. The rules an agent
is held to must be the ones it can check before its session ends, and
gh-aw's collector cannot run on the agent's machine: so `handback check`
runs `collect`, and so does the check job.

gh-aw's collector adds a `report_incomplete` item of its own to a result
holding nothing but `missing_tool` and `missing_data`, or nothing at all;
`collect` does not. No run may hand one back: check leaves out exactly
that last item, refuses any other, and apply's handlers get only the
requests check accepted.

Both run with gh-aw's
[`safe-outputs.urls`](https://github.github.com/gh-aw/reference/glossary/#url-sanitization-policy-safe-outputsurls)
set to `allowed-or-code-region`. Its default redacts every URL that is
not `https://` to an allowed domain, in code blocks too, and a
non-`https` one up to the next space, so build output was lost: Cargo's
`path+file://` package ids took the JSON after them with them
([#401](https://github.com/cgwalters-forge/agentic-job/issues/401)).
Now URLs in inline code and code blocks are kept, and those in prose
are filtered. gh-aw's idea of code is not exactly GitHub's
(an HTML block around a fence, escaped backticks, a span across a blank
line), which no longer matters for https links: see below.

An `https://` link to any public host is kept as written, in prose and
code, for every output type
([#918](https://github.com/cgwalters-forge/agentic-job/issues/918)).
The filter removed source links from reports without preventing a leak: the
sandbox has no credential worth leaking, its reads are open to any host anyway,
and GitHub fetches images through its own proxy. The pinned sanitizer
has no setting that keeps every https link, and no wildcard for every
domain, so `policy` gives it, as
[`safe-outputs.allowed-domains`](https://github.github.com/gh-aw/reference/safe-outputs/)
(`GH_AW_ALLOWED_DOMAINS` to the handlers; `collect` keeps the same), every
top-level domain in IANA's list, whose subdomains it keeps.
`just refresh-top-level-domains` updates the list; a link to a domain
newer than it, to an address or to a host of one label is still
redacted, as is a non-`https` URL in prose. gh-aw's other sanitizing
stays: mentions, bot triggers, HTML and link titles. A bounds file's
top-level `allowed_domains` (from
[#910](https://github.com/cgwalters-forge/agentic-job/issues/910)) is
accepted and ignored. gh-aw's redaction takes a Markdown link's
closing parenthesis with it, posting `[text](http://host/path)` as
`[text]((host/redacted)`, so check makes that `text (host/redacted)`
before apply. `agentic-job handback check` notes, for each request, the
hosts whose links would be redacted, before the session ends.

Secrets are not filtered by shape either, beyond redacting logs. `run`
refuses to upload anything while the hand-back or a file that could not
be redacted holds an upstream credential the run itself holds, its run token
among them: that one would be a real leak. The separate agent-facing inference
and MCP proxy tokens are replaced before upload, as described below.
Check and `run` refuse a PEM
private key anywhere in the outputs, code included, unless the caller opts in
to the narrowly scoped [public-base exception](#public-base-secret-evidence).
Any other credential-shaped string (a `ghp_`, `sk-`
or `AKIA` token, a JWT) is most likely a test fixture. Refusing these strings
caused runs to lose all their work
([#720](https://github.com/cgwalters-forge/agentic-job/issues/720)). The string
is now kept and reported as a warning by file, line and pattern, never by
the string, in check's report and summary and in the run's summary.
`agentic-job handback check` runs the scan of
`agentic-job handback scan --base BASE_SHA` too, which lists the same
by file and line in the change's diff and in `out/`, and exits 1 only
for a private key or a `praxis-run-` broker run token the change adds or
`out/` holds: `run` refuses its own by value, and the agent cannot tell
it from another by shape. Known upstream credentials without a listed shape
are refused only at upload. The final refusal names the file, line and rule, never
the string: `known run secret: SOURCE` distinguishes a value held by the run
from `pattern: private key header`. Source names are fixed public labels, not
credential values; other environment tokens use `environment *_TOKEN` rather
than arbitrary environment variable names. These appear in the job's log,
its summary and, through the run action's
`secret-at` output, the status comment, since such a run uploads nothing
else to look in publicly. On a secret refusal, `run` moves its staging directory
to `OUT/refused-handback` with mode 0700 on the operator's host storage. It
contains the hand-back, run files and transcript, not a publishable artifact.
Another run using that `OUT` is refused rather than erasing the recovery copy.
Keep `OUT` on private persistent storage for recovery; the shipped Actions
uploads deliberately exclude this directory. An ephemeral runner's removal
also removes its local recovery copy: this is not remote private artifact storage.

Inference addresses are not credentials. Before upload, hand-back patches,
PR bodies and safe outputs replace them with `<inference-address>`. The separate
agent-facing inference and MCP proxy tokens become `<agent-inference-token>`
and `<mcp-proxy-token>`; the run summary counts all these replacements.
Publication still requires confirmation that the inference run ended at the
proxy. The original bytes of every hand-back file are independently scanned
for upstream credentials and private keys before any replacement, so redaction
cannot hide an overlapping credential and a refusal retains the original work.
`GH_TOKEN`, other held `*_TOKEN` values, broker run tokens, provider API keys
and upstream MCP credentials remain refusals. If a token has both an agent-facing
and an upstream role (direct broker mode), the upstream refusal wins.
`allow-base-address-lines`
is now a legacy no-op. A placeholder may break a build; review or continuation
must repair added values rather than discard the work. Opted-in
[old-side replay](#endpoint-redacted-patch-replay) can repair patch application. All
other bounds and check/apply refusals remain. Logs and transcripts keep their
current redaction; see
[inference address redaction](inference.md#what-run-does).

### Endpoint-redacted patch replay

The threat is a producer treating a placeholder as a wildcard for arbitrary
base bytes, inventing substitution evidence, or publishing a tree different
from the checked trial. `[commit] replay-redacted-endpoints = true` is off by
default. It authenticates only inference endpoint substitutions, not token
placeholders. It currently supports **primary native GitHub create_pull_request**
publication; that output must already be routed through `native_handlers`.
Legacy handlers, pushes, other forges and endpoint-bearing replacement/secondary
carriers fail closed. No target bounds or redaction exceptions are changed.

The trusted policy job's existing `capture-base-secrets` command records only
the configured broker endpoint authorities' byte lengths and SHA-256 digests in
`public-base.json`. They come from trusted runtime configuration, never proposals
or the agent's base evidence. Configure the same authorities that the producer
redacts: resolving or overriding an authority only in the agent job does not
authorize it for replay. Missing or different provenance fails closed.
The existing private-key/run-credential scan of originals, overlap refusal,
private retention and inference-end gates are unchanged.

After normal collection and patch validation, check independently fetches the
target branch, verifies the declared base's ancestry, and reads bounded blobs
from that exact commit without running target code. Every old-side line must
match at its declared coordinate, either exactly or after the authenticated
endpoint substitution, including all surrounding bytes. Paths, hunk counts,
non-overlap and old/new coordinates are validated. Only deletion and context
bytes can be recovered; additions keep placeholders. Replay admits at most
eight endpoint fingerprints (8–512 bytes each), 50 paths, 1 MiB of base blobs,
and 1 MiB each of input and recovered patch. Non-ASCII/ambiguous paths,
no-final-newline markers and non-text blobs fail closed rather than acquire
different replay semantics.

Check runs a real `git am --keep-cr`, compares changed paths with the normal
check result, and binds the redacted patch digest, declared base, endpoint
fingerprints and resulting tree in `report.patch.replay`. Artifacts contain
only the redacted patch and value-free receipt. The apply workflow's
`replay-trial --checked DIR` repeats that independent trial. Native publication
reconstructs in memory again and pushes that very commit only after its tree
and paths match the receipt; it never hands raw patches to legacy handlers.
Replay failures report fixed, value-free guidance before publication. No raw
replay patch or base blob is logged or uploaded.

Offline regression tests cover collection/redaction, check, real Git trials
and local bare-repository pushes. Hosted replay of the reported failures and
release/pin rollout remain separate acceptance work; ordinary local tests do
not establish either. Do not rerun production jobs merely to test this option.

### Public-base secret evidence

The threat is a producer laundering a new private key through an already-public
header, a different file or forged base history. The option
`[commit] allow-base-secret-lines = true` is off by default. It permits only exact
base-file lines in structurally validated patch hunks: removals, retained
context and moves consuming removals in the same file. New files, extra copies,
changed lines, mail messages, requests and replacement series get no exception.
PEM keys additionally require the entire unchanged block in the hunk, including
for removals: a producer can invent old body lines, so authenticating only the
header could disclose a new key before patch application refuses it. A matching
footer must follow the header. Header-only fixtures and limited context that
does not contain the whole block fail closed; quoting syntax cannot prove that
a string closes.
Known run-secret values
remain refused, even on an otherwise eligible line. Other token shapes remain
warnings, not newly forbidden strings.

The trusted policy job captures evidence before the producer starts using
`capture-base-secrets --config FILE --policy FILE --run-id ID --output FILE`.
It fetches the public base without credentials and never checks out or executes
target code. Evidence contains exact line/block SHA-256 digests and occurrence
counts, scoped by base commit, patch name and file. Capture bounds are 1 MiB of
matching lines, 50 files, 1 MiB total secret-bearing file contents and 1 MiB
serialized evidence; git operations have timeouts. Exceeding a bound refuses.
Private targets cannot enable this exception. Secondary patches are not covered
by the policy job's evidence. A base branch advancing between capture and run
can conservatively refuse the allowance; rerun to capture the new base.

`check --base-secret-evidence FILE` reads this file from the trusted policy
artifact, **never from the proposals artifact**. A standalone caller must keep
this argument and file outside the producer's control. Omit it to retain the
default refusal. `run` separately captures the same bounded evidence from its
base checkout before starting the agent for its upload gate and local handback
check. Logs/transcripts stay redacted. Each allowance reports
“base already contains this; allowed” with its location, never its value.
This repository enables the option in `.github/agentic-job/hosted.toml` so runs
can delete already-public corpus fixtures without admitting new keys.

One file is derived from gh-aw:
[`safe-outputs/validation.json`](../safe-outputs/validation.json), the
rules of each type. gh-aw's compiler writes those into the workflows it
generates and publishes them nowhere else, so
[`validation.mjs`](../safe-outputs/validation.mjs) reads them out of
gh-aw's own compiled workflows, and CI fails when the file is not what
the pinned commit gives. The same script reads, out of the handlers' code
at that commit, the limits they hold a request to at apply and their
errors: a comment's length and links (E006, E008), counted again with
the footer gh-aw adds and apply's own note and marker, and the labels of an issue or of `add_labels`
(E003). It fails on a limit check in the handlers it does not list.
`agentic-job handback check` refuses a request over one in the session,
in the handler's words, so the agent can still change it; apply refused
a comment of 58 links after the session, and it was lost whole
([#963](https://github.com/cgwalters-forge/agentic-job/issues/963)).
It also refuses a `missing_data` with no `reason`, which gh-aw takes and
the status comment can only quote as "none given"
([#1102](https://github.com/cgwalters-forge/agentic-job/issues/1102));
`check` does not, as it would refuse a change handed back with it.

The types a run can be allowed are `create_pull_request`, `create_issue`, `create_discussion`, `add_comment`,
`close_issue`, `add_labels`, `remove_labels`, `update_issue`, `update_pull_request`,
`mark_pull_request_as_ready_for_review`, `create_check_run`, `update_project`, `push_to_pull_request_branch`,
`add_reviewer`, `assign_to_user`, `close_pull_request`, `link_sub_issue`, `hide_comment`,
`create_pull_request_review_comment`, `reply_to_pull_request_review_comment`,
`resolve_pull_request_review_thread`,
`document`, `noop`, `missing_tool` and `missing_data`.

### Durable findings documents

The threat is an untrusted request overwriting an unrelated gist or choosing
public visibility using the applying account's credential. `document` is off
unless bounds allow it and route it to the native GitHub publisher. Updates
require an exact ID in trusted bounds; apply also verifies that the gist belongs
to its authenticated account and has the policy's visibility before writing.
No owner, visibility, deletion or filename rename can be selected by a request.

```toml
native_handlers = ["document"]

[github.outputs.document]
max = 1
# Optional; absence means secret creates and no updates.
document = { public = false, gist_ids = ["abcdef0123456789abcdef0123456789"] }
```

Organization bounds intersect IDs and permit public visibility only if both
files enable it. **Secret is not private:** anyone with the URL can read a
secret gist. The issue comment exposes that URL to the issue's readers. This
does not add a private storage mechanism or give the producer/check job a token.
Apply needs a user token with gist-write permission (a classic PAT's `gist`
scope), plus issue-comment permission. The repository job token cannot write
gists. In role mode the gist uses `publication` and its link comment uses
`review`; gist updates must be owned by the publication account. No caller is
enabled by this change.

For example, request a new document with:

```json
{"type":"document","title":"Topic findings","files":{"findings.md":"# Topic\n\nEvidence and open questions."},"summary":["Saved the evidence.","Corrected one claim.","Recorded the remaining question."]}
```

Add `"gist_id":"abcdef0123456789abcdef0123456789"` to update that same gist.
The request has no repository or issue destination: the caller's fixed comment
target supplies both. Check refuses a run without that target, more than one
document, or a document mixed with any other writing output. Non-writing `noop`,
`missing_tool` and `missing_data` remain possible. One document request includes
both the gist write and its one short issue comment; it does not require an
`add_comment` allowance. Use `notify: none` to avoid a separate run-status
notification comment if the caller wants only the document comment.

Files are an object of Markdown basenames to nonempty text: 1–10 files, names
at most 128 ASCII bytes (letters, digits, dots, hyphens and underscores, no
leading dot), ending in `.md`. Title is 1–128 UTF-8 bytes. Summary is exactly
three nonempty single-line strings, each at most 200 UTF-8 bytes. Title, names,
contents and summary together may not exceed 46,000 UTF-8 bytes. Check refuses
oversize content rather than truncating it, scans for private keys before
sanitizing, and uses the same Markdown/mention/URL sanitizer as comments. The
ordinary run-secret refusal and credential-shape warnings still apply. Unknown
request fields refuse. Updates replace the supplied files' contents, retain
unmentioned files, and create a revision of the same gist, not a new gist.

The native result/created-item manifest records `url`, `id` and the exact
`metadata.revision`. Apply posts one comment linking that immutable revision,
followed by the three summary lines. A later run's caller supplies the prior
document URL and content in its task/context input, and allowlists the ID in
bounds, so the run can extend the existing document instead of starting over.
There is no implicit gist discovery or background memory fetch. Concurrent
updates have no compare-and-swap lease; callers should serialize runs per topic.

Gist writes and comments are not transactional. No write is automatically
retried: a lost response can leave an uncertain write. If the gist succeeds but
the comment fails, apply fails and retains the URL/revision in its created-item
record for recovery. Inspect it and the destination before retrying; replay can
create another gist/revision/comment. The pinned gh-aw adapter, non-GitHub
publishers and standalone CLI apply do not implement `document`.

### Proposing follow-up issues

A run can propose follow-ups with its hand-back as `create_issue` requests
([#3191](https://github.com/cgwalters-forge/agentic-job/issues/3191)). Each
is opened in the caller's output repository, under the per-type `max` and
total `max_outputs`, with the footer linking the run; in a run for an issue
of the run's repository it is made that issue's sub-issue. A run that
cannot know what earlier runs filed would open the same follow-up again
each time, so the bound can ask apply to search first:

```toml
native_handlers = ["create_issue"]

[github.outputs]
create_issue = { max = 3, comment_on_duplicate = true }
```

With it, apply searches the repository's open issues, oldest first, for
one whose title is exactly the one the issue would be opened with, title
prefix included (so a run stopped at a limit, whose prefix says so, matches
only its own kind), and posts the body, footer included, as a comment on
the oldest of the first 100 answers instead of opening an issue. Labels are
not applied and no sub-issue is linked. So a refinement of an existing issue
(a split, a narrower scope, acceptance criteria) is a `create_issue` naming
that issue's title. A pull request, a closed issue or another repository's
issue is not a match, and a search that fails (one over the forge's 256
characters among them) fails the request rather than open a possible
duplicate. The search sees what the forge has indexed, so an issue opened
moments earlier may be missed. Only
[agentic-job's own handler](#agentic-jobs-own-handlers) searches, so the
setting requires `create_issue` in `native_handlers`, and with organization
bounds both files must set it.

This reaches further than `create_issue` alone: a run can comment on any
open issue of the output repository, one a person filed too, by naming its
title, past `add_comment`'s fixed item, with the mentions an issue's body
may have. Each request is still one write, counted by `create_issue`'s
`max`. A re-run of apply does not find a comment it made earlier, as it
finds an issue, and comments again. Off (the default), every request opens
an issue.

### Updating project fields

`update_project` admits exact Projects v2 URLs, exact field names, and a count:

```toml
[github.outputs.update_project]
max = 3
projects = ["https://github.com/orgs/example/projects/1"]
fields = ["Status", "Turn", "Run", "Result"]
```

Both lists must be explicit and nonempty. Each request includes `project`,
`target_repo` equal to the run's exact `repo`, `content_type: "issue"`, a positive
integer `content_number` no greater than 2,147,483,647, and a nonempty `fields`
object. Values may be strings or
numbers; null/clearing is not supported by the pinned handler. Field options and types must already exist on
GitHub. The handler can add the issue to the named project if it is not there.
Other repositories, unlisted projects or fields, draft/PR content, aliases,
project/schema mutations and temporary IDs are not exposed. Per-type `max` and
total `max_outputs` count requests, not fields. The whole hand-back is refused
when it exceeds either count. This accepts agent-board's documented
`reconcile plan --emit` output without translating its routing keys.

Organization project writes require the caller's apply environment token; see
[token setup](workflow.md#the-apply-job-and-its-token). The repository job token
cannot write organization projects, so a call without `apply-environment` is
refused `update_project` at admission, before an agent runs, and `outputs: all`
leaves it out. The token stays in deterministic apply and, when explicitly
supplied, status jobs, never in the proposals producer or check.

Apply also guards the handler's GraphQL client: it refuses implicit field
creation and field IDs not read back with an exact allowlisted name. This stops
the handler's normalization from writing an unlisted field or creating schema.

### Closing issues and changing labels

These operations are bounded to the run's exact `repo`, admitted by the caller's
repository bounds, and their per-type `max` and the total `max_outputs`. They do
not use `output-repo` or fall back to the triggering event's issue. Requests must
include that explicit `repo` and a positive integer `issue_number` for
`close_issue`, or `item_number` for `add_labels` and `remove_labels` (issues or pull requests;
on GitLab exactly one of `issue_number` and `pull_request_number` instead:
[neutral profile](#neutral-profile)).
Temporary IDs, target aliases and duplicate relationships are refused.

```toml
[github.outputs.close_issue]
max = 2

[github.outputs.add_labels]
max = 3
allowed = ["triage", "documentation"]
blocked = ["release"]

[github.outputs.remove_labels]
max = 2
allowed = ["triage", "in-progress"]
blocked = ["release"]
```

`add_labels` requires an explicit `allowed` list; an empty one permits no labels.
Labels must be plain strings, matching that list case-insensitively, and not in
`blocked`. To keep the handler's final API payload identical to the checked labels,
names must be 1–64 ASCII characters: letters, digits, spaces or `- _ . / :`,
with no leading/trailing whitespace or leading `-`. Unicode and other punctuation
are refused rather than sanitized. `max` bounds both requests and labels within
each request; requests exceeding either limit are refused, not partially applied.
The handler does not create missing labels. Create the labels first.
`remove_labels` is off unless listed in bounds. Its explicit `allowed` list
stops an agent from removing authorization or automation labels outside the
caller's policy. It uses the same name restrictions, case-insensitive exact
allow/block matching, repository scope and request/label caps as `add_labels`.
It requires a nonempty `labels` array of strings; an empty allowlist permits
no removals. Apply removes each checked label separately; an absent label is
a no-op. Reapplying a request is therefore safe. No label definitions are deleted.
The pinned handler records other API errors as `failedLabels` but can report
success after partial removal; callers should inspect the apply log when a
label transition matters, rather than treating job success as atomic completion.
For example, `{"type":"close_issue","repo":"OWNER/REPO","issue_number":7,"state_reason":"not_planned","body":"Overtaken by #9."}`
posts the body on issue 7 and closes it. The body is required, so whoever
watches an issue learns why it was closed; `state_reason` is `completed` or
`not_planned`, `completed` when left out. Apply refuses the run, before it
applies anything, when a `close_issue` names a pull request (they share
numbers, and the handler would close one through the issues API) or an issue
transferred to another repository. A re-run
finds the comment by its name, as for a pull request's closing comment, and
closes the issue if the attempt stopped in between, but not one reopened since.
These operations need issue-write access in apply (PR labels can instead use
pull-request write access). No producer or check token gains write access.

### Updating issues and pull requests

`update_issue` and `update_pull_request` change only the fields their bounds
list, and `check` refuses a request holding any other key. The pinned handlers
cannot be relied on for this: `update_issue` ignores `allow_title` and
`allow_status`, and a request's `draft` and `update_branch` override
`update_pull_request`'s configuration.

```toml
[github.outputs.update_issue]
max = 1
fields = ["body"]          # of "title", "body", "status"

[github.outputs.update_pull_request]
max = 1
fields = ["title", "body"] # of "title", "body", "draft", "update_branch"
```

`fields` must be explicit and nonempty; organization bounds narrow it. A listed
`body` also admits `operation` (`append`, `prepend`, `replace` or
`replace-island`, which keeps one section a re-run replaces). An issue's
`labels`, `assignees` and `milestone` cannot be listed: labels would replace
every label past `add_labels`'s bounds, and nothing bounds the others.
Requests name the run's exact `repo` and a positive integer `issue_number`, or
`pull_request_number`; aliases and temporary IDs are refused, as above. GitHub
numbers issues and pull requests together, so an `update_issue` can edit a pull
request's title, body or state through the issues API.

Apply opens a pull request as a draft unless the bounds set
`ready_when_complete` and the work is complete ([ready or draft](#ready-or-draft)).
An agent taking one out of draft, with
`draft: false` or `mark_pull_request_as_ready_for_review`, is refused unless
the bounds list `draft` or that type; no shipped bounds file does. Mark-ready
requests take only `repo`, `pull_request_number` and the `reason` the handler
posts as a comment. `update_branch` merges the base into the pull request's
branch with the apply credential, which needs push access to it.

Apply needs `issues: write` for `update_issue`, and `pull-requests: write`
for the other two. No producer or check token gains write access.

### Ready or draft

By default every pull request is a draft, so "draft" says nothing about
the work. A bounds file can make it mean "a checkpoint, not finished":

```toml
[github.outputs]
create_pull_request = { max = 1, ready_when_complete = true }
# and for a continuation of a pull request:
# push_to_pull_request_branch = { max = 1, branches = ["agent-run-*"], ready_when_complete = true }
```

Organization bounds can only turn it off. With it, apply opens a pull
request ready for review when the work is complete, and as a draft when it
is not: when the run was stopped at a limit (exit state 124 or 3, applied
only with `apply-partial`), or when the pull request's body holds a
checkpoint. The agent writes one when it nears a limit, as the hand-back
notice says, or knows the work is unfinished; a pull request made up from
an outcome whose `stopped_early` is set, or that has no summary, gets one
too, under `ready_when_complete`. A checkpoint is shown, not hidden:

````markdown
```checkpoint
{"reason": "budget", "done": "the parser", "left": "its tests", "next": "add tests for the new cases"}
```
````

`reason` is `budget`, `runtime`, `cap` or `incomplete`; the other three are
nonempty strings. The agent is also asked to keep a checkpoint in its
outcome from the start ([harness](harness.md#limits)); while that
is not `"complete": true`, the pull request made up from the outcome, and
the agent's own request if its body or message holds no checkpoint,
end with it as `incomplete`, each field cut to 400 characters. So do they,
with the outcome's `stopped_early` as what is left, when the run stopped
early, even after the agent marked its checkpoint complete. With
`ready_when_complete`, `check` refuses the hand-back for a malformed checkpoint,
a second one, a line starting like the fence with more on it, or one over
8 KiB, rather than take it for complete work. Apply records the reason in
`applied.json`'s `checkpoint`: the exit state's (`runtime` for 124, `cap`
for 3, which does not tell a request, task or spending limit apart) when
the run was stopped, the checkpoint's otherwise, and null for complete work.

A push to a pull request (a continuation) works the same way, its commit
message holding the checkpoint. Once the push is verified, apply marks the
pull request ready for complete work and converts it to a draft at a
checkpoint, with the apply credential, which then needs pull-request write
access. This automatic transition needs no separate mark-ready bound:
what decides is `ready_when_complete`, the exit state and check's
report, not a request, and the [review](review.md) job remains the merge
gate. A run stopped at a limit still pushes nothing (RC-020). A run that
ends with neither complete work nor a checkpoint, nor any output its run
requires, fails as before.

Immediately before marking a continuation ready, apply reads its current labels: a case-insensitive `hold`, or a failed label read, leaves it draft and records why in `applied.json`'s `readiness.reason`, without undoing or failing the push.

What the checks stop is unfinished work opening ready for review, where a
reader or a poller would take it for finished: a stopped run cannot claim
to be complete, and a checkpoint check cannot read is refused, not ignored.

#### Unchanged completion remains unavailable

The threat is an agent-authored `outcome.json` or `noop` clearing an unfinished
continuation, or evidence from another target, head, run or attempt doing so.
There is an inert, off-by-default candidate and independently checked result
described below, but **no unchanged apply readiness or caller activation**.
A missing checkpoint in the check report is not proof of completion.
An unchanged result cannot trigger the readiness transition above,
even with `ready_when_complete`; that path still requires a push.

Merged [#3382](https://github.com/cgwalters-forge/agentic-job/pull/3382) preserved
the fail-closed behavior while documenting these gaps. The optional
`bind-continuation` workflow input (default `false`) now carries an admitted
push's repository, positive PR number and exact head together with the trusted
caller's `github.run_id` and `github.run_attempt` in `Policy.continuation`.
It requires a local admitted push, not legacy named proposals or external output.
The producer's existing hand-back `Request` carries that policy, checks its run
and checkout head, and never reconstructs identity from outcomes, JSONL or
inference registration. The run action refuses a policy from another attempt
before starting the producer.

Policy's `--continuation-run-id` and `--continuation-attempt` must be supplied
together by a trusted caller. Check receives the full tuple separately as
`--continuation-context` (at most 4096 bytes), plus the current `--run-id` and
`--run-attempt`. The library's `Trusted.continuation` requires exact equality
with the admitted policy; missing context or a different repository, PR, head,
run or attempt is refused. Only an accepted report carries `continuation`.
This field is identity (optionally including a caller-pinned verification
specification), **not a completion claim** or required-verification result.

Raw proposal ID and digest prove only the run: without more, a fresh checker
could read an earlier attempt's raw upload and stamp it with the current
identity. The artifact API exposes no producer attempt, and an agent job's
reported attempt, an attempt-looking upload name or inference registration
would not independently prove one. Check's bound path instead reads two
server-set timestamps before downloading anything: the raw upload's
`created_at` and this attempt's `run_started_at`, from the run-attempt endpoint
for its own `github.run_id` and `github.run_attempt`. GitHub starts an attempt
only after the previous one has completed, so an upload created strictly after
this attempt started is this attempt's; an upload of the same second, an expired
or other-run upload, a legacy proposals name and an unreadable attempt are
refused. The policy context must also name this run and attempt, so a policy
job kept from an earlier attempt by "re-run failed jobs" is refused too: re-run
all jobs instead.

The checked upload then reserves
`<artifact-prefix>checked-outputs-<run-id>-<attempt>` without overwrite. Apply
derives the expected suffix from its own trusted Actions context, not artifact
metadata, and requires the policy context to name that same run/attempt. Before
downloading it checks the ID, exact name, digest and run as before, and requires
one unexpired artifact of that name with that ID. The lookup is bounded to 100
artifacts in the run; a larger listing is refused, not partially searched.
An earlier-attempt artifact keeps its old name and cannot substitute; a name
preoccupied by another upload makes check's upload fail rather than authorizing
it. Check also exposes its trusted upload job's `artifact-attempt`, preserved
unchanged through the detector job; apply requires it to equal the current
attempt, so rerunning detection cannot relabel an earlier check. After download,
apply requires the report and included policy to match the
whole admitted tuple before any credentialed checkout or mutation. Checked
provenance relies on this checker-owned, collision-refusing namespace, the
trusted workflow pin and successful check job, not a producer-supplied attempt
field. Legacy callers omit the context and keep
their existing run-only artifact contract, with no unchanged-completion eligibility.

The concrete threat addressed by the optional `policy --continuation-verification
JSON` is a worker choosing an empty required set, somebody else's green jobs or
a dispatcher SHA unrelated to the tested tree. Only the trusted caller supplies
this specification. It becomes `continuation.verification` and must match the
independently supplied `check --continuation-context` exactly. No shipped workflow
or caller supplies this new CLI-only option; `bind-continuation` alone remains
identity-only. There is no deployment, dispatch, token-permission change, second
receipt, hold exception or readiness transition.

The specification requires `method: "actions-push-v1"`, `repository`,
`workflow` (a flat `.github/workflows/NAME.yml` path), `source` (full lowercase
commit), positive verifier `run_id` and `attempt`, and `required_jobs` (1–20
distinct job IDs/names, at most 64 ASCII letters, digits, underscores or hyphens
each). Target repository/PR/head and producer run/attempt remain the outer tuple.
The verifier repository must equal the target repository and `source` must equal
the tested PR head. The caller must independently review and trust the workflow
at that exact head; it is not trusted merely because it is proposed by the agent.
Neither identity nor
requirements can come from the producer's outcome or candidate.

The supported verifier semantics are deliberately narrow: a successful completed
`push` run in the target repository at the exact admitted head. For this event,
[GitHub executes the workflow at the pushed commit](https://docs.github.com/en/actions/reference/workflows-and-actions/events-that-trigger-workflows#push),
so the run's source SHA authenticates the workflow source, not just a dispatcher
commit. A separate current open-PR API read must match the admitted PR number,
head and head/base repositories (fork and cross-repository verification are
unsupported). A push need not originate from a PR; the exact current head is the
binding. The API run's repository, head repository, workflow path, source SHA,
run ID and latest attempt must all match. The workflow is read through the
contents API at that exact source revision.
Only canonical `serde_json::to_vec_pretty` JSON, without a trailing newline,
is supported as a YAML subset; general YAML, aliases and duplicate fields are
refused. This is an inert method contract, not a workflow to deploy.

The workflow allows only top-level `name`, `on`, `permissions` and `jobs`, with
`on` equal to `"push"`. Its jobs must be exactly the required set.
Each job allows only `name` (equal to its ID), `runs-on`, `steps`, `timeout-minutes`
and `permissions`; no conditional, matrix, reusable workflow or continued-error
job is accepted. Its first step must be exactly:

```json
{
  "name": "Establish tested tree",
  "uses": "actions/checkout@34e114876b0b11c390a56381ad16ebd13914f8d5",
  "with": {
    "repository": "${{ github.repository }}",
    "ref": "${{ github.sha }}",
    "persist-credentials": false
  }
}
```

These exact event expressions are required, not dispatcher inputs, mutable refs,
or the default checkout. The authenticated push event supplies the admitted
repository and commit. A literal self-referential source SHA in the workflow
would be impossible to construct. At least one following verification step is required; each
has a unique nonempty `name`, nonempty `run`, optional `shell`, and no other keys.
The trusted caller must review and pin the **whole source**, including those
commands and their dependencies, as actually testing that checkout. Structural
checkout validation cannot establish what arbitrary test commands mean. Check
never executes them, the proposed target code or agent-proposed commands.

The reader makes at most six authenticated GETs, each at most 1 MiB and 10 seconds,
with a 60-second total deadline, no redirects/retries or pagination. It refuses
non-200, unreadable/malformed metadata, any Link header, more than 100 jobs or a
count mismatch. Each required name must occur exactly once, at the pinned
run/attempt/source, completed successfully. Every reported step must succeed,
and each defined step must occur exactly once; missing, skipped, failed,
cancelled or ambiguous results refuse. The run and PR are re-read unchanged
before acceptance, closing head/rerun races. API origin and existing read-only
token come from `GITHUB_API_URL` and `GH_TOKEN`/`GITHUB_TOKEN`, never the hand-back.

**Unsupported bindings and missing engineering contracts:** a dispatch run's
`head_sha` authenticates the dispatcher, not the target checkout. Supporting that
case requires server-authenticated immutable event inputs/tested-tree metadata
and a pinned workflow contract interpreting them. `pull_request_target` is also
unsupported: REST `head_sha` can identify the PR head rather than the executed
default-branch workflow source. A concrete read-only observation is
[cli/cli run 43458281490](https://api.github.com/repos/cli/cli/actions/runs/43458281490):
its REST run/jobs head is `f219d43648a38f528a207c6f707a678e986dc079`, while
its recorded PR base is `3d5a9e355a837f2f5ee78d7484c118cc1342ad1a`.
Authenticating that event's immutable executed workflow source requires a
separate server-backed source contract; substituting a current default-branch
or PR-base SHA is not sufficient. Fork runs, cross-repository verifiers, mutable
refs, merge-tree testing, reusable workflows and general YAML are refused, not
guessed from check names. Their event/source and tested-tree contracts must be
specified and authenticated before extending this method. The push fixture's
REST shape was checked against
[run 43543815563](https://api.github.com/repos/cgwalters-forge/agentic-job/actions/runs/43543815563)
(push, matching run/head repositories and commit, empty PR links); this is a
read-only metadata observation, **not live verifier acceptance**.

With trusted verification present, the producer can explicitly write
`out/unchanged-candidate.json` (at most 16 KiB) containing only `identity` (the
whole continuation tuple), `checkpoint` (`complete: true`, nonempty `done` up to
4096 bytes, empty `left` and `next`), and `stopped_early: null`. All fields are
required and duplicate/unknown fields refuse. The producer requires a readable
unchanged checkout at the admitted head and an exactly matching explicit outcome
checkpoint/non-stopped outcome. No candidate is synthesized from a noop or raw
outcome. Check repeats candidate validation through bounded no-follow file and
secret checks, refuses patches/memory or non-noop requests beside it, then reads
independent results. Producer feedback does not read the API or stamp a checked
disposition. Outcomes remain diagnostics outside the hand-back;
`outcome.json.tests` and `test-evidence.json` are **agent-reported**, not independent
proof. The producer's clean-tree and completion declarations are agent-reported
too: even independently passing required jobs do **not** prove semantic task
completion or that the agent performed all requested work.

**Serialized handoff to #3381:** only a successful independent CLI check adds
`unchanged_completion` to the existing `report.json`, with `disposition:
"unchanged-verified"`, `identity` (including verifier specification), and
`verified_jobs` (exact required names). It travels with the policy through the
existing checker-owned, attempt-bound artifact above, not a parallel receipt.
The #3381 consumer must authenticate that artifact and match the whole admitted
repository/PR/head/producer run/attempt and verifier specification; an outcome,
noop, missing checkpoint or `continuation` alone is never sufficient. Consumption
and apply readiness remain unimplemented here. Agent-board #852 integration and
tracker #1071's separately authorized live acceptance remain outside this change.

`tests/run.rs` exercises the serialized producer → collector → independent CLI
checker with authenticated local API fixtures, including a positive control and
adversarial identity, source, checkout, result, context and checkpoint cases.
The pre-existing serialized fallback still proves that legacy complete-looking
outcomes/noops are diagnostics and raw/invented evidence is refused. Artifact
attempt/replay and apply identity regressions remain in the workflow tests.

### Requesting reviewers and assigning users

Both notify whoever they name, so an agent could otherwise page anyone with
access to the repository. Each is off unless listed in bounds, and then needs
a nonempty `allowed` list of logins; a bounds file without one is refused.

```toml
[github.outputs.add_reviewer]
max = 1
allowed = ["octocat"]

[github.outputs.assign_to_user]
max = 1
allowed = ["octocat", "hubot"]
```

A request names the run's exact `repo` and a positive integer
`pull_request_number` (`add_reviewer`) or `issue_number` (`assign_to_user`),
with a nonempty `reviewers` or `assignees` array. `check` refuses the whole
hand-back if a login is not in `allowed` exactly as written (the pinned
handlers compare logins case-sensitively and would otherwise drop it
silently), or if a request names more logins than `max`. Target aliases,
`team_reviewers` and the singular `assignee` are refused. GitHub also
accepts a pull request's number as `issue_number`. Apply does not unassign
current assignees. The pinned `add_reviewer` handler requests Copilot's
review bot for the login `copilot`; list it only to allow that. `add_reviewer` needs pull-request write access in
apply, and `assign_to_user` issue write access; the listed users must already
be able to review or be assigned. No producer or check token gains write access.

### Closing pull requests and linking sub-issues

`close_pull_request` and `link_sub_issue` are off unless listed in bounds, and
have the same repository scope and caps as the issue operations above: an
explicit `repo` that is the run's, and positive integers, never temporary IDs,
target aliases or the triggering event's item. Without these rules an agent
could close or link items in another repository the apply token reaches, or
let the handler pick the pull request or issue the run was started from.

```toml
[github.outputs.close_pull_request]
max = 1

[github.outputs.link_sub_issue]
max = 2
```

`{"type":"close_pull_request","repo":"OWNER/REPO","pull_request_number":7,"body":"Superseded by #8."}`
posts `body` on pull request 7 and closes it; gh-aw's collector requires the body.
A re-run of apply finds that comment by its hidden name and posts it only once.
`{"type":"link_sub_issue","repo":"OWNER/REPO","parent_issue_number":5,"sub_issue_number":6}`
makes issue 6 a sub-issue of issue 5; the handler skips a sub-issue that already
has a parent. Apply needs pull-request write access for the first and issue
write access for the second.

### Posting a check run

An agent-chosen `success` could satisfy a required check, so `create_check_run`
is off unless listed in bounds, and its bounds pin the check run's name:

```toml
[github.outputs.create_check_run]
max = 1
name = "agent verdict"
```

The name is 1–64 bytes of UTF-8, without control characters or surrounding
whitespace. gh-aw's handler takes it from apply's configuration, never from
the request; check refuses a request that names another one, and the
`success` conclusion. Other conclusions remain the agent's, and GitHub counts
`neutral` and `skipped` as passing a required check: pin a name no ruleset or
branch protection requires. When two bounds files both allow the type, their
names must be the same.

A request must give a positive integer `pull_request_number`, and no alias for
it; for example `{"type":"create_check_run","pull_request_number":7,"conclusion":"neutral","title":"Verdict","summary":"..."}`.
The handler posts on that pull request's current head in the calling
repository, so apply refuses a run whose `repo` is another repository.
Which pull request in it is the agent's choice. GitHub lets only an app
create check runs: apply needs `checks: write` for the job token, and fails
with `SAFE_OUTPUTS_PAT` set to a user's token. If the pinned name is the
calling workflow's name, the handler appends "(Result)" to it.

### Starting a discussion

`create_discussion` is off unless listed in bounds, and its bounds pin the
category, by name, slug or node ID:

```toml
[github.outputs.create_discussion]
max = 1
category = "Agent reports"
```

The category is 1–64 bytes of UTF-8, without control characters or surrounding
whitespace; when two bounds files both allow the type, theirs must be the
same. gh-aw's handler takes a request's own `category` over its
configuration's, so check refuses a request naming any other than the exact
pin, and one naming another repository. The handler posts in Announcements,
or the first category, when it does not find the one it was given; apply
refuses to post in a category not read back under the pin, so a pin that
names no category in the repository fails the job rather than posting
elsewhere. Pin a category whose readers expect agent posts.

The discussion goes to the run's `repo`. It is not turned into an issue when
discussions are off or the token cannot post one, and older discussions are
not closed. The collector drops a request's `labels` and `temporary_id`. Apply
needs `discussions: write` for the job token, or a `SAFE_OUTPUTS_PAT` that
can post discussions there. A re-run of apply posts a discussion again: unlike
an issue, it is not looked for under its name first.

### Hiding a comment

`hide_comment` minimizes a comment on the run's triggering issue or pull
request. That is moderating what other people wrote, a maintainer's
included: a reader sees it folded under the reason, and an agent misled by
the item's text could fold the comments that argue with it. It is off
unless listed in bounds, which pin the reasons it may give:

```toml
[github.outputs.hide_comment]
max = 3
allowed_reasons = ["SPAM", "OFF_TOPIC"]
```

The reasons are those of gh-aw's collector, `SPAM`, `ABUSE`, `OFF_TOPIC`,
`OUTDATED`, `RESOLVED` and `LOW_QUALITY`; the list is nonempty, since the
handler takes an empty one for any reason, and two bounds files keep the
reasons they share. Check refuses a request for another reason (none given
is `SPAM`, as the handler takes it), one naming another repository than the
item's, and every request of a run without one item: the event's, or a
numeric `comment-target`, which takes the event's place, never `*`. The
item's repository is a comment's: `item-repo`, else `output-repo`, else the
calling one; an event-triggered run whose `output-repo` is another
repository is refused the type before its agent starts, since the event's
item is in the calling one. Only the handler can look a comment up, so it
is given that item's number as its `target` and the repository as
`target-repo`, as gh-aw's `target: triggering` would from the event, and
refuses a comment anywhere else; a run without one item gets no handler.
Apply needs `issues: write` for an issue's comments, or `pull-requests: write`
for a pull request's, for the job token, or a `SAFE_OUTPUTS_PAT` that can
moderate comments there. A re-run hides the comments again, including one
a maintainer unhid in between.

### Review comments on the pull request

#### Head-bound advisory publication

The concrete threat is stale or redirected agent prose borrowing the writer's
credential after the reviewed PR changes. Trusted-base callers may opt in with
`advisory: true` on `policy.yml` or `agentic-job.yml`; it defaults to false.
This is an **event review** mode, not a generic stale-comment bypass. Set
`event: true`, `review: true`, `kind: analysis`, `outputs: add_comment,noop`,
`max-outputs: '1'`, `notify: none`, `apply-partial: false`, and `review-task`
to a trusted-base task that asks for prose, never APPROVE/CHANGES. Leave
`review-item`, `review-head`, `comment-target`, `output-repo`, `item-repo`,
`apply-environment` and proposals inputs empty. The existing review admission
still checks authorized events/actors, the configured base, public visibility
and an exact head. Dispatch and inline findings are not part of this API.
No caller is enabled here; the ordinary review workflow is unchanged.

Bounds must admit one `add_comment` and one `noop`. Policy routes the comment
through the existing native publisher, independent of ordinary handler routing.
Its optional `advisory` object contains `repo`, numeric `pull`, base branch `base`
and full lowercase `head`. The policy CLI accepts trusted `--advisory-item N`
and `--advisory-head SHA`; the workflow supplies them only from the narrowed
admitted event, not a request or sandbox artifact. The base binds the branch,
not the base branch's advancing tip. Check copies this policy into its existing
digest-bound checked artifact; no new service, token or artifact channel exists.
The workflow's returned `review` flag is false in this mode: verdict validation,
folding, review submission and review statuses are not advisory operations.
Do not wire an advisory call to `review submit`, `review status` or approval carry.
No classifier result or bucket escalation is produced; #3040 remains separate.

The entire handback is exactly one of:

```json
{"type":"add_comment","repo":"OWNER/REPO","item_number":7,"body":"Advisory prose."}
```

```json
{"type":"noop","message":"No useful advisory to publish."}
```

Unknown fields (including SHA, mode, aliases, reply IDs and verdict metadata),
other destinations, duplicate requests, mixed comment/noop and empty outputs
refuse. Check validates raw JSONL before collector field dropping as well as the
collected output, independently of the normal count checks. Text is limited to
46,000 UTF-8 bytes, leaving space for trusted framing and deduplication markers;
the writer independently refuses a final body over 48,000 bytes including all
footers and trusted markers. Neither check nor writer truncates to meet this cap.
Ordinary review verdict validation and generic output limits remain unchanged.

Apply retains cancellation, successful-check/agent-exit gates, same-run artifact
name/ID/digest verification, and the existing author-checked run/index/content
deduplication marker. A noop posts nothing. Immediately before comment POST,
the writer reads the PR again and refuses a closed PR, different number,
base repository/branch or head. GitHub offers no conditional issue-comment POST:
the PR can still move in the residual read-to-POST API race. The comment names
the exact reviewed head even then. Serialize apply attempts as usual: marker
lookup is not an atomic lock. A lost POST response is ambiguous; no automatic
POST retry is added. Inspect the destination before retrying; if the comment
landed, a rerun's existing guard recognizes its marker and skips it, otherwise
it may post after the same fresh PR validation. A failed/overflowed lookup must
not be treated as absence. A later run is a different advisory, not deduplicated
against an earlier run merely because its prose is identical.

For actions#195/#202, pin all policy/check/apply workflows and binaries to the
same **new release containing this API**, or one source commit using the existing
source-build path. Existing releases do not accept `advisory`; no version is
released by this change. The external actions wrapper must forward the boolean
from trusted-base configuration, never expose it as untrusted output selection,
and consume the returned policy/check artifacts unchanged. It must not call the
verdict/status/submit helpers for this mode. Model selection, caller migration
and #3040's classifier are intentionally not implemented.

`create_pull_request_review_comment` comments on a line of the run's
triggering pull request's diff, `reply_to_pull_request_review_comment`
replies to a review comment there, and `resolve_pull_request_review_thread`
resolves a thread. They give a review inline comments without a verdict:
the comments go in one review of event `COMMENT`, and
`submit_pull_request_review` is not offered. Each is off unless listed in
bounds, with a `max` and nothing else:

```toml
[github.outputs]
create_pull_request_review_comment = { max = 10 }
reply_to_pull_request_review_comment = { max = 5 }
resolve_pull_request_review_thread = { max = 5 }
```

They are held to the run's item as `hide_comment` is, for the same
reason: an agent misled by text it read could otherwise comment on, or
resolve the threads of, another pull request. Check refuses a request whose
`pull_request_number` is not the item's, one naming another repository
than the item's, and every request of a run without one item; policy
refuses the types to an event-triggered run whose `output-repo` is another
repository. Apply gives each handler the item's number as its `target` and
its repository as `target-repo`, so a comment goes on that pull request's
diff, and the resolve handler looks the thread up and refuses one
elsewhere. The reply handler does not look its comment up, so apply looks
it up first and refuses the run, before applying anything, when it is on
another pull request. An item that is an issue has no diff: the handlers
fail there.

Resolving a thread is the agent's to decide: a ruleset requiring
conversation resolution before merging counts a thread the agent resolved,
a maintainer's included. Bounds list the type only where that is wanted.
Apply needs `pull-requests: write` for the job token, or a
`SAFE_OUTPUTS_PAT` that can review the pull request. A re-run posts the
comments and replies again, and leaves a thread resolved before as it is.

### Pushing to a pull request's branch

#### Replacing the complete series

The threat to stop before allowing a history rewrite is overwriting another
writer's advance. A second threat is hiding a forbidden intermediate edit
behind a later revert. Replacement therefore uses an exact head lease and
checks every commit's patch, not just the final tree.

Replacement is off by default. The caller may add
`replacement_max_commits = 10` to `[github.outputs.push_to_pull_request_branch]`
(maximum 50). Organization bounds intersect this ceiling; zero in either
file forbids replacement. The ordinary one-commit push remains unchanged.
The same head repository and branch checks apply; no write token
is given to the producer or checker, and a partial run cannot replace history.

Each commit of a series keeps to `max_patch_files`, and by default so does
the series in all. A pull request that grew over several pushes, each
within that limit, can outgrow it, and a rebase onto a moved base must
carry all of it at once (#3017). For that, the caller may add
`replacement_max_files = 200` beside `replacement_max_commits` (maximum
500): the most files a replacement series may touch in all. Organization
bounds intersect it, taking a file's `max_patch_files` where it sets none,
and the patch byte limit still bounds the series.

The producer runs `agentic-job handback replace --base BASE_SHA [RANGE]`
in its checkout, alongside its `push_to_pull_request_branch` request.
The range defaults to `BASE_SHA..HEAD`. The command generates the mails
itself, preserving final newlines, and tests the series with `git am` in
an independent scratch repository before atomically writing
`out/replacement.json` under its home. A failed validation leaves any
existing handback untouched. Do not construct the mails or JSON by hand:
shell command substitution strips final newlines and can corrupt a patch.
Capture repairs missing final newlines with a warning; check still refuses
unrepaired mails as a backstop. This helper grants no additional authority:
the existing policy and independent check/apply limits remain unchanged.
An external proposals artifact names
the file `replacement.json`. Its strict JSON shape is:

```json
{"base_commit":"BASE_SHA","commits":["FIRST_MAIL","SECOND_MAIL"]}
```

`BASE_SHA` must be the base branch head read by the policy job (the run's
brief names it), or the current head of the PR's base branch resolved by
trusted apply. A newer snapshot between the policy head and the current head
is also accepted after apply proves both ancestry relationships.
To squash or reword without rebasing, `BASE_SHA` may also be the unique merge
base of the policy-pinned PR head and target branch snapshot. For a
fork-to-upstream PR this is the upstream target, not the fork's `main`.
Only when caller bounds set `[github.outputs] upstream-pull-request-base = true`,
for a fork-side PR whose head is in that same fork, policy and apply look
for a unique open PR in the forge-reported parent with the same author and
the exact same head repository, branch and commit. When present, that PR
supplies the target snapshot. A failed lookup, no match, several matches or
a mismatched one retain the addressed PR's target rather than refusing the
push. This read-only association never changes the push destination or
grants publication authority. The default is off. Enabling it trusts the parent's
history on the fork's PR branch: rebasing onto an admitted parent snapshot can
bring in parent commits, including workflows, outside the checked mails. Only
enable it for callers that accept that upstream history and its CI consequences.
Both bounds files must enable it when organization bounds also apply.
Policy resolves the branch ref, not the PR's possibly stale
base SHA, and run fetches that snapshot into the producer checkout. Each string is one plain
`git format-patch --stdout --no-signature --no-renames -1 COMMIT` mail with
a valid `Date:` header, no cover letter and no base header. This is the full
replacement series, including any original commits to keep, rather than a
fixup on the old head. It can reword, squash or rebase onto that admitted
base snapshot. Commit messages, authors and existing trailers are preserved;
run does not append its ordinary single-commit trailers to these mails.
Do not include `base.json` or an `aw-*.patch` alongside a replacement.
Run copies the series without resetting the producer's checkout; it does
not collect additional uncommitted changes on this path.
`handback replace` refuses a replay whose final tree differs from the
producer's intended `HEAD` tree, including an incomplete revision range.

The entire JSON fits `max_patch_bytes`. Check bounds the number of mails,
checks each with the ordinary path/type rules, and bounds the union of
changed paths by `max_patch_files`. Empty commits and multiple mails in a
string are refused. Apply builds only a linear series using plain `git am`
on the trusted base and compares every commit's actual paths to check's list.
No producer repository, bundle, hooks or configuration is imported. A fixed
committer and author-derived committer dates make the resulting head stable.
Apply pushes it with `--force-with-lease=refs/heads/BRANCH:ORIGINAL_HEAD`.
An exact already-applied head is a no-op; a different head, even with the
same tree, refuses the replacement. The final remote head is verified.

The policy base remains an admitted snapshot if the branch advances. A fix
run may also fetch a newer head and rebase onto it; apply independently reads
the PR's base branch and its current head. A base other than those exact
heads must be between them, or be the unique merge base of the policy-pinned
PR head and target snapshot, proved by ancestry before materializing or pushing.
Check validates the claimed full commit ID, not its
forge membership. A head that advances again before apply resolves it does
not invalidate the earlier snapshot; a rewritten history that no longer
contains it requires a new proposal or the policy snapshot. This prevents an arbitrary producer
commit from becoming the root of the replacement series. An arbitrary older
ancestor is not admitted: it could omit target changes from the checked mails.

`push_to_pull_request_branch` lets a follow-up run fix an open pull request:
its change goes onto that pull request's branch as one commit, not into a new
pull request. It goes to the pull request's head repository, whoever opened
the pull request, where the identity apply holds may push: its own fork
([pull requests come from a fork](workflow.md#pull-requests-come-from-a-fork)),
another fork whose owner gave it write access, or the target repository
itself. The target's CI runs a fork's commit as it ran the pull request's
first one: as a fork's, with a read-only token, no secrets and no OIDC token.
The head repository's own workflows are different: apply turns Actions off
only in its own fork, and elsewhere the `push` and `pull_request` workflows
of the target or of the other fork run the agent's commit with whatever
secrets, write token and OIDC access they hold
([#340](https://github.com/cgwalters-forge/agentic-job/issues/340),
[#430](https://github.com/cgwalters-forge/agentic-job/issues/430)). So apply
pushes to any head repository but its own fork only when one of two sources
accepts it: the caller's bounds match that head repository, or its default
branch has `.github/agentic-job/accept-owner-branches` naming that repository
(`owner/repo`) on a line of its own. Write access alone is not acceptance;
a fork's inherited file naming its parent does not accept the fork.

The threat is running agent-written code in a repository whose workflows can
reach credentials or other privileged resources. The caller may choose to
accept that CI execution, with no extra gate, in its dispatch and fix bounds:

```toml
[github.outputs]
own-branch-repos = ["example-org/*"]
```

This is off by default (an empty list), accepts at most 100 patterns of 1–256
bytes, and uses the existing case-insensitive repository glob syntax (`*`
within a segment, `**` across segments). Check validates these bounds and
binds them into apply's configuration; organization bounds must also match
the head repository. The repository file remains an independent source of
acceptance. Both sources cover fix pushes and new PR branches in repositories
the applying account [owns](workflow.md#a-repository-the-applying-account-owns).
Neither grants write access or bypasses branch protection, default-branch
refusals, patch limits or `.github` protection.

GitLab bounds take the same key, with the same limits and intersection, in
`[gitlab.outputs]`; Forgejo's refuse it. Where the bounds name no `push_repo`
and the patterns match the target project, the caller may pass the target
itself as `--push-repo`: apply then pushes the merge request's branch to the
target and opens the merge request there, or pushes a fix on an open merge
request's branch in it, instead of using a fork
([publishing to GitLab](#publishing-to-gitlab)). A new branch must be named
as a run's (`agent-run-` and digits) and not exist yet. Apply reads the project and its protected branch
rules first and refuses its default branch and any branch a rule names, `*`
wildcards included (at most 2,000 rules). The single commit, head lease,
`Draft:` title, protected paths and output limits are unchanged. Refusing `.github`
keeps the agent from adding workflows there, not from changing the build
scripts, tests and local actions the existing ones run. Accept only a repository whose
workflows give a branch nothing an agent is not to have; where that
repository is also the caller, keep its apply environment to the default
branch, so that a branch's workflows cannot use its token. Any other head
repository has to be a fork, and not the calling repository, which holds the
run's secrets. "May push" is write access to the head repository: a fork's
pull request that lets the target's maintainers edit it is not enough. It is
off unless a bounds file lists it, with globs of the branches a push may go to:

```toml
[github.outputs.push_to_pull_request_branch]
max = 1
branches = ["agent-run-*", "dispatch/**"]
```

Unlike `bases`, the `branches` globs match case exactly: `dispatch/**` does
not admit `DISPATCH/x`, since a forge keeps a branch name's case. The branch
of a pull request apply opened is the caller's `branch-prefix` followed by
`agent-run-RUNID`.

The caller names the pull request by number (`push-item`, the `fix` profile of
[dispatch](dispatch.md)); the agent never does. The policy job reads that pull
request with its read-only token and refuses it unless it is open, its base is
in the run's repository and its head repository still exists. The outputs must be
applied there (`output-repo` empty or that repository), and apply must hold
`SAFE_OUTPUTS_PAT` from an `apply-environment`: the job token names no user.
Policy refuses anything else before the agent runs. Its branch must match
`branches` (`bases` does not apply), and `policy.json` records the number as
the push's `target` and the head commit the branch was at as its `head`. A
run with a push has no `create_pull_request`: it hands back one patch.

The repository must be within `repos`, unless the pull request is the
applying account's own (#3162). Its authorship is then the permission,
with no per-repository entry, where the push's bound names that account:

```toml
[github.outputs.push_to_pull_request_branch]
max = 1
branches = ["agent-run-*", "dispatch/**"]
own_author = "example-bot"
```

Off by default and supported only on GitHub; Forgejo and GitLab bounds
and compiled policies refuse this exception until their native publishers
enforce the author and applying-identity check. `own_author` is the login of the user apply pushes as
(`SAFE_OUTPUTS_PAT`, or `PUSH_TOKEN` under role bindings); an app's
`name[bot]` identity cannot use it. The policy job reads the pull
request's author with the branch and head. If `repos` does not list the
repository, policy admits it only when that author is `own_author`, and
records the login as the push's `author`. Such a run may ask for the
push, `noop`, `missing_tool` and `missing_data`. Besides the push, the
only write to a repository the bounds never listed is the run's status
comment on that pull request, where the caller posts one (`notify`): no
requested comment, label or close. Apply reads the pull request again and refuses
unless it is still by `author`, and `author` is the identity apply holds.
The branch globs, replacement limits and every apply check below are those
of any push. This stops a fix run admitted this way from pushing to a
stranger's pull request in an unlisted repository, even one whose branch
the applying account may push to. An organization bounds file that
lists the repository does not lift the check, and two files naming
different authors are refused.

The run clones the target's default branch, fetches `head` by its commit (the
forge serves a fork pull request's head from the target too) and starts there:

- the run refuses to start when the checkout is not at `head`;
- check refuses a hand-back whose base is not `head`, a push line naming any
  branch but the pull request's, and the same patch rules as a pull request
   (protected files, top-level dot-folders, size and file count), including the
   same exact-repository `.github` exemption as a new pull request;
- apply reads the pull request again with its own token, before anything is
  forked, fetched or pushed, and refuses unless it is open, from the policy's
  branch, and that branch is neither its head repository's default branch nor
  protected nor one a ruleset applies to (any rule: a ruleset on every branch
  leaves nothing to push to); it refuses a head repository its
  identity cannot push to, saying so, one that is neither a fork of the target nor the
  target, the calling repository unless it is the target, a branch of the
  target itself that the target does not accept, and the `.github` exemption anywhere but its own fork. For a pull request from that
  fork it makes or finds the fork and turns its Actions off, as for a new
  pull request. gh-aw's handler is given the head repository as the only one
  it may push to, and refuses a pull request from any other;
- the handler applies the patch on `head` and pushes one commit without force,
    with no fallback to a new pull request. Only the `.github` exemption
    enables `allow_workflows` and the matching dot-folder exclusion. A
   branch that moved since `head` was read makes the push not a fast-forward,
   which the forge refuses: the pull request has to be run again. Before the
   handler runs, apply leaves out a push if the fetched head branch already
   holds exactly one commit on `head` with the checked tree. This succeeds as
   already applied, without pushing again. Apply then fetches the branch back from the head repository and
   refuses unless it is that one commit on `head` with the checked tree.

The final check also runs for an already-applied push: a branch moved between
the guard and the final fetch still fails. A merge commit, another tree, or
the checked tree on another parent does not count as already applied.

A partial run (one stopped at a limit, applied under `apply-partial`) is not
pushed: nothing on a pushed commit would say the work was cut short, so
apply fails instead.

Anyone who may push to the head repository, the identity apply holds, and
maintainers of the target a fork's pull request lets edit it can move its
branch. One of them rewriting it so
that `head` is no longer in it is the case the handler does not refuse: it
logs a warning and applies the patch with `git am --3way` on the branch as it
finds it, that push succeeds, and apply's last step fails after the commit is
on the branch. The handler does not check the pull request's state; apply
does, so a pull request closed before apply runs is not pushed to.

## The bounds and the policy

A caller keeps a bounds file in its repository
([this repository's](../.github/agentic-job/allow.toml)): the `hosts` a
clone URL may name, globs of `repos` and `bases`, `max_outputs`,
`max_patch_bytes`, `max_patch_files`, and under its forge section's
`outputs` each type with its ceiling. `agentic-job policy` checks one run's request against
it (`--repo`, `--clone-url`, `--base`, `--kind`, `--outputs`,
`--max-outputs`) and prints `policy.json`, or every reason for refusing.
`--outputs all` is every type the bounds list, and `--max-outputs max`
their own ceiling. It runs in a job of its own, before the agent's
machine starts.
On GitHub, `repos` may also contain `{org = "cgwalters-forge", forks = false}`.
This is opt-in: no shipped bounds enable it. Policy reads the live repository
through `GITHUB_API_URL` with the read-only `GH_TOKEN`, and requires its
`full_name` and organization owner to match, and both `fork` and `archived`
to be false. Missing metadata or an API failure refuses admission, rather
than trusting an organization name prefix that could admit forks or transferred
repositories. The rule requires `hosts = ["github.com"]`; unknown rule keys
are refused. To admit selected forks rather than arbitrary organization forks,
use a rule such as
`{org = "example-org", forks = true, properties = { category = "mirror" }, topics = ["managed-fork"]}`.
Fork rules require nonempty `properties` and `topics`, and a live
`parent.full_name` naming a repository. Every configured topic and string-valued
custom property must match exactly; properties are read from
`repos/OWNER/NAME/properties/values`. Missing or unreadable metadata refuses
with a diagnostic naming the requirement. Property and topic names and values
come only from the caller; nothing enables fork admission by default.
Exact string entries can explicitly admit
forks, archived repositories or other owners. Organization rules may be combined
only with exact string entries, not globs; `own_author` admission cannot bypass
their restrictions. Existing bounds containing only string globs are unchanged.
Item repositories are checked the same
way, and both bounds files must independently admit them when `--org-allow`
is used. Each needed metadata read has a 1 MiB response limit, a 120-second
timeout and no redirects; `check` consumes only the resulting concrete
repository policy, never an organization-wide permission. Patch/output limits
and exact-name protection exemptions are unchanged.

A top-level `private = true` admits a target that is not public, under
the conditions of [private repositories](private-repositories.md); it is
off by default. A top-level `allow_http`, empty by default, lists hosts
of `hosts` whose clone URL may be plain `http://`, for a self-hosted
forge on a private network without TLS: anyone on that network can then
read and alter the clone, and a private repository's read token crosses
it unencrypted. It may not name `github.com` or a host under it, with or
without a port or user, and
`run` lets git use plain HTTP only for a target admitted that way, so no
other clone can be downgraded by a redirect. With organization bounds,
both files must name the host. A top-level `allowed_domains` is
accepted and ignored:
links to every public host are kept ([above](#what-is-gh-aws-and-why)).
A top-level `native_handlers`, empty by default, lists `add_comment`,
`create_pull_request`, `add_labels`, `remove_labels`, `close_issue`,
`close_pull_request`, `push_to_pull_request_branch`, `create_issue` or
`create_pull_request_review_comment` for apply to publish with
[agentic-job's own handlers](#agentic-jobs-own-handlers) on GitHub rather
than gh-aw's; each must be a type the bounds allow, and with
organization bounds a type is routed only where both files name it.

Exactly one forge section says where the outputs are applied
([#1393](https://github.com/cgwalters-forge/agentic-job/issues/1393)):
`[github]`, `[forgejo]` or `[gitlab]`. None, or more than one, is
refused, and with organization bounds both files must name the same
forge. Each section has its own `outputs` table, which is required and
off GitHub may list only the [neutral profile](#neutral-profile).
`[github]` alone also holds what only GitHub implements today:
`[github.trigger]` ([events](events.md)), `[github.memory]` (below),
`[github.test_evidence]` ([test evidence](#repeated-test-evidence)) and
`[github.secondary_pull_request]` ([below](#a-secondary-pull-request)).
`[forgejo]` and `[gitlab]` hold `push_repo = "OWNER/NAME"`, the fork that
[Forgejo's](#publishing-to-forgejo) or [GitLab's](#publishing-to-gitlab)
apply pushes a pull request's branch to. It may not be of the target's
owner, a section that allows `create_pull_request` must name it, and
with organization bounds both files must name it. Every section refuses
keys it does not know, so a GitHub-only table in another forge's section
is refused.

```toml
[forgejo]
push_repo = "bot/NAME"

[forgejo.outputs]
create_pull_request = { max = 1 }
noop = { max = 1 }
```

The sections replaced the top-level `outputs`, `trigger`, `memory`,
`secondary_pull_request` and `push_repo` keys and the scalar `forge`,
which are now refused as unknown: a caller moves its GitHub keys under
`[github]`. The compiled `policy.json` is unchanged.

A `[github.memory]` table lets a run hand back the agent's notes
([below](#what-the-agent-does)); without it none is handed back, and
`check` refuses one. Its keys, all optional, and their ceilings, which are
gh-aw's repo-memory defaults:

```toml
[github.memory]
max_files = 20              # at most 100
max_file_bytes = 16384      # at most 102400 (100 KiB)
max_bytes = 65536           # all files together; at least max_file_bytes, at most 1 MiB
extensions = ["md", "txt", "json"] # from md, txt, json, jsonl, csv
```

With organization bounds, memory is allowed only where both files allow
it, within the smaller of each limit and the extensions both list.
Storing the memory (apply) and giving it back to the next run (the agent
job) are not implemented yet; both are tracked in
[#119](https://github.com/cgwalters-forge/agentic-job/issues/119). Until
then the brief does not mention memory.

Some things no bounds file can change. A run hands back one patch, so at
most one pull request. A pull request is a draft unless it is complete
work under `ready_when_complete`. An `analysis` run may
not ask for one. gh-aw's default list of protected file names, less
`README.md`, and every top-level dot-folder are protected by default; a bounds file can take names off
that list and exempt the `.github` folder for repositories it names exactly
(case-insensitive OWNER/REPO, no globs), and cannot add to the list. No
other dot-folder can be exempted: check refuses `.husky/`, `.vscode/`,
`.circleci/` and `.tekton/` whatever the policy says.
For example, to allow CONTRIBUTING.md and workflow edits in one repository, add this to the
bounds file (not to the caller workflow):

```toml
[unprotected_files]
repos = ["OWNER/REPO"]
files = ["CONTRIBUTING.md"]
dot_folders = [".github"] # optional, and only ".github"; see the protections below
```

A bounds file can also protect more paths, in every repository it admits,
with a top-level `protected` list of globs: paths a run must never change,
such as a wiki's raw source files. They match as a push's `branches` do
(`*` within one directory, `**` across them, case counting) against the
path from the repository root, so `raw/**` covers everything under `raw/`
and not `wiki/raw/`, and `**/*.pem` misses a `.pem` file at the root
(list `*.pem` too). A glob only ever adds protection; it cannot take
anything off the list above. Check refuses a patch touching a matching path,
naming the path and the glob, and the brief tells the agent the globs.
With organization bounds, both files' globs apply. A file may list at most
64 globs of at most 256 bytes each, of plain relative components (no
leading or trailing `/`, `.` or `..`); `?`, `[...]` and `{a,b}` are refused
rather than taken literally. The key is top-level, so it goes before the
file's first table:

```toml
protected = ["raw/**"]
```

Who the hand-back's commit is by is otherwise the agent machine's to say
(`[commit] author`), so a compromised one could pass a commit off as a
maintainer's. A bounds file can pin it, as `Name <address>` in plain ASCII:
`commit_author = "github-actions[bot] <41898282+github-actions[bot]@users.noreply.github.com>"`.
`run` then commits as that author, and `check` refuses a patch whose
`From:` is anyone else's. Two bounds files that pin different authors
refuse every run. A [replacement](#replacing-the-complete-series)
keeps its commits' own authors and is not held to the pin, so bounds that
pin an author should leave `replacement_max_commits` at zero. Whether or not
one is pinned, `check` refuses a mail header given twice and a `From:`,
`Subject:`, `Date:` or `[PATCH]` line at the start of the message, which
`git am` would take over the mail's own.

This does not relax the fixed patch refusals below. New executable files
remain refused: add a script without its executable bit and run it with
its interpreter. Check refusals appear as run annotations and, when a
comment target is available, in the run's conclusion comment.

The exemption does not reach protected file names, git's own files
inside `.github/` (`.github/CODEOWNERS`, `.github/.git/`) or the review's
[merge policy](review.md#merge-policy), `.github/agentic-job/merge.toml`. Organization and
caller bounds must both permit it. It applies to `create_pull_request` and
`push_to_pull_request_branch`, including replacement series, only for the
same listed repositories. A fix push still requires the open PR and head
repository/branch checks described above, and is refused the exemption
anywhere but apply's own fork. A repository
[its applying account owns](workflow.md#a-repository-the-applying-account-owns), whose
new pull request's branch is pushed to it and not to a fork, cannot have the `.github`
exemption either: apply refuses the pull request. Workflow changes are pushed only to
apply's fork, which has Actions turned off, and reach the repository as a
fork pull request. Its `pull_request` CI gets no secrets and a read-only
token, not the target repository's write credentials. Operators must configure
and enforce pre-merge review and the intended required checks; the exemption
does not provide these merge protections automatically. If relying on the trusted
[workflow ingress check](workflow-ingress.md) as a merge gate, an administrator
must enforce that workflow with a ruleset: a required status name alone can be
imitated by PR-owned workflows. The trusted
[workflow ingress check](workflow-ingress.md) flags known-bad workflow patterns
and new analyzer ignores; it does not prove a workflow safe or replace review.
Reviewers must treat changes to the caller's bounds (`.github/agentic-job/`)
or to the workflow that calls agentic-job as policy changes: the exemption lets
an agent propose widening its own bounds, which takes effect once merged.

The output check is not the gate against a malicious workflow edit. Before
review, the target's `pull_request` CI can run the edited workflows, choosing
their runners (`runs-on`), matrices and job counts. Fork token restrictions do
not protect a self-hosted runner from that code; do not make self-hosted runners
reachable by fork pull request workflows. Two additional measures are optional
hardening, not prerequisites for the exemption:

- Requiring workflow approval for all external contributors stops an edited
  workflow from spending CI resources or choosing runners before a human looks,
  which matters especially with self-hosted runners.
- Keeping the apply account (the user of `SAFE_OUTPUTS_PAT`) outside the
  repository's and organization's membership and collaborator roles makes that
  external-contributor approval policy apply to its fork pull requests, since
  members and collaborators bypass it.

The apply credential needs classic PAT `repo` and `workflow` scopes (or a
fine-grained token with Contents and Workflows write permissions on the fork)
to push workflow files. No agent or check job gains a write credential.

`policy.json` holds, as `safe_outputs`, gh-aw's own configuration format:
the collector reads that part as it is. The additional `unprotected_dot_folders`
list, on both patch-carrying outputs, is enforced by check. Apply passes it to
gh-aw's handler as `protected_dot_folder_excludes`, keeping only `.github`
whatever the list says, and keeps `protect_top_level_dot_folders`
on, so the handler still refuses every other dot-folder before and after it
applies the patch. `protected_files_policy` stays `blocked`, so protected
basenames remain refused.

gh-aw's per-type `target-repo` and `allowed-repos`, and its other
`protected-files` policies (`request-review`, `fallback-to-issue`), are
deliberately not offered: a bounds file that names one is refused as an
unknown key. Destinations stay fixed by the caller
([target repositories](workflow.md#the-apply-job-and-its-token)), never
chosen per type or by the agent, and a patch that touches a protected file
is refused rather than sent for review or turned into an issue.

### A secondary pull request

A `[github.secondary_pull_request]` table names one further, fixed repository
that a run may propose one pull request to, without making
the repositories in `repos` writable
([#1075](https://github.com/cgwalters-forge/agentic-job/issues/1075)).
It stops an agent from choosing where that pull request goes: the
repository, base and branch are the bounds', and the request gives
only the title and body. Off by default; bounds without it are
unaffected. What the caller's `SAFE_OUTPUTS_PAT` needs for it is in
[the workflow guide](workflow.md#a-secondary-pull-request).

```toml
[github.secondary_pull_request]
repo = "cgwalters-forge/misctool"
base = "main"
branch_prefix = "agentic-job/"
max = 1
max_patch_bytes = 65536
max_patch_files = 10
```

It is one table, not a list. `repo` is one exact OWNER/NAME, `base` one
exact branch, and `branch_prefix` ends in `/` and forms an unambiguous
branch name. `max` must be 1, and the patch limits have no defaults
(at least 1024 bytes and 1 file). Its own
`[github.secondary_pull_request.unprotected_files]` takes the same keys as the
top-level one but may name only `repo`; nothing is inherited from the
top-level exemptions, so protected files and `.github` stay protected
unless exempted here. The top-level `protected` globs, which only take
away, hold for it too. It is for GitHub only, which its place in
`[github]` says.

`policy` adds it to `policy.json` only for a branch run that may open its
own pull request, and refuses one whose run works on, or applies to, that
same repository. Organization bounds keep it only where both files name
the same repository, base and prefix, within the tighter budgets. `run`
clones the repository at its base into `~/work/secondary/OWNER/NAME`, with
no credential (a run that opens a pull request is public). A change there
is handed back as its own patch, with `secondary-base.json`, only for a
`create_pull_request` whose `repo` names that repository; without one it
is dropped with a warning. The request goes on the run's branch under the
prefix, and its patch is named as gh-aw's handler looks for it first when
a request names a `repo` (`aw-OWNER-NAME-agentic-job-agent-run-ID.patch`),
never as the run's own. Check counts that request against the secondary's
own `max` (the collector is given the sum of both), and against
`max_outputs` like any other request, so raise that by one to leave the
run's own requests their room; it holds it to the
secondary's base, to being a draft and to that branch of this run
(`check --run-id`, never an earlier run's branch, whose open pull request
it would push to), and its patch to its own base file, budgets and
protected files and to the bounds' `commit_author`. check.yml hands that
patch on apart, in `secondary/` of its artifact, so that apply's trial of
the run's own patch never takes it, and leaves its request out of the
requests apply's handlers get, which would refuse it; it uploads
`policy.json` beside them. A request naming any other repository
is refused as before.

`agentic-job secondary-pull-request --policy FILE --checked DIR --run-id ID
--run-url URL` is apply's pass for it, which apply.yml runs once gh-aw's
handlers have applied everything else, only where check reported a
request or a patch for it, with `SAFE_OUTPUTS_PAT`, and not the job
token, in its environment; a staged apply skips it. What it prints, its
`error:` lines included, goes into apply's summary, and a failure fails
apply and says so in the status comment. It holds check's report and the patch in `secondary/` to the
policy again, as the Forgejo apply does: the repository, base, prefix and
budgets are the policy's, and the branch must be this run's under the
prefix, so a request can choose only the title and body. Then, as
apply.yml does for the run's own pull request, it forks the repository
into the token's account (never the repository itself, an owner's, or the
run's own repository should that be the token's fork of it), waits
until git reaches the fork, turns the fork's Actions off and reads that
back, pushes the branch to the fork only if it does not exist yet, and
opens the pull request as a draft. A refusal or failure is an `error:`
line naming the secondary pull request and a failed exit, with nothing
written to the forge for a refusal. It has no recovery as the Forgejo apply
has: when the pull request cannot be opened after the push, the error
names the pushed commit and branch, which stays in the fork until someone
opens the pull request from it or deletes it.

## Without an agent

The producer need not be an agent. Any job can upload a hand-back and
pass its artifact name as `proposals-artifact` to the reusable workflow,
which then runs no agent job: policy, check and apply are the same jobs,
on separate machines, as for an agent's
([proposals from a non-agent job](workflow.md#proposals-from-a-non-agent-job)).
Check trusts the producer no more than an agent: the artifact name picks
untrusted data, never the policy, binary or handlers, and every rule
below holds. For requests without a change only `outputs.jsonl` is
needed. A change adds `base.json`, `{"repo": "OWNER/NAME", "ref": "BASE",
"commit": "SHA"}`, and one `aw-BRANCH.patch`: `git format-patch` of one
commit on that base, with an `X-GH-AW-Base-Commit: SHA` header after
its first line, on the branch `agent-run-RUNID` of the same run, which
apply requires. No other file is needed.

[example-deterministic.yml](../.github/workflows/example-deterministic.yml)
is such a job: it runs secure-host, then `cargo fmt --all`, and hands
back the change as a `create_pull_request`, or a `noop` when nothing
changed. CI's `e2e-deterministic` runs it with `apply-staged`. The
producer needs only `contents: read`, and its job runs secure-host before
the formatter, as [`workflows check`](workflows-check.md) requires of a
job that does not call the reusable workflow: what it builds or formats
runs as the runner's user, without root or a credential that can write.
The smallest call that can open a pull request from it:

- `id`, `repo`, `allow` and `proposals-artifact`; no task, agent or
  configuration.
- `outputs: create_pull_request,noop`, within the bounds file's
  `[github.outputs]`, `max_patch_bytes` and `max_patch_files`; the example
  also narrows `max-outputs` to `"1"`, the one request it makes.
- `apply-environment` with `SAFE_OUTPUTS_PAT` passed explicitly: policy
  refuses `create_pull_request` without one, as the job token cannot fork.
  A comment needs no environment, only `issues: write` for the job token.
- `contents`, `issues`, `pull-requests` and `actions` read, and
  `id-token: write`, which GitHub validates for the skipped register job;
  nothing requests an OIDC token.

## What the agent does

`run`'s brief tells the agent to put its requests in
`out/safe-outputs.jsonl` under its home and to leave its change
uncommitted. `run` then makes the patch itself, with git running as the
sandbox user: `git format-patch` of one commit against the commit the
run started from, with gh-aw's `X-GH-AW-Base-Commit` header. The
hand-back is `outputs.jsonl`, `base.json` and at most one
`aw-BRANCH.patch`, and for a
[secondary pull request](#a-secondary-pull-request)
its own patch and `secondary-base.json`. gh-aw's agents call an MCP server that validates each
request as it is made; here it is a plain file.

Capture accepts at most 1 MiB and 1000 nonblank request lines (blank lines
are ignored). Overflow refuses the requests whole, with any change or
replacement series, before making a fallback request; no prefix is published.
`handback check` reports that refusal. Downstream collection still validates
every captured request under the existing byte and policy count bounds.

With `[commit] format = true` in the runner configuration (off by
default), a branch run whose change has Rust in it (a new or changed
`.rs` file, or a commit of the agent's that touches one) is formatted
before the patch is made, so that a hand-back does not spend a CI cycle
and a fix round on `cargo fmt --check`. In a checkout with a
`Cargo.toml`, `run` runs `just fmt` where the Justfile has that recipe,
else `cargo fmt --all`. Like git there, it runs as the sandbox user with
the agent's confinement, and so can do nothing the agent could not:
Cargo is kept offline and rustup (1.28.1 or later) may not install a
toolchain the checkout names, within a five-minute timeout. A missing rustfmt or a formatter that
fails is a warning in the job's log, which gives only the exit status,
since rustfmt's errors quote the agent's source; the change is then
taken unformatted. The result is the agent's change like any other,
and `check` holds it to every bound.
Before invoking the formatter, `run` snapshots the agent's tree, including
uncommitted and new files. It restores any formatter changes to paths that
did not differ from the run's base in that snapshot, including files the
formatter creates or deletes: a workspace-wide formatter cannot widen the
agent's patch. On formatter failure it restores all formatter changes and
takes the original, unformatted change. If the snapshot or restoration
cannot be completed, the patch is dropped rather than handed back with an
unknown scope. A repository's `fmt` recipe is still repository code, not a
trusted guarantee of semantic equivalence; it has only the agent's authority
and its result passes through the same independent patch checks.
Only the run's own checkout is formatted, not a
[secondary pull request](#a-secondary-pull-request)'s.

Where the policy has `[memory]`, `run` also packs the flat directory
`~/memory/` into `memory.json`, `{"files": {"NAME": "text", ...}}`,
for an analysis run as for a branch run. Like `replacement.json`, it is
agentic-job's file, not a gh-aw request type, and gh-aw's collector never
reads it. Each file is read as the sandbox user, without following links.
No directory hands back no `memory.json`, which leaves the memory as it
was; an empty one hands back `{"files": {}}`. A link, a subdirectory, a
secret-shaped string or any file `check` would refuse drops the whole memory, with a warning in
the run's summary (`memory_dropped`); the change and the requests are
handed back all the same. A hand-back of memory alone is uploaded like
any other.

The requests file is read the same way, and one the agent left that is
not taken (a link, not a regular file, over 1 MiB or 1000 nonblank lines,
or unreadable) drops
the whole hand-back, with the reason in the run's summary
(`requests_dropped`, and `patch.error` for the change). The run does not
make up a pull request from the outcome in its place: that would hand
the change back under words the agent did not write and lose every
request it did, a `noop` or an open checkpoint among them. A session
that reminds the agent of a missing hand-back names the file and the
limit to it first.

Keep requests within 1000 nonblank lines: capture refuses an overflow whole,
before making a fallback request. `handback check` reports that refusal too.

The brief tells the agent to leave a part of a change that check would
refuse out and say so, except when it is the whole task: then the agent
makes it anyway, so that the run fails with check naming the file rather
than ending well with nothing handed back.

The brief holds only what every run needs: where it hands back, its
limits, and the validator. `agentic-job handback guide` prints the rest
for the agent that needs it: the formats, the protected paths, the
checkpoint, replacing a branch's commits and containers behind the proxy.
`agentic-job handback check` tells the agent, while it can still fix it,
what the run would refuse or lose of what it would hand back now. It runs
`run`'s own capture, on a copy of the checkout, since capture commits
there; then `check`'s own checks on the result; then the shape scan of
`agentic-job handback scan`, which stands in for the final gate's scan
by value of the run's own secrets ([above](#what-is-gh-aws-and-why)).
It also reports a missing or unreadable `outcome.json`, and a change left
as a draft by its checkpoint. Each problem is a line,
`WHERE: WHAT; HOW TO FIX`, and the command exits 1 while there is one. It
reads the run's policy, checkout and base from
`~/.config/agentic-job/handback.json`, which `run` writes without the
clone URLs. The agent can change that file, and so mislead only itself:
the check job reads the policy the policy job printed. The requests are
validated by [`collect`](#off-github), which fixtures hold to gh-aw's
collector, so a missing or malformed field is refused in the session in
the words the check job would use. `handback guide` lists each
allowed type's fields from the same table.

For a `push_to_pull_request_branch` request without `message`, `run` fills
that field from the outcome summary (or its default run description), the
same fallback it uses for the patch's commit message. Where the outcome
has no summary, the default description says the change is partial: an
agent that wrote none may have been cut off before it could. An explicit `message`
is preserved, including an invalid value for the collector to refuse. This
does not validate requests while the producer runs or replace the separate
check job.

## The check, in two halves

The check job runs on a machine the agent never touched, with read
access only. First the collector, `agentic-job collect`: which types
exist, how many of each, the fields of each, and the sanitizing of their
text. Then

```text
agentic-job check --policy FILE --outputs DIR --collected FILE [--report FILE] [--run-id ID]
```

takes the collector's result and does none of it again, except to
count. It refuses a hand-back holding any other file, a file over its
size or a private key, and reports any other string shaped like a
credential as a warning; a request naming another
repository or base than the policy's; a pull request that asks not to be
a draft, or does not come with exactly its patch; and, under
`ready_when_complete`, a malformed [checkpoint](#ready-or-draft). It refuses any request
holding `agentic-job-applied`, the name apply hides in what it posts
so that a re-run leaves it out
([running apply again](workflow.md#running-apply-again)).

It refuses a `memory.json` where the policy has no `[memory]`, and
otherwise holds it to those bounds, beside a patch or a replacement: no
unknown field, no name given twice, no more files or bytes than the bounds allow, names that
match `^[A-Za-z0-9][A-Za-z0-9._-]{0,63}$` without `..` and end in one of
the listed extensions as written (`.MD` is not `md`), and UTF-8 text with
no control character but newline, carriage return and tab. A
secret-shaped string is refused in the names and text as JSON decodes
them, not only in the file as written. The report and
the summary count its files and bytes and never show what they say.

The workflow also supplies `--comment-repo OWNER/REPO --comment-target NUMBER`
when the caller fixes a comment destination. These paired options bind comments
to that repository and issue/PR, independently of the code repository. Explicit
redirections, including PR-number aliases and existing-comment/reply IDs, are
refused rather than silently retargeted.

The patch is read as git reads it and must be exactly what
`format-patch` writes. Refused are protected files (the policy's, and
git's own files and CI, hook and editor configuration), paths that are
not plain relative ones, binaries, symlinks, submodules, new
executables, mode changes, renames, and a patch over its file count.
Beyond what the old tree's check refused, it also refuses a change
carried in the commit message, a second mail, any mail header
`format-patch` does not write, and a file whose header states no mode:
git would apply each, and a reader looking for `diff --git` lines would
miss it. `--report` is the verdict as JSON, with the paths the patch
names. CI runs a corpus of hand-backs through the old tree's check and
this one, which must agree but for those differences
(`crates/agentic-job/tests/corpus`). `crates/agentic-job/tests/check.rs`
checks the hand-backs of two real runs (`safe-outputs/fixtures`).
It also runs the output-count corpus cases through Rust `policy`, `collect`
and `check`: comments, missing tools and missing data at and above their
per-type limits, mixed outputs at the total limit, and a total-limit refusal
where every type remains within its own limit. This coverage runs without
Node or external checkouts; the legacy corpus retains its live upstream
comparisons until their replacement or removal is authorized separately.

`check` reads text, on a machine without the repository. It cannot see
that `git am --3way` follows renames, that the base commit is only the
hand-back's claim
([#17](https://github.com/cgwalters-forge/agentic-job/issues/17)), or
whether the patch's `From:` line identifies its real author
([#22](https://github.com/cgwalters-forge/agentic-job/issues/22)). The
first two are settled by the apply job; `commit_author`, when configured,
pins the declared author but does not prove authorship:
[what the apply job does before it writes](workflow.md#what-the-apply-job-does-before-it-writes).

### Repeated test evidence

A run may hand back what a test run on its change did, beside a pull
request's patch, as
[the external runner contract](dispatch.md#repeated-test-evidence-and-acceptance)
asks: `test-evidence.json` and one log per attempt,
`test-evidence-N.log`. It is off by default. A `[github.test_evidence]`
table in the bounds turns it on, and with organization bounds both files
must have it, within the smaller of each limit:

```toml
[github.test_evidence]
max_attempts = 5       # at most 10
max_log_bytes = 262144 # each log; at most 1 MiB
```

The agent writes the manifest and the logs to `~/out`. `run` takes them
as it takes the requests, as the sandbox user, without following a link.
It drops the evidence, and never the change, if the manifest is not a
regular file of at most 64 KiB, if a log is not a regular file within
`max_log_bytes`, or if any of it holds a secret-shaped string. It also
drops what `check` would refuse, evidence where the policy allows a push,
and evidence without a patch. The reason goes to the job's log, and `agentic-job handback check`
reports it.

Only opted-in pull request runs receive evidence instructions in their
brief and `agentic-job handback guide`. In v1, `base` **and** `head` are
the starting commit the checked patch applies to, not a newly made
commit. `tree` is the full Git tree ID of that base with the tested patch
applied. Finish all edits and formatting first, stage exactly the intended
patch files with `git add -- <paths>` (including intended new files, not
ignored artifacts), and record `git write-tree` before testing that tree.
Leave changes uncommitted; `git reset --mixed STARTING_COMMIT` unstages
them without changing working files. Any later edit requires retesting
and recording the newly tested tree, not merely changing the manifest's
ID. Collection-time formatting can also make a stale tree; apply still
refuses it rather than rebinding old results to the new tree.

Plan attempts before testing and record every `pass`, `fail`, `skipped`
and `not-run`, numbered 1 to N in order, with real durations and exact
regular-file log names `out/test-evidence-1.log` through
`out/test-evidence-N.log` under the agent's home. A skipped/not-run log
explains why; even those attempts cannot be omitted. Never invent results.
The trusted policy's attempt and per-log byte limits appear in the brief;
the full guide lists the manifest fields and limits. The example below
illustrates the format, not results of a real run.

```json
{
  "schema": "agentic-job/test-evidence/v1",
  "base": "COMMIT", "head": "COMMIT", "tree": "TREE",
  "image": "quay.io/example/bootc@sha256:...",
  "test": "install-to-disk",
  "command": "cargo xtask test-install",
  "profile": "devspace-rhel10-64",
  "resources": {"cpus": 64, "memory_mib": 262144, "disk_gib": 500},
  "planned_attempts": 3,
  "attempts": [
    {"attempt": 1, "outcome": "fail", "duration_s": 600, "log": "test-evidence-1.log"},
    {"attempt": 2, "outcome": "not-run", "duration_s": 0, "log": "test-evidence-2.log"},
    {"attempt": 3, "outcome": "pass", "duration_s": 590, "log": "test-evidence-3.log"}
  ]
}
```

`check` refuses the evidence, and with it the hand-back, in these cases:

- the bounds have no `[github.test_evidence]`;
- it is beside a push or a replacement series, or there is no patch;
- a log has no manifest, or a field is unknown, missing or given twice;
- the schema is not this one;
- `base` or `head` is not the commit the checked patch applies to;
- `tree` is not a full object ID;
- the image, test or profile is not a name of letters, digits and
  `._:/@+=-`, or the command is not one line of at most 1024 characters;
- a resource is zero;
- more attempts are planned than `max_attempts`, or other than all the
  planned attempts are reported, numbered 1 to N in order;
- an outcome is not `pass`, `fail`, `skipped` or `not-run`;
- a duration is over a day;
- a log is not `test-evidence-N.log` for its attempt, or is missing,
  a link, not a regular file or over `max_log_bytes`;
- a log belongs to no attempt.

The report's `test_evidence` holds the names, the base, the tree and the
count of each outcome. The command and the logs are not in it.

Check runs without the repository, so it cannot see the tree. Apply
can. Its trial applies the checked patch to its base. Before anything is
published, `agentic-job test-evidence` refuses a manifest whose `tree` is
not the tree that trial made. It then adds one paragraph to the pull
request: the count of each outcome, whether every planned attempt
passed, and a link to the run, whose checked upload holds the manifest
and the logs. One pass after two failures is not a repeated pass, and the
paragraph says so. A valid manifest shows that the evidence belongs to
this patch. It does not show that the tests say what is true. Where the
bounds take evidence and a pull request patch came without it, check's
summary says that no test result is claimed. Its report adds
`test_evidence_missing: true` (omitted otherwise), derived from trusted
policy and the checked patch, not a producer's status. Apply adds one
fixed draft paragraph saying the evidence was absent or dropped during
collection and **no repeated-test acceptance is claimed**. It never
publishes producer drop diagnostics. This does not accept a malformed
manifest that reaches check or soften apply's stale-tree refusal.
Unconfigured hand-backs and drafts are unchanged; no correlation or
external-runner preflight is added here.

## Who applies

The rule, in the operator's words: "I like what GH AW does requiring a
separate job VM that does the apply and only that VM has the write
secrets."

The apply job has a machine of its own and a write credential. Event
notification jobs can also write, but do not apply agent outputs.
Apply runs gh-aw's pinned handlers on the
checked outputs, or [agentic-job's own](#agentic-jobs-own-handlers) for
the types the bounds route to them, and nothing else that came from the
agent's machine.
The workflow explicitly forwards `SAFE_OUTPUTS_PAT` and the optional role
secrets, never `secrets: inherit`. The legacy PAT also reaches the separate
`apply-token` precheck when requested and the notify/conclude status steps;
in role mode those status steps use `STATUS_TOKEN`. Neither agent nor check
receives these secrets. Which token, and how to set it up, is in
[the apply job and its token](workflow.md#the-apply-job-and-its-token).
If it is a classic personal access token of a bot account, everything
that account can do is reachable from the apply job.

## What gh-aw's scripts need

This is for a workflow gh-aw did not generate; the
[reusable workflow](../.github/workflows/agentic-job.yml) is the worked
example. The setup action is given the `destination`
`${{ runner.temp }}/gh-aw/actions`. It empties `/tmp/gh-aw`, so a job
puts its files there afterwards. Each script runs in an
`actions/github-script` step that calls
`setupGlobals(core, github, context, exec, io, getOctokit)` from
`setup_globals.cjs` and then the script's `main()`.

gh-aw's collector would read three paths from its environment:
`GH_AW_SAFE_OUTPUTS` (the agent's `outputs.jsonl`),
`GH_AW_SAFE_OUTPUTS_CONFIG_PATH` (`.safe_outputs` of `policy.json`, with a
secondary pull request's `max` added to `create_pull_request`'s) and
`GH_AW_VALIDATION_CONFIG_PATH` (`validation.json`). It writes
`/tmp/gh-aw/agent_output.json`, `{items, errors}`, and succeeds whatever
it refused. check.yml runs `collect` in its place, which writes the same
file and exits 1 where it refused a line; either way, the job fails on a
non-empty `errors` itself.

The handlers read `GH_AW_AGENT_OUTPUT`,
`GH_AW_SAFE_OUTPUTS_HANDLER_CONFIG` (JSON, in the variable itself),
`GH_AW_WORKFLOW_ID` and `GH_AW_WORKFLOW_NAME`. They need the patch at
`/tmp/gh-aw/aw-BRANCH.patch`; for a patch, a checkout of the output repository at the
base branch, whole and with credentials persisted, since they push with
it; git's `user.name` and `user.email` (`git am` keeps the patch's
author and needs a committer); and the token of their step for the API.
Comment-only results need the API token, not a checkout or a fetched base.
The configuration is `.safe_outputs` of `policy.json` with settings added:
`create_pull_request` gets `signed_commits: false` (a signed push is
made through the API as the token's owner), `fallback_as_issue: false`,
`preserve_branch_name: true`, `auto_close_issue: false` (apply supplies the
issue reference itself, rather than the handler), `target-repo`, `base_branch`,
`branch_prefix`, `title_prefix`, and the applying account's fork (or the
output repository, where [its owner applies](workflow.md#a-repository-the-applying-account-owns)) as
`head-repo` and as the one entry of `allowed_repos`, which the handler
requires of a `head-repo`; the agent cannot name it, since check refuses
a request's `repo`. Without a fork there is no `create_pull_request`
handler ([pull requests come from a fork](workflow.md#pull-requests-come-from-a-fork)).
`add_comment`, `hide_comment` and the [review comment
types](#review-comments-on-the-pull-request) get `target-repo` and `target`. They list what they made in
`/tmp/gh-aw/safe-output-items.jsonl`. Where the forge refuses a pull
request, the upstream handler would open a fallback issue despite
`fallback_as_issue: false`; the workflow lets no handler open more
issues than the run's `create_issue` outputs allow.

Part of what the handlers log is the agent's text: the patch's first
lines before `git am`, and git's own `Applying: subject`. The runner
reads a workflow command in any line a step writes, so a commit message
could set a step output no handler wrote (`created_pr_url`, which
conclude reports as the run's result) or mask text from the log. The
reusable workflow hands the handlers a `core` and an `exec` whose output
is escaped as `run` escapes the agent's log
(`workflow/workflow-commands.cjs`); a workflow of your own should do the
same, since `check` cannot refuse `##[` in file content the preview
prints too.

CI drives `collect` and the handlers with the scripted agent, and
[`safe-outputs-probe.yml`](../.github/workflows/safe-outputs-probe.yml)
drives gh-aw's own collector and handlers on two fixtures when dispatched. Deployment evidence is in the
[workflow guide](workflow.md#what-has-run-and-what-has-not).

### The publication corpus

Replacing the handlers for the [neutral profile](#neutral-profile)'s
GitHub types means a second implementation holding apply's write
credential. Before it may publish, it has to send what the pinned
handlers send. `crates/agentic-job/tests/publication.rs` records that
from the pinned code itself, not from what anyone expects of it: each
case of `tests/data/publication/cases.json` runs apply.yml's step that
writes the handlers' configuration, its re-run guard (policy's binary,
`agentic-job applied`) and its handler step, the last in the
`actions/github-script` bundle apply.yml pins,
against a loopback forge that records every request and keeps what was
posted, with git pushes going to local bare repositories. Nothing reaches
a real forge. Where applicable it also runs the request-editing steps
before the guard: moving check's folded review findings into place
(generated by `agentic-job review fold`), adding the partial-run note,
and linking the caller's issue to a pull request. Their edited items,
outputs and annotations are recorded, so the corpus captures what the
guard and handlers receive as well as what they send.
The cases are the forge's starting state, its failures, the event the
run is for (a dispatch with none by default) and
the requests; the golden file of each holds the method, path, body and
its keys' order of every request, the step outputs, annotations and
summary, the guard's kept and skipped items, `safe-output-items.jsonl`,
and the commits pushed. They cover `add_comment`, `create_pull_request`,
`push_to_pull_request_branch`, `create_issue`, `close_issue`,
`close_pull_request`, `add_labels`, `remove_labels`,
`create_pull_request_review_comment`, `noop` and `missing_data`; the
footer and execution marker, the applied name and its digest, the second
sanitizing, a `max` and a link limit, a re-run finding its comment on a
second page, a handler replacing an older workflow comment past its first
page, re-runs of an issue and a pull request, half-closed,
reopened and already closed issues and pull requests, labels left out
by the allowed list, a blocked pattern, a repeat or a missing label, an
issue made for an issue event (its sub-issue link and the comment in its
place where the forge refuses the link), a review comment outside the
pull request's diff, re-runs mixing both sets of handlers, and
failures of the forge and of the guard. Push re-runs cover a completed
push and a commit that landed before its activation comment failed;
the guard skips both on re-run, including the lost activation comment.
Each attempt records its newly pushed commits separately. Commit records
include the patch author, apply's bot committer and preserved `Generated-by`
and co-author trailers under apply.yml's unsigned handler configuration;
no extra bot co-author is added. Partial pull requests and folded verdict
comments are also re-run to check their edited requests' stable names.

The golden files name the gh-aw and github-script commits they were
recorded at, and the ordinary test suite fails when apply.yml pins
others, or when CI's `publication` job checks out others. That job runs
the pinned code again and fails on any difference, printing a unified diff
for each changed golden (at most 120 lines and 16 KiB, plus a truncation
notice), with the complete actual file's temporary path. So an update of
either action (Dependabot's included) also updates the job's `ref:`
lines and records the corpus again with `just publication-corpus`,
which needs node 24, as github-script runs on, and replaces
`/tmp/gh-aw`. Review the diff: it is the change in what gets published.
Never edit expected output by hand. Run regeneration twice and compare
the files byte for byte, then run the ignored publication test with
`AGENTIC_JOB_TEST_GH_AW` and `AGENTIC_JOB_TEST_GITHUB_SCRIPT` pointing at
clean checkouts of those pins and without `AGENTIC_JOB_BLESS_PUBLICATION`.

The same job runs each case again with its types that
[agentic-job's own handlers](#agentic-jobs-own-handlers) publish routed
to them (or only those a case names, to mix the two): apply.yml's two
steps for them, then gh-aw's, have to make the recorded writes, in the
recorded order, and the same `safe-output-items.jsonl` and pushed
commits. A type is routed only once its cases match. The ordinary
suite runs those two steps on each case's recorded requests without the
pinned code, and the unit tests in the library's `apply/publish.rs` hold the rest of
what gh-aw's handler step records to the corpus: its outputs, summary
and error report.

### agentic-job's own handlers

Bounds that list `add_comment`, `create_pull_request`, `add_labels`,
`remove_labels`, `close_issue`, `close_pull_request`,
`push_to_pull_request_branch`, `create_issue` or
`create_pull_request_review_comment` in
`native_handlers` ([the bounds](#the-bounds-and-the-policy)) have apply
publish those types with `agentic-job publish` instead of gh-aw's
handlers, in a step of policy's binary before gh-aw's: a port of those
handlers at the pin, on the GitHub [`Publisher`](../crates/safe-outputs/src/apply/github.rs)
and its client, which hold apply's token. It is off by default; every
other type stays gh-aw's, and everything before the handlers runs as
before (the fork step, the patch's trial, the partial note, the issue
link and the guard against re-runs, `agentic-job applied`, which also
finishes a half-closed item and leaves out a push an earlier attempt
made, even one whose comment failed).

Except for an issue under
[`comment_on_duplicate`](#proposing-follow-up-issues), what it sends is
what gh-aw's handlers send: the second sanitizing with
the same mentions allowed (the item's author and the event's people;
none in a closing comment), the footer, the workflow and execution
markers, the applied name hidden as apply.yml's hook hides it, the
comment limits, the title prefix, the draft setting, and the branch
pushed to the `head-repo` the fork step chose, committed by the job's
git identity. A push applies check's patch on the head the run was
asked for, with git's lease on that head
([the same push](../crates/safe-outputs/src/apply/git.rs) apply makes
off GitHub), to the branch of the pull request the handler's `target`
names, which has to be from `head-repo`, neither its default branch nor
protected, and comments on it with the commit. Its commit keeps the
patch's author and message, trailers included, and is dated the
patch's author date, so that it is the same commit whenever it is made;
gh-aw's is dated when it is made. An issue made in a run for an issue
event in the run's repository says it is related to that issue and is
linked as its sub-issue, or that issue gets gh-aw's comment saying so
where the forge will not link them. Review comments are kept, as gh-aw's
review buffer keeps them, and submitted as one review of event
`COMMENT` on the pull request's head after every other routed request:
one on a path the pull request does not change is left out, and those
the forge cannot anchor are put in the review's body; a locked pull
request's review is skipped, and any other refusal fails the comments.
Labels are filtered by the handler's `allowed` and
`blocked` patterns, at most 10 added in one request, or removed one at
a time, at most the handler's `max`: a label the item lacks is skipped,
and one the forge will not remove reported without failing the
request. A closing
comment is posted first, even on an item someone closed already, which
is not closed again; a pull request is closed even where its comment
fails, an issue is not. It writes the same
`safe-output-items.jsonl` entries (with an item's state before and after
its labels change, a push's head before and after, and the review the
comments went into), step outputs (`created_pr_number`,
`created_issue_number`, `push_commit_sha`, `comment_id`,
`code_push_failure_count`, `items_failed` and the rest), summary and
`safe-output-errors.json`, as `publish-errors.json`; the [publication
corpus](#the-publication-corpus) holds it to all of them.

Each request goes to one of the two: it writes gh-aw's step the other
requests (`gh-aw-output.json`) before it publishes anything. The routed
requests must come first in the run's order, after nothing but `noop`,
`missing_tool` and `missing_data`, so that publishing them first keeps
the run's order. Where gh-aw's handlers would do something it does not,
it refuses the whole run before the first write, and gh-aw's step is
given no request: a request after another type, a field or handler
setting it does not read (a comment's `comment_id` or `reply_to_id`, a
pull request's labels, stack fields or another base, a closed issue's
`duplicate_of`, labels' intent metadata or `create_if_missing`), a
temporary ID (`#aw_`), an item named other than by a positive integer
number, a label other than a plain one of at most 64 letters, digits,
spaces and `-_./:`, a label pattern that is not ASCII, a dispatch whose
inputs gh-aw would read the event from, a mention gh-aw would look up,
a file gh-aw's footer would read in `/tmp/gh-aw`, a push without the
policy's pull request, head and branch or with a replacement series
(which the guard pushes), an issue linked to another one, an issue in a
run leaving gh-aw's handlers a pull request or a push (apply.yml lets
gh-aw's step open issues in their place up to the run's `create_issue`
count, which would then not bound both), a review comment other than one
line or range of a path, and review comments in a run with any of
gh-aw's types, whose review gh-aw would submit after them. `check` (and so
`handback check`) refuses the order, the fields, the numbers, the labels
and the temporary IDs, which depend on the requests alone, while the
agent can still change them. A run with no routed request is given to gh-aw's step
whole, held to none of these. A failure is not answered as gh-aw would answer it:
a pull request the forge refuses opens no fallback issue, a comment on
something that is not an issue or pull request is not retried on a
discussion, a push onto a branch that was rewritten since the run was
asked for is not applied on whatever it now holds, and the routed
comments after a failed pull request or push are not posted (gh-aw's
would carry a note of the failure). Each of these fails the job, and
`diagnostics handler-errors` reports why. gh-aw's own comments after a
pull request or push that failed here do carry that note: it is written
into the requests gh-aw's step is given, as its handler manager would
add it.

Every `update_project` field is checked against the live project in a
step before both, so that a field or option the pinned handler would
skip refuses the run before either writes anything.

## Off GitHub

`policy`, `collect` and `check` need no forge; gh-aw's handlers run
under `actions/github-script`. A caller that is not on GitHub (Forgejo or
GitLab) runs

```text
agentic-job collect --policy FILE --outputs DIR --collected FILE
```

on the checking machine, then `check` with the same `--collected`, as
check.yml does on GitHub ([above](#the-check-in-two-halves)). It
reads `outputs.jsonl` (at most 1 MiB, never through a link) and writes
the `{items, errors}` gh-aw's collector would, given the policy's
`safe_outputs`, with gh-aw's URL policy `allowed-or-code-region` and the
policy's allowed hosts. It exits 1 if it refused a line.

It takes every type a policy may allow, the 24 of
`safe-outputs/validation.json`: their fields validated and their text
sanitized as gh-aw does (HTML comments, tags and link titles, URLs and
their hosts, entities and hiding characters, template delimiters,
unbalanced fences, the length limits), and the rules gh-aw checks a type
against as a whole, such as an `update_issue` changing something or a
review comment's `start_line` not after its `line`. A type outside that
table is refused rather than passed on unsanitized. A test compares its
result with what gh-aw's collector wrote for the same lines and
configuration (`crates/agentic-job/tests/data/collect`, regenerated with
`just collect-fixtures GH_AW_JS` when gh-aw's pin moves), and its
built-in field rules with `safe-outputs/validation.json`. Where they
differ it mostly refuses more (a line that is not JSON is not
repaired); the other differences are in characters no renderer takes
for a line end, listed in `crates/safe-outputs/src/collect/mod.rs`. Like gh-aw's, it passes a
few fields on unchecked, where gh-aw has no check for their type
(`assign_to_user`'s `assignees`, `update_project`'s `fields`, …); `check`
holds those to the policy.

As gh-aw's collector does, it leaves @-mentions in what opens or
comments on an issue, a pull request or a discussion to the applier,
which knows who may be mentioned where it posts; in the other types,
such as `noop`, `missing_tool` and `missing_data`, it wraps them in code.
For Forgejo and GitLab, the applier is `apply`, described below.
On GitHub, gh-aw's handlers or the opt-in native handlers apply them.

### Neutral inline comments

An agent misled by repository text must not comment on another PR/MR or
attach a finding to a newer revision it never read. Off GitHub,
`create_pull_request_review_comment` therefore reuses the fixed comment
destination guards and requires the trusted check job to supply the
admitted head, never one taken from agent output:

```text
agentic-job check --policy policy.json --outputs OUT --collected collected.json \
  --report report.json --comment-repo OWNER/NAME --comment-target NUMBER \
  --review-head SHA
```

The type remains off unless bounds list
`create_pull_request_review_comment = { max = N }` under their forge
section's `outputs`.
`check` records `inline_target: {repo, number, head}` in its trusted upload.
Apply requires that repository and number to match policy and its own
`--comment-target`; it does not accept a head from the request. This adds
no write permission to the agent or check jobs: only apply holds the token.
No existing non-GitHub workflow caller enables this output by default.

The request uses the existing `repo`, `pull_request_number`, `path`, `line`,
optional `side` (`LEFT` or `RIGHT`, default `RIGHT`) and `body` fields.
`start_line`, `start_side` and every other unmapped field are refused before
collection can drop them, and again in check, not shortened to one line.
Count limits, the 65,000-character
body bound, the existing comment length/link envelope (including reserved
footer space), mention filtering and GitLab quick-action escaping still apply.
Check measures the escaped text against that envelope; apply also bounds the
final body including its actual footer to 65,000 UTF-16 units before any write.

Forgejo reads the PR identity and head and a bounded raw `.diff`, validates
the file and line against complete hunk lengths, then reads the head again.
Forgejo folds a new review's comments into the token user's pending review
and submits its draft comments too, which no check read, so apply reads at
most 20 pages of 50 reviews and refuses when any is `PENDING`. The scan must
account for the unfiltered `X-Total-Count`; hidden reviews, missing or changing
counts and incomplete scans fail closed, even when a filtered page is empty.
It posts one `COMMENT` review per operation with `commit_id` and an
`old_position` or `new_position` line number. The returned review identifies
that head, but its comments identify blame-based commits: on the pinned
Forgejo, a deleted line in the live one-change fixture identifies the base,
not the head. GitLab resolves the repository
path to its project ID and reads only `merge_requests`, never `issues` with
a colliding iid. It requires current `diff_refs.base_sha`, `start_sha` and
`head_sha`, reads at most 20 pages of 100 diff files (each response at most
1 MiB), validates the anchor, and rereads the target and diff refs. Its
discussion position includes both paths and all three SHAs, with both old
and new line numbers for context, or one for a deletion/addition.

Both mappings preflight every operation before any write and repeat their
checks immediately before posting. Stale heads, foreign/closed items,
missing files, missing/truncated diffs, ambiguous positions and out-of-diff
lines fail closed. A `push_to_pull_request_branch` and inline comments on the
same PR/MR are refused together when planning: the push would move the head
the comments were checked against. Forgejo's raw diff is limited to 1 MiB; quoted paths it
cannot represent are refused. The forge APIs have no conditional-write
head lease: an update racing the last read can make the pinned comment
outdated, but cannot retarget its commit. No approval, reviewer assignment,
reply or thread resolution is added.

Loopback tests replay stored API-shaped JSON and diff fixtures for both
mappings, both sides and context lines, colliding iids, moved heads,
refusals before writes and partial failures. These fixtures are not live
forge captures. CI's `forgejo` job runs the live inline scenario against
its pinned container: RIGHT added and LEFT deleted lines are read back with
their path, line and side-aware commit (head/base in this fixture), separately
from the checked target and submitted review's current-head binding.
Stale heads after a push, out-of-diff lines
and the apply identity's pending review are refused before writes. This
exercises the real diff endpoint, position semantics and review listing's
`X-Total-Count` contract, but not multi-page review scans. CI's `gitlab` job
also exercises live inline discussions against a pinned local GitLab CE
container, reading back path, line and side on both sides. A failed later
write names already published URLs; retrying may duplicate comments because
these publishers do not add deduplication markers.

### Publishing to Forgejo

```text
FORGEJO_TOKEN=... agentic-job apply --forge forgejo --server URL --repo OWNER/NAME \
  --policy policy.json --checked DIR --run-url URL [--comment-target NUMBER] \
  [--push-repo OWNER/NAME] [--recover-pushed-commit SHA] \
  [--status pending|success|failure|error --status-sha SHA]
```

publishes what `check` accepted to a Forgejo (or Gitea) repository,
from a job of its own that holds the write token, as the apply job does
on GitHub. `DIR` is what the check job uploads: check's `report.json`
and the patch it accepted. The token comes only from `FORGEJO_TOKEN`,
or the [role tokens](#forgejo-and-gitlab-roles) when the caller binds roles,
goes only in an `Authorization` header (to git through its
environment), and is taken out of any error. Nothing names a host:
`--server` and `--run-url` are the caller's.
Remote servers require HTTPS unless the run's bounds name their authority in
`allow_http` (empty by default); literal loopback addresses remain accepted.
Like clone URLs, this is an exact, case-insensitive match including the port:
`forgejo:3000` does not admit `forgejo:3001`, `forgejo.evil` or `xforgejo`.
Opting in sends the publish token and writes unencrypted over that network.

The token needs the scopes `write:repository` and `write:issue`, no more.
CI's `forgejo` job runs apply with only those against a Forgejo LTS container,
in [crates/agentic-job/tests/forgejo.rs](../crates/agentic-job/tests/forgejo.rs).

It publishes `add_comment`, to `--comment-target` in the repository,
`create_pull_request`, `create_pull_request_review_comment`
([neutral inline comments](#neutral-inline-comments)), `push_to_pull_request_branch`
([below](#pushing-to-a-pull-requests-branch-on-forgejo)), and the issue and label types
[below](#labels-issues-and-closing-on-forgejo); `noop`, `missing_tool` and
`missing_data` write nothing. Any other type is refused by
name, as is a report check refused. Before anything is written, apply
holds the report to the policy again: the repository, `max_outputs` and
each type's count, a request naming another repository, item, base or
draft state, the applied marker, the handlers' length and link limits,
and the patch (its name, size, base commit and check's patch rules, read
again). A same-sized patch changed after check is not caught: the
upload has to come from the check job, as on GitHub, where apply
holds it to its digest. The bodies are the collector's, sanitized once;
gh-aw's handlers' second pass is not repeated. Before publication, apply
inserts a zero-width break in user and team mentions and Forgejo `!N`
references outside code spans and fences. Closing and reopening references
share the collector's cap of ten; later ones are neutralized too.
Then apply asks the forge what only it can say about each request, still
before any write, and the pull request is
opened or pushed to, its push making the last checks, then issues created,
comments posted, labels changed, items closed and the caller's
[commit status](#commit-statuses-on-forgejo) set; a failure after a write
names what was made.

A pull request's branch goes to a fork, never to the target repository.
`--push-repo` is required for one and must be the `push_repo` the bounds
name ([above](#the-bounds-and-the-policy)), never one a hand-back names.
It must be another owner's repository, since Forgejo reads a head of the
target's own owner as the target's own branch. A `[forgejo]` section
that allows `create_pull_request` without `push_repo` is refused, so
`policy` admits no pull request that apply would then refuse. Before pushing, apply reads both
repositories through the API. It refuses a push repository that is not
a fork of the target, and, unless it is private, one whose target is not
public: private, internal, under an owner that is not public, or of a
private run. It also refuses when the forge does not report one of these.

For the pull request, apply fetches the base branch from the target into an empty
repository, applies the patch on check's base commit with git configured
only by apply (no hooks, no credential helpers, no redirects; carriage
returns kept, as on GitHub), refuses
it if it changed any path the patch did not name, and pushes it to the
request's branch in the fork, which must not exist. Then `POST /api/v1/repos/OWNER/NAME/pulls`
opens it against the target with head `FORK_OWNER:BRANCH`. Forgejo has no draft pull request, so a draft's title starts
with `WIP:`, which it refuses to merge; under `ready_when_complete`, complete
work opens ready.

If the push succeeds but opening the pull request fails, the error names
the fork, branch and full commit SHA. Retry the same checked input
with `--recover-pushed-commit SHA` to open the PR without another push.
Recovery requires both the reconstructed checked commit and the remote
branch to match that exact SHA; it refuses changed inputs or a moved branch.
The committer date is the patch's author date so retries reconstruct the
same commit. If the POST's response was lost, first check whether the PR
already exists; recovery does not detect an already-created PR.

The pushed commit's message is the patch's, verbatim, as `git am`
reads it; apply adds nothing to it. A pull request's or comment's body
is the agent's body, then a blank line and the footer
`> Generated by [agentic-job](RUN)`, where `RUN` is `--run-url`:

```text
BODY

> Generated by [agentic-job](RUN)
```

If the body ends with a trailer block, the footer goes before it instead,
and the block stays the body's last lines byte for byte:

```text
BODY

> Generated by [agentic-job](RUN)

Generated-by: https://github.com/cgwalters/#llms
Closes #5
```

A trailer block is the run of `Key: value` lines and `Closes #N`,
`Fixes #N` or `Resolves #N` lines (in any case) that ends the body, with
no blank line among them, after a blank line or at the body's start.
`BODY` is what comes before it, without trailing whitespace. A trailer-shaped
line elsewhere stays where it is. apply writes no `agentic-job-applied`
marker on Forgejo, so nothing else is added.

Because the pull request comes from a fork, the target's CI treats it as
a fork's pull request. check's protected files keep the patch out of CI
configuration, but not out of the code a workflow runs, so the agent's
code runs in the target's `pull_request` workflows. The operator must make
sure those workflows give a fork's pull request no secrets and no write
token. That is Forgejo Actions' default: a `pull_request` run from a fork
gets no repository or organization secrets, and its automatic token can
only read. To check, read the target's workflow directories
(`.forgejo/workflows/`, or `.github/workflows/` without it). No
`pull_request_target` workflow may check out or run the pull request's
head, since it runs with the target's secrets. No workflow may hand a
credential to jobs through anything but `secrets` (a runner's own
environment or files, for example). Runners that take these jobs must hold
no credential of their own. The fork's own push workflows run the code too,
so the fork should have Actions disabled or no secrets. Comments involve no
push.

#### Pushing to a pull request's branch on Forgejo

`push_to_pull_request_branch` adds one commit to the branch of an open
pull request from the bounds' fork, as on GitHub
([pushing to a pull request's branch](#pushing-to-a-pull-requests-branch)): the pull
request, its branch and its head are the policy's, which the policy job
read and held to the bounds' push `branches`; the request may only repeat
them. `--push-repo` is required and must be the bounds' `push_repo`, of
another owner, as for a new pull request. `policy` refuses a push for a
private run, as on GitHub. Before any write, apply reads
the two repositories as above (a fork of the target, private unless the
target is public) and `GET /api/v1/repos/OWNER/NAME/pulls/N`,
and refuses unless the pull request is open, into the target, from the
bounds' fork and the policy's branch exactly, and at the head the run was
asked for. A branch that moved is refused, never pushed over, and no other
branch or repository is tried.

It reads the patch again as for a new pull request: its size, the push's
protected files and paths, `commit_author`, and its base commit, which
must be the pinned head. It fetches the branch from the fork, applies the
patch on that head as above, refuses it if it changed any path the patch
did not name, and pushes the commit, made on the head and so a fast
forward of it, under a lease on the head: a branch that moved after the
forge answered is refused too. The
commit's message is the patch's. apply does not mark the pull request
ready, so `ready_when_complete` is refused, as is a replacement series.
A re-run after the push is refused at the head, which has moved; the
error after a later failure names the pull request.

#### Commit statuses on Forgejo

With `--status STATE --status-sha SHA`, apply sets a commit status on
`SHA` in the target, after every other write:
`POST /api/v1/repos/OWNER/NAME/statuses/SHA` with that state, the context
`agentic-job`, a fixed description for the state and `--run-url` as its
link. All four are the caller's. `STATE` is `pending`, `success`,
`failure` or `error`, which GitHub and Forgejo both have; before any
write, apply refuses a `SHA` that is not a full commit ID or one the
forge does not have. Without the two options it sets none. A refused
hand-back, or one whose publishing fails, gets no status from apply.

No request can ask for a status. The agent's requests stay gh-aw's types
([neutral profile](#neutral-profile)); a GitHub `create_check_run` is
refused off GitHub, and an agent-visible status type would be a new
verb, which needs its own approved and versioned contract rather than an
unversioned JSONL line.

#### Labels, issues and closing on Forgejo

`add_labels`, `remove_labels`, `close_issue`, `close_pull_request` and
`create_issue` are held to the same rules as on GitHub
([closing issues and changing labels](#closing-issues-and-changing-labels),
[closing pull requests](#closing-pull-requests-and-linking-sub-issues)):
the policy's explicit `repo`, a positive integer target of the field for
its kind, each type's `max` and the label `allowed` and `blocked` lists.
apply also refuses, rather than drops, a field Forgejo has no meaning
for: `create_issue`'s `temporary_id`, `parent`, `blocked_by` and
`fields`, `close_issue`'s `confidence`, `rationale`, `suggest` and
`duplicate_of`, and a `state_reason` other than `completed`, since
Forgejo records no reason for closing. A title is at most 128
characters and a body 65000, before the footer. Titles and bodies, a
closing comment's included, get the mention filter and footer above.

Before the first write, apply reads each target through
`GET /repos/OWNER/NAME/issues/N` and refuses one the forge does not
answer for as that number of this repository (one moved elsewhere), a
`close_issue` naming a pull request and a `close_pull_request` naming an
issue: Forgejo numbers the two together. For `add_labels` and
`create_issue` it reads the repository's labels and refuses a label it
lacks, by name, matched exactly or in another case when only one label is
so named. It never creates a label; organization labels cannot be added.
Names differing only in case are each their own label. Forgejo keeps one
label of an [exclusive scope](https://forgejo.org/docs/latest/user/labels/#scoped-labels)
on an item and removes the item's other when adding one, so apply refuses
two requested labels of one scope, and an addition that would remove a
label of the item implicitly. Preflight projects each item's labels in
batch order: an explicitly allowed `remove_labels ["status/old"]` followed
by `add_labels ["status/new"]` can transition an exclusive scope in one
batch. Both operations need their own label authorization; removing a
different item's label or adding before removing does not authorize the
transition. Every operation is preflighted before any write, and each write
still checks the live item and labels. A concurrent change can therefore
stop a partly applied batch; projection is not a transaction.
`remove_labels` looks at the item's labels: one it lacks is no change,
and a name matching two of them in another case is refused.
The repository listing accepts up to 1000 labels, using pages of 50 and
at most one extra sentinel page to distinguish exactly 1000 from overflow.
Only an empty page ends the listing: Forgejo may cap a page below the
requested size. A listing that has not ended within 21 pages is refused,
even below 1000 labels on a server configured with smaller pages.

A label is added by its ID, only if the item lacks it, and removed only if
the item has it, so a re-run changes nothing more. Forgejo's removal takes
a name, looked for among the repository's labels, then the
organization's, and only then as an ID, so apply removes a label by its
exact name and refuses one that name could resolve otherwise: an
organization's label, a name of digits, or one another repository label
has in another case. Closing posts the body
as a comment, then sets the item's `state` to `closed`; an item already
closed gets neither. If closing fails after the comment, the error names
the comment, and a re-run comments again: Forgejo gets no marker to find
it by; so does one Forgejo refuses to close, such as an issue with open
dependencies. `create_issue` posts the title, body and label IDs, and
fails, naming the issue, if Forgejo created it without them, as it does
for a token that may not set labels.

Not done: re-run detection (a
re-run with a pull request or a push is refused at its branch; one with
comments or a new issue posts them again), review replies, thread resolution
and approval verdicts. Single-line inline comments are supported as described above.

### Publishing to GitLab

The publication filter counts nested cross-project closing references such as
`Closes group/subgroup/project#12` toward the same ten-reference cap as
`Closes #12` and `Closes group/project#12`. Later matches have their keyword
and reference broken with zero-width spaces, including in purported code,
so a subgroup path cannot bypass the cap. This extends the existing filter,
not the allowed output types or targets; GitHub and Forgejo parsing is unchanged.
GitLab's `Closing`, `Fixing`, `Resolving` and `Implementing` variants, an optional
colon after a keyword, and an optional `issue` or `issues` before the reference
also consume that budget (for example, `Fixing: issue group/subgroup/project#12`).
This prevents those alternate spellings from bypassing the existing cap; it
adds no option and does not enable publication for any caller.
This is a cap on recognized keyword/reference pairs, not a complete parser for
[GitLab's closing patterns](https://docs.gitlab.com/user/project/issues/managing_issues/#default-closing-pattern):
reference lists, full-URL references and administrator-customized patterns are
not covered. Review the issues-to-close widget before merging an MR.

CI's `gitlab` job runs apply against a pinned, throwaway GitLab CE container
on loopback, in [crates/agentic-job/tests/gitlab.rs](../crates/agentic-job/tests/gitlab.rs).
The test bootstraps its own bot, target project, fork and runtime-generated PAT
with only `api`: this scope covers both API writes and git-over-HTTP pushes;
`write_repository` alone cannot publish notes or merge requests. It checks a
comment, a fork merge request and inline discussions, including neutralized
quick actions and `@all`. Like `forgejo`, the job runs on pull requests with a
read-only job token, no repository secret and no external GitLab account or
environment. Ordinary `cargo test` skips it; it is not required until stable.
The closing-cap fixture creates eleven distinct issues and compares exact
project/iid pairs from GitLab's `closes_issues` API: an unfiltered control MR
must reference all eleven, while an apply-published MR must reference only the
first ten. It uses one `Closes project#iid` pair per line, not lists, URLs or
custom patterns. It does not merge either MR and verifies the issues stay open;
this checks GitLab's predicted merge consequences, not actual merge-time closure.
The job generates and masks its disposable root password before container
creation: a fixed fixture password was rejected during admin seeding in
[this failed run](https://github.com/cgwalters-forge/agentic-job/actions/runs/42442455838/job/128614408124).
The [subsequent job](https://github.com/cgwalters-forge/agentic-job/actions/runs/42907789357/job/130150336450)
reached readiness, then failed because the fixture expected the wrong
protected-path diagnostic. The fixture now checks the structural refusal of
`.gitlab-ci.yml` and that it publishes nothing. The
[next job](https://github.com/cgwalters-forge/agentic-job/actions/runs/43351323097/job/131642896219)
read back the note and fork MR, but the branch-list API returned its cached
pre-push response. The fixture now waits for that cache to expire, still
requiring both fork branches and an unchanged `main`. Passing live inline
publication proof remains tracked by
[#3179](https://github.com/cgwalters-forge/agentic-job/issues/3179).

Also publishes `create_pull_request_review_comment` as head-bound discussions
([neutral inline comments](#neutral-inline-comments)), independently of the
plain note's `--comment-target-kind`; inline comments always target an MR.

```text
GITLAB_TOKEN=... agentic-job apply --forge gitlab --server URL --repo GROUP/PROJECT \
  --policy policy.json --checked DIR --run-url URL \
  [--comment-target IID --comment-target-kind issue|pull-request [--run-summary]] \
  [--push-repo GROUP/PROJECT] [--recover-pushed-commit SHA] \
  [--status STATE --status-sha SHA --status-ref REF --status-pipeline-id ID]
```

publishes to a GitLab project through its REST API v4, as
[Forgejo's](#publishing-to-forgejo) does, with the same server, token
and pre-write checks. The token comes only from `GITLAB_TOKEN`, or the
[role tokens](#forgejo-and-gitlab-roles), and goes
only in an `Authorization: Bearer` header (to git as `oauth2` over
Basic, through its environment). The policy must be for GitLab
(`"forge": "gitlab"`, from a `[gitlab]` bounds section). It publishes the types below, and writes nothing
for `noop`, `missing_tool` and `missing_data`:

- `add_comment` is a note on the caller's issue or merge request.
  GitLab numbers the two apart (`#5` and `!5`), so the caller names the
  kind with `--comment-target-kind`; without it a comment is refused.
  Before posting, apply reads the item by its iid under the project's
  URL-encoded path, and refuses it unless GitLab answers for that iid
  of that project, and the project under that path, not one it was
  renamed or moved to. The note then goes to the project's ID as read,
  as does the merge request below to the fork's.
- `create_pull_request` pushes the branch to the bounds' `push_repo`, a
  fork of the project, and opens the merge request on the fork with the
  project as its `target_project_id`. The fork must be GitLab's fork of
  that project (`forked_from_project`), and private unless the project
  is public and the run is not private. A draft is a `Draft:` title.
  With [`own-branch-repos`](#pushing-to-a-pull-requests-branch) accepting
  the project, and no `push_repo`, the branch and merge request go to the
  project itself instead; fixes pushed to an open merge request's branch alike.
- `push_to_pull_request_branch` adds one commit to the branch of the
  policy's merge request, as on Forgejo
  ([pushing to a pull request's branch](#pushing-to-a-pull-requests-branch-on-forgejo)):
  the same patch, protected path, `commit_author`, head and lease rules,
  and the same git push. Before any write, apply reads the project and
  the fork as for a new merge request, then the merge request by its iid
  under the project's ID, and refuses it unless GitLab answers for that
  iid of that project and into it (`project_id` and
  `target_project_id`), open, from the fork by its ID
  (`source_project_id`) and the policy's branch (`source_branch`), at
  the head the run was asked for (`sha`). A merge request from another
  fork, merged, closed or moved on is refused, as is one from the project
  itself unless `own-branch-repos` accepts it, which puts the project in
  the fork's place.
- `--status` sets the caller's commit status after every other write,
  off by default, never from agent JSONL. To prevent attaching a result
  to the wrong pipeline or taking over another run's job, GitLab requires
  the trusted caller's `--status-ref REF` and `--status-pipeline-id ID`.
  The existing project-local pipeline must match the project's ID, the
  full `--status-sha` and the exact ref, be explicitly unarchived and have
  no CI configuration errors (`yaml_errors`). Missing context is an explicit
  refusal, not automatic pipeline discovery; legacy calls without status
  and Forgejo's status flags are unchanged. `POST /projects/ID/statuses/SHA`
  carries both ref and pipeline ID, the fixed name `agentic-job`, a fixed
  description and `--run-url` as its link. GitLab has no `error`, so
  `failure` and `error` are both `failed`, with distinct descriptions;
  `pending` and `success` keep their names.
- `--run-summary`, off by default, posts the run's `summary.md` as a
  note on the comment target, after the requests and before the status.
  GitHub renders that file in the job summary, but GitLab has no job
  summary and shows a `.md` artifact as plain text. The summary still goes
  through `check`, like every other write. The check job reads the file
  with `check --run-summary FILE` (from the `agent-run` artifact), without
  following a link, and limits it to the job summary's size. It refuses a
  file that is not text or that holds a string shaped like a credential,
  which `run`'s redaction should already have replaced. It then sanitizes
  the file as the collector sanitizes a comment's body, so a link to a
  host the policy does not keep is redacted; an image link would otherwise
  send whatever the agent read to that host from every reader's browser.
  The result goes into the report as `run_summary`. A summary that fails
  these checks is left out with a warning, and the run's requests are
  checked without it. Apply posts the summary only from that report, with
  its mentions and quick actions broken as an `add_comment`'s are. It
  leaves out a note longer than GitLab's 1,000,000 characters. A batch
  that `check` refused posts nothing, the summary included, and a rerun
  posts the note again.

Status targeting follows GitLab's documented
[commit status API](https://docs.gitlab.com/api/commits/#set-commit-pipeline-status)
and [pipeline API](https://docs.gitlab.com/api/pipelines/#get-a-single-pipeline).
It requires GitLab 18.5 or later: status listing needs the `pipeline_id`
filter (17.9+), and the pipeline API must expose a boolean `archived`
field (18.5+). Older responses refuse before any write, rather than guess
archive eligibility. GitLab may otherwise choose among duplicate pipelines or create an
external pipeline; apply deliberately does neither. A commit readable in
the target project's object store is not sufficient: a fork-only head
without the matching pipeline in that project is refused before any
write, including a push. For an MR, GitLab documents targeting the source
branch's commit. The caller must provide an existing pipeline in the
publication project for that SHA/ref, or omit status; apply never moves
publication to the fork or reads these settings from checked agent output.
No token scope, secret, workflow permission or JSONL capability is added.

Preflight and the final status operation both read all statuses for this
name, SHA, ref and pipeline, with `all=true`, at most 20 pages of 100
entries (a full final page refuses incomplete selection). The greatest
numeric job ID is current, regardless of list order; duplicate IDs or
responses outside the requested context refuse. Only that current job's
full state, description and run URL can suppress the POST. An older match
cannot hide a newer different result, and `failure` followed by `error`
updates the description. Any pending or running job for this context
whose URL is not this run's refuses, even if an even newer job matches:
GitLab could otherwise update that unfinished job, stealing its identity.

Every listed job must carry the exact string `name`, `sha` and `ref`
requested, not just the newest job. Missing, null, wrongly typed or different
values refuse rather than trusting the API's query filters. Loopback regression
tests cover each field on the first and a later page, at both preflight and
final publication, and assert that refusal sends no mutation. These tests do
not prove live GitLab filtering or eliminate the races below.

These reads are not a transaction. A pipeline can disappear, a competing
run can publish between the read and POST, and GitLab can reject the
request (including pending conflicts, 409 update conflicts or 422 job
limits). Apply sends at most one POST, never blindly retries an error or
lost response, and never changes the name or run URL to bypass a conflict.
A later explicit rerun reads the current value again. If status fails
after a push or other write, the error includes the URLs already published
(for example the MR URL); those writes remain published. Inspect that MR,
the commit page and the trusted run URL before retrying: status rerun
safety does not make an already-applied branch push replayable.

Other GitLab outputs:

- `add_labels` and `remove_labels` change the labels of the issue or the
  merge request their `issue_number` or `pull_request_number` names:
  exactly one of the two, never `item_number`
  ([neutral profile](#neutral-profile)). `close_issue` closes the issue
  its `issue_number` names, and `close_pull_request` the merge request
  its `pull_request_number` names. `create_issue` opens an issue. These
  are held to the rules Forgejo's are
  ([labels, issues and closing on Forgejo](#labels-issues-and-closing-on-forgejo)):
  the policy's explicit `repo`, each type's `max`, the label lists, the
  fields apply maps, and a `state_reason` of `completed` only, as GitLab
  records no reason either.

Before the first write, apply reads each item as a note's is read: by
its iid under the issues or the merge requests of the project's path,
of the kind its request names, refused unless GitLab answers for that
iid of that project. GitLab creates a label it is given and lacks, so
apply reads the project's labels (its groups' included) and refuses one
it lacks by that exact name, a name with a comma, which GitLab reads as
two, and two of one [scope](https://docs.gitlab.com/user/project/labels/#scoped-labels)
(`scope::value`), or an addition that would remove a label of the
item's scope: GitLab keeps one label of a scope, and no request names
that removal. It reads them again just before its own write. A label is
added only if the item lacks it and removed only if it has it, in one
update (`PUT` with `add_labels` or `remove_labels`), and the answer must
show the change, as GitLab ignores labels a token may not set; a new
issue's alike. Closing posts the body as a note, then sets
`state_event` to `close`; an item already closed, or a merge request
merged, gets neither, and a locked merge request is refused. If closing
fails after the note, the error names it, and a re-run notes again.

Every body and merge request title has GitLab's mentions broken:
`@user`, `@group/subgroup`, `@all` and `@here`, after anything but an
ASCII letter, digit or `_` as GitLab reads them, so `x.@all` too (and a
link such as `https://social.example/@user` gets the break as well). A
pull request's title has its mentions broken on Forgejo too now. On GitLab,
mentions are broken inside code too: differing interpretations of escaped
backticks or fences must not leave a live notification. Every
body also has its
[quick actions](https://docs.gitlab.com/user/project/quick_actions/)
broken: a line starting with `/` (`/merge`, `/approve`, `/close`) after
any indentation gets a zero-width break before it, so GitLab does not run
it with the token's rights. This applies inside code too, though GitLab
skips code there, as a fence it reads otherwise would run the command.
The length and link limits are the same as Forgejo's.

Not done, each a later slice of
[tracker#786](https://github.com/cgwalters-forge/tracker/issues/786):
review replies and thread resolution, marking a merge request ready,
re-run detection for notes and new issues, and an end-to-end test
against a GitLab instance.

## Neutral profile

The requests stay gh-aw's JSONL on every forge, with its type and field
names: agents already know them, and nothing on the line changes. What
differs per forge is which types and fields mean the same thing there.
That is the *neutral profile*, from the research and plan in
[#1393](https://github.com/cgwalters-forge/agentic-job/issues/1393#issuecomment-6278826860).
The bounds' forge section selects it, and `policy.json` carries it as `forge`
and `contract`. The contract is a number, now 1, that follows the gh-aw
commit pinned [above](#what-is-gh-aws-and-why) and is raised when a
type or field changes meaning there. `check` refuses a policy written
for another contract. A policy without the two keys is GitHub's, at the
current contract.

| gh-aw type | GitHub | Forgejo | GitLab |
| --- | --- | --- | --- |
| `add_comment` | issue comment | issue comment | note on the caller's issue or merge request, of the kind the caller names |
| `create_pull_request` | pull request from a fork; `draft` | pull request; draft is a `WIP:` title | merge request opened on the fork with `target_project_id`; draft is a `Draft:` title |
| `push_to_pull_request_branch` | git push | git push | git push |
| `create_pull_request_review_comment` | review comment | review comment, by line number | discussion with a base, start and head commit position |
| `add_labels`, `remove_labels` | by name | by name or ID | by name; apply must refuse a label that does not exist, which GitLab would create |
| `close_issue`, `close_pull_request` | `state` | `state` | `state_event` |
| `create_issue` | issue | issue (labels by ID) | issue |
| `noop`, `missing_tool`, `missing_data` | no write | no write | no write |

These are the types a bounds file off GitHub may list; `policy` refuses
any other there, and `check` refuses a policy that holds one. The list
is of what is held, not of what is refused, so a type nobody has mapped
stays GitHub-only. GitHub-only because no other forge has the object:
`create_discussion`, `update_project`, `hide_comment`, `link_sub_issue`
and `create_check_run` (check runs are for GitHub Apps; the common
subset is a commit status with a pinned context, which only the caller
sets: [commit statuses on Forgejo](#commit-statuses-on-forgejo)). GitHub-only until
someone maps them: `update_issue`, `update_pull_request`,
`mark_pull_request_as_ready_for_review`, `add_reviewer`,
`assign_to_user`, `reply_to_pull_request_review_comment` and
`resolve_pull_request_review_thread`. A forge-native operation added
later gets a forge prefix, as gh-aw does for its Jira and Linear types.

A request names the kind of item it targets. GitHub and Forgejo number
issues and pull requests together, so gh-aw's `item_number` is one
item there. GitLab's `#5` and `!5` are different items, so `check`
refuses an `item_number` on GitLab. A type whose target must name its
kind there uses gh-aw's `issue_number` or `pull_request_number` where it
has them. `add_labels` and `remove_labels` have only `item_number` in
gh-aw's rules, so on GitLab the collector also takes `issue_number` and
`pull_request_number` for them, and `check` requires exactly one, of the
policy's explicit `repo`. The collector drops a field its rules do not
list; on GitLab it refuses instead a request with an `issue_number` or a
`pull_request_number` that its type does not take there (an
`add_comment`'s, or a `close_issue`'s `pull_request_number`), whose
target would otherwise be lost. A comment goes only to the run's own
item, whose kind the caller names. GitHub's and Forgejo's requests are
collected as before. The contract stays 1: no policy changes, and a
binary of before, given such a request, drops the target and `check`
refuses the request for lacking one.

The bounds that already exist are neutral: `hosts`, `repos`, `bases`,
`max_outputs`, each type's `max`, push `branches`, label lists,
protected files and dot-folders, and `commit_author`. A check run's
`name`, a discussion's `category` and `projects` are GitHub's.

Apply acts as one identity per role, which the caller's configuration
maps to a credential; a request never chooses one. Producer and check hold
none of these write credentials; trusted status jobs may also hold the status
credential (or the legacy PAT):

- GitHub: `SAFE_OUTPUTS_PAT` (or the job token), or the caller-bound
  [role credentials](#caller-bound-publisher-roles), including supported App tokens.
- Forgejo: a bot user's token.
- GitLab: a project or group access token, a bot member with a role.

Pushing and opening a change can be separate roles, as in
[service-gator](https://github.com/LobsterTrap/service-gator/tree/b69814b140bf7c8385014560857760fe8fb71f03):
a fork identity that may push, and an upstream one that may only open
pull requests. On Forgejo and GitLab those are the `fork_push` and
`publication` [role tokens](#forgejo-and-gitlab-roles).

Both publishers implement the listed neutral types, including
`create_pull_request_review_comment`, with the field restrictions above.
GitLab's mentions and quick actions are broken before publication.

## Library boundary

The safe-output contract is becoming a component of its own
([tracker#1047](https://github.com/cgwalters-forge/tracker/issues/1047)),
so that another project, or a deterministic CI job, can collect and
check requests without agentic-job's runner, secure-host or GitHub's
environment. The first step is `crates/safe-outputs`, a library in this
workspace that depends on neither agentic-job nor secure-host. It reads
no environment or credential of its own: it is given text, settings and
a token. Bounds parsing, the check and publication safety belong to the
component, and event admission, run identity, artifacts, checkpoints,
memory, secret scanning and credential acquisition to its caller. The
collector, the policy, bounds parsing, the check, publishing to Forgejo
and GitLab, GitHub's client and native publishing, where a run's commit
goes on GitHub, the replacement series and the secondary pull request
have moved. agentic-job keeps their commands: reading the environment,
its no-follow file reads, step outputs, and escaping what the library
hands back before it reaches a log.

Moved into `crates/safe-outputs`, with no change in behaviour:

| What | From | To |
| --- | --- | --- |
| Output type names, `OUTPUT_TYPES`, `HIDE_REASONS`, the review-thread types | `policy.rs` | `vocabulary.rs` |
| `Forge` (its name, `holds`, `refuses_field`), `CONTRACT`, `NEUTRAL_OUTPUTS`, `ITEM_NUMBER`, `KIND_TARGETS` | `policy.rs` | `vocabulary.rs` |
| `GH_AW_LINK_DOMAINS`, `link_domains` and `top-level-domains.txt`; the link rule `Policy::keeps_link_to` now calls | `policy.rs` | `vocabulary.rs` |
| `OUTPUTS_FILE`, `MAX_OUTPUTS_BYTES` | `check/mod.rs` | `vocabulary.rs` |
| The collector's type table, validation, `field_guide` and `collect`; the sanitizer and Markdown scanning | `collect/` | `collect/` |
| The neutral inline comment's field list, which the collector refuses before it could drop a field | `apply/inline.rs` | `collect::inline_field_names` |
| `Policy` and its parts (`Kind`, `SafeOutputs`, `OutputLimit`, `PullRequest`, `Push`, `PatchRules`, `Memory`, `Secondary`, `ContextRepo`), `Policy::validate`, the protected-file defaults, globs and name patterns, and which clone URLs a policy may name | `policy.rs`, `run/clone.rs` | `contract.rs` |
| `Bounds` (its `[github]`, `[forgejo]` and `[gitlab]` sections, and the `[github.trigger]` table typed by the caller), `SecondaryPullRequest`, `Unprotected`, `Bounds::validate`, `clone_url_problem`, and `intersect`, which holds a run to the organization's bounds too | `policy.rs` | `bounds.rs` |
| Counts, targets and redirections (`redirections_to`), patch names, `base.json` and the run's branch, the patch rules, link repair, handler limits and replacement series | `check/` | `check/` |
| `CheckedTarget`, the trusted head of a neutral inline comment that check writes and apply reads back, and `checked_target` | `apply/inline.rs` | `check/inline.rs` |
| apply's `plan` and `publish`, `Op`, `Publisher`, `Target`, the footer and the report read back | `apply/mod.rs` | `apply/mod.rs` |
| The Forgejo and GitLab publishers, their push and its guards, neutral inline comments and their anchors, and the filtering of mentions and quick actions | `apply/` | `apply/` |
| The inline comment fixtures | `crates/agentic-job/tests/data/inline` | `crates/safe-outputs/tests/data/inline` |
| GitHub's REST API, git and `Publisher` (`Github`, `GithubPublisher`) | `apply/github.rs` | `apply/github.rs` |
| GitHub's native publishing (`agentic-job publish`): its plan, gh-aw's handler ports and their records | `apply/publish.rs` | `apply/publish.rs` |
| Caller-bound publisher roles (`Role`, `Identity`, `Credential`, `read`, `Routed`) | `apply/roles.rs` | `apply/roles.rs` |
| Where a run's commit goes on GitHub (`agentic-job push`): `resolve`, `target` and the owner-branches opt-in | `apply/push.rs` | `apply/push.rs` |
| The replacement series' trial and leased push (`agentic-job replacement`) | `apply/replacement.rs` | `apply/replacement.rs` |
| The secondary pull request's plan and opening (`agentic-job secondary-pull-request`) | `apply/secondary.rs` | `apply/secondary.rs` |

`apply::plan` decides every write before the first, refusing with every
reason found, and `apply::publish` asks the forge about every op
(`Publisher::preflight`) before it writes any, as before. It is given
the check job's upload as `Upload`: its directory and the caller's read
of a file, which must not follow a link (agentic-job's is secure-host's
`files::read_regular`). The trusted caller also gives the forge, the
repository, the fork, the comment target, the run's link and the status
(`Target`), and how it names itself (`Provenance`): the footer's link
text, the commit status context and the committer, which agentic-job
gives as `agentic-job`, `agentic-job` and `agentic-job
<agentic-job@invalid>`, so what it posts is unchanged. The publishers
take the server and the token as arguments. `apply::testing` (feature
`test-support`) holds the mock forge, test repositories and a GitHub
client of the mock, which agentic-job's tests of its GitHub commands use
too.

GitHub's client takes the API, the token and the `Provenance` whose name
it sends as its user agent and whose committer commits a push that names
none; agentic-job reads `GITHUB_API_URL` and the token's variable for it,
or the role bindings and their tokens, which it gives `Github::with_roles`.
For Forgejo and GitLab it builds one publisher per role from those tokens
and gives them to `roles::Routed`, which checks each identity first.
`apply::publish::apply` is given the requests, the handlers'
configuration, the upload and the policy (`Checked`), the run as gh-aw's
handlers read it from a lookup of variables the caller gives
(`Run::read`); it hides the line naming an earlier attempt's write as
apply.yml's hook does, by the marker check refuses in requests
(`check::APPLIED_MARKER`). `publish::check_server` refuses a git server
that is not https, before the token goes to it. It writes gh-aw's records where `Records` says, and gives each line of the
step's log to the caller as an `Annotation` (a workflow command's kind
and its text), as it gives each retry's warning to `Github::warning_with`:
the caller writes them escaped, as agentic-job does with secure-host's
`workflow_commands`, so that nothing the forge or the agent wrote is read
as a command.

`apply::push::target` and `apply::replacement::trial` take the caller's
no-follow read as `Upload` does, and `apply::secondary::plan` the upload
and the `Provenance` whose name its footer gives. `replacement`'s errors
hold git's messages, with the agent's text, as git wrote them: agentic-job
escapes the whole message before it reaches the step's log.
`GithubPublisher` is made only by `publish::publisher`, so its server
check cannot be skipped.

`check::check` is the check's entry point. It is given the hand-back's
files as its caller read them (`Handback`), the collector's result, the
policy, and what the trusted caller says of the run (`Trusted`: the fixed
comment target and the run's identifier); the policy already holds the
repository, base, pinned head, targets and limits that the read-only
policy job compiled. It reads no runner or Actions state. Two things it
asks its caller for, in the order its refusals have always come: what the
caller's own publishers refuse (`Publishers`: apply's neutral inline
comments and its native handlers), and a lifecycle callback given the
request that carries the patch, where agentic-job checks the checkpoint
and memory. The returned refusals are in the order found; agentic-job's
`Verdict` drops repeats, as before.

`collect::collect_bytes` is the bounded entry point: it refuses a file
past `MAX_OUTPUTS_BYTES` or not UTF-8 whole, and otherwise returns the
same `{items, errors}` as `collect`, which takes text its caller has
already bounded. Reading the file without following a link stays with
the caller; agentic-job's `collect` reads it with secure-host's
`files::read_regular`, as before. agentic-job re-exports the vocabulary
and the collector at their old paths, so `policy.json`, the wire format,
the sanitizer's results and every refusal are unchanged.

`decode::decode` is the framing alone, read-only, for a caller that
admits requests by rules of its own (agent-board's supervisor hand-back,
[agent-board#507](https://github.com/cgwalters-forge/agent-board/issues/507)).
Given the bytes of an `outputs.jsonl`, it refuses them past
`MAX_OUTPUTS_BYTES` before parsing anything, then requires UTF-8, skips
blank lines and returns each other line in order as its `type` and its
JSON object as parsed, unchanged and in key order (a key given twice
keeps its last value, as in JavaScript). A line that is not JSON,
not an object, or without a string `type` refuses the whole input. It
sanitizes nothing and knows no type, limit or forge; its errors
(`DecodeError`) name the line and the kind of failure and quote nothing,
since the input may hold a credential. Lines are numbered as gh-aw's
collector numbers them, after JavaScript's whitespace is trimmed from
both ends of the input; each line is trimmed the same way, so CRLF is
taken.
`collect` and `collect_bytes` frame with the same functions, then refuse
a malformed line in gh-aw's words and go on to the next, so the two
cannot drift apart: the collector is `decode`'s framing plus gh-aw's
per-type validation and sanitizing.

Staying in agentic-job: the `collect` command's arguments, exit state and
printing, and the configuration it builds from `policy.json` (a
secondary pull request's `max` added to `create_pull_request`'s)
(`collect.rs`); reading bounds and policy files (`policy::Load`),
compiling a run's request into its policy (`policy::Compile`, whose body
is as it was) and admission (`policy.rs`, its `context` and `dispatch`
modules, `event/`); `check/`, the adapter that keeps the hand-back's
layout and the report: it reads the directory without following a link,
holds each file to its size, refuses a private key and warns of other
secret-shaped strings (`redact.rs`, whose patterns stay here, apart from
the library and from [#2026](https://github.com/cgwalters-forge/agentic-job/issues/2026)),
checks `memory.json`, test evidence and the checkpoint, and writes `Verdict`; `apply/`'s
commands, the files they read and the tokens they take from the
environment, the status comment (`status.rs`), the result
(`result.rs`), the guard against applying twice (`applied.rs`) and the
readiness and issue-reference integration; `handback.rs`, run identity, artifacts
and checkpoints.

The per-forge bounds of [#2107](https://github.com/cgwalters-forge/agentic-job/pull/2107)
([#1393](https://github.com/cgwalters-forge/agentic-job/issues/1393))
integrate here: its `[github]`, `[forgejo]` and `[gitlab]` sections, and
the refusals of none or two, change the `Bounds` struct and
`Bounds::validate`, now in `bounds.rs`; the refusal of a type the forge
profile does not hold stays a crate-private trait, `ForgeAdmission`, in
`contract.rs`. Its changes to `compile` and its tests apply where they
were, in `policy.rs`. `policy.json` is unchanged by it, so the check is too.

gh-aw has no library to depend on instead. At the pinned commit its
safe-output code is CommonJS under `actions/setup/js`
(`collect_ndjson_output.cjs`, `safe_output_type_validator.cjs`,
`sanitize_content.cjs`, `sanitize_content_core.cjs`,
`safe_output_handler_manager.cjs`), built by `make actions-build` and
committed; the `actions/setup` action, a `node24` action, copies those
files to a destination (and can report a tracing span), nothing more. That directory's `package.json` has
development dependencies and no name or version, so nothing is
published to npm. The per-type rules exist only inside the workflows
gh-aw's compiler writes, which is why `safe-outputs/validation.mjs`
reads them out of gh-aw's own compiled workflows. Reuse of gh-aw's code
means pinning that action's commit, as apply.yml does.

### Upstream JavaScript disposition

The pinned JavaScript stays outside the library, at the GitHub adapter's edge.
Following [cgwalters's 13 November response](https://github.com/cgwalters-forge/agentic-job/issues/2026#issuecomment-6860948527),
keep reusing gh-aw's handlers unchanged through the existing immutable setup-action
pin, rather than porting them for language uniformity. The Rust collector/checker
remains the common contract for local handback and non-GitHub publishers. Preserve
these drivers and their tests because they execute or compare actual upstream code:

- `safe-outputs/validation.mjs` extracts compiled validation rules and footer/handler
  limits into `validation.json`, rather than maintaining another set by hand.
- `crates/agentic-job/tests/corpus/collect.cjs` drives the pinned collector to
  record parity fixtures; `handlers.test.mjs` executes the pinned handlers against
  mocked forge calls.
- The two `github-script` steps in `safe-outputs-probe.yml` probe the actual
  upstream collector and handler manager.
- CI's apply-guard rerun exercises apply's actual guard rather than a model of it.
  `apply.yml` continues to execute the upstream handlers under `actions/github-script`.

The JS ratchet still requires shrinkage outside `site/`, `.github/actions/` and
the exact three existing corpus harness paths. Its temporary `corpus.test.mjs`
allowance and old-tree CI inputs remain until tracker#1455 supplies trusted
effective opt-in, compatible exact producer/checker revisions and public-base
evidence for fixture deletion. This disposition neither enables that override nor
declares the no-JavaScript 1.0 bar met; #2026 remains open.

No concrete offline/distribution need for bundling has been established. Before
changing delivery, a packaging proposal must demonstrate that benefit and inventory
shipped scripts, dependencies and license notices while preserving publication
goldens, bounds and check/apply separation. This does not approve vendoring or a
submodule design; current contribution constraints still apply. Standalone adoption
remains under [#2398](https://github.com/cgwalters-forge/agentic-job/issues/2398).

The library's tests read `safe-outputs/validation.json` and the parity
fixtures in `crates/agentic-job/tests/data/collect` where they are, rather
than copies; these are part of the export root below. Its check tests read the policies in
`crates/safe-outputs/tests/data`, which agentic-job's tests compare with
what `policy` compiles, so that neither drifts from the other.

### Self-contained export root

The export boundary is the path inventory
[`export.paths`](../crates/safe-outputs/export.paths), **not just the crate
directory**. It retains paths deliberately: the two parity corpora under
`crates/agentic-job/tests/data` are data, not a dependency on runner source.
The root includes the component, collector and publication corpora, generated
validation and its generator, real-run fixtures, both license texts, this
reference and the run-contract specification. Each asset still has one maintained
source; no fixture, license or generated validation is copied into a second
maintained location. Runner-specific sections and links in the reference/spec
remain context, not a standalone promise to provide the runner.

The crate manifest spells out package metadata, dependency features and lints;
it inherits nothing from agentic-job's workspace. The export installs
[`export.toml`](../crates/safe-outputs/export.toml) as its root `Cargo.toml`,
with only this member and the existing release profile. `publish = false`
remains intentional. Neither the contract, bounds nor publication defaults
change. Since no maintained asset moves, workspace consumer paths and the
release source-digest inputs do not change.

Run `just test-safe-outputs-export` after `cargo test --locked -p safe-outputs`
has cached dependencies (about three minutes on an unprivileged runner). This
opt-in smoke test copies only the inventory into a temporary directory and uses
a fresh target directory. It does an offline build to prune the workspace lock,
then locked/offline default library/CLI build and tests, a no-default-feature
library build and tests, and a separate no-default-feature `test-support`
consumer test. It asserts there is no runner manifest/source or secure-host
tree. It never runs host setup, reads a forge credential, or publishes.
The ordinary workspace suite does not run this expensive ignored test.

### History-preserving transfer (not publication)

After merging this preparation, use a disposable clone with `git-filter-repo`
installed. From the source repository root, the following retains the history
of every inventory path without rewriting the source checkout:

```sh
git clone --no-local . /tmp/safe-outputs-history
git -C /tmp/safe-outputs-history filter-repo --paths-from-file "$PWD/crates/safe-outputs/export.paths"
cp /tmp/safe-outputs-history/crates/safe-outputs/export.toml /tmp/safe-outputs-history/Cargo.toml
cargo build --offline --manifest-path /tmp/safe-outputs-history/Cargo.toml -p safe-outputs
cargo test --locked --offline --manifest-path /tmp/safe-outputs-history/Cargo.toml -p safe-outputs
cargo build --locked --offline --manifest-path /tmp/safe-outputs-history/Cargo.toml -p safe-outputs --no-default-features
cargo test --locked --offline --manifest-path /tmp/safe-outputs-history/Cargo.toml -p safe-outputs --no-default-features --lib
```

Use a new, absent destination instead of reusing that temporary path. The first
offline build prunes unrelated lock entries without upgrading the retained
resolution; review the lock diff. In that clone, record the new root manifest
and pruned lock as a transfer-only commit. Preserve `filter-repo`'s commit map
and compare the inventory's final file contents against the source revision,
then inspect `git log --all --stat` for retained history. `git-filter-repo` does
not follow historical renames: if older pre-extraction history is required,
identify and explicitly include its earlier paths before filtering, and check
the resulting history separately. Do not call a copied-tree smoke test evidence
that this history rewrite succeeded. This preparation runs the copied-tree
proof; the actual history-transfer verification remains an adoption prerequisite.

The runner keeps the hooks described above: admission and policy compilation,
no-follow bounded reads, secret scanning, lifecycle/checkpoint checks, trusted
run identity, artifact transport, credential acquisition, escaping and apply
deduplication. It also keeps the pinned gh-aw workflow adapter and corpus
regeneration harness. The export's recorded fixtures exercise the library
offline; regenerating them still requires the caller's `just collect-fixtures`
and `just publication-corpus`, the pinned gh-aw/github-script sources and the
caller workflow. The validation generator is exported unchanged and still
requires the pinned gh-aw compiled workflows. This does not expand or resolve
[#2026](https://github.com/cgwalters-forge/agentic-job/issues/2026).

Later adoption under [#2398](https://github.com/cgwalters-forge/agentic-job/issues/2398)
must authorize the destination, verify the actual history transfer, install
standalone CI for this test matrix and fixture provenance, decide independent
versioning/release policy, and review an immutable dependency/binary pin in each
caller. The current runner path dependency and action/binary pins remain in
place. No external repository, CI dispatch, release or publication is part of
this preparation; #2398 remains open.
