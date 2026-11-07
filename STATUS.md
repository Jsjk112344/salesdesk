# Project status

Product name: **SalesDesk** (renamed from ProofDesk on 2026-11-05). Existing operational
identifiers and dated historical entries retain their original names.

Current checkpoint: **Hook-first video v5 is prepared at 3:17.**
The 463-word script has 54 guide caption cues. The opening stops at 0:08, 0:20,
0:26 and 0:32; dated industry statistics precede the retained walkthrough.
Both silent exports are 197.000 s, 1080p/30fps. See `docs/video/REVIEW-v5.md`,
`docs/video/video-plan-v5.md` and `docs/video/_review/v5-contact.png`.
Original public execution evidence is unchanged. Owner records VO, aligns final
captions/audio, uploads and submits. No receipt exists.

Public URL: https://salesdesk.149.28.51.139.sslip.io

## Hackathon phase 1: 2026-11-05 ET

- Owner authorization: $150 aggregate of $200 credit for inference and compute; public
  activation authorized. Deadline supplied by owner: Nov 8, 18:00 ET; target 16:00 ET.
- Authenticated model catalog GET succeeded. Selected `qwen3.8-flash-next`, JSON-object
  output and reasoning disabled. Catalog rates: $0.10 input / $0.20 output per million tokens.
- Genuine benchmark executed in Docker and accepted live analysis observed. Research and
  outreach accepted live on the labelled Harbor Vale synthetic scenario, with a verified
  Docker demonstration and an unsent draft. No validator changes.
- Prompt iteration resolved excessive summary length, unsupported quantities, and forbidden
  outcome wording (including negated wording). Final analysis and both prospect contracts passed.
- Accounting so far: 13 durable request reservations ($0.0261248 worst case), 12 responses
  with usage ($0.0039680 estimated token cost). One interrupted harness reservation has no
  observed provider usage and remains charged at its full reservation. Prior exhausted
  ledger remains untouched ($0.0040384 reserved). These are estimates, not billing receipts.
- Inference sub-envelope: $0.15, 64 requests, preserving existing six-request batch limits;
  analysis debugging stays under the owner's 40-request limit. No new compute provisioned.
  Existing VM accrual/credit balance has not been verified against account billing.
- Public workers prefer accepted responses for identical serialized inputs, revalidate
  through the same contracts, label replay, and reserve no paid capacity for cache hits.
  Timestamp metadata remains in sources but is excluded from research prompt identity.
  Different inputs use Vultr; genuine failures remain visible, with no silent substitution.
- Checks: Ruff, formatting, compileall, frontend build, repository links/patterns passed;
  offline suite 93 tests, six Docker skips; new replay test passed separately. Live Docker
  benchmark and prospect execution passed. An initial operator harness failed before
  completing inference; corrected to an isolated store with guarded subprocess entry.
- Private VM SSH and health verified; public ingress not activated yet.

## Initialization checkpoint: 2026-11-03

- Track: Blast Radius Zero (working choice from the project discussion).
- Rules checked: official event, LabLab terms and rule book on 2026-11-03.
- Existing-code baseline: empty new repository; original scaffold and planning only.
- Repository publication: https://github.com/Jsjk112344/proofdesk is PUBLIC.
  Unauthenticated metadata, README and MIT license access verified.
- GitHub protections: secret scanning, push protection and private vulnerability
  reporting enabled and verified.
- GitHub CI: [initial scaffold run](https://github.com/Jsjk112344/proofdesk/actions/runs/41681064090)
  passed on initialization commit fe195c1. Subsequent runs remain visible in Actions.
- Local scaffold: React/Vite screen and FastAPI health endpoint implemented.
- Observed local checks: locked dependency sync, Ruff lint/format, Python compilation,
  TypeScript/Vite build, API and built-page HTTP smoke checks, publication-file patterns
  and documentation links passed. Browser interaction and deployment remain unverified.
- Live research, model calls and generated-code execution: not implemented.
- Containment: not implemented or verified.
- Deployment resources: none provisioned by this project.
- Authorized cloud/model budget: none established; credits and inference coverage unverified.
- Public demo/video/slides: pending. Public code alone does not complete the entry.
- Submission: not submitted; no receipt.

## Open questions

Exact deadline/timezone and remote prize eligibility need organizer confirmation.
The public event date range does not establish an exact submission hour.
Before provisioning, confirm credit redemption, service coverage, resource pricing,
authorized spending cap and cleanup ownership. Do not publish account/billing details.

## Initial next implementation (superseded by the execution slice below)

Prove one bounded journey using permitted example inputs: sourced use case, demonstration
execution, artifact verification and saved draft. Establish runner containment before
allowing untrusted code. Select and evaluate Vultr models with an authorized call budget.

## Local execution slice: 2026-11-03

- Baseline inspected: `4bcbf91`, clean working tree. Work on `feat/local-execution-slice`.
- Implemented: CLI controller/runner interface, original labelled synthetic extraction,
  disposable Docker execution, fixed externally configured resource limits, pre-task
  kernel checks, strict artifact validation and atomic local execution records with
  documented JSON Schema. No HTTP execution endpoint, model or autonomous retry loop.
- Docker rechecked: client 29.6.2, server 29.5.2, Colima Linux/arm64, cgroup v2, seccomp.
  Official Python 3.12 slim Bookworm image explicitly pulled and digest pinned. No private
  images were reused; unrelated containers were left alone.
- Observed successful CLI probe pass: 15 labelled cases plus final valid fixture, every
  case matched its expected result and verified container removal. Example evidence IDs:
  `bda9f6c5cf2c4acb913072e3bae36dce` (wrong output, exit 0, rejected),
  `990d82f4334443a083d32b8eacd83e78` (deadline),
  `e44f58be38dd48eaad13bf76a0c30e38` (host canary),
  `4ed9daa3dffa46849e9818956c607bcb` (subsequent valid extraction).
  Full records are ignored under `.local/executions/<id>/record.json`.
- Actual resource behavior observed: memory allocation exited nonzero under the RAM cap;
  process creation hit EAGAIN; tmpfs writes hit ENOSPC; root writes failed. CPU quota was
  read from the kernel, not benchmarked. stdout and archive floods hit transport caps.
- Signal checks: SIGINT and SIGTERM produced interrupted records with verified removal;
  SIGKILL recovery removed the abandoned container and reconciled its pending record.
  A new valid task succeeded after each. Missing executable fault injection produced
  `docker_unavailable`, no task exit code or artifact, and explicitly unverified cleanup.
- Completed verification: all eight unittest groups passed with Docker enabled (including
  all live probe cases and three signal/crash cases). Offline run passed six groups and
  explicitly skipped two Docker groups. Locked sync, Ruff lint/format, compileall and
  TypeScript/Vite production build passed locally. Node was v26.5.0 here; CI remains pinned
  to Node 24. No remote CI run is claimed for this branch.
- Final live suite completed with all eight groups passing in 23.621 seconds, including
  a synthetic controller-secret sentinel and refusal to start work before crash recovery.
  Publication pattern/local-link checks passed for 46 tracked files; no labelled task
  containers remained after the suite. These checks do not constitute a full security audit.
- Initial runtime finding: Docker's copy API could not see `/work/out` on task tmpfs.
  Replaced collection with a bounded tar stream inside the task mount namespace. The
  host never extracts archive paths. Collection is not an atomic snapshot; only exactly
  validated bytes are accepted. Early failed attempts remain in local records.
- Initial signal harness readiness check omitted Docker's required PID column; corrected
  the test and reran it successfully. This was not a passed signal check before correction.
- Documentation now separates implemented local boundaries from future product criteria.
  Existing UI remains a health-check scaffold with updated status copy. CI adds offline
  behavior tests; live Docker tests remain opt-in. Added dev-only jsonschema and recorded
  dependencies/references in THIRD_PARTY.md.
- Commands run: `docker version`, `docker info`, explicit pinned image pull,
  `uv run python -m backend.app.execution run`,
  `uv run python -m backend.app.execution probe all`,
  `uv run python -m unittest discover -s backend/tests -v`,
  `PROOFDESK_DOCKER_TESTS=1 uv run python -m unittest discover -s backend/tests -v`,
  targeted signal recovery test, `uv sync --locked`, Ruff lint/format, Python compileall,
  `npm --prefix frontend ci`, TypeScript/Vite build and publication-file/link checks.
- Limitations: ordinary local Docker observations, no general escape guarantee; no Vultr
  runtime verification. Hard crashes/daemon outages require explicit recovery, with no
  independent watchdog service. Local records have no aggregate retention quota. Only
  synthetic inputs and a fixed extraction contract are supported. See SECURITY.md.
- Cloud/model spending: none; no credentials, account access or budget needed/used.
  Event and terms refreshed through the requested vultr-agent-rush skill; credits remain
  unverified. Nothing provisioned, pushed publicly or submitted in this session.
- Next step: under an explicit small spending cap and securely configured inference
  credential, connect one Vultr Serverless Inference model, generate a script, inspect
  an actual failure and make one bounded correction through this same controller.
  First add the corresponding provider, retry and spend accounting tests. Deployment,
  live research, outreach and hackathon readiness remain pending.

## Bounded generation and rejection fixes: 2026-11-03

- Resumed `feat/local-execution-slice` at `95b67b5`, clean working tree. No unrelated
  changes existed; existing fixture commands and the web health scaffold are preserved.
  Used the vultr-agent-rush skill for controller/containment/budget discipline. No new
  competition/market research or product research feature was added; only official
  provider technical references were checked (recorded in THIRD_PARTY.md).
- Fixed both reviewed rejection defects before model work: input/source bounds now
  precede content persistence/hashing, and pre-dispatch rejections never read reusable
  runner evidence or exit codes. Only bounded metadata is saved. Success → rejection →
  success with the same runner passes offline and in real Docker; successful task
  evidence identifies its own container. Record v2 documents null rejection hashes.
- Implemented controller-only Vultr HTTPS adapter with explicit model/deadline/token/
  response bounds, usage telemetry, strict protocol checks, no redirects, compression,
  SDK retries or provider fallback. A killable controller transport process enforces
  the total request deadline; it never executes returned code. No new dependencies.
- Implemented worst-case request/token/cost reservations, retained on errors/timeouts.
  Live requests require a key plus an exact owner-approved plan. Durable local approval
  ledgers prevent reloading a plan from resetting capacity; exhausted/corrupt ledgers
  stop. Current authorization remains **$0**; no live plan/key was required or used.
- Added `generate --provider fake|vultr`: source generation → existing Docker controller
  → exact validation → at most one eligible correction. Each generation and task has
  separate records linked by workflow/attempt and request/response/source hashes.
  Unsafe artifacts, policy/resource/infrastructure and cleanup failures stop immediately.
  Pending workflows/requests are abandoned on explicit recovery, without resend/refund.
- Added three synthetic evaluation cases (original, reordered EUR input, held-out Unicode/
  whitespace/three-item/zero-value input). Only the development document enters prompts;
  no expected answer enters generation or correction. An offline held-out-failure test
  inspects feedback and confirms document/answer withholding. These are public fixtures
  authored with the parser, not an independent model-quality benchmark.
- Provenance distinguishes `deterministic_synthetic_fixture`, `offline_provider_fixture`
  and future `vultr_model_generated` execution. Fake usage is explicitly synthetic;
  accepted response bytes and source are saved exactly. Malformed/oversized responses
  retain bounded sanitized metadata, no returned content. No offline pass is live evidence.
- Observed offline suite: 34 tests discovered, 30 passed and four Docker methods skipped
  explicitly (3.142 seconds). Covers missing key/approval, HTTP/transport errors, malformed/
  oversized responses, usage/token/request/cost limits, durable failed-call reservations,
  cleanup exceptions, terminal containment failures, held-out withholding and recovery.
- Observed final full Docker-enabled suite: all **34 tests passed** in **32.359 seconds**,
  including existing 15 probes, SIGINT/SIGTERM/SIGKILL recovery, rejection reuse, and new
  fake-provider Docker workflows (success, one correction, second failure stops). A final
  targeted recovery check also passed after ordering receipt recovery before workflow
  finalization, so interrupted recovery can be repeated. No paid requests occurred.
- Example ignored local workflow evidence from that full pass:
  `d978734133004f7fb793d7e5417395fe` — first incorrect output, one correction, all three
  cases passed; `232a644d4fc54d7686ecf313fa8d33f2` — two rejected script attempts, stopped.
  Earlier direct CLI `generate --provider fake --fake-outcome correct-once` also succeeded
  (`ea3bbc710e144294baa5c6e7b8b40556`). These scripts are canned fixture responses executed
  in Docker, not model-generated code.
- Actual CLI missing-credential check (key explicitly removed from environment) produced
  `missing_vultr_credentials`, zero reserved/sent requests and no task executions:
  `bcd80eecf2284a658548d9aa7ca8d612`. Its intended provider is labelled Vultr; it is not a
  live inference observation. Other provider failures were injected offline.
- Other completed checks: `uv sync --locked`, Ruff lint and formatting, Python compileall,
  `npm --prefix frontend ci`, TypeScript/Vite production build, and git whitespace checks.
  README, SECURITY, architecture, record v2/schema, acceptance, environment placeholders,
  contributor status and minimal screen status copy are aligned with implementation.
- Remaining limitations: no live Vultr request, selected model, verified price/billing,
  deployment or general escape guarantee. Input token admission uses a conservative byte
  estimate, requiring selected-tokenizer verification before live approval. Local ledgers
  are checkout-scoped and trusted, not account-wide billing controls; hard crashes still
  require explicit recovery. Local storage has no aggregate retention quota.
- Next authorized boundary: prepare the exact model/current pricing/tokenizer plan and
  conservative cap in docs/inference.md, then obtain only missing owner authorization
  before any paid call. No live spending, provisioning, outreach, publication, push or
  submission was performed in this continuation. No receipt or remote CI run is claimed.
- Final publication-pattern/local-link check passed for all 57 tracked files. No labelled
  ProofDesk task containers remained after verification. Only the intended implementation,
  tests, synthetic fixtures and documentation are included in the local commit.

## First-live preflight and authorization: 2026-11-03

- Resumed at requested commit `8413fcd` with a clean tree. Read contributor, architecture,
  inference and security instructions; used the vultr-agent-rush skill. No subagents,
  prospect research or Slack work were used.
- Refreshed official event/terms, Vultr model/pricing, completion limits and reasoning
  documentation. An actual public model metadata GET returned HTTP 200 for
  `qwen3.8-flash-next`, confirming $0.10/$0.20 per million input/output tokens and
  262,144-token context/output capacity. This metadata lookup is not inference.
- Owner explicitly approved `proofdesk-live-2026-11-03`: $0.02 total cap, at most two
  requests with one eligible correction, 60 seconds/request, 12,000 input and 4,096
  completion tokens/request, 32,192 reserved tokens total. Maximum token-priced API
  reservation is $0.0040384. Exact JSON is ignored at
  `.local/live-preflight/authorized-plan.json`; no ledger was reset or paid request sent.
- No inference credential was found in the process environment, project `.env`, or
  standard Vultr configuration locations. The owner's credential-location question is
  pending. No unrelated private repositories or correspondence were searched.
- Public upstream tokenizer/config/template are ignored local inspection materials.
  The initial request is 1,523 bytes; controller admission estimates 1,779 tokens;
  the inspected upstream default text template tokenizes to 360 tokens. Provider-side
  framing and usage still need an authorized live response. No template code executed.
- Observed offline tests: 34 discovered, 30 passed and four Docker tests skipped
  (3.685 seconds). Observed full local Docker suite: **all 34 passed in 40.360 seconds**.
  Docker server 29.5.2, Linux/arm64, cgroup v2/seccomp; pinned image present. Runner
  readiness passed after tests and no checkout-labelled task containers remained.
- Locked sync, Ruff lint/format, compileall, TypeScript/Vite build, and repository
  publication-pattern/local-link checks passed. Test log, catalog response/hash receipt,
  tokenizer/hash checks and readiness summary are ignored under `.local/live-preflight/`.
- Actual live generation/extraction remains **not attempted**, with $0 spent by this
  continuation. No live workflow ID, provider usage or model-quality result is claimed.
  The web journey is pending the requested live-generation prerequisite. Next action:
  use the owner's local credential location, run the exact approved plan through the
  existing sandbox/verification workflow, preserve the outcome, then build the minimal
  document-selection/run/progress/results journey if generation succeeds.

## First live requests, synthetic web journey and private Vultr deployment: 2026-11-05

- Selected challenge is now **Powering the Future of Work**, explicitly confirmed by the
  owner. Updated current contributor/README/architecture/submission guidance; historical
  Blast Radius Zero checkpoints remain dated. Refreshed official event/terms and current
  Vultr catalog/reasoning documentation. No registration, submission, public push or
  publication was performed. No prospect research or Slack work was added.
- Resumed commit `8413fcd`, preserving the three existing uncommitted documentation files.
  The console screenshot is unchanged and excluded via local `.git/info/exclude`; it was
  not opened, staged, committed or included in the release. Initial diff backup is ignored
  at `.local/live-preflight/continuation-start.patch`. No subagents were used.
- The ignored project `.env` provided the local inference credential. Checked only presence
  and model/endpoint match; no secret value was printed. Catalog GET on 2026-11-05 returned
  HTTP 200 and confirmed `qwen3.8-flash-next`, $0.10/$0.20 per million input/output tokens,
  context/output capacity and reasoning budget support. The Nov 3 approval file/identity
  was left intact; the Nov 5 metadata/receipt was saved separately.
- Actual initial workflow `985e8177be3b44828a04507c6e00d57e`: HTTP 200, 360 input + 4,096
  completion tokens, `provider_incomplete_response`. It stopped terminally with zero task
  executions and no automatic correction. Its full reservation was retained.
- The owner separately approved `proofdesk-followup-2026-11-05`: low reasoning effort,
  512-token reasoning cap, same original allowance/ledger, one request and no correction.
  Added bounded request-control loading/validation, receipt metadata and a one-attempt
  workflow restriction. A meaningful offline test verifies that controls cannot change
  the parent model/approval or restore the consumed ledger.
- Actual follow-up `6a7535b5c2714dfc948fc31d4b7e4fc0`: HTTP 200, 348 input + 1,091 completion
  tokens, `provider_malformed_response`. Zero task executions. Rejected content was not
  retained under the existing protocol contract; the exact invalid field/source defect
  is unknown. Do not infer Markdown fences or a model-name mismatch without evidence.
- The same ledger `95977722843a1e73f60b836ec4898f6400702edc8028f4bf4d15fb245736a8e6`
  records **2 requests, 32,192 tokens and $0.0040384 reserved**, under the $0.02 cap.
  Usage-priced estimate is $0.0011082 excluding unverified fees/tax/invoice rounding.
  No billing receipt/refund is claimed. **No request slots remain; no further paid call
  is authorized. Successful live-generated extraction remains unachieved.** Actual
  workflow/generation receipts and sanitized checkpoint stay ignored in `.local/`.
- Implemented minimal React journey: choose a synthetic document → start → saved progress
  → verified table/JSON, code and execution evidence → session history/reload. It clearly
  labels the original fixture parser and separately shows failed live provider checks.
  No fake live-generation success, fabricated progress percentage or automatic retry.
- Implemented fixed-input API, opaque HttpOnly/SameSite session capabilities, cross-session
  read refusal, same-origin/host checks, 2 KiB body limit, idempotency, one active run,
  five runs per anonymous session and twenty total by default, with durable local records.
  This is not enterprise account authentication. A trusted subprocess integrates the
  existing Docker controller and excludes inference keys from worker environments.
  Saved result hashes are checked before rendering; task text is escaped.
- Observed local checks: all **42 Docker-enabled tests passed**, covering existing probes/
  signal recovery and the new web worker/documents, ownership, quotas, duplicate requests,
  crash handling and artifact integrity. Offline suite: 37 passed, five Docker tests
  skipped explicitly. Local actual HTTP checks also executed all three documents with
  totals 1,600 / 408 / 2,195 cents and verified removal; web run IDs:
  `8cb77806cfcb443aa4c8e163755eb02d`, `f9fac6e95e804f74ab3feb61672eec1e`,
  `59e9adf33e4c4ccb9ec321804bac8c7e`.
- Owner-provided Vultr VM inspected over the existing SSH identity: Ubuntu 24.04, x86-64,
  4 GB class memory. Installed distribution Docker/Python venv tooling and pinned uv;
  no new VM, subscription, GPU, payment method or cloud resource was created. Existing
  VM billing and eventual VM teardown remain owner-managed. No credits were assumed.
- Private deployment installed at `/opt/proofdesk` with a hash-manifested allowlist bundle.
  Non-root `proofdesk` controller is a trusted Docker-group member. systemd service is
  active, bound only to `127.0.0.1:8000`; no public ingress/HTTPS was enabled. No inference
  key, approval or spending ledger was copied. Runtime: Docker 29.1.3, x86-64, cgroup v2,
  default seccomp/AppArmor; the pinned task image pulled successfully.
- Actual Vultr HTTP web runs succeeded for all three documents with exact totals and
  verified removal: `63542045d93b400ba71cf844e467fe9a` / task
  `0d4229124900407db36a5f8d1d95d96a`; `ba41aa7f8f9b4151b385d3d39e8e9489` / task
  `1e202748fa80430a8a6ac4d55a4c85dd`; `ce4d5d5d2b7f41199338ceb7e984b142` / task
  `8d5ef801b9354f3196068d31666a0453`. All are **deterministic fixture** execution.
  The 15 original fault probes plus final valid fixture also passed on this VM. No
  labelled task containers remained. Records stay on the VM and are copied locally
  under ignored `.local/deployment/`; this is narrow runtime evidence, not a general
  escape-protection guarantee.
- Browser interaction checks passed in a disposable network-disabled Playwright container
  against an explicitly mocked API: selection/start/progress/result, evidence/code tabs,
  reload history, mobile layout and no page errors. No browser ran on the host. PNG/JSON
  collection uses bounded tar reads without host extraction; container absence verified.
  Screenshots stay ignored in `.local/browser/`. An initial screenshot-copy attempt hit
  the already-known Docker tmpfs copy limitation; corrected collection and reran the
  browser check successfully. Mocked UI checks are separate from real HTTP/task evidence.
- Added dev-only HTTPX test dependency and documented licenses/references. No new app
  runtime dependency. Current checks also include locked sync, Ruff lint/format,
  compileall, TypeScript/Vite build, shell syntax and publication/local-link scanning.
- Next boundaries: inspect the private UI through SSH; successful model generation still
  requires a separately reviewed future plan, with no implicit budget reset. Public
  ingress/HTTPS and exact-content publication remain unapproved. Submission assets,
  public demo and receipt remain pending. Existing uncommitted work remains uncommitted.
- Final reviewed private bundle SHA-256:
  `7a9688341d3f923d7a8425d64eacc32e866bc4dbee06c8178d1c65b3d6ffa28d`.
  Server source hashes matched the manifest after installation. Final post-update web run
  `85054aab7ef3432fb74366f143d453d0` / task `afa9b547bde24deaac75c4b35ca38259`
  validated the Unicode fixture at 2,195 cents with verified cleanup. Its ignored receipt
  is `.local/deployment/final-server-check.json`.
- Final review added a recovery guard: a surviving worker cannot revive terminal work
  or publish a result after a new API process marks it abandoned. The focused seven-test
  web suite, including real Docker execution, passed after that change; the complete
  42-test Docker suite passed before it. Final formatted browser build and interaction
  checks also passed. All 66 intended worktree files passed bounded publication-pattern/
  local-link scans; shell syntax, Ruff, compileall and whitespace checks passed. The
  temporary local verification server was stopped; the private Vultr service remains active.

## Sales agent reorientation, model-integration fix and redeployment: 2026-11-05 (second continuation)

- Resumed `8413fcd` with the earlier uncommitted web/deployment work intact and preserved.
  Verified the VM facts over SSH before changes (host `proofdesk-web`, Ubuntu 24.04 x86-64,
  service active as `proofdesk`, API on `127.0.0.1:8000`, `/opt/proofdesk`, Docker 29.1.3,
  5 web runs and 22 execution records present, no labelled containers). Used the
  vultr-agent-rush skill's challenge/deployment/budget discipline and the impeccable skill's
  product-register guidance; no Ducket code, data or tokens were used. No subagents.
- Refreshed the event page (now served from lablab.build): Future of Work requires a Vultr
  VM backend, web app, public repo, demo URL and video; **Serverless Inference and
  sandboxing are optional** and remain ProofDesk's own choices. Refreshed the official
  chat-completion contract, reasoning and limits docs and the public model catalog (free
  GET, receipt `.local/live-preflight/catalog-receipt-2026-11-05-session2.json`:
  `qwen3.8-flash-next`, $0.10/$0.20 per million tokens, `response_format` and
  `reasoning.max_tokens` supported). No paid request was made in this continuation.
- Reoriented the product: new `backend/app/sales/` package (SSRF-protected retrieval,
  verbatim evidence and controller demonstration rule, separate research/outreach/source
  contracts with sanitized diagnostics, controller-owned drafting with footnotes, prospect
  store with ownership/idempotency/quotas/draft versions/review, agent orchestration),
  `sales_worker.py` subprocess, `python -m backend.app.sales` CLI, new `/api/prospects`
  endpoints (create, list, detail, draft edit, review) and a rewritten React workspace
  (landing form, Research/Demonstration/Outreach views, secondary Technical details). The
  extraction endpoints remain as the demonstration capability only. Three synthetic
  prospect sites were authored under `fixtures/prospects/`.
- Model integration: `generation/provider.py` now shares transport, usage accounting and
  ledgers across contracts through `complete()`; receipts are schema v2 with `contract`,
  `request_options`, `response_model`/`model_echo_matches`, `finish_reason`,
  reasoning presence/chars/tokens, `content_chars`, `content_head` and a field-level
  `diagnostic` on rejection; rejected content is never stored. Documented compatibility
  changes: the response `model` echo is recorded instead of rejected (official contract:
  "may differ from request"), `reasoning: {"enabled": false}` and
  `response_format: {"type": "json_object"}` are supported request options, plans may hold
  up to six requests. Fences, tool calls, non-`stop` finishes, missing usage and oversize
  bodies still fail closed. A `ReplayProvider` serves saved accepted responses for
  byte-identical requests. **The second live failure's root cause remains unknown**; the
  model-echo rule is a documented possibility, not an established cause.
- Live-validation plan prepared (unapproved, `approval_reference` empty) at
  `.local/live-preflight/proposed-sales-plan-2026-11-05.json`: `qwen3.8-flash-next`, 60 s
  deadline, 16,000 input / 2,048 completion tokens, reasoning disabled, at most four
  requests (research, outreach, code generation, one eligible correction), no retries,
  worst case 72,192 tokens / **$0.0080384**, requested ceiling **$0.01**, new ledger
  identity. Zero live requests were sent; the exhausted ledger was not touched.
- Observed offline suite: **67 tests passed**, 5 Docker tests skipped. Covers URL/address
  policy (loopback, private, link-local, mapped, ULA, mixed answers, redirect to metadata,
  redirect loops), size/type/encoding/page caps, fixture sites, evidence rules, contract
  acceptance and rejections (unknown source, excerpt not in source, unknown claim id, key
  mismatch, unsupported numbers/savings words, named greeting, demo mention without
  verification), reproduced live failure shapes with field-level diagnostics, journeys
  (relevant, failed demo, irrelevant, sparse, blocked fetch, hostile page, live mode with
  fixture responses and a fabricated-citation stop, live mode without plan), ownership,
  quotas, idempotency, edits/review, recovery and API behaviour.
- Observed full Docker suite: **all 67 tests passed in 41.510 s** (log
  `.local/live-preflight/docker-tests-2026-11-05-session2.log`), including the 15 probes,
  signal/crash recovery, web worker documents and generated-response fixtures; no labelled
  containers remained. Lint/format, compileall, TypeScript/Vite build and the publication/
  link scan (84 worktree files) passed.
- Observed CLI journeys with real local Docker: `f2d2c63bf0744427b718af9799d7e921` (synthetic
  3PL: 4 pages, 6 verbatim claims, demonstration verified), `310274a8f4964e2bac26659efc9527d3`
  (synthetic bakery: skipped as irrelevant), `f4084526c5b34f84b2f2b2538766c2fe` (synthetic
  placeholder: insufficient evidence).
- Observed actual local HTTP journey (`.local/live-preflight/local-web-http-2026-11-05-session2.json`):
  policy rejections over the API, idempotent duplicate, refusal while active, sample
  prospect `ee7edb5d889f4bb49cf9deda667f9805` with demonstration execution
  `319e6dba76cd49b9a501d33384482c15` (exit 0, 1,600 cents, cleanup verified), review of v1,
  edit to v2 resetting review, stale review refused, **real retrieval of
  `https://example.com/`** (prospect `4e3d454636404b4ba839205fde85bd72`, insufficient
  evidence, honest draft), cross-session 404s and reload history.
- Observed mocked-UI browser check in the disposable network-disabled container: 10 checks
  passed (landing asks for offering/website, blocked-address message, research brief,
  demonstration, review/edit, reload, skipped demonstration, model-validation failure
  diagnostic, mobile layout, no page errors). Screenshots under `.local/browser/`.
- Redeployed the private release (bundle SHA-256
  `0806010ef9fbf0eeda7b735b0c87b8cf7a2a5b9d27dd127d825a871f8a16a0e5`, 52 allowlisted files,
  no credentials/records/screenshots) after snapshotting the previous install to
  `/opt/proofdesk-rollback/proofdesk-20261105T200643Z.tar.gz` (excludes `.local`). Service
  restarted and active on loopback only; all 52 manifest hashes matched; prior records
  preserved (5 web runs, 22 executions). No ingress, credential, plan or ledger deployed.
- Observed actual Vultr HTTP journey on the VM (`.local/deployment/vultr-sales-check-2026-11-05.json`):
  policy rejections, idempotent duplicate, sample prospect `56e1dba371704e9d9517a099dc1e3753`
  with demonstration execution `2d981ba27b3348d5aa95eb3f8c74bc83` on the VM (exit 0,
  1,600 cents, cleanup verified), review/edit/stale-review behaviour, real retrieval of
  `https://example.com/` from the VM (prospect `469323cd9c254dd5a6fbcde81cd7d62f`,
  insufficient evidence), cross-session 404 and reload history. Copies of those records are
  under ignored `.local/deployment/vultr-prospects/` and `vultr-executions/`.
- Not done: `.env.example` could not be updated because the session's permission policy
  denies every tool call touching `.env` paths; the new variables
  (`PROOFDESK_SALES_LIVE_PLAN`, `PROOFDESK_PROSPECT_STORE`, `PROOFDESK_WEB_MAX_PROSPECTS`)
  are documented in README and infra docs instead. Nothing was committed, pushed,
  published or submitted. Successful live inference, public demo, video and submission
  remain pending; those criteria are reported as incomplete.
- Next concrete action: Phase 1 of [docs/plan.md](docs/plan.md) (failure-story README,
  invariants-to-evidence table with a drift checker; no budget needed), then owner approval
  of the proposed live-validation plan for Phase 2: one authorized run of
  `python -m backend.app.sales run --sample harbor-vale-freight --provider vultr
  --authorization <plan>` plus the code-generation workflow, preserving receipts and
  reporting the sanitized diagnostics if any contract rejects the response. Phases 3 to 5
  (honest measurement, public evidence page, submission assets) and their authorizations
  are defined in the plan.

## SalesDesk rename and forward-plan correction: 2026-11-05

- Owner renamed the product to SalesDesk and requested the revised forward plan. Updated
  app navigation, page metadata, API title/health identity, exported draft filenames and
  copy, research user-agent, package metadata/locks, fixture branding and current docs.
- Kept the checkout path, Vultr hostname/resources, `proofdesk` service/user/install path,
  `PROOFDESK_*` configuration, session cookie/header, execution labels and historical
  approval/record identifiers intact for compatibility. Existing dated history is preserved.
- GitHub repository is now public at https://github.com/Jsjk112344/salesdesk. Updated origin
  and current links. A separate clean worktree published only a branding change on main,
  commit `52330e0`; it did not publish the uncommitted sales implementation. Reconcile that
  branding commit when eventually integrating `feat/local-execution-slice`; never reset
  the existing working tree to main. The temporary branding worktree was removed afterward.
- Revised docs/plan.md: correct overstated guarantees, complete one useful live sales
  journey, prepare the public product alongside it, evaluate factual support and draft
  usefulness separately, then finalize submission assets. Generated code is optional for
  the first live sales milestone; a rejected request leaves that milestone incomplete.
- The preceding review reproduced two contract gaps without paid calls: an unrelated
  lunar-warehouse claim paired with a genuine freight quote passed research validation;
  an unsupported 42-warehouse statement passed outreach validation. These remain unfixed
  implementation work for the next session. Existing tests passing does not resolve them.
- Observed rename checks: locked dependency sync, Ruff lint/format, frontend production
  build, publication/local-link check and all 67 Docker-enabled backend tests passed.
  Disposable browser sales-journey checks passed with mocked API and SalesDesk copy;
  container removal verified. No live inference or new paid resource was used.
- Updated existing private Vultr deployment with an allowlisted bundle, SHA-256
  `5b42caa1cc537d005503ce5699a37299249563ea0563c8039588a37ff81c6d70`.
  Verified all 52 manifest hashes, HTML title, served JS branding and health service
  `salesdesk`; mode remains `deterministic`. All 29 existing prospect/execution/web records
  were unchanged. No public ingress, credential or budget ledger was added.
- Rollback snapshot: `/opt/proofdesk-rollback/before-salesdesk-20261105T202746Z.tar.gz`.
  Live verification receipt: `/root/salesdesk-brand-verification.json` on the VM.
- This checkpoint supersedes the previous "failure-story README and drift checker" next
  action. Next session implements Phase 1's contract corrections with positive/negative
  regression tests, prepares one concrete bounded live-debug/evaluation authorization,
  and pursues Phase 2 success once approved. No new spending authorization was granted.
- Remote CI for the isolated public branding commit passed:
  https://github.com/Jsjk112344/salesdesk/actions/runs/42103778400.
  The existing local tunnel also returned `service: salesdesk` from `/api/health`.

## Phase 1 contract corrections, envelope ledger and public-demo preparation: 2026-11-05 (third continuation)

- Resumed the uncommitted SalesDesk working tree on `feat/local-execution-slice` (HEAD
  `8413fcd`) and preserved it. Read the contributor, plan, status, README, security,
  inference, architecture and contributing documents and the vultr-agent-rush skill. No
  subagents, Slack, CRM or external services were used. The public branding commit
  `52330e0` on main was inspected (13 files, STATUS.md conflicts against HEAD) and is
  reconciled by merge below; the working tree was never reset.
- **Both reproduced defects were turned into failing regression tests first, then fixed.**
  (1) "They operate a warehouse on the Moon." attached to a genuine freight excerpt now
  fails the research contract with field `claims[0].text`, observed
  `interpretation_not_grounded`: a claim's text may only recombine words and numbers from
  its own verified quotation (light stemming, company name allowed). (2) "Your team operates
  42 warehouses" now fails the outreach contract with `unsupported_quantity`
  (`numeral`, `no_matching_number`); written numbers, quantifiers, percentages and
  currency amounts are covered, and a genuine number reused for a different subject
  ("fleet of 38 warehouses", "300 invoices", "24,000 pallets", "2009 pallets") fails with
  `number_in_other_context`. Supported counterparts pass ("a fleet of 38 vehicles", "more
  than 300 suppliers", "since 2009 … two bonded warehouses", the verified demonstration's
  figures). Quantities are also refused in the brief's summary, hypothesis, unknowns and
  relevance reason. Outreach numbers must come from claims the paragraph cites.
- Representation: quotations carry `verification: verbatim_quotation`; interpretations
  carry `text_kind` (`verbatim`, `grounded_restatement`, `model_summary`). The UI shows
  the quotation as the fact and labels restatements and model summaries as not verified.
  Prompts tell the model the same rules. These are lexical/attributional checks; README,
  SECURITY, architecture, inference and the UI now say so (mechanism/evidence/limitation
  table in README) and no longer claim byte-exact artifact comparison (it is canonical
  JSON values), universal factual accuracy or sandbox escape protection.
- Implemented an optional aggregate **envelope** in plan files with its own durable,
  file-locked ledger that every batch reserves against first, so batched plans cannot
  exceed the owner's total and a plan with changed model settings reopens the same
  aggregate. Exhaustion stops before dispatch (`model_envelope_exhausted`); tampering
  stops (`model_envelope_ledger_invalid`); nothing refunds. Covered by
  `test_envelope_aggregates_batches_and_never_resets`. The exhausted 2026-11-05 ledger
  was not touched.
- Prepared the consolidated authorization proposal (docs/inference.md and ignored
  `.local/live-preflight/proposed-live-envelope-2026-11-05.json` plus four batch plan
  files): `qwen3.8-flash-next`, rates re-read today ($0.10/$0.20 per million tokens,
  receipt byte-identical to the earlier one), per request 16,000/2,048 tokens and 60 s,
  worst case $0.0020096; batch 1 live debugging ≤ 6 requests ($0.015); batches 2–4
  evaluation 16 requests; envelope 22 requests / 397,056 tokens / worst case $0.0442112,
  requested ceiling **$0.05**; no retries; permitted adjustments listed. **Not approved;
  no live request was sent; $0 model usage this continuation.** The key in the ignored
  `.env` was only checked for presence.
- Implemented public-demo mode (`PROOFDESK_PUBLIC_DEMO=1`): synthetic scenarios only unless
  a host is allowlisted, three prospects per session, bounded total (100 default, 200 cap),
  truthful `public_demo` flag in API and UI, live mode refused without `PROOFDESK_PUBLIC_LIVE=1`.
  Prepared `infra/Caddyfile.public` and `infra/proofdesk-public.conf` (inert templates in
  the bundle) and the activation proposal `docs/public-demo.md`. **Not activated**; the
  hostname and approval are requested there.
- Observed checks: offline suite **71 tests passed**, 5 Docker methods skipped (4.8 s);
  Docker-enabled suite **all 71 passed in 46.8 s**, no labelled containers remained (log
  `.local/live-preflight/docker-tests-2026-11-05-session3.log`); Ruff lint/format,
  compileall, TypeScript/Vite build and the publication/link scan (88 worktree files)
  passed; disposable browser check **11 interactions passed** including the new public-mode
  pass (`.local/browser/browser-check.json`). Local rule-based CLI journey with real Docker:
  prospect `6f242e07e5cf40ff810a421f75813b1a`, 6 verbatim claims, demonstration verified.
- Updated the private Vultr deployment: bundle SHA-256
  `58cb4de2b299ef8e7ab8e24ab3dd332febc61083ed7ff16baf0e465128b5f187` (54 allowlisted files,
  no credentials or records); rollback snapshot
  `/opt/proofdesk-rollback/before-phase1-20261105T211841Z.tar.gz`; all 54 manifest hashes
  matched; service active on loopback, `public_demo: false`; existing records preserved
  (2 prospects / 23 executions / 5 web runs before and after the update). Observed VM HTTP
  journey afterwards: prospect `34bc4c057d5e47578019df31f74268e2`, rule-based, 6 claims with
  the new labels, demonstration execution `bdf6885e2cd84326898a6d175e6ba835` verified (exit
  0, 1,600 cents, cleanup verified), cross-session 404, no containers left (copy at
  `.local/deployment/vultr-phase1-journey-2026-11-05.json`).
- Tool rejection: the session's permission policy denied the write to `.env.example`
  (reads of variable names worked); the new variables are documented in README and
  infra/README instead.
- Evidence kinds this checkpoint: **rule-based** (local CLI and VM HTTP journeys, real
  Docker), **offline fixture** (contract, envelope, public-mode and journey tests), **mocked
  UI** (browser). **No live model output and no replay output exist for the sales
  contracts.** Executor review only; no human seller feedback was collected.
- Next concrete action: owner approval of the consolidated envelope (write the approval
  reference into the envelope block and batch 1), then one authorized run of
  `uv run --env-file .env python -m backend.app.sales run --sample harbor-vale-freight
  --provider vultr --authorization .local/live-preflight/proposed-batch-1-live-debug-2026-11-05.json`,
  preserving receipts and reviewing factual support, specificity, demonstration relevance
  and draft usefulness. A rejected response is diagnostic progress, not completion. In
  parallel, the owner's hostname decision and approval of docs/public-demo.md unblock
  public activation.

## Historical campaign experiment, durable jobs and private Vultr verification: 2026-11-05 (fourth continuation)

- Resumed `ee64b08` with the untracked `docs/session-prompts/` preserved. The owner's expanded
  direction (evidence, statistics and AI reasoning → approved next actions → scheduled work →
  measured results, with Slack/HubSpot and all integrations deferred) is recorded in AGENTS.md
  and docs/plan.md. No subagents; no Ducket code or data; the vultr-agent-rush skill's
  challenge/deployment/budget discipline was followed.
- **Data.** The pinned Hillstrom file (3,964,977 bytes, SHA-256 `0e5893…1aece`) imported with
  64,000 rows and exactly the documented arms (Mens 21,307 / 3,894 / 267 / $30,311.69; Womens
  21,387 / 3,238 / 189 / $23,038.11; No E-Mail 21,306 / 2,262 / 122 / $13,908.33) locally and
  on the VM; equal-valued rows keep their multiplicity (57,438 distinct lines, maximum 31).
  Checksum, size, header, arm, non-finite/negative/over-precise spend, non-binary and missing
  values are rejected visibly (offline tests). Rights boundary recorded in THIRD_PARTY.md.
- **Computation.** `backend/app/experiments/analysis_program.py` (`salesdesk-analysis-1`, 9.4 KB)
  runs in the sandbox with a 30 s wall clock and 1 MiB typed input (controller extension with a
  result validator; schema updated). Hillstrom result: purchase rate 1.25% (267/21,307) vs 0.57%
  (122/21,306), difference +0.68 pp (Newcombe 95% CI +0.50 to +0.86), visits +7.66 pp (+7.00 to
  +8.32), incremental spend +$0.77 per assigned customer (seeded 2,000-resample bootstrap 95% CI
  +$0.49 to +$1.06). Reconciliation against the importer's Decimal aggregates and the
  controller's Wilson/Newcombe matched. Newcombe's six published Table II intervals and a
  bisection cross-check of Wilson pass offline. Artifact SHA-256
  `3b3152bfdf0d6cd72552d3a0cb3d1bd5e5220a8001eef68c69a944b1ea519469` was reproduced by two local
  runs and two VM runs (same pinned image).
- **Interpretation.** Rule-based reading (labelled, passes the same analysis contract); live mode
  reuses the provider transport and ledgers; the contract refuses raw numbers, ROI wording,
  unknown metric ids and actions against the historical records; a failed live step preserves
  the statistical result (offline tests with fixture responses, including budget exhaustion).
  **Live AI status: not demonstrated.** Zero live requests were sent; $0 model usage.
- **Tasks and jobs.** SQLite store under `.local/experiments/` with unique operation keys,
  lease-claimed jobs (`analyze_plan`, `prepare_packet`), bounded single requeue, unique
  artifacts per job, approval bound to proposal/artifact/plan hashes, invalidation on edit,
  stale approval refused by the worker, packet assembly without a model call, readiness checks
  separating entered inputs from external prerequisites.
- **Observed local evidence.** Offline suite **93 tests passed** (6 Docker methods skipped);
  Docker-enabled suite **93 passed in 41.6 s** (log `.local/live-preflight/docker-tests-2026-11-05-session4.log`,
  rerun after the recovery fix `…session4b.log`, no labelled containers remained); Ruff
  lint/format, compileall, TypeScript/Vite build, publication/link scan passed; browser check
  **18 interactions passed** (experiment overview → plan → results → interpretation → next
  action → packet → queue, prospect journey, public mode, mobile; `.local/browser/`). Real
  local HTTP journey with real Docker and a controlled API restart during the analysis job
  (`.local/live-preflight/local-experiment-http-2026-11-05.json`): job requeued
  (`interrupted_requeued`), attempt 2 succeeded, single artifact, packet prepared after a 15 s
  absence, cross-session 404s.
- **Private Vultr deployment.** Bundle `4b11b686…b92b` (66 files, no dataset, no secrets)
  deployed after snapshot `/opt/proofdesk-rollback/before-experiments-20261106T001348Z.tar.gz`;
  dataset copied by scp to `.local/data-research/hillstrom/` (0600, owner `proofdesk`) and
  imported as the service user; all 66 manifest hashes matched; prior records preserved (3
  prospects / 24 executions / 5 web runs). The first VM journey exposed a restart race: SIGTERM
  during `docker create` left a "Created" container and the job failed `cleanup_unverified`
  (preserved as job `61d439f3…`). Fix: bounded repeated removal in `DockerRunner.cleanup`,
  interruption takes precedence over the cleanup check, and the API runs the existing sandbox
  recovery at startup. Redeployed bundle `847be36d…be9b` after snapshot
  `before-experiments-fix-20261106T001755Z.tar.gz`; startup recovery removed
  `proofdesk-72987a42…` and reconciled its record (`last_recovery` in the overview).
- **Observed VM journey** (`.local/deployment/vultr-experiment-journey-2026-11-05.json`, through
  an SSH tunnel on 18001; port 18000 is held by a stale tunnel from an earlier session): plan
  `84445f7f…`, analysis job `d467a214…` interrupted by `systemctl restart proofdesk` at
  00:18:18 UTC, requeued and completed on attempt 2 (execution `213702c0…`, cleanup verified),
  identical artifact hash on the second run, proposal v2, task approved (old version refused),
  packet job `6ada9af0…` due 20 s later ran with the client absent, packet
  `212e1e60…` downloadable (10,759 bytes Markdown), task completed, cross-session 404s. VM
  state afterwards: 2 plans, jobs {failed 1, succeeded 3}, tasks {completed 1}, 28 executions,
  0 labelled containers, service active on loopback only, no public ports.
- **Public access.** Public-demo mode extends to experiments (3 plans / 6 runs / 6 tasks /
  3 queued jobs per session, 24-hour due horizon, 200 jobs total, no live mode), tested
  offline and in the browser check. Not activated: the hostname decision and approval of
  docs/public-demo.md remain the exact gap; no ingress, Caddy, DNS or certificate exists.
- Tool rejection: `.env.example` remains untouched by policy; variables are documented in
  README. Nothing was committed, pushed, published or submitted. Video and submission assets
  are pending (walkthrough drafted in docs/demo-walkthrough.md).
- Next concrete actions: (1) owner approval of batch A in
  `.local/live-preflight/proposed-analysis-envelope-2026-11-05.json`, then one local and one VM
  run with `PROOFDESK_ANALYSIS_LIVE_PLAN`; (2) hostname decision and approval of
  docs/public-demo.md for public activation; (3) commit the reviewed working tree on
  `feat/local-execution-slice` and plan the public push; (4) record the video.

## Hackathon phase 2 activation attempt

- Existing VM is in EWR (New Jersey), hostname proofdesk-web, instance metadata id
  113716844. No new VM provisioned. Caddy installed; public-demo and live plans configured
  through root-owned systemd configuration; credentials excluded from release and logs.
- Selected hostname: salesdesk.149.28.51.139.sslip.io, DNS resolves to the existing VM.
- Host firewall permits TCP 80/443, Caddy listens on both, API stays on loopback.
- External connections still time out and ACME validation reports connection timeout.
  Public HTTPS is NOT verified. Owner asked to open the upstream Vultr firewall or locate
  management credentials; only the inference key is configured locally.
- Public URL is pending external ingress, not ready for judges. Subsequent UI work may
  proceed while the external firewall is corrected; activation acceptance remains open.

## Hackathon phase 3

- Analyst badges, two-door vocabulary and Verification disclosures applied; internal
  identifiers and routes preserved. Existing green workspace identity retained.
- Frontend production build passed; 94 backend tests passed with six explicit Docker
  skips. Repository/link check passed. Real HTTP journey on the public-mode Vultr runtime
  passed through SSH forwarding: real Docker statistics, accepted saved replay, stale
  approval refusal, identical artifacts, packet completion while absent and isolation.
  This proves the VM workflow, not external ingress or a browser interaction.

## Hackathon phase 4

- Home now presents the supplied sales-analyst pitch, two entry cards, large dashboard
  numbers, saved campaigns and a working new-plan link. Dataset moved below the fold.
- Production build, backend suite (94, six Docker skips), and real VM HTTP journey passed.
  The journey used public-mode limits and accepted replay with real Docker execution.

## Hackathon phase 5

- Plan tabs reduced to Result, Next move, Verification. Shared Analyst activity derives
  progress from saved job/prospect events, execution records and generation receipts;
  per-step evidence is collapsed. Motion respects reduced-motion preference.
- One approval action creates/reuses a task, binds its version and schedules preparation
  through the existing endpoints. Unsaved edits disable approval. Packet status, timestamp,
  summary and download persist across tabs and reloads.
- Build and 94 backend tests passed (six Docker skips). Real VM HTTP journey passed.
  Disposable browser checks passed: combined approval, dirty edits, reload, three tabs,
  verification, prospect review invalidation, rejected research, mobile overflow, no page
  errors. Updated stale screenshot expectations after first collection failure; corrected
  a test selector that matched both disclosed and collapsed diagnostics.
- Owner reports upstream firewall updated. Public HTTP now responds; certificate retry is
  deferred until the ACME retry window after earlier connection failures. HTTPS pending.

## Hackathon phase 6

- Public sessions initialize one benchmark analysis, example approval/ready packet and
  Harbor Vale prospect with an unsent draft via normal operations and workers. Stable
  operation keys prevent duplicates; seed consumes the existing session quotas.
- Initialization never re-approves visitor edits or revives cancelled work. Example
  approval is labelled. Private mode refuses the endpoint. Public forms expose working
  synthetic-scenario controls rather than disabled real-website controls.
- Build, 96 backend tests (six Docker skips), disposable browser checks, required real
  HTTP journey and a separate real Docker seed journey passed. Seed evidence:
  `.local/live-preflight/phase6-seed-evidence.json`; one plan/run/task/prospect, two jobs,
  accepted replay for analysis and prospect, ready packet, repeat initialization unchanged,
  cross-session 404. Accepted live responses retain Replay labels in new sessions.

## Hackathon phase 7 and public acceptance: 2026-11-05 ET

- Caddy issued a trusted Let's Encrypt certificate after the upstream firewall was opened
  and the issuer's retry window elapsed. External HTTPS home and health now load without
  certificate overrides. Existing VM: EWR, two logical CPUs, about four GiB RAM observed.
- Earlier public verification release archive SHA-256:
  `938b3f0b0e25d0c13c0708fca9cc9593d16dcf916c483e9845959dcfeb61f04d`.
  Archive checksum was verified on the VM before extraction; root-owned model configuration,
  stores, raw dataset, replay cache and all ledgers were preserved. A rollback snapshot exists.
- Public real-HTTP journey passed: genuine Docker analysis, identical result artifacts,
  accepted Replay interpretation, stale approval refusal, scheduled packet completion during
  client absence, Markdown download, review completion and cross-session 404s. Evidence:
  `.local/deployment/final-public-journey.json`.
- Separate public seed check passed: one plan/run/task/prospect, two jobs, example packet
  ready, prospect draft unsent, repeated initialization unchanged, cross-session 404. Both
  analyst contracts used accepted replay. Evidence: `.local/live-preflight/final-public-seed.json`.
- Real public browser check passed from outside the VM: fresh-session seed, charts, edit and
  save, Approve & schedule, close tab, reopen to ready packet, authenticated Markdown download,
  example prospect draft, mobile without horizontal overflow, no page errors. This was the
  public backend, not a mocked API. Screenshots are in `docs/assets/`; browser evidence is
  `.local/live-preflight/live-browser.json`.
- Verification: all 97 backend tests passed with Docker enabled (no skips); frontend build,
  Ruff lint/format, compileall and repository links/patterns passed. Updated disposable-browser
  mocked-API checks also passed. Screenshots were visually inspected on desktop and mobile.
- One verification started during service startup and received temporary HTTP 502; the
  rerun after health was ready passed. Earlier firewall/ACME and harness failures remain
  documented above and are not counted as successful checks.
- Accounting: local hackathon ledger retains 13 requests / $0.0261248 worst-case reservations;
  12 observed responses estimate $0.0039680 token cost. One uncertain reservation remains
  fully counted. Prior exhausted ledger remains $0.0040384 reserved. VM hackathon envelope
  has zero paid reservations: public checks used accepted replay. No new compute provisioned;
  existing VM accrual and credit balance remain owner-managed and unverified against billing.
  Total current + prior reservations: $0.0301632, separate from compute. Owner cap remains $150.
- README now contains the pitch, live URL, try-it, architecture, Vultr roles, analyst design,
  setup, limits and MIT terms. Demo script (2:45), seven-slide outline and LabLab form copy
  are ready in docs. Five real public screenshots support the slide/cover assets.
- Remaining submission work: record/upload video, export/upload slides PDF, paste the form
  and submit by the owner-supplied Nov 8 deadline (target 16:00 ET; deadline 18:00 ET).
  These files do not claim a recording, exported PDF, official submission or receipt.
- Phase commits are local on `feat/local-execution-slice`; no GitHub push is claimed in this
  refactor. Pre-existing session-prompt files and the root screenshot remain untouched.

- Final public-mode correction: Live is now selected without the old public-live opt-in.
  Missing plan/credential produces a visible failed step instead of a rule-based substitute.
  A dedicated regression test confirms this; the final full Docker suite passed 97 tests.
  Pending approval in the activity trace now respects the current next-move version.

## Final deployment receipt

- Runtime commit: `38e687e`; release archive SHA-256
  `b93be2f59fcd40a5488c48439a1da650efc12de3f35ccc186dcd70134b2efad9`.
  VM checksum verified before extraction. The obsolete public-live opt-in was removed
  from service configuration; health still reports public demo and Live mode.
- The complete public HTTP journey, idempotent seed/isolation check and real public
  browser close/reopen/download check passed again on this final runtime. Evidence:
  `.local/deployment/final-default-live-public-journey.json`,
  `.local/live-preflight/final-public-seed.json`, and
  `.local/live-preflight/live-browser.json`. Refreshed real screenshots are in docs/assets.
- Final backend suite: 97 tests passed with Docker enabled. Frontend build, mocked browser,
  lint, format, compile and repository content/link checks passed. No safety validator,
  sandbox limit, SSRF check, quota or approval binding was relaxed.
- No final GitHub push, video recording, PDF export or official submission is claimed.

## Presentation refresh, steps 1–4: 2026-11-05 ET

- Merged the local execution branch into main and pushed with owner authorization.
  GitHub main's README was fetched unauthenticated and verified to show SalesDesk and
  https://salesdesk.149.28.51.139.sslip.io. Merge: `bafd7cc`.
- Analyst badges and the home tile now name Qwen 3.8 on Vultr Inference; cached responses
  disclose that provenance in tooltips and Verification. Rule-based and failed states
  remain separate. Plan content follows activity, result, next move, then packet; the
  packet leads with its approved summary/download and collapses missing launch inputs.
- Analysis prompt only: opening takeaway, recommended next move, detailed reading; caveats
  in Unknowns / Alternative explanations. Final accepted live response and replay passed
  the unchanged contract. Request SHA-256:
  `01e4acb4098e62f02f18790f3f6acb012a884ab271b23866da516a90456fa980`.
  Accepted cache installed on the VM for the new prompt; runtime deployment follows step 9.
- This step used 10 paid requests ($0.020096 worst-case reservations; $0.0051333 estimated
  usage). Intermediate failures: unsupported quantities and forbidden outcome wording;
  four later pre-dispatch input-size refusals made no paid reservation. Prompt shortened
  within the existing input cap. Failed reservations retained; no ledger reset.
- Local aggregate envelope now 23 requests / $0.0462208 reservations. Prior exhausted
  approval remains $0.0040384. Combined reserved $0.0502592, separate from VM compute.
  Observed usage total including prior checkpoint: $0.0091013, with the old uncertain
  reservation still counted in full. This is token accounting, not account billing.
- Frontend builds after steps 2–3 and replay regression checks passed. Validator, replay
  dispatch mechanism, sandbox policy, source rules and approval bindings are unchanged.


## Presentation refresh, steps 5–9 and public acceptance: 2026-11-05 ET

- Step 5 (`8d0bbcc`): metric references, exploratory breakdowns and the retrospective
  badge moved into Verification. The home disclaimer sentence remains in README only.
- Step 6 (`21cda1c`): activity is a single vertical column, preserving steps and disclosures.
- Step 7 (`85ef769`): outreach/brief currency displays as $16.00. Stored evidence and
  draft bytes/hashes are preserved; formatting alone does not create an unsaved edit.
- Step 8 (`2457e61`): slides cite Salesforce's seventh State of Sales and its 2026 report
  announcement for sales workload/capacity evidence. Cost slide uses explicitly assumed
  team-hours; inference cost moved to architecture; Hillstrom result moved to the demo.
  Slide 6 reports 18.38 seconds measured in SalesDesk's own recorded workflow, with exact
  timestamps and scope in docs/workflow-measurement.json. Submission title and script
  match owner copy; the script uses a fresh Womens comparison and a longer close/reopen beat.
- Step 9: redeployed the allowlisted release on the existing Vultr VM, retaining all
  .local records, accepted caches, budget ledgers and root-owned service configuration.
  Final archive SHA-256: `436fb9ac0b6baf4f556591e746c3564a6405768e38d43ce448475c667bb01789`.
  Verified archive checksum and every installed manifest file hash (67 files). A rollback
  snapshot exists. The final visual fix keeps the longer Qwen badge inside the sidebar.
- Final public HTTP journey passed on this release: genuine Docker statistics,
  reproducible artifact bytes, stale-version approval refusal, packet preparation while
  absent, Markdown download, review completion and cross-session 404s. Evidence:
  .local/deployment/presentation-final-public-journey.json.
- Fresh external Chromium session passed without TLS exceptions: refreshed seed cache
  identity, Qwen/cached tooltip, requested content order, hidden technical details,
  closed launch-input disclosure, vertical activity, new Womens E-Mail vs No E-Mail live
  inference, dirty-edit refusal, exact-version approval, packet completion while closed,
  reopen/download, $16.00 outreach, and desktop/mobile without overflow or page errors.
  Final live plan: `452be24f88c34fadac0978f8289f8ba9`. It passed on its first run.
  Tab closed at 2026-11-06T03:34:56.742Z, packet ready at 2026-11-06T03:36:01.402263+00:00,
  reopened at 2026-11-06T03:36:06.851Z. Evidence: .local/live-preflight/live-browser.json
  and .local/deployment/presentation-public-acceptance.json. All five docs/assets images
  were retaken from this release; desktop/mobile and result/outreach layouts inspected.
- Full suite passed before release and after the initial public screenshots: 97 backend
  tests with Docker enabled, no skips; frontend build, locked sync, Ruff lint/format,
  compileall, publication/local-link checks and disposable mocked-browser checks passed.
  Final post-screenshot suite also passed all 97 tests with Docker enabled, no skips
  (.local/step9-final-full-suite.log); final build, lint, format, compile, locked sync
  and repository checks passed. Latest mocked-browser evidence is
  .local/step9-final-mocked-browser.log.
- Corrected verification harness issues: an initial health assertion expected "ok" while
  the existing health contract returns "experiment_workspace" (HTTP 200); a browser
  timestamp with seconds was refused by Playwright's datetime-local fill. The corrected
  minute-precision scheduling input passed. These failures are not counted as passes.
- Three fresh VM Womens responses passed the unchanged contract, including the final
  screenshot run. VM reservations: 3 / $0.0060288; estimated token usage $0.0015611.
  This presentation task added 13 paid requests across local/VM: $0.0261248 reserved,
  $0.0066944 estimated usage. Total current+prior reservations across local/VM now
  $0.0562880; hackathon observed usage estimate $0.0106624. Prior uncertain reservation
  remains fully counted. No new compute, budget-limit expansion or ledger reset; these
  are token estimates, separate from account/compute billing and the owner's $150 cap.
- Source comparison against the step-1 merge confirms every execution/sandbox file,
  validator, provider/replay mechanism, service/store/job state rule and approval binding
  is unchanged. Backend changes are confined to the analysis SYSTEM prompt.
- Untracked docs/session-prompts/ and screenshot-2026-11-05.png remain untouched. The
  video script is prepared and its live journey rehearsed; no narrated recording, PDF
  export or official hackathon submission/receipt is claimed.


## Compact demo presentation: 2026-11-06

- Frontend only: campaign answer hero with two large purchase rates, a single existing
  approval/download slot, purchase bar chart, collapsed full analysis, a five-line Next
  move summary with Edit/Advanced, and a compact activity stepper. Active jobs expand
  activity and completion collapses it. Raw evidence/ids/hashes live in Verification.
- Prospect defaults to the draft, with Approve draft (same exact-version review), an
  excerpt, collapsed full editable draft and source list. Save appears only for edits;
  Copy/Download are ghost actions. Research and Demonstration retain their full content
  on demand; examples have one small Example badge.
- Home retains hero, two door cards and stats, with one filled action. Campaign list and
  footers/sidebar Interpretation removed. The one Verification link opens source context
  in a dialog, rather than a home-page disclosure. The sidebar retains saved analyses and
  a New analysis plan link. Full wording is retained in README and Verification.
- Build and updated disposable-browser checks passed at 1440×900, including one primary
  action above fold, dirty-edit refusal, saved approval/download across reloads, exact-version
  draft review/invalidation, Advanced, full analysis, receipt access and mobile overflow.
- Backend diff is empty. No validators/contracts, sandbox rules, jobs, replay, schema,
  approval bindings or stored-data semantics changed. The existing campaign approval and
  draft-review request handlers were compared with the starting commit byte for byte.
  Only normal operations in fresh isolated verification sessions created demo records.
- Public before heights: home 900 px; campaign before approval 4,048 px; after approval
  4,366 px; prospect 1,452 px. New frontend preview heights: 900 / 1,037 / 1,078 / 900 px.
  All four primary actions are visible in the first 900 px. Exact bounds and screenshot
  hashes are in docs/assets/readability-measurements.json; new images use readability-*.png.
- Deployment blocker: SCP/SSH to the documented VM timed out on port 22. Repeated bounded
  SSH checks also timed out. No installation or restart is claimed. Owner asked for the
  current SSH endpoint or restored SSH access; authorization to deploy/push already exists.
- Prepared release archive SHA-256:
  `cc3bbbe06cace1365ee9076187f1c640cf331e17eb0dd4f9dd8c0d82755ad997` (67 files).
  Existing deployed salesdesk-*.png screenshots are preserved. The new screenshots are
  explicitly labelled as real-backend integration previews with local frontend overrides,
  not as an observed deployment. No API responses, origin headers or cookies were mocked
  in this preview; baseline and new measurements used the same normal benchmark comparison.
- Existing public HTTP journey passed, with real Docker analysis, identical artifacts,
  stale approval refusal, scheduled packet completion, downloads and cross-session 404s:
  .local/demo-readability/public-journey.json. A direct new-UI browser check against the
  still-old deployed assets failed its expected single-primary assertion; it is not counted
  as acceptance. Real-backend preview passed in .local/demo-readability/preview/measurements.json.
- Early local browser failures corrected before final checks: lifted dirty-edit state
  needed synchronous notification to disable approval immediately, and the mock task fixture
  copied an old proposal hash instead of matching the existing API's current proposal hash.
  These corrections did not change backend authorization or approval rules.
- Analysis/prospect checks used accepted caches; no new paid calls or budget changes were
  required. Last recorded reservations remain $0.0562880 across current/prior local/VM
  approvals, separate from compute billing. No provisioning or ledger reset.
- Remaining: restore SSH, install/checksum/verify the release, take direct deployed browser
  screenshots and rerun the journey on that release. Untracked session prompts and the root
  screenshot remain untouched. Do not describe the new UI as live until verified.


## Compact UI deployment retry succeeded: 2026-11-06

- SSH worked on the owner's retry request. Rebuilt the committed source `ecf3714`,
  uploaded the allowlisted archive, verified its checksum and all 67 installed file hashes,
  took a rollback snapshot, resynced locked runtime dependencies and restarted proofdesk.
  Stores, raw dataset, caches, budget ledgers and root-owned configuration were preserved.
- Release archive SHA-256:
  `27c29612c0933663f7176836ec0d69b24e259c645ae5603881819f1981e72c4c`.
  HTTPS health reports public demo/live analyst mode; runtime source is
  `ecf37140d07994d4930e84f701a41a1b57729554`.
- Fresh external Chromium acceptance passed directly against the deployed URL, with no
  local asset overrides, mocked API responses or TLS exceptions. Verified one filled
  primary action above fold; answer and rates; compact/active/completed stepper behavior;
  preparation → ready/download in the answer card; collapsed analysis and supporting
  inputs; reload and download; editing removes the prior packet from the current approval
  slot; exact-version draft review and invalidation; Research/Demonstration/Verification;
  and desktop/mobile without horizontal overflow or page errors.
- Direct deployed heights at 1440×900: home 900 px;
  campaign before approval 1037 px;
  campaign after approval 1078 px;
  prospect 900 px. Before heights were
  900 / 4,048 / 4,366 / 1,452 px. All primary actions are visible without scrolling.
- Updated both readability-*.png and canonical salesdesk-*.png screenshots in docs/assets
  from the direct deployed browser. Receipt: docs/assets/readability-measurements.json.
  Browser evidence: .local/demo-readability/final/measurements.json. The former preview
  documentation is updated to distinguish this direct public acceptance from the earlier
  local-asset preview and the resolved SSH blocker.
- Real HTTP journey passed again on this release: genuine Docker statistics, identical
  artifacts on rerun, refusal of an old approval version, scheduled packet completion,
  Markdown download, review completion and cross-session 404s. Evidence:
  .local/demo-readability/deployed-journey.json. Build passed on retry; the unchanged
  frontend's mocked-browser suite had already passed before deployment.
- No application/backend changes in this retry; no validators, contracts, jobs, sandbox,
  replay, approval binding, quotas, budgets or saved-data semantics changed. Verification
  used normal fresh demo sessions and accepted caches; no new paid requests were needed.
  The deployment blocker is resolved. Untracked session prompts and root screenshot remain
  untouched. Narrated recording, slide PDF and official submission remain outstanding.

## Dealer-group rebuild: steps 0–3, 2026-11-06

- Working repository located at `/Users/justin/Desktop/Projects/proofdesk` (SalesDesk
  remote); the session initially opened the unrelated SoloForge workspace. No SoloForge
  files changed. Existing untracked owner prompts and screenshot preserved.
- Direction and data boundaries committed; synthetic generator produces 24 rooftops,
  3,000 units, 9,000 open leads, 2,400 historical leads and exactly 600 cold leads.
- CSV ingestion: UTF-8 CSVs, 10 MiB/file, 50,000 rows, header synonyms, bounded errors,
  typed validation, cross-file rooftop references and session-scoped staging. Raw exports
  never enter model requests; templates are downloadable.
- Parallel jobs reuse the existing SQLite lease operations and scheduler. Configured
  concurrency defaults to six. Parent roll-up waits for terminal children. Per-job Docker
  namespaces preserve abandoned-container refusal without serializing sibling jobs.
  Limits remain unchanged: 128 MiB/container, half CPU, no network/host mounts/credentials,
  30 s analysis deadline, 1 MiB typed input, 16 KiB result artifact.
- Observed local full review: **16.223 s**, peak **6 concurrent children**, all 24
  succeeded; current and prior-night snapshots used 48 cleaned disposable sandboxes.
  Evidence: ignored `.local/dealer-acceptance/acceptance.json` and execution records.
  This run used labelled deterministic interpretation; no inference requests.
- Sandy Docker acceptance confirms Maria G. ranks first and S00138 (silver RAV4 Hybrid
  XLE, 74 days) is the best match. Tampered KPI output is refused by reconciliation.
- Backend suite, frontend build and existing disposable browser checks passed after
  steps 0, 1, 2 and 3. Step 3 adds opt-in real Docker tests (passed). New dealer browser
  screens, live contracts and deployment acceptance are still pending at this checkpoint.
- Step 4 resource plan within the existing $150 authorization: reuse the running VM;
  add a bounded dealer inference envelope of $0.15, 64 requests and 1,048,576 reserved
  tokens, with separate six-request plans per rooftop/group. Existing ledgers stay intact.
  Authenticated model catalog checked 2026-11-06: qwen3.8-flash-next, $0.10 input and
  $0.20 output per million tokens; JSON output, reasoning disabled. No new VM/paid service.

## Dealer analyst live acceptance: step 4, 2026-11-06

- Both new Qwen contracts accepted live for the full sample: **24 rooftop briefs and
  one group brief**. Maria's follow-up uses the matched silver RAV4 facts and her CR-V
  trade through controller-rendered placeholders. Only curated validated facts/metrics
  enter inference, never uploaded raw rows, notes, contact details or salesperson names.
- Prompt pass 1 accepted 20 rooftops and rejected four findings for written quantities.
  Prompt pass 2 supplied safe finding patterns; all 24 rooftops and the group passed.
  Validators were not relaxed. Rejected response contents were neither saved nor executed.
- Accounting: **49 live requests**, **45 accepted responses**, **4 rejected requests**;
  accepted provider usage totals **$0.0132054 estimated token cost**. Four rejected-call
  usage receipts were overwritten by the initial operator harness; they are accounted
  pessimistically at **$0.0080384**, giving **$0.0212438** accepted-plus-uncertain estimate.
  All 49 reservations remain charged: **$0.0984704** under the new $0.15 envelope.
  Token estimates are separate from account compute billing. The harness now retains a
  unique attempt receipt directory; exhausted ledgers were never reset or reused.
- Accepted exact-input responses are in ignored `.local/replays/`; the complete accepted
  sample review is in `.local/dealer-sample-review.json`. These are actual Docker metrics
  and live inference responses, not fabricated progress or fixture model outputs.
- Contract tests cover unknown leads/stock/metric references, literal quantities,
  unsupported features and sends. Backend suite, frontend build and browser checks passed
  at the step 4 checkpoint. Deployment replay verification remains to be performed.

## Dealer approvals and recurrence: step 5, 2026-11-06

- Ranked follow-ups materialize from accepted results. Qwen drafts cover the top leads;
  remaining leads use explicit controller-template provenance. A failed live brief never
  silently becomes a rule-based response.
- Approve/all binds draft hash, version and immutable lead/unit snapshot. Editing message
  text clears approval; preparation and every download recheck the exact versions.
  Per-store durable worker output includes follow-ups.md, crm-tasks.csv (today's task due
  date) and transfer-requests.csv. CSV formula cells are escaped. Nothing is sent.
- The API scheduler dispatches recurring 2 AM America/Denver reviews. The next due time is
  recomputed after a run, with session expiry and run quotas. Saved review snapshots supply
  subsequent deltas. Nightly scheduling continues when the browser is closed.
- Handoff tests passed: task generation, exact-version refusal after edit, cross-session
  access refusal, formula escaping and Mountain Time recurrence. Backend suite, frontend
  build and retained browser check passed at this checkpoint; new dealer UI is in progress.
- Group screen acceptance: direct local browser against the real API (no mocks or asset
  overrides) passed at 1440×900: hero, real stat strip, regional SVG map and first tile row
  above the fold; 24 tiles; exactly one primary action. Mobile has no horizontal overflow
  or page errors. Screenshots are in ignored `.local/dealer-browser/` pending deployment.
- Store/lead UI acceptance: direct local browser passed for Sandy. Header, four KPI
  values and first two follow-up cards fit 1440×900. Maria's drawer shows the sold blue
  RAV4, CR-V trade, silver 74-day match, three scored candidates and message previews.
  Mobile has no overflow or page errors. Existing campaign/prospect browser tests also
  pass through retained unlinked routes. A local HTTP request-id issue was fixed with
  crypto.getRandomValues; strict session initialization now shares one bootstrap request.
- Full local direct-browser acceptance passed: actual 24-child review (15.382 s measured
  from browser click to visible group result), real mid-progress screenshot, Sandy/Maria,
  approve all, three downloads, reload, cross-session refusal, recurring toggle persistence,
  data templates and validation, desktop/mobile without page errors. No mocked API or
  asset overrides. Evidence: `.local/dealer-browser-journey-final/dealer-browser-check.json`.
- Group briefing input now sorts rooftop ties by id before serialization. Canonicalizing
  these inputs required additional accepted group requests; final accounting follows the
  deployment check. All rooftop replay requests remained exact matches.

## Public dealer deployment acceptance: 2026-11-06

- Runtime `ca5b45d` deployed to the existing Vultr VM. Release SHA-256
  `c3fa60c6b14619c5a4eea47ce1efdde8107f6b653a83e75e4447b12c21aba07f`;
  all 85 runtime files verified on the VM. Rollback snapshot retained. Existing stores,
  root-owned credentials, Caddy configuration and exhausted budget ledgers preserved.
- Direct external Chromium acceptance passed on public HTTPS, without mocks, local asset
  overrides or TLS exceptions. All 24 child jobs succeeded, group roll-up succeeded and
  Sandy's approved handoff succeeded. Three exports downloaded; reload, cross-session
  refusal, schedule persistence, template links and mobile checks passed.
- **Measured full-run wall-clock: 108.396 s** from browser click to visible group result.
  Child execution span was 104.844237 s; the roll-up worker took 1.004630 s. This run
  actually executed current and prior-night analyses on Vultr; inference used accepted
  exact-input replay, revalidated through the unchanged contracts.
- Observed VM: 2 CPUs, 3,910 MiB reported RAM (nominal 4 GiB), EWR/New Jersey. Peak
  concurrent rooftop jobs **6**; observed application cgroup peak **581.55 MiB**; minimum
  available host memory **2,755.46 MiB** during acceptance. Service cap raised to 1.5 GiB;
  individual Docker limits remain 128 MiB and half CPU. No new compute provisioned.
- Screens captured directly from deployment: Group, real live run, Sandy store, Maria
  drawer, downloads and mobile. Evidence: `.local/dealer-public-acceptance/` plus
  `.local/deployment/dealer-vm-monitor.json`.
- Final review adds a per-run clock for recurrence (uploaded source timestamps stay fixed;
  inventory age advances; sample dates move together) and explicit Qwen/template/human-edit
  draft labels. These refinements passed 108 backend tests (7 opt-in skips); real Sandy
  Docker and clock tests passed separately. A final release and public recheck follow.
- Final dealer inference accounting: **51 live requests**, **47 accepted unique responses**,
  four rejected requests with uncertain usage retained pessimistically. Accepted reported
  usage estimates **$0.0143516**; uncertainty allowance **$0.0080384**; combined estimate
  **$0.0223900**. Durable reservations total **$0.1024896**, separate from prior engine
  envelopes and compute billing. `scripts/dealer_accounting.py` audits these read-only.
  The first deployed full run produced **25 saved_replay receipts, zero failures and zero
  fresh paid requests**. No ledger was reset. Existing VM billing/credit balance remains
  unverified against an account billing API.
- Final edge-case checks: new source assumptions hide incompatible saved sample numbers
  until a fresh run; approvals bind the source-data hash; re-exporting an edited draft keeps
  the other still-approved tasks from that review. Synthetic exports identify their data
  label. Never-contacted imported leads use creation time. Recoverable gross includes
  negative listed margins rather than silently flooring them at zero. Sample metrics and
  accepted model inputs remain unchanged. Timeline ages use the saved review's reference.
- Full opt-in Docker suite passed: **110 tests, no skips**. The added never-contacted
  ingestion case also passed in the final offline suite: **111 tests, 7 opt-in skips**.
  Frontend production build, retained mocked-browser journey, Ruff/formatting and repository
  checks passed. Final public release acceptance is recorded next.


## Final dealer release verified: 2026-11-06

- Release `a5fc406` installed; all 85 runtime hashes verified. Runtime archive SHA-256:
  `81f1215546665adb8d56637a317d802c91913d3f2dc4b0d6251729317627a9a0`.
  Private auxiliary archive SHA-256:
  `d03cae6250c1accc11a1ced5cd5a3ff909f8df3e72b5dba14d92164382fdd4d0`.
  Existing records/credentials/ledgers preserved; saved sample now binds entered assumptions.
- Final direct external HTTPS browser journey passed: **119.419 seconds** from Run click
  to visible group brief. All 24 rooftop jobs and the parent succeeded; current/prior
  snapshots really executed in Docker on Vultr. Sandy/Maria, exact approvals, three
  downloads, reload, cross-session refusal, persisted schedule and mobile all passed.
- Peak concurrent children **6**; observed controller/worker peak **641.59 MiB**; minimum
  available VM RAM **2,682.91 MiB**. The unchanged per-container caps held on the existing
  2-CPU / nominal 4-GiB EWR VM. No new instance or service was provisioned.
- Public captures refreshed: Group, live run, Sandy, Maria, downloads, mobile. Final
  evidence: `.local/dealer-final-public/` and `.local/deployment/dealer-final-vm-monitor.json`.
  Test schedule was disabled after proving persistence; owner schedules are not needed
  for acceptance. Runtime flags retain the legacy health status for compatibility and
  separately report `product_surface=dealer_group_workspace` and concurrency six.
- No paid requests in the deployed full reviews; all inference steps revalidated exact
  accepted replay. Dealer accounting remains 51 live requests, 47 accepted responses,
  four rejected/uncertain calls, $0.0143516 accepted usage plus $0.0080384 uncertainty,
  $0.0223900 conservative estimate and $0.1024896 pessimistic reservations.
- A final UI regression check covers re-preparing the remaining approved store queue
  after skipping an already approved item. This only changes approval-action availability,
  not the measured analysis engine or matching results.

## Shipped handoff and final receipts: 2026-11-06 ET

- Final runtime: **3307d43ecdb8235ba7c25c01c5546f6b362ac3d9**, archive SHA-256
  **1a8572e06e4af2bdf60554f35b91c145741045579806c8047a01f370ba2e09ff**;
  all 85 installed runtime file hashes verified. A transient SSH timeout on the last UI
  update resolved on retry; the public service is active and there is no deployment blocker.
- Direct public acceptance passed on that final UI, without mocks, asset overrides or TLS
  exceptions: group/map/first tile row, Sandy's first two cards, Maria and score breakdown,
  approve-all exports, reload, cross-session refusal, skip-after-approval and fresh export,
  schedule persistence/cleanup, templates, store navigation from the bottom of the grid,
  and mobile without overflow or page errors. Transit status and absent contact facts
  are shown explicitly. Earlier full run **119.419 s** used the same unchanged backend.
- Final backend suite: **112 tests, 7 opt-in skips**, passed. The full opt-in Docker suite
  passed separately (110 tests, no skips). Production frontend build, retained legacy UI
  browser checks, Ruff, formatting, compilation and publication checks passed. Seed
  regeneration now matches all five committed data files; the added test verifies it.
- Final VM audit at 00:49 UTC November 7 (November 6 ET): **50 saved_replay receipts**,
  **zero failed inference receipts**, **zero new paid VM requests**; dealer reservations
  remain **51 / $0.1024896**. Conservative token-cost estimate remains **$0.0223900**,
  including the four uncertain rejected calls. Compute billing remains separate.
- Canonical screenshots are refreshed in docs/assets: Group, real live run, store, Maria,
  downloads and mobile. `dealer-release-evidence.json` records their hashes and separates
  the measured full-run capture from the final UI captures; `dealer-handoff-check.json`,
  `dealer-runtime-check.json` and `dealer-inference-accounting.json` contain sanitized receipts.
- The older operator test schedule was disabled by its captured job identity; newer browser
  tests disable their own schedule after proving persistence. Unrelated owner records,
  raw historical dataset, keys, ledgers and the pre-existing untracked session prompts/root
  screenshot remain untouched. Local live acceptance stopped before VM spend authority moved.
- README, architecture, inference/deployment/public-demo/provenance docs, sourced slides,
  2:45 demo script and submission copy describe the dealer product. All changes are committed
  and pushed to main. **Owner actions:** record the narrated video, export slides as PDF,
  verify the final LabLab form and submit. Nothing has been submitted; no receipt exists.

## Video preparation, source fixes: 2026-11-06 ET

- Camera-readiness source changes vary the fictional store contact/sold-interest records:
  12–85 at risk per rooftop, 1,050 group total, 652 cold. Sandy's original 40-lead queue,
  Maria, inventory, match rules and sandbox limits are preserved. Counts are not capped.
- Group brief inputs now explain the metric denominators and use `matched_in_stock` for
  the in-stock finding, matching the dashboard. Old replay inputs no longer match.
- Focused fixture/contract checks passed (six); offline suite passed (113, seven opt-in
  skips before the additional source-variation check). Frontend production build passed.
  A concurrent broad Docker check encountered the controller's exclusive lock; a serial
  containment recheck is in progress. No validator or execution policy was weakened.
- A separate bounded video inference envelope ($0.15 / 64 requests, six per plan) was
  prepared under the existing $150 hackathon authorization for the requested complete
  live measurement. Original plans and all durable ledgers remain unchanged. Provider
  catalog authenticated successfully: $0.10 input / $0.20 output per million tokens.
- Deployment, refreshed sample acceptance, public measurements and video assets follow.

## Video camera fixes, live acceptance: 2026-11-06 ET

- Runtime `4bf709e` deployed to public HTTPS; archive SHA-256
  `268f5c6a37414c321591bb2dd351b90c539676082eb284ea0acb30b4edd1593d`,
  all 85 runtime file hashes verified. Rollback and original sample/ledgers preserved.
- Fresh public full run succeeded: 24 child jobs plus group roll-up, **25 live Qwen
  responses / zero replay / zero failed briefs**. Six real stores entered running state
  in the first 20 seconds. Final result capture completed **140.131 s** after Run click;
  this includes final API/render/screenshot overhead, not just server compute.
- Final stat strip: **9,000 leads reviewed / 1,050 at risk / 1,007 best matches in stock /
  792 distinct aged units matched / $3,434,800 estimated recoverable gross** (UI $3.4M).
  Store risks range 12–85. Sandy is 40. No queue cap exists. Updated accepted sample
  installed separately; fresh public sessions open it on Group view with Run available.
- Group brief now says **1,007 at-risk leads have a best match in stock**, matching the
  stat strip. The 1,050 wider count includes in-transit best matches. All contracts,
  sandbox limits, exact-version approvals and replay labelling are unchanged.
- Actual complete-run live inference: **$0.0077789**, calculated from the 25 provider
  usage receipts at authenticated catalog rates ($0.10 input / $0.20 output per million).
  Say **“under one cent a run”**, replacing “a few cents.” This excludes VM compute and
  is a token-cost calculation, not a provider billing receipt. Durable reservations
  remain pessimistic and are never refunded/reset. Prior aggregate $0.0223900 includes
  unrelated debugging/uncertain calls; it was not the cost of one complete run.
- Maria remains: enquiry nine days earlier, contact seven days earlier, blue unit sold
  six days earlier; silver 2024 RAV4 Hybrid XLE, S00138, 74 days, $32,900, score 98;
  2017 Honda CR-V trade. Video copy now calls carrying cost an entered assumption and
  makes explicit that SalesDesk prepares drafts/tasks and sends no customer messages.
- Offline checks: 113 passed/discovered with seven opt-in skips; focused fixture/contract
  suite six passed after adding source-variation coverage. Broad Docker run had lock
  contention; isolated rerun passed signals/recovery and reuse, but filesystem probe
  exceeded its unchanged deadline. This is a failed local containment check, not a pass.
  Dealer's real Docker reconciliation/cleanup passed; public full execution passed.
- Evidence: `docs/video/measured-run.json` has metrics, Maria and 25 inference receipts;
  private raw browser/job observations remain under `.local/video-prep/`. No credentials
  or session cookies enter published video artifacts.


## Scripted public scene takes verified: 2026-11-06 ET

- Camera label runtime `61efa5c` deployed, all 85 file hashes verified, archive SHA-256
  `63efc9eba33c3fd41698340b029cf921a50f37faa0a8bf574dd41b59be7ca653`.
  Main header stays visible while scrolling; the actual data label is also inside Maria's
  drawer. No validators, model permissions, sandbox caps or approval bindings changed.
- Recorded all requested app scenes at 1440×900, deviceScaleFactor 2, using a single fresh
  public context; eight H.264/30fps MP4s include the genuine CSV export preview. All 33
  choreography stills are 2880×1800. The injected pointer is visible, smoothly moved and
  checked before each shot; no app text, API response, progress or value is overridden.
- Final take: completion observed **121.290 s**, finished Group
  visible **124.177 s**. All 24 stores succeeded with identical final
  metrics; Qwen output is accepted exact-input replay. Narration and the labelled jump-cut
  card disclose that fact and use the recorded take's measured time. Separate full-live
  measurement remains 140.131 s / 25 fresh responses / $0.0077789 token cost.
- Fresh saved Group, Run availability, real counter reset, six analysing tiles, Sandy/Maria,
  40 approved task rows, byte-identical real download, cross-session refusal, and schedule
  persistence after tab close passed. Test schedules were disabled using their own identity.
  Final browser reported no page errors.
- Earlier recorder attempts exposed a CSP-incompatible wait expression and an uninvoked
  pointer initializer. Fixed the recorder without relaxing CSP, verified pointer dimensions,
  and re-recorded the entire journey. Published takes are the corrected final pass.
- CSV backup shows the unchanged downloaded bytes in a plain-text browser viewer. Native
  spreadsheet and browser-chrome close-gesture re-takes remain optional. Schedule closes
  its page at eight seconds and holds the real final frame to fill its 12-second slot.
- Latest offline suite: **114 tests, seven opt-in skips**, passed. Lint/format passed.
  The earlier local filesystem Docker probe timeout remains disclosed, not relabelled a pass.
- `docs/video/scene-manifest.json`, `recorded-run.json` and `inference-accounting.json`
  identify captures and the read-only 25-request / $0.0502400 durable reservation audit.
  The stat strip displays full **$3,434,800**; narration rounds to **$3.4 million**.


## Timed rough cut verified: 2026-11-06 ET

- Exported `rough-cut.mp4` (burned captions) and `rough-cut-nosubs.mp4`, both exactly
  **180.000 seconds**, 1920×1080, H.264, 30 fps, one video stream and no audio.
- All app footage is actual public output at normal speed. The full-run shortening is
  visibly labelled with the recorded 124.177-second time and accepted-Qwen-replay
  disclosure. No numbers or progress were composited onto the app.
- The edit follows the supplied slot boundaries, with 0.4-second card crossfades, black
  opening/closing fades, gentle opening zoom, stat/drawer punch-ins, and an eight-second
  hold on the completed architecture after its initial one-step-per-second build.
- The Group cursor sweep was re-taken against the exact same completed review to align
  risk, stock, aged-unit and gross narration. No new review or inference was triggered.
  The CSV plays at 2:06–2:09, followed by three seconds back on the real Ready state.
- Inter SemiBold captions are styled on a 1920×1080 ASS canvas, 42 px, white, 60% dark
  box, bottom center. The ASS is derived from the 39 SRT cues. Narration and caption
  words match after punctuation/spacing normalization. Voice audio is intentionally absent.
- Thirteen 1920×1080 PNG cards include transparent/composited titles, jump cut, before/after,
  full architecture plus seven builds, and end card. The eight-page PDF was rendered
  and visually checked; Inter loaded successfully, with included OFL font licenses.
- Media properties passed ffprobe assertions. Visual samples across the app, title, jump
  cut, stat strip, Maria, export, Ready, schedule and slides were inspected. Evidence is
  in `rough-cut-check.json`; source takes and all 33 2x stills remain available for editing.


## Video owner hand-off complete: 2026-11-06 ET

- `docs/video/RECORDING.md` contains the clean final narration, voiceover workflow, exact
  start states for optional Screen Studio takes, current facts and pre-export checklist.
  `narration.txt` is the plain-text read. `ARTIFACTS.md` indexes every deliverable;
  `artifact-manifest.json` records sizes and SHA-256 hashes for the prepared kit.
- Final public fresh-session check passed again: saved Group results, Run available,
  correct metrics, preserved Maria and the sample label inside the actual drawer.
- README, deployment, acceptance, public-demo and inference docs now describe the
  observed camera fixes, separate full-live cost and recorded replay-based take.
- Both final MP4s are 180.000 seconds, silent, H.264, 1920×1080, 30 fps. The architecture
  reveals six successive steps over six seconds and holds the completed seventh build
  for eight seconds. CSV/Ready positions match the supplied plan. The eight-page PDF
  and all 13 cards use the actual app palette, logo and locally loaded Inter fonts.
- The final script and all 39 subtitle cues have identical normalized words. There is
  no recorded voice track. The owner must record VO, align the final edit/captions,
  optionally re-take the hero/export/tab-close scenes, upload video and slide PDF, and
  submit by the owner's **Nov 8, 16:00 ET target**, ahead of the supplied 18:00 ET deadline.
- Official event page requires video but did not state a length limit in the checked
  content. General LabLab guidance recommends under five minutes / up to 300 MB; the
  event form prevails. Its signed-in limit remains **unconfirmed**, explicitly left on
  the pre-export checklist. No submission was made and no receipt is claimed.
- The separate pre-existing recording-plan work and session notes remain untouched.

## SalesDesk video v2 and per-store trace: 2026-11-06 ET

- Shipped the compact seven-step Agent trace. Group tiles open stores during running
  child jobs; rows read only the corresponding leased child's events and reconciled
  outputs. No staged delays, relaxed validators, changed sandbox bounds, approval
  binding changes or replay-label changes. Final runtime release: 1c2cf6b; all 85
  deployed file hashes verified after deployment.
- Offline suite: 114 tests, seven optional Docker skips, all executed tests passed.
  Three dealer job tests passed with Docker enabled, including real Sandy execution,
  cleanup, trace/event agreement and rejection of tampered counts/scores. Frontend
  build, Ruff, formatting and repository checks passed. Public 390px viewport had
  seven completed trace rows and no horizontal overflow.
- Two public runs completed successfully: initial trace verification 138.317 seconds;
  final recorded run 124.758 seconds. Each reused 25 accepted Qwen responses, with
  zero new inference calls / $0 new inference usage. No ledgers reset, no new compute
  provisioned; VM accrual remains distinct and unverified against billing.
- Final facts: 1,050 risk leads, 1,007 in-stock best matches, 792 distinct aged units,
  $3,434,800 estimated gross. Sandy: 375 open, 40 risk, 25 cold; 117 local and 1,638
  nearby sister-store cars; 70,200 scored pairs, top store score 100, 40 drafts with
  three Qwen-authored follow-ups. Maria remains 98 / 74 days / 2017 CR-V trade.
- Narration removes the unsupported call-count claim, replaces “two minutes” with
  “two minutes, five seconds”, states three Qwen follow-ups and drops the night-cost
  claim. The 34 SRT cues match the clean VO script; no disclaimers in either.
- Both exports are exactly 165.000 seconds, 1920x1080, 30fps, H.264 and silent.
  Animated HTML/Playwright cards, four chapter titles, real public scene takes, 2x
  stills, 14 review frames and v2-contact.png are committed. Maria's SMS has a
  12-second caption-free hold. Actual UI score 98 is preserved rather than fabricated
  count-up animation. Tight crops retain the app's actual sample badge in the border.
- RECORDING.md supplies the clean VO, retiming, optional Screen Studio retakes and
  pre-export checklist. V1 hand-off is archived. Owner still records voice, finishes
  the edit, confirms the signed-in LabLab length limit, uploads and submits by the
  Nov 8 16:00 ET target. Public event content gives no length limit; general guide
  pages failed to load. No submission or receipt is claimed.

## SalesDesk video v3: public UI and full-frame recording (2026-11-06 ET)

- Raised dealer UI text to 13 px minimum and desktop trace rows to 15 px. Compact
  spacing, collapsed running map and smaller idle map keep headline, live metrics,
  progress and more than eight store tiles above the fold at 1280×720. Real job
  state drives colour/pulse/check motion with reduced-motion support.
- Trace and first follow-up fit together. Maria's wanted car, timeline, best match
  score and SMS fit in one view; breakdown and alternatives expand on demand.
  Before/after 1280×720 screenshots and details: `docs/video/REVIEW-v3.md`.
- Redeployed the allowlisted UI archive
  `1a847c76cd70990bc33bb8612c8f3c136ecf7c858a922df7a5d89c7ab0a4cfbf`;
  all 85 installed hashes matched. Rollback and runtime state/ledgers preserved.
- Recorded every app scene again at 1280×720, deviceScaleFactor 1.5, output 1080p.
  The first capture after restart timed out; a subsequent fresh public capture
  and full recording passed. Two real reviews succeeded: first 123.683 seconds,
  final **127.493 seconds**; each reused 25 accepted Qwen responses with no new
  inference calls / **$0 new inference usage**. Compute billing remains separate
  and unverified against billing; no new compute provisioned or ledger reset.
- Added the separate 24-store fan-out motion graphic with six active stores at a
  time, lead/car/brief icons and counters to 24 / 9,000, sourced from the original
  v2 recorded facts. It cuts to three seconds of genuine Group mid-run footage.
- Whole platform frames replace editorial detail crops and transplanted sample
  badges. Removed empty Playwright recorder padding while retaining the entire
  CSS viewport; future recorder uses CSS-size video and whole-frame scaling.
  Same-session Maria/Ready retakes corrected a summary-click choreography issue;
  SMS is fully visible, with a 12-second quiet hold. No new inference for retakes.
- Green chapter pills slide in at top left and stay through each chapter;
  captions stay bottom centre. Separate missed-follow-up promise, impact headline
  and new end card match owner wording. Time skip now says **2 min 7 sec**.
- Both final exports are **165.000 seconds**, 4,950 frames, 1920×1080, 30 fps,
  H.264, silent. Sixteen-frame contact sheet: `docs/video/_review/v3-contact.png`.
  Thirty-five subtitle cues match the clean narration; end footer stays visible.
- Frontend build, Ruff, formatting, compilation, repository checks and 114 offline
  tests passed (seven optional skips). Direct public browser layout/toggle checks
  passed with no page errors or horizontal overflow. No new containment acceptance
  claimed; no backend contracts, sandbox bounds or approval bindings changed.
- Owner still records VO, aligns the final captions/audio/edit, confirms signed-in
  upload limits, uploads the video/slides and submits by **Sunday Nov 8, 16:00 ET**.
  No upload, submission or receipt is claimed.

## Video v3 cursor/camera polish and enterprise tagline (2026-11-06 ET)

- Re-recorded Maria and the match view with the cursor parked off text and a locked
  camera; removed the animated pixel-rounded zoom responsible for stepping. No
  hover sweeps, breakdown toggles or scrolling interrupt the Maria reading hold.
- Mid-run Group now cuts in after its pointer settles. Approval has one paced
  cosine cursor move and a genuine click; approval/Ready use a separate saved-sample
  session with identical Maria SMS. No new review or inference was triggered.
  Original 127.493-second Group/trace evidence and all product metrics are unchanged.
- Video title/end card use “SalesDesk: Your AI enterprise sales analyst”. VO script,
  maintained SRT/ASS, plan, recording hand-off and contact sheet agree.
- Both rebuilt cuts remain exactly 165.000 seconds, 4,950 frames, 1080p/30fps, silent.
  A sampled static-Maria-region check passed with negligible frame variation;
  `docs/video/v3-motion-check.json` records the check. Recording had no page errors;
  media, subtitle agreement, Ruff/format and repository checks passed.
- This is a video-asset revision; no app redeploy or backend/model changes. Owner
  should use the updated enterprise line when recording the VO.

## Conversational video v4 retiming (2026-11-07 ET)

- The owner-approved 472-word rewrite is preserved verbatim in `narration-v4.txt`.
  Rebuilt the edit at **204.000 seconds (3:24)** with paragraph breathing space
  rather than compressing the read into the previous 2:45 cut. V3 remains preserved.
- Replaced the old thesis/promise slogans with the manager's review steps and a
  practical morning workflow. Enterprise analyst branding remains. Numbers retain
  their slide/count-up treatment with factual labels matching the new explanation.
- Maria runs 1:50–2:27, with model/trim/98/colour at 1:52–2:03, timeline at
  2:03–2:13 and SMS/trade-in at 2:13–2:27. The earlier silent reading gap is gone.
  Camera stays locked and cursor parked; captions sit below the actual SMS.
- Queue/approval/Ready now follow the spoken order at 2:27–2:40. Matched-lead and
  gross cards change at 2:40 / 2:46; architecture starts at 2:56. URLs stay visible
  across the final 16 seconds. Scene stops and source offsets are in the v4 plan
  and shot manifest; 55 guide cues match every approved spoken word.
- Both exports passed H.264, 1920×1080, 30fps, 6,120 frames, exact 204-second and
  silent-stream checks. Caption limits/non-overlap, contiguous shot spans, scene
  bindings, Ruff/format, repository links and whitespace passed. Contact sheet is
  `docs/video/_review/v4-contact.png`; timing checks are `v4-timing-check.json`.
- Reused accepted v3 public footage and original editorial assets. Only the fan-out
  graphic changes tempo; app footage remains normal speed. No new review,
  inference, customer contact or app deployment; source runtime/cost evidence stays
  unchanged (127.493 seconds, 25 accepted Qwen replays, $0 new inference usage).
- No recorded VO was supplied: these are paced guide cues, not audio-aligned cues.
  Owner records the approved read, aligns final captions/audio and uploads/submits
  by the supplied Sunday Nov 8, 16:00 ET target. No submission or receipt claimed.

## Hook-first video v5 delivery: 2026-11-07 ET

- Reassembled both silent cuts at **197.000 seconds, 5910 frames**, 1920×1080/30fps.
  Opening stops match the owner's 8/20/26/32-second structure. The universal hook
  is retained; Maria and the thesis are condensed for the supplied windows.
- Maria's last contact is a week ago; no unsupported call count is asserted.
  The proof card shows **42.7%** qualified leads mishandled and **61.2%** of
  eventual buyers purchasing within three days. Foureyes' April 22, 2026 report
  covers January–December 2025 activity. Source/date stay on screen, outside VO.
  Industry populations remain separate from synthetic dealer-group metrics.
- The existing walkthrough shifts seven seconds earlier, preserving whole-screen
  footage, parked cursor and locked camera. No new public run, inference, deploy or
  spend: original source remains 127.493 seconds, 25 accepted replays, $0 new inference.
- Verified all **54 guide cues / 463 words**, contiguous shots and caption limits;
  export probes, Python lint/format, repository links and whitespace checks pass.
  Updated hand-off, review sheet, contact sheet and artifact hashes. No recorded VO
  was supplied; align final captions to the owner's recording before upload.
- Owner still records VO, completes the audio edit, uploads and submits by the
  owner-supplied Sunday November 8, 16:00 ET target. No submission receipt exists.
