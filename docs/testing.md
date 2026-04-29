# Testing quickstart

- Unit/type tests: `pnpm test` (Vitest) and `pnpm run check` (typecheck).
- Live-suite posture:
  - stable baseline:
    - keep small, repeatable, and operationally useful
    - prefer one-provider baselines plus the few highest-value matrix checks
  - extended matrix:
    - keep the broader mixed-provider/operator-control proofs opt-in
    - use for periodic confidence, not every routine pass
  - flaky-but-informative probes:
    - keep separately gated
    - do not promote into the stable baseline until they stop needing special
      handling
- Current live-suite tier map:
  - stable baseline:
    - `tests/live/team-grok-live.test.ts`
      - default `AURACALL_LIVE_TEST=1` cases only:
        - `auracall-solo`
        - `auracall-two-step`
        - `auracall-multi-agent`
    - `tests/live/team-chatgpt-live.test.ts`
      - `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_TEAM_LIVE_TEST=1`
      - single-provider ChatGPT baseline only
  - extended matrix:
    - `tests/live/team-gemini-live.test.ts`
      - `AURACALL_LIVE_TEST=1 AURACALL_GEMINI_TEAM_LIVE_TEST=1`
      - keep opt-in because Gemini still depends on exported-cookie preflight
        and stricter browser/session conditions on this machine
    - `tests/live/team-grok-live.test.ts`
      - `AURACALL_TOOLING_LIVE_TEST=1`
      - `AURACALL_APPROVAL_LIVE_TEST=1`
      - `AURACALL_REJECTION_LIVE_TEST=1`
      - `AURACALL_CANCELLATION_LIVE_TEST=1`
    - `tests/live/team-chatgpt-live.test.ts`
      - `AURACALL_CHATGPT_APPROVAL_LIVE_TEST=1`
      - `AURACALL_CHATGPT_CANCELLATION_LIVE_TEST=1`
    - `tests/live/team-multiservice-live.test.ts`
      - all mixed-provider happy-path and operator-control gates stay here by
        default
  - flaky-but-informative probes:
    - provider/browser cases that still need bounded reruns or stricter
      preflight, especially Gemini-resume cases that can intermittently fail
      with transient fetch/browser instability
    - do not promote those probes into the stable baseline until they stop
      needing:
        - exported-cookie or manual-auth preflight beyond the normal path
        - one bounded rerun to distinguish provider noise from product
          regressions
        - provider-specific cooldown/captcha handling
- Routine live commands:
  - stable baseline:
    - `pnpm run test:live:team:baseline`
    - current scope:
      - `tests/live/team-grok-live.test.ts` default Grok baseline cases
      - `tests/live/team-chatgpt-live.test.ts` single-provider ChatGPT
        baseline
    - the test files themselves now carry matching tier comments near the
      env-gate definitions so operators can see baseline versus matrix intent
      without leaving the suite
  - extended matrix:
    - run file-level suites with explicit opt-in gates, for example:
      - `AURACALL_LIVE_TEST=1 AURACALL_GEMINI_TEAM_LIVE_TEST=1 pnpm vitest run tests/live/team-gemini-live.test.ts`
      - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_TEAM_LIVE_TEST=1 pnpm vitest run tests/live/team-multiservice-live.test.ts`
      - `AURACALL_LIVE_TEST=1 AURACALL_APPROVAL_LIVE_TEST=1 pnpm vitest run tests/live/team-grok-live.test.ts -t "human escalation"`
  - do not use `pnpm test:live` as the routine baseline command for this phase:
    - it still sweeps a much broader live surface than the current team
      baseline
    - keep it for wider opt-in live coverage, not for the small default target
- Local `api serve` smoke:
  - terminal 1: `pnpm tsx bin/auracall.ts api serve --port 8080`
    - non-default runtime profile: `pnpm tsx bin/auracall.ts --profile auracall-gemini-pro api serve --port 8080`
    - startup logs should include `Active AuraCall runtime profile: <name>`
  - optional startup-recovery tuning:
    - disable startup recovery: `pnpm tsx bin/auracall.ts api serve --port 8080 --no-recover-runs-on-start`
    - cap startup recovery: `pnpm tsx bin/auracall.ts api serve --port 8080 --recover-runs-on-start-max 25`
    - recover only team source runs: `pnpm tsx bin/auracall.ts api serve --port 8080 --recover-runs-on-start-source team-run`
    - recover both sources: `pnpm tsx bin/auracall.ts api serve --port 8080 --recover-runs-on-start-source all`
    - wrapper contract:
      - default startup recovery scope remains `direct`
      - `team-run` recovers only team runs
      - `all` recovers both direct and team runs
      - the startup cap still applies after widening scope to `all`
  - terminal 2: `curl http://127.0.0.1:8080/status`
    - current expected status includes bounded background-drain visibility:
      - `backgroundDrain.enabled`
      - `backgroundDrain.intervalMs`
      - `backgroundDrain.state`
      - `backgroundDrain.paused`
      - `backgroundDrain.lastTrigger`
    - current expected status also includes the live local runner heartbeat:
      - `runner.id`
      - `runner.hostId`
      - `runner.status = active`
      - `runner.lastHeartbeatAt`
      - `runner.expiresAt`
      - `runner.lastActivityAt`
      - `runner.lastClaimedRunId`
    - current expected status also includes read-only runner topology:
      - `runnerTopology.localExecutionOwnerRunnerId`
      - `runnerTopology.generatedAt`
      - `runnerTopology.metrics.totalRunnerCount`
      - `runnerTopology.metrics.activeRunnerCount`
      - `runnerTopology.metrics.staleRunnerCount`
      - `runnerTopology.metrics.freshRunnerCount`
      - `runnerTopology.metrics.expiredRunnerCount`
      - `runnerTopology.metrics.browserCapableRunnerCount`
      - `runnerTopology.metrics.displayedRunnerCount`
      - `runnerTopology.metrics.omittedRunnerCount`
      - plain `/status` compacts `runnerTopology.runners` to the local owner
        plus fresh/active runners so long-lived dogfood environments do not
        dump stale runner history by default
      - use `GET /status?runnerTopology=full` when forensic debugging needs
        every stored runner entry
      - `runnerTopology.runners[].runnerId`
      - `runnerTopology.runners[].selectedAsLocalExecutionOwner`
      - topology readback must not select claims, acquire leases, execute
        steps, or reassign work to another runner
    - current expected status also includes read-only account mirror posture:
      - `accountMirrorStatus.object = account_mirror_status`
      - `accountMirrorStatus.metrics.total`
      - `accountMirrorStatus.metrics.eligible`
      - `accountMirrorStatus.metrics.delayed`
      - `accountMirrorStatus.metrics.blocked`
      - `accountMirrorStatus.entries[].provider`
      - `accountMirrorStatus.entries[].runtimeProfileId`
      - `accountMirrorStatus.entries[].browserProfileId`
      - `accountMirrorStatus.entries[].expectedIdentityKey`
      - `accountMirrorStatus.entries[].accountLevel`
      - `accountMirrorStatus.entries[].status = eligible|delayed|blocked`
      - `accountMirrorStatus.entries[].mirrorState.queued`
      - `accountMirrorStatus.entries[].mirrorState.running`
      - `accountMirrorStatus.entries[].mirrorState.lastDispatcherKey`
      - `accountMirrorStatus.entries[].metadataCounts`
      - `accountMirrorStatus.entries[].metadataEvidence`
      - `accountMirrorStatus.entries[].metadataEvidence.attachmentInventory`
      - `accountMirrorStatus.entries[].mirrorCompleteness.state = none|complete|in_progress|unknown`
      - `accountMirrorStatus.entries[].mirrorCompleteness.remainingDetailSurfaces`
      - this readback may hydrate counts/evidence from the existing provider
        cache store, but it must not enqueue browser work or scrape provider
        pages
    - current expected status also includes lazy account mirror scheduler
      posture:
      - `accountMirrorScheduler.enabled`
      - `accountMirrorScheduler.dryRun`
      - `accountMirrorScheduler.intervalMs`
      - `accountMirrorScheduler.state = disabled|idle|scheduled|running|paused`
      - `accountMirrorScheduler.paused`
      - `accountMirrorScheduler.lastStartedAt`
      - `accountMirrorScheduler.lastCompletedAt`
      - `accountMirrorScheduler.lastPass`
      - `accountMirrorScheduler.history.object = account_mirror_scheduler_pass_history`
      - `accountMirrorScheduler.history.entries[]`
      - `accountMirrorScheduler.lastPass.selectedTarget.mirrorCompleteness`
      - `accountMirrorScheduler.lastPass.backpressure.reason = none|routine-delayed|blocked-by-browser-work|yielded-to-queued-work`
      - `accountMirrorScheduler.lastPass.metrics.inProgressEligibleTargets`
      - `accountMirrorScheduler.lastPass.metrics.delayedTargets`
      - `accountMirrorScheduler.lastPass.metrics.blockedTargets`
      - `accountMirrorScheduler.lastPass.metrics.defaultChatgptDelayedTargets`
      - routine scheduler refreshes use zero dispatcher queue wait and should
        block/yield when real browser work already owns the control plane
      - after a routine mirror acquires the dispatcher, bounded attachment
        inventory should check for queued browser work between
        project/conversation detail reads; a yield marks the inventory
        truncated and preserves the cursor for the next pass
      - the scheduler is disabled unless
        `--account-mirror-scheduler-interval-ms <ms>` is set
      - without `--account-mirror-scheduler-execute`, scheduler passes are
        dry-run only and must not call the refresh service or acquire the
        browser dispatcher
      - the first executable scheduler slice may request at most one
        default-ChatGPT routine refresh per pass
      - scheduler operator controls share `POST /status`:
        - pause: `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"accountMirrorScheduler":{"action":"pause"}}'`
        - resume: `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"accountMirrorScheduler":{"action":"resume"}}'`
        - dry-run one pass: `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"accountMirrorScheduler":{"action":"run-once"}}'`
      - execute one pass only when the server was started with
        `--account-mirror-scheduler-execute`:
        `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"accountMirrorScheduler":{"action":"run-once","dryRun":false}}'`
      - installed execute dogfood should use a long interval plus one manual
        `run-once` to avoid repeated provider navigation; the validated
        default-ChatGPT pass completed with five cached projects and 64 cached
        conversations for `ecochran76@gmail.com`
    - dedicated mirror posture route:
      - `GET /v1/account-mirrors/status`
      - `GET /v1/account-mirrors/status?provider=chatgpt&runtimeProfile=default`
      - `GET /v1/account-mirrors/status?provider=chatgpt&runtimeProfile=default&explicitRefresh=true`
      - `explicitRefresh=true` evaluates the shorter polite interval but still
        remains read-only in this slice
    - dedicated mirror manifest catalog route:
      - `GET /v1/account-mirrors/catalog`
      - `GET /v1/account-mirrors/catalog?provider=chatgpt&runtimeProfile=default&kind=all&limit=50`
      - `kind` can be `all`, `projects`, `conversations`, `artifacts`,
        `files`, or `media`
      - this readback returns cached project/conversation/artifact/file/media
        manifest rows by provider plus bound identity; it must not acquire the
        browser dispatcher, launch browsers, submit prompts, scrape provider
        pages, or load conversation ids
    - explicit mirror refresh route:
      - `POST /v1/account-mirrors/refresh`
      - body: `{"provider":"chatgpt","runtimeProfile":"default","explicitRefresh":true}`
      - current implementation is default-ChatGPT only
      - it acquires the browser operation dispatcher and records
        queued/running/completed evidence
      - after dispatcher acquisition it verifies the bound ChatGPT identity,
        then collects bounded project/conversation metadata only
      - on success it persists the mirror snapshot under the existing provider
        cache key for `provider + boundIdentity`; AuraCall runtime profile and
        browser profile are stored as refresh provenance, not as duplicate
        mirror data ownership
      - the same success path persists bounded project and conversation
        manifests into the existing identity-scoped provider cache datasets,
        plus lightweight account-mirror artifact/file/media manifests; this does
        not fetch full conversation bodies or binary artifacts
      - it must not submit prompts, fetch full conversation bodies, or load
        immature conversation ids
    - MCP parity:
      - `account_mirror_status`
      - `account_mirror_catalog`
      - `account_mirror_refresh`
      - status/catalog are read-only; refresh is explicit,
        dispatcher-owned, and metadata-only in this slice
    - plain `/status` also includes a compact direct-run local claim snapshot:
      - `localClaimSummary.sourceKind = direct`
      - `localClaimSummary.runnerId`
      - `localClaimSummary.selectedRunIds`
      - `localClaimSummary.blockedRunIds`
      - `localClaimSummary.notReadyRunIds`
      - `localClaimSummary.unavailableRunIds`
      - `localClaimSummary.statusByRunId`
  - optional operator control on the same surface:
    - pause: `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"backgroundDrain":{"action":"pause"}}'`
    - resume: `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"backgroundDrain":{"action":"resume"}}'`
    - cancel one active local run:
      - `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"runControl":{"action":"cancel-run","runId":"<response_id>"}}'`
    - resume one paused human-escalation direct or team run:
      - `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"runControl":{"action":"resume-human-escalation","runId":"<response_id>","note":"human approved resume","guidance":{"action":"retry-with-guidance"},"override":{"promptAppend":"Retry the resumed step.","structuredContext":{"approvedPath":"/repo/approved"}}}}'`
    - trigger one targeted drain pass for a direct or team run:
      - `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"runControl":{"action":"drain-run","runId":"<response_id>"}}'`
      - if the local configured runner cannot safely claim that run, targeted
        drain should return `status = skipped` with
        `skipReason = claim-owner-unavailable`
      - if the run is already leased by the configured server-local runner,
        targeted drain should reuse that lease and execute one host pass
    - claim one scheduler-authorized local run without executing it:
      - `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"schedulerControl":{"action":"claim-local-run","runId":"<response_id>","schedulerId":"operator:local-status"}}'`
      - accepted only when scheduler authority selects the server-local runner
      - follow with `runControl.action = "drain-run"` for immediate execution
        through the existing local-owned lease
      - for bounded multi-pass drain accounting:
        - preserve repeated executions for the same run across passes
        - but count one reclaimed stale lease only once in
          `expiredLeaseRunIds`
    - response/readback should preserve both targeted-drain outcomes:
      - `operatorControlSummary.targetedDrain.status = executed|skipped`
      - skipped targeted drain keeps `skipReason = claim-owner-unavailable`
      - `reason` should preserve the specific local-claim explanation when one
        is available
      - recovery detail timeline retains the persisted skipped drain note
    - when multiple resume/drain operator-control entries exist on one run,
      response readback should prefer the latest persisted resume summary and
      the latest persisted targeted-drain note
    - required structured-report / JSON requested outputs should not be
      satisfied by internal structured outputs alone:
      - `response.output`
      - `human.resume.<stepId>`
      - `step.localActionOutcomes.<stepId>`
    - orchestration timeline summaries stay bounded:
      - keep full `total`
      - but limit `items` to the newest `10` entries on both response readback
        and recovery detail
    - handoff-transfer summaries should prefer stored consumed transfer state
      over planned handoff fallback when both exist
    - cancellation readback should also preserve the no-note fallback:
      - if no cancellation `note-added` event exists, fall back to the
        cancelled run's `updatedAt`
      - read back `source = null` and `reason = null`
      - keep that fallback explicit on both:
        - `GET /v1/responses/{response_id}`
    - `GET /v1/team-runs/inspect?taskRunSpecId=<task_run_spec_id>`
    - `GET /v1/team-runs/inspect?teamRunId=<team_run_id>`
    - `GET /v1/runtime-runs/inspect?runId=<run_id>`
    - `GET /v1/runtime-runs/inspect?runtimeRunId=<runtime_run_id>`
    - `GET /v1/runtime-runs/inspect?teamRunId=<team_run_id>`
    - `GET /v1/runtime-runs/inspect?taskRunSpecId=<task_run_spec_id>`
    - `GET /v1/runtime-runs/inspect?runId=<run_id>&runnerId=<runner_id>`
    - `GET /v1/runtime-runs/inspect?runId=<run_id>&probe=service-state`
    - `GET /v1/runtime-runs/inspect?runId=<run_id>&diagnostics=browser-state`
    - `GET /v1/runtime-runs/inspect?runId=<run_id>&authority=scheduler`
    - CLI equivalent for read-only scheduler evidence:
      - `pnpm tsx bin/auracall.ts api inspect-run --run-id <run_id> --authority scheduler`
        - `GET /status/recovery/{run_id}`
    - resolve one pending local-action request on a direct or team run:
      - `curl -s http://127.0.0.1:8080/status -H 'Content-Type: application/json' -d '{"localActionControl":{"action":"resolve-request","runId":"<response_id>","requestId":"<request_id>","resolution":"approved|rejected|cancelled"}}'`
      - successful local-action resolution should also return bounded:
        - `resolvedAt`
        - `ownerStepId`
      - successful human-escalation resume should also return bounded:
        - `resumedAt`
        - `resumedStepId`
  - create bounded response:
    - `curl -s http://127.0.0.1:8080/v1/responses -H 'Content-Type: application/json' -d '{"model":"gpt-5.2","input":"Reply exactly with: local api smoke"}'`
    - browser-backed ChatGPT tool smoke:
      `curl -s http://127.0.0.1:8080/v1/responses -H 'Content-Type: application/json' -d '{"model":"gpt-5.2-thinking","input":"Use Deep Research to prepare a tiny smoke-test plan.","auracall":{"runtimeProfile":"wsl-chrome-3","service":"chatgpt","transport":"browser","composerTool":"deep-research","deepResearchPlanAction":"edit"}}'`
  - read it back:
    - copy the returned `id`, then run `curl http://127.0.0.1:8080/v1/responses/<response_id>`
    - for compact operator status, run
      `curl http://127.0.0.1:8080/v1/runs/<response_id>/status`
      Browser-backed ChatGPT Deep Research `edit` runs should expose
      `metadata.browserRunSummary.chatgptDeepResearchReviewEvidence` here,
      including the review stage and screenshot path when capture succeeds.
    - CLI parity for the same durable status envelope:
      `pnpm tsx bin/auracall.ts run status <response_id> --json`
    - completed ChatGPT Deep Research report retrieval:
      `pnpm tsx bin/auracall.ts --profile wsl-chrome-3 conversations artifacts fetch <conversation_id> --target chatgpt`
      should return `document` artifacts materialized from the Deep Research
      iframe: inline Markdown plus provider-exported Word and PDF files when
      the finished report exposes those export options.
  - create a shared-contract CLI media request:
    - `pnpm tsx bin/auracall.ts media generate --provider chatgpt --type image -p "Generate an image of an asphalt secret agent" --json`
    - `pnpm tsx bin/auracall.ts media generate --provider gemini --type image -p "Generate an image of an asphalt secret agent" --json`
    - Gemini API image generation uses the same durable contract when
      `GEMINI_API_KEY` is set, but provider API media access is parked for
      now; run this only when deliberately validating that non-primary path:
      `pnpm tsx bin/auracall.ts media generate --provider gemini --type image --transport api -p "Generate an image of an asphalt secret agent" --count 1 --json`
    - for async browser smokes, add `--no-wait` and poll with
      `pnpm tsx bin/auracall.ts run status <media_generation_id> --json`
    - prefer this command for new media automation and routine operator
      smokes; the older Gemini-only `--generate-image <file>` flag is a
      compatibility shortcut for direct one-file browser image saves and does
      not produce a durable media-generation record
  - create a browser-transport Gemini image request only after capability
    discovery reports `gemini.media.create_image` as `available`; the local API
    then selects `Create image`, records media-generation `timeline[]`
    milestones, and materializes generated image artifacts:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"gemini","mediaType":"image","transport":"browser","prompt":"Generate an image of an asphalt secret agent"}'`
  - create a browser-transport ChatGPT image request only when the managed
    ChatGPT browser profile is already authenticated; the local API selects the
    ChatGPT `Create image` composer tool, records the submitted tab target id,
    and performs post-submit image readback/materialization on that same tab
    without re-opening or reloading the conversation:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"chatgpt","mediaType":"image","transport":"browser","prompt":"Generate an image of an asphalt secret agent"}'`
  - create a browser-transport Gemini video request only when intentionally
    spending one of the small daily Gemini video-generation quota slots:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"gemini","mediaType":"video","transport":"browser","prompt":"Generate a video of an asphalt secret agent"}'`
    - routine validation should use fixture tests instead of live video
      generation
    - expected successful runs include `capability_discovered`,
      `executor_started`, optional `browser_operation_queued`,
      `browser_operation_acquired`, `browser_target_attached`,
      `capability_selected`, `prompt_submitted`, repeated `artifact_poll`,
      `video_visible`, `artifact_materialized`, and `completed`
    - generated videos should cache as `video/mp4` artifacts with the
      materialization method reported in status diagnostics
  - create a browser-transport Gemini music request only when intentionally
    spending Gemini media-generation quota:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"gemini","mediaType":"music","transport":"browser","prompt":"Create a spy theme song"}'`
    - routine validation should use fixture tests instead of live music
      generation
    - expected successful runs include `capability_discovered`,
      `executor_started`, optional `browser_operation_queued`,
      `browser_operation_acquired`, `browser_target_attached`,
      `capability_selected`, `prompt_submitted`, repeated `artifact_poll`,
      `music_visible`, `artifact_materialized`, and `completed`
    - generated music should cache every provider download variant exposed by
      readback, including video with album art and MP3 audio
    - when Gemini exposes one generated music artifact plus `downloadOptions`,
      the executor should materialize each option as a separate variant by
      selecting the requested visible provider menu item on the submitted tab
    - when fresh readback exposes only the generic `Download track` control,
      the executor should still request Gemini's known music variants
      (`VideoAudio with cover art`, `Audio onlyMP3 track`) for menu-backed
      materialization
    - explicit variant materialization should fail that variant rather than
      caching the default generated MP4 URL under MP3 metadata
    - read-only artifact discovery should preserve already-visible provider
      download option labels, such as `Download as video with album art` and
      `Download as MP3`, without clicking the menu during routine validation
    - `/v1/media-generations/<id>/status`, `/v1/runs/<id>/status`, MCP
      `media_generation_status`, MCP `run_status`, and CLI `run status --json`
      should surface provider labels as compact artifact `downloadLabel`,
      `downloadVariant`, and `downloadOptions`
    - the MCP status schemas should also advertise compact artifact checksum
      and preview/full-quality comparison fields so callers can rely on
      `checksumSha256`, `previewArtifactId`, `previewSize`,
      `previewChecksumSha256`, and `fullQualityDiffersFromPreview` when a
      provider adapter records them
  - create a browser-transport Grok image request only after capability
    discovery reports `grok.media.imagine_image` as `available`; the local API
    first checks the explicit `/imagine` entrypoint and fails before prompt
    submission when the capability is `account_gated` or otherwise unavailable:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"grok","mediaType":"image","transport":"browser","prompt":"Generate an image of an asphalt secret agent"}'`
    - gated failures should include `capability_unavailable` before terminal
      `failed` in `timeline[]`, with `metadata.capabilityId`,
      `metadata.capabilityAvailability`, and the inspection command in
      `failure.details`
    - available Grok image runs should materialize bounded visible Imagine
      tiles through the active browser tab, then compare one preview against
      the provider download-button result before using remote media fetch as a
      fallback
    - after a fresh Grok image run completes, operators can explicitly retry
      resumed full-quality discovery without submitting another prompt:
      `pnpm tsx bin/auracall.ts media materialize <media_generation_id> --count 1 --json`;
      the retry must use the browser-service operation dispatcher, preserve the
      existing terminal run status, and merge any new artifacts into the same
      media-generation artifact directory. Current live proof covers the
      navigate-away path where the active tab is later on `https://grok.com/files`
      and the materializer opens a `/files?file=...` detail row to use
      `Download Image`.
      If that detail page loads but the download control is missing, status
      diagnostics should include bounded `filesDetail*` evidence: href/title,
      readiness, download-control count/labels, visible image labels, and
      visible button labels.
  - create a browser-transport Grok video request:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"grok","mediaType":"video","transport":"browser","prompt":"Generate a video of an asphalt secret agent"}'`
    - expected successful runs include `capability_discovered`,
      `executor_started`, `browser_target_attached`, `prompt_inserted`,
      `submit_path_observed`, `prompt_submitted`, repeated
      `run_state_observed`, `video_visible`, `artifact_materialized`, and
      `completed`
    - generated videos should cache as `video/mp4` artifacts, preferably with
      `materialization = download-button`
    - diagnostic readback of an already-submitted manual Grok video tab is
      gated behind explicit metadata:
      `grokVideoReadbackProbe = true`, `grokVideoReadbackTabTargetId`, and
      `grokVideoReadbackDevtoolsPort`; it must direct-connect to the existing
      tab only and must not submit, navigate, reload, or fall back to
      browser-service target resolution; use
      `docs/grok-imagine-video-readback-runbook.md` for the bounded manual
      live probe
    - read back the same id through both
      `/v1/media-generations/<id>/status` and `/v1/runs/<id>/status`; both
      should agree on terminal state, last event, artifact count, and cached
      artifact paths
    - status `diagnostics` should summarize capability preflight, submitted
      tab id/url, provider route progression, artifact polling/progress
      counts, terminal run-state counts, and materialization source from the
      persisted timeline without requiring `diagnostics=browser-state`
  - list workbench capabilities for service discovery:
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=gemini"`
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=chatgpt"`
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=grok"`
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=grok&diagnostics=browser-state"`
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=grok&entrypoint=grok-imagine&diagnostics=browser-state"`
    - `curl -s "http://127.0.0.1:8080/v1/workbench-capabilities?provider=grok&entrypoint=grok-imagine&discoveryAction=grok-imagine-video-mode"`
    - `auracall capabilities --target gemini --json`
    - `auracall capabilities --target chatgpt --json`
    - `auracall capabilities --target grok --json`
    - `auracall capabilities --target grok --diagnostics browser-state --json`
    - `auracall capabilities --target grok --entrypoint grok-imagine --diagnostics browser-state --json`
    - `auracall capabilities --target grok --entrypoint grok-imagine --discovery-action grok-imagine-video-mode --json`
    - `auracall capabilities --target gemini --static --json` for a no-browser
      catalog check
    - use `category=research|media|canvas|connector|skill|app|search|file|other`
      to narrow the report
    - static entries are intentionally conservative until live browser/provider
      discovery proves current account availability
    - `diagnostics=browser-state` / `--diagnostics browser-state` adds bounded
      target/document/provider evidence and a stored PNG screenshot path
    - `entrypoint=grok-imagine` / `--entrypoint grok-imagine` opens or reuses
      the Grok `/imagine` route through browser-service control-plane
      attribution for read-only inspection only
    - Grok `/imagine` diagnostics include provider-owned read-only
      `run_state`, pending, terminal image/video, media URL, and
      materialization-control evidence when visible, plus bounded masonry and
      filmstrip visible-tile evidence. They do not submit a prompt or click
      generation controls.
    - a passive `Upgrade to SuperGrok` upsell alone is not an account gate
      when usable Image/Video controls or generated media are visible; blocking
      gate classification requires contextual generation-limit/subscription
      evidence with no ready composer or media
    - with the configured `api serve` runtime, `provider=gemini`,
      `provider=chatgpt`, and `provider=grok` can merge read-only
      feature-signature evidence from the matching managed browser profile;
      unfiltered reports remain static/cheap
  - create/read media-generation contract record:
    - `curl -s http://127.0.0.1:8080/v1/media-generations -H 'Content-Type: application/json' -d '{"provider":"gemini","mediaType":"image","prompt":"Generate an image of an asphalt secret agent","aspectRatio":"1:1"}'`
    - for active polling, request async creation:
      `curl -s "http://127.0.0.1:8080/v1/media-generations?wait=false" -H 'Content-Type: application/json' -d '{"provider":"gemini","mediaType":"image","transport":"browser","prompt":"Generate an image of an asphalt secret agent","aspectRatio":"1:1"}'`
    - the same contract accepts `mediaType = music|video`; Gemini music may
      still materialize over a video transport artifact
    - unsupported provider/media combinations return a persisted `failed`
      response with a provider-specific `failure.code`
    - copy the returned `id`, then run `curl http://127.0.0.1:8080/v1/media-generations/<media_generation_id>`
    - for compact operator status, run
      `curl http://127.0.0.1:8080/v1/media-generations/<media_generation_id>/status`
    - while a browser-backed media job is still running, add
      `?diagnostics=browser-state` to capture bounded live browser evidence
      from the active provider target, including recent Aura-Call browser
      mutation records when present
    - for the generic run-status surface, run
      `curl http://127.0.0.1:8080/v1/runs/<media_generation_id>/status`
    - the generic status route accepts the same
      `?diagnostics=browser-state` switch for running browser-backed media jobs
    - CLI parity for the same durable status envelope:
      `pnpm tsx bin/auracall.ts run status <media_generation_id> --json`
    - inspect `timeline[]` for `running_persisted`, `executor_started`,
      optional `browser_operation_queued`, `browser_operation_acquired`,
      provider-specific progress, and terminal `completed|failed` evidence
  - create bounded team run:
    - `curl -s http://127.0.0.1:8080/v1/team-runs -H 'Content-Type: application/json' -d '{"teamId":"ops","objective":"Reply with one bounded team result.","responseFormat":"markdown","maxTurns":2}'`
    - with background drain enabled, creation returns after persistence and
      the server-owned background drain advances the run; poll the response
      readback link for terminal output
  - read/inspect the team run:
    - copy `execution.teamRunId`, then run `curl "http://127.0.0.1:8080/v1/team-runs/inspect?teamRunId=<team_run_id>"`
    - copy `execution.runtimeRunId`, then run `curl "http://127.0.0.1:8080/v1/runtime-runs/inspect?runtimeRunId=<runtime_run_id>"`
    - response readback is also available at `GET /v1/responses/<runtime_run_id>`
  - current expected posture:
    - `POST /v1/responses` persists the run and the server-owned background
      drain advances it
    - `POST /v1/team-runs` constructs one bounded `TaskRunSpec`, projects one
      `TeamRun`, and executes one `sourceKind = team-run` runtime through the
      same server-owned host/runner path
    - direct browser-backed `/v1/responses` runs now use the configured
      stored-step executor path instead of a no-op wrapper path
    - managed browser response/chat execution now waits through the
      browser-service operation dispatcher when another operation owns the same
      managed browser profile; login/setup/manual-verification flows still
      surface busy state immediately
    - `api serve` now also persists one bounded local runner record and keeps
      it heartbeated while the server stays up
    - `GET /v1/runtime-runs/inspect` now exposes the bounded queue projection
      for one persisted runtime run:
      - `resolvedBy`
      - `queryId`
      - `queryRunId`
      - `matchingRuntimeRunCount`
      - bounded `matchingRuntimeRunIds`
      - `queueState`
      - `claimState`
      - `nextRunnableStepId`
      - `activeLeaseId`
      - `activeLeaseOwnerId`
      - optional `serviceState` when explicitly requested with
        `probe=service-state`
        - `probeStatus = observed|unavailable`
        - keep it separate from queue/lease posture
        - current default live probe coverage is:
          - ChatGPT on the managed browser path
          - Gemini on browser-backed runtime profiles only
            - active browser-backed Gemini runs prefer provider-owned
              lottie/avatar spinner evidence when visible, then fall back to
              executor-owned transient `thinking`
          - Grok on browser-backed runtime profiles only
            - active browser-backed Grok runs prefer executor-owned transient
              `thinking` state before DOM/page fallback
        - Gemini API-backed runtime profiles still return honest
          `unavailable` posture
        - Grok API-backed runtime profiles still return honest `unavailable`
          posture
      - optional `browserDiagnostics` when explicitly requested with
        `diagnostics=browser-state`
        - live, bounded, and run-scoped to the active step
        - includes target URL/title/id, document readiness, visible control
          counts, provider evidence, recent browser mutation records, and a
          stored PNG screenshot path
        - `GET /v1/runs/<id>/status?diagnostics=browser-state` and
          `GET /v1/media-generations/<id>/status?diagnostics=browser-state`
          expose the same bounded browser snapshot for active browser-backed
          media jobs, using the media run's recorded `tabTargetId` when present
        - `GET /v1/workbench-capabilities?provider=<provider>&diagnostics=browser-state`
          exposes the same bounded browser snapshot for current workbench
          capability discovery, including Grok Imagine gating evidence
      - optional `schedulerAuthority` when explicitly requested with
        `authority=scheduler`
        - read-only authority evidence only
        - returns decision, reason, active lease posture, candidates,
          selected runner evidence, future mutation label, and
          `mutationAllowed = false`
      - step-id buckets for running/waiting/deferred/terminal posture
      - bounded affinity posture
        - `requiredService`
        - `requiredRuntimeProfileId`
        - `requiredBrowserProfileId`
        - `requiredHostId`
        - `hostRequirement`
        - `requiredServiceAccountId`
        - `browserRequired`
        - `eligibilityNote`
      - when configured service identity exists for the active step service,
        runtime inspection and local claim evaluation should require the same
        `service-account:<service>:<identity-key>` id that `api serve` runner
        records advertise
      - this id is derived from config only:
        - identity key preference is `email`, then `handle`, then `name`
        - `api serve` does not live-probe the browser account during runner
          registration
        - a match proves configured account affinity, not independent proof of
          the currently logged-in browser tab
    - if `runnerId` is supplied, the same inspection route should also include
      one bounded persisted runner summary and evaluate queue affinity against
      that runner
      - `api serve` derives runner `serviceAccountIds` from configured service
        identities when present, using
        `service-account:<service>:<identity-key>`
      - when configured identities are absent or incomplete for a
        browser-capable runner, expect `eligibilityNote` to preserve that caveat
    - bounded local claims now use that live runner id as the lease owner
    - successful direct-run execution now also updates that persisted runner
      record with:
      - `lastActivityAt`
      - `lastClaimedRunId`
    - while a direct-run step is still executing, the active lease should now
      also be refreshed under the live runner owner instead of relying on the
      initial claim timestamp alone
    - if that configured runner owner is missing or stale, new local claims
      should be skipped instead of silently falling back to a generic host id
    - `POST /status` run cancellation is now bounded to active locally owned
      runs:
      - active local runner-owned run => cancelled + lease released with
        `cancelled`
      - inactive or not-owned run => 409
    - `POST /status` human-escalation resume is now bounded to direct or
      team runs currently paused for human escalation:
      - paused human-escalation run => resumed to `running` / resumed step
        returned to `runnable`
      - any other run => 409
    - `POST /status` targeted drain is now bounded to direct or team runs:
      - runnable or resumed run => one targeted host drain pass and
        immediate execution if claimable
      - skipped or non-runnable run => 409
    - `POST /status` local-action resolution is now bounded to currently
      `requested` direct or team local action records:
      - requested request => approved/rejected/cancelled and reflected in later
        `metadata.executionSummary.localActionSummary`
      - already-resolved request => 409
    - `POST /status` scheduler local claim is bounded to the server-local runner:
      - local claimable run => active lease acquired for the server-local runner
      - expired stale/missing-owner lease => old lease expired and new local
        lease acquired
      - fresh active lease, active owner, non-local selected runner, or blocked
        affinity/capability => 409 with no mutation
    - when multiple persisted `step.localActionOutcomes.<stepId>` summaries
      exist on the same run, response readback should prefer the terminal
      step's summary instead of older step-local action summaries
    - if a running step finishes after an external/local cancellation wins the
      persist race, the final stored run must remain `cancelled`
    - the create response may initially be `in_progress`
    - `GET /v1/responses/<response_id>` should converge to `completed`,
      `failed`, or `cancelled`
    - terminal direct-run readback now also includes bounded execution details
      under `metadata.executionSummary`
    - when one run contains both:
      - a failed step
      - a later succeeded or cancelled step
      terminal readback should still prefer the failed step for:
      - `terminalStepId`
      - `completedAt`
      - `failureSummary`
    - if stored shared-state exposes `structuredOutputs[key="response.output"]`,
      preserve that structured mixed output on `response.output`
    - keep the split explicit:
      - `response.output` is the transport payload
      - runtime/readback summaries stay under `metadata.executionSummary`
      - do not leak execution-summary fields into individual `output` items
    - runtime-backed readback now also includes bounded assignment identity:
      - `metadata.taskRunSpecId`
      - task-backed runtime execution now also injects bounded assignment
        context into step execution:
        - `taskContext`
        - `taskStructuredContext`
        - `taskInputArtifacts`
        - dependency-scoped `taskTransfer` from incoming planned handoffs
      - task-backed team planning now also shapes bounded inter-step handoffs
        under handoff `structuredData.taskTransfer`:
        - `title`
        - `objective`
        - `successCriteria`
        - bounded `requestedOutputs`
        - bounded `inputArtifacts`
      - runtime-backed response/recovery readback now also includes bounded
        persisted task assignment identity when a stored `taskRunSpec` exists:
        - response: `metadata.taskRunSpecSummary`
        - recovery detail: `taskRunSpecSummary` on team-run-backed recovery
          detail only
        - public team inspection: `inspection.taskRunSpecSummary`
        - fields:
          - `id`
          - `teamId`
          - `title`
          - `objective`
          - `createdAt`
          - `persistedAt`
          - `requestedOutputCount`
          - `inputArtifactCount`
      - runtime-backed detailed response readback now also includes bounded
        task assignment artifact refs:
        - `metadata.executionSummary.inputArtifactSummary.total`
        - `metadata.executionSummary.inputArtifactSummary.items[*].id`
        - `metadata.executionSummary.inputArtifactSummary.items[*].kind`
        - `metadata.executionSummary.inputArtifactSummary.items[*].title`
        - `metadata.executionSummary.inputArtifactSummary.items[*].path`
        - `metadata.executionSummary.inputArtifactSummary.items[*].uri`
        - terminal readback should use the terminal step's artifact set when
          present, otherwise the latest earlier step with artifacts
      - runtime-backed detailed response readback now also includes bounded
        consumed handoff transfer context:
        - `metadata.executionSummary.handoffTransferSummary.total`
        - `metadata.executionSummary.handoffTransferSummary.items[*].handoffId`
        - `metadata.executionSummary.handoffTransferSummary.items[*].fromStepId`
        - `metadata.executionSummary.handoffTransferSummary.items[*].fromAgentId`
      - `metadata.executionSummary.handoffTransferSummary.items[*].title`
      - `metadata.executionSummary.handoffTransferSummary.items[*].objective`
      - `metadata.executionSummary.handoffTransferSummary.items[*].requestedOutputCount`
      - `metadata.executionSummary.handoffTransferSummary.items[*].inputArtifactCount`
      - response readback prefers stored consumed transfer state when present;
        recovery detail falls back to planned handoff transfer data when no
        stored consumed summary exists
      - runtime-backed detailed response readback now also includes bounded
        orchestration timeline summary from durable shared-state history:
        - `metadata.executionSummary.orchestrationTimelineSummary.total`
        - `metadata.executionSummary.orchestrationTimelineSummary.items[*].type`
        - `metadata.executionSummary.orchestrationTimelineSummary.items[*].createdAt`
        - `metadata.executionSummary.orchestrationTimelineSummary.items[*].stepId`
        - `metadata.executionSummary.orchestrationTimelineSummary.items[*].note`
        - `metadata.executionSummary.orchestrationTimelineSummary.items[*].handoffId`
      - requested-output fulfillment reads now also include
        `metadata.executionSummary.requestedOutputSummary`
        - `total`
        - `fulfilledCount`
        - `missingRequiredCount`
        - bounded per-item `label`
        - bounded per-item `kind`
        - bounded per-item `format`
        - bounded per-item `destination`
        - bounded per-item `required`
        - bounded per-item `fulfilled`
        - bounded per-item `evidence`
      - required requested-output policy reads now also include
        `metadata.executionSummary.requestedOutputPolicy`
        - `status`
        - `message`
        - `missingRequiredLabels`
      - terminal readback uses the terminal step's requested-output contract,
        not older step requests
      - if required requested outputs are still missing at terminal readback,
        the response now reads back as:
        - `status = failed`
        - `metadata.executionSummary.failureSummary.code = requested_output_required_missing`
        - stored runtime/service terminal state should also already be `failed`
          for those same clearly missing-required cases
      - explicit terminal step failure still wins over the derived
        `requested_output_required_missing` fallback
      - if the next runnable step would exceed
        `constraints.providerBudget.maxRequests`, stored runtime/service state
        should fail before execution with:
        - `failure.code = task_provider_request_limit_exceeded`
      - if cumulative stored provider usage already exceeds
        `constraints.providerBudget.maxTokens`, stored runtime/service state
        should fail before the next step executes with:
        - `failure.code = task_provider_token_limit_exceeded`
      - when the stored execution callback reports real usage, response
        readback now also includes:
        - `metadata.executionSummary.providerUsageSummary.ownerStepId`
        - `metadata.executionSummary.providerUsageSummary.generatedAt`
        - `metadata.executionSummary.providerUsageSummary.inputTokens`
        - `metadata.executionSummary.providerUsageSummary.outputTokens`
        - `metadata.executionSummary.providerUsageSummary.reasoningTokens`
        - `metadata.executionSummary.providerUsageSummary.totalTokens`
      - terminal step provider-usage summary wins over older step summaries
      - resumed/drained operator lifecycle reads now also include
        `metadata.executionSummary.operatorControlSummary`
        - `humanEscalationResume.resumedAt`
        - `humanEscalationResume.note`
        - `targetedDrain.requestedAt`
        - `targetedDrain.status`
        - `targetedDrain.reason`
        - `targetedDrain.skipReason`
      - local-action terminal reads now also include
        `metadata.executionSummary.localActionSummary`
      - cancelled terminal reads now also include
        `metadata.executionSummary.cancellationSummary`
      - current hardening checkpoint summary:
        - response metadata stays compact and `stepSummaries` carry per-step
          routing
        - recovery detail stays the lifecycle/timeline surface
        - targeted drain, cancellation fallback, requested-output policy,
          failure precedence, provider-usage precedence, input-artifact
          precedence/fallback, and transfer precedence/fallback are all now
          explicit and test-backed
  - mixed-provider cancelled local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "cancels auracall-cross-service-tooling local action"`
    - current expected posture:
      - initial `auracall-cross-service-tooling` run is `cancelled` with
        `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Grok after requesting one bounded local shell action:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = cancelled`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.cancelled = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_CROSS_SERVICE_CANCELLATION_LIVE_SMOKE_OK`
  - mixed-provider rejected local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "rejects auracall-cross-service-tooling local action"`
    - current expected posture:
      - initial `auracall-cross-service-tooling` run is `cancelled` with
        `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Grok after requesting one bounded local shell action:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = rejected`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.rejected = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
          `AURACALL_CROSS_SERVICE_REJECTION_LIVE_SMOKE_OK`
  - mixed-provider approval live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "approves auracall-cross-service-tooling human escalation"`
    - current expected posture:
      - initial `auracall-cross-service-tooling` run is `cancelled` with
        `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Grok after one policy-blocked local shell action
      - existing `POST /status` `resume-human-escalation`, then `drain-run`,
        completes the same team run
      - this is operator approval to continue after a blocked action, not a
        `localActionControl.resolve-request` `approved` mutation
      - final stored/readback state includes:
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
          `AURACALL_CROSS_SERVICE_APPROVAL_LIVE_SMOKE_OK`
  - reverse-order mixed-provider approval live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "approves auracall-reverse-cross-service-tooling human escalation"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-tooling` run is `cancelled`
        with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on ChatGPT after one policy-blocked local shell action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - existing `POST /status` `resume-human-escalation`, then `drain-run`,
        completes the same team run
      - this is operator approval to continue after a blocked action, not a
        `localActionControl.resolve-request` `approved` mutation
      - final stored/readback state includes:
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
        - stored local action remains `rejected` as evidence of the original
          policy stop
      - final terminal step summary
          `AURACALL_REVERSE_CROSS_SERVICE_APPROVAL_LIVE_SMOKE_OK`
  - reverse-order mixed-provider cancelled local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "cancels auracall-reverse-cross-service-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-tooling` run is `cancelled`
        with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on ChatGPT after requesting one bounded local shell
        action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = cancelled`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.cancelled = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_REVERSE_CROSS_SERVICE_CANCELLATION_LIVE_SMOKE_OK`
  - reverse-order mixed-provider rejected local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "rejects auracall-reverse-cross-service-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-tooling` run is `cancelled`
        with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on ChatGPT after requesting one bounded local shell
        action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = rejected`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.rejected = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_REVERSE_CROSS_SERVICE_REJECTION_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini approval live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_GEMINI_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "approves auracall-reverse-cross-service-gemini-tooling human escalation"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-gemini-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on Gemini after one policy-blocked local shell action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - existing `POST /status` `resume-human-escalation`, then `drain-run`,
        completes the same team run
      - this is operator approval to continue after a blocked action, not a
        `localActionControl.resolve-request` `approved` mutation
      - final stored/readback state includes:
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
        - stored local action remains `rejected` as evidence of the original
          policy stop
      - final terminal step summary
        `AURACALL_REVERSE_CROSS_SERVICE_GEMINI_APPROVAL_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini cancelled local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_GEMINI_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "cancels auracall-reverse-cross-service-gemini-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-gemini-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on Gemini after requesting one bounded local shell
        action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = cancelled`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.cancelled = 1`
        - bounded `operatorControlSummary`
      - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_REVERSE_CROSS_SERVICE_GEMINI_CANCELLATION_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini rejected local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_REVERSE_GEMINI_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "rejects auracall-reverse-cross-service-gemini-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-gemini-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Grok:
        - `runtimeProfileId = auracall-grok-auto`
        - `service = grok`
      - step 2 pauses on Gemini after requesting one bounded local shell
        action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = rejected`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.rejected = 1`
        - bounded `operatorControlSummary`
      - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_REVERSE_CROSS_SERVICE_GEMINI_REJECTION_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini-to-ChatGPT approval live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_TO_CHATGPT_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "approves auracall-reverse-cross-service-chatgpt-tooling human escalation"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-chatgpt-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Gemini:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - step 2 pauses on ChatGPT after one policy-blocked local shell action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - existing `POST /status` `resume-human-escalation`, then `drain-run`,
        completes the same team run
      - this is operator approval to continue after a blocked action, not a
        `localActionControl.resolve-request` `approved` mutation
      - final stored/readback state includes:
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - stored local action remains `rejected` as evidence of the original
          policy stop
      - final terminal step summary
        `AURACALL_GEMINI_TO_CHATGPT_APPROVAL_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini-to-ChatGPT cancelled local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_TO_CHATGPT_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "cancels auracall-reverse-cross-service-chatgpt-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-chatgpt-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Gemini:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - step 2 pauses on ChatGPT after requesting one bounded local shell
        action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = cancelled`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.cancelled = 1`
        - bounded `operatorControlSummary`
      - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_GEMINI_TO_CHATGPT_CANCELLATION_LIVE_SMOKE_OK`
  - reverse-order mixed-provider Gemini-to-ChatGPT rejected local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_TO_CHATGPT_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "rejects auracall-reverse-cross-service-chatgpt-tooling local action"`
    - current expected posture:
      - initial `auracall-reverse-cross-service-chatgpt-tooling` run is
        `cancelled` with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on Gemini:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - step 2 pauses on ChatGPT after requesting one bounded local shell
        action:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = rejected`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.rejected = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_GEMINI_TO_CHATGPT_REJECTION_LIVE_SMOKE_OK`
  - mixed-provider Gemini approval live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "approves auracall-cross-service-gemini-tooling human escalation"`
    - current expected posture:
      - initial `auracall-cross-service-gemini-tooling` run is `cancelled` with
        `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Gemini after one policy-blocked local shell action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - existing `POST /status` `resume-human-escalation`, then `drain-run`,
        completes the same team run
      - this is operator approval to continue after a blocked action, not a
        `localActionControl.resolve-request` `approved` mutation
      - final stored/readback state includes:
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
  - mixed-provider Gemini rejected local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "rejects auracall-cross-service-gemini-tooling local action"`
    - current expected posture:
      - initial `auracall-cross-service-gemini-tooling` run is `cancelled`
        with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Gemini after requesting one bounded local shell
        action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = rejected`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.rejected = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_CROSS_SERVICE_GEMINI_REJECTION_LIVE_SMOKE_OK`
  - mixed-provider Gemini cancelled local-action live proof:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_GEMINI_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts -t "cancels auracall-cross-service-gemini-tooling local action"`
    - current expected posture:
      - initial `auracall-cross-service-gemini-tooling` run is `cancelled`
        with `finalOutputSummary = paused for human escalation`
      - step 1 succeeds on ChatGPT:
        - `runtimeProfileId = wsl-chrome-2`
        - `service = chatgpt`
      - step 2 pauses on Gemini after requesting one bounded local shell
        action:
        - `runtimeProfileId = auracall-gemini-pro`
        - `service = gemini`
      - `POST /status` `localActionControl.resolve-request` with
        `resolution = cancelled`, then `resume-human-escalation`, then
        `drain-run` completes the same team run
      - final stored/readback state includes:
        - `metadata.executionSummary.localActionSummary.counts.cancelled = 1`
        - bounded `operatorControlSummary`
        - bounded resumed execution timeline on
          `GET /status/recovery/<run_id>`
      - final terminal step summary
        `AURACALL_CROSS_SERVICE_GEMINI_CANCELLATION_LIVE_SMOKE_OK`
  - optional recovery summary:
    - `curl http://127.0.0.1:8080/status?recovery=true`
    - optional per-run detail:
      - `curl http://127.0.0.1:8080/status/recovery/<run_id>`
    - current expected recovery fields include:
      - `reclaimableRunIds`
      - `recoverableStrandedRunIds`
      - `activeLeaseRunIds`
      - `strandedRunIds`
      - `cancelledRunIds`
      - `idleRunIds`
      - `activeLeaseHealth.freshRunIds`
      - `activeLeaseHealth.staleHeartbeatRunIds`
      - `activeLeaseHealth.suspiciousIdleRunIds`
      - `activeLeaseHealth.reasonsByRunId`
      - `leaseRepair.locallyReclaimableRunIds`
      - `leaseRepair.inspectOnlyRunIds`
      - `leaseRepair.notReclaimableRunIds`
      - `leaseRepair.repairedRunIds`
      - `leaseRepair.reasonsByRunId`
      - `metrics.reclaimableCount`
      - `metrics.recoverableStrandedCount`
      - `metrics.activeLeaseCount`
      - `metrics.strandedCount`
      - `metrics.idleCount`
      - `metrics.actionableCount`
      - `metrics.nonExecutableCount`
      - `localClaim.runnerId`
      - `localClaim.selectedRunIds`
      - `localClaim.blockedRunIds`
      - `localClaim.notReadyRunIds`
      - `localClaim.unavailableRunIds`
      - `localClaim.statusByRunId`
      - `localClaim.reasonsByRunId`
    - startup recovery/batch-drain reporting now collapses repeated skipped
      states per run and suppresses follow-up terminal `no-runnable-step`
      entries after a run already executed in the same bounded batch
    - `GET /status/recovery/<run_id>` stays a separate read-only detail surface
      so `/status?recovery=true` can stay compact
    - compact summary contract:
      - `GET /status?recovery=true` should not grow per-run detail fields such
        as:
        - `taskRunSpecId`
        - `orchestrationTimelineSummary`
        - `handoffTransferSummary`
        - `leaseHealth`
    - compact local-claim contract:
      - top-level `/status.localClaimSummary` stays the direct-run local-claim
        snapshot
      - `recoverySummary.localClaim` is the recovery-filtered aggregate that
        follows `sourceKind=direct|team-run|all`
    - compact server-posture contract:
      - top-level `/status.runner` and `/status.backgroundDrain` stay the
        server posture snapshot
      - recovery/source filters do not reshape them into recovery-scoped
        fields
      - they continue to describe the current server process even when
        `recoverySummary` is filtered to `team-run` or `all`
    - the per-run detail surface now also includes bounded assignment identity:
      - `taskRunSpecId`
    - the per-run detail surface now also includes bounded orchestration
      timeline summary from durable shared-state history:
      - `orchestrationTimelineSummary.total`
      - `orchestrationTimelineSummary.items[*].type`
      - `orchestrationTimelineSummary.items[*].createdAt`
      - `orchestrationTimelineSummary.items[*].stepId`
      - `orchestrationTimelineSummary.items[*].note`
      - `orchestrationTimelineSummary.items[*].handoffId`
    - the per-run detail surface now also includes bounded consumed handoff
      transfer context when incoming planned handoffs carry task-aware transfer
      data:
      - `handoffTransferSummary.total`
      - `handoffTransferSummary.items[*].handoffId`
      - `handoffTransferSummary.items[*].fromStepId`
      - `handoffTransferSummary.items[*].fromAgentId`
      - `handoffTransferSummary.items[*].title`
      - `handoffTransferSummary.items[*].objective`
      - `handoffTransferSummary.items[*].requestedOutputCount`
      - `handoffTransferSummary.items[*].inputArtifactCount`
    - the per-run detail surface now also reports active-lease health under
      `leaseHealth`, including whether the lease looks fresh, stale-heartbeat,
      or suspiciously idle
    - bounded host drain and startup recovery logs now also break out
      `stale-heartbeat` separately; `suspiciously-idle` remains read-only
    - `POST /status` now also supports one bounded stale-heartbeat repair
      action:
      - `{"leaseRepair":{"action":"repair-stale-heartbeat","runId":"..."}}`
      - it succeeds only when the run is currently `stale-heartbeat` and the
        durable repair posture is already `locally-reclaimable`
      - successful action results should also include bounded
        `reconciliationReason`
      - suspiciously-idle leases remain diagnostic-only and should return 409
    - recovery summary/detail now also surface bounded operator attention for
      stale-heartbeat and suspiciously-idle active-lease cases:
      - `recoverySummary.attention.staleHeartbeatInspectOnlyRunIds`
      - `recoverySummary.attention.reasonsByRunId`
      - per-run `attention.kind = stale-heartbeat-inspect-only|suspiciously-idle`
    - recovery summary/detail now also surface bounded cancellation readback:
      - `recoverySummary.cancelledRunIds`
      - `recoverySummary.cancellation.reasonsByRunId`
      - per-run `cancellation.cancelledAt`
      - per-run `cancellation.source`
      - per-run `cancellation.reason`
    - startup recovery logs now also emit bounded stale-heartbeat attention
      when unrepaired inspect-only cases remain:
      - `attention=stale-heartbeat-inspect-only:<count>`
      - `attention=suspiciously-idle:<count>` when active leases look
        idle-but-not-stale
    - the per-run detail surface now also reports the configured local runner's
      claim posture under `localClaim`, including whether it is currently
      selected for local claiming
    - host recovery no longer treats every expired active lease as
      automatically reclaimable
    - bounded host lease repair now first consults persisted runner liveness:
      - stale or missing runner + expired lease => locally reclaimable
      - active runner + expired lease => still reported as `active-lease`
    - when startup recovery is capped, only still-executable work should report
      `limit-reached`; idle and active-lease runs should keep their real skip
      reasons
    - mixed-batch host drain now prioritizes actionable work in this order:
      - runnable
      - recoverable stranded
      - then non-executable classes
    - within each class, scheduling is intentionally oldest-first by
      `createdAt`
    - when both actionable classes are present and `maxRuns > 1`, one slot is
      reserved for the oldest recoverable-stranded run and the remaining slots
      go to oldest runnable runs
    - startup recovery logs now also emit aggregate metrics aligned with the
      same vocabulary; runner-aware startup skips may now also surface
      `claim-owner-unavailable` when the local runner cannot safely claim work:
      - `deferred-by-budget`
      - `active-lease`
      - `stale-heartbeat`
      - `stranded`
      - `idle`
    - current mixed-batch priority is:
      - runnable
      - recoverable stranded
      - then non-executable classes
- Service-volatility refactor rule: do not treat this as a pure config shuffle. Every extraction phase must keep a named regression set green and every service slice must declare its own acceptance bar before implementation starts. See [service-volatility-refactor-plan.md](/home/ecochran76/workspace.local/auracall/docs/dev/plans/0012-2026-04-14-service-volatility-refactor.md) and [service-volatility-service-plan-template.md](/home/ecochran76/workspace.local/auracall/docs/dev/service-volatility-service-plan-template.md).
- Gemini unit/regression: `pnpm vitest run tests/gemini.test.ts tests/gemini-web`.
- Gemini support matrix checkpoint:
  - API:
    - text: supported
    - streaming: supported
    - search/tooling: partially supported through `web_search_preview -> googleSearch`
    - attachments/files: not yet documented as a first-class Gemini API surface
    - image generation/editing: not yet documented as a first-class Gemini API surface
- Gemini web/browser:
    - text: supported
    - attachments: supported
    - YouTube: supported
    - generate-image: supported
    - edit-image: supported
    - Gem URL targeting: supported
    - cookie/login flow: supported
    - conversation context read: supported for canonical `messages[]`, visible
      sent `files[]`, and proven generated `artifacts[]`
    - conversation files list: supported for visible direct `/app/<id>` upload
      chips
    - conversation files fetch: partially supported for visible direct
      `/app/<id>` upload chips, including text-file chips and uploaded-image
      chips
    - account files: not supported
    - conversation artifact lane: closed for now at the proven
      image/music/video/canvas/deep-research surfaces; only reopen for
      regressions or newly proven live DOM surfaces
  - browser doctor: partially supported
      - `auracall doctor --target gemini --json` now reports live account
        identity plus detected Gemini feature signature when a managed Gemini
        browser session is alive
      - when browser-tools sees a blocking page such as `google.com/sorry`,
        CAPTCHA / reCAPTCHA, Cloudflare, or another human-verification
        interstitial, the embedded runtime report now carries a first-class
        blocking classification instead of only raw page text
      - package-owned `browser-tools probe|doctor` now also exit nonzero on
        those blocking pages instead of quietly reporting them as ordinary page
        probes
      - `auracall doctor --target ...` and `auracall features --target ...`
        now exit nonzero on those blocking surfaces and tell the operator to
        clear the page manually before retrying
      - `auracall features snapshot|diff --target ...` now also stop early on
        those blocking surfaces instead of writing misleading anti-drift output
      - `auracall setup --target ...` now also checks for a blocking surface
        after login and before live verification, so setup stops early instead
        of burning a verification run on a page that already needs manual
        clearance
      - `auracall login --target ...` now checks the managed browser after
        launch and exits nonzero with the same manual-clear guidance if the
        page is already blocked
      - shared browser execution now also does one early blocking-page probe
        after navigation settles, so headful browser runs stop before deeper
        automation on obviously blocked pages and leave the browser open for
        manual clearance
      - `auracall features --target gemini --json` is now the first-class live
        feature-discovery surface for Gemini tools, toggles, and upload paths
      - when browser-service can gather a live Gemini `uiList` census, doctor
        now merges that runtime evidence into `featureStatus.detected.evidence`
        instead of silently trusting a weaker provider-local fallback probe
      - full live selector diagnosis is still not implemented in
        `auracall doctor`, but package-owned DOM discovery is now available via
        `pnpm tsx scripts/browser-tools.ts ... search`
      - current live Gemini drawer proof on `default`:
        - `search --class-includes toolbox-drawer-button --text Tools`
          finds the real `Tools` opener
        - after opening the drawer, `search --class-includes toolbox-drawer-item-list-button --role menuitemcheckbox`
          finds:
          - `Create image`
          - `Canvas`
          - `Deep research`
          - `Create video`
          - `Create music`
          - `Guided learning`
        - `search --aria-label "Personal Intelligence" --role switch`
          returns the live switch state
        - `ls --limit-per-kind 10`
          returns the broader page census:
          - drawer surface under `menus`
          - drawer rows under `menuItems`
          - `Personal Intelligence` under `switches`
          - prompt composer under `inputs`
          - upload surfaces under `uploadCandidates`
          - hidden chooser paths under `fileInputs` when present
          - heuristic interaction hints such as:
            - `hard-click-preferred`
            - `hover-or-pointer-state-likely`
            - `file-chooser-candidate`
- Browser feature discovery:
  - `auracall features --target gemini --json`
    - returns `contract: "auracall.browser-features"`
    - current live `default` proof includes:
      - `modes`
        - `canvas`
        - `create image`
        - `create music`
        - `create video`
        - `deep research`
      - `toggles.personal intelligence = true`
      - browser-tools `uiList` evidence with:
        - `menus = 1`
        - `menuItems = 6`
        - `switches = 1`
        - `uploadCandidates = 3`
  - `auracall features snapshot --target gemini --json`
    - writes under:
      - `~/.auracall/feature-snapshots/<auracallProfile>/gemini/`
    - updates:
      - `latest.json`
  - `auracall features diff --target gemini --json`
    - compares live discovery to the latest saved snapshot by default
    - current live `default` proof returns:
      - `changed = false`
  - treat unsupported or undocumented cells as non-commitments until the Gemini completion plan advances them.
- Browser smokes: `pnpm test:browser` (builds, checks DevTools port 45871 or `AURACALL_BROWSER_PORT`, then runs headful browser smokes with GPT-5.2 for most cases and GPT-5.2 Pro for the reattach + markdown checks). Requires a signed-in Chrome profile; runs headful but now starts Chrome with `browser.hideWindow` as a best-effort minimized/no-focus-steal launch. On the current WSL/X11 stack, the active window stays unchanged even though DevTools may still report `windowState: normal`.
- Grok browser smoke: `pnpm test:grok-smoke` (requires an active Grok session; uses the Aura-Call browser registry or `AURACALL_BROWSER_PORT`).
- Grok acceptance bar: run `DISPLAY=:0.0 pnpm test:grok-acceptance` on the authenticated WSL Grok profile before calling Grok browser support "fully functional." The script executes the canonical WSL-primary checklist from `docs/dev/smoke-tests.md` and covers project CRUD, instructions/files CRUD, project-knowledge cache freshness, account-wide `/files` CRUD plus `account-files` cache freshness, project conversation CRUD, root/non-project conversation-file parity, append-only `conversations files add`, markdown capture, the medium-file guard, and cleanup. If Grok's root conversation list lags after a browser-file prompt, the runner now logs that and falls back to the fresh browser session `conversationId` so the rest of the CRUD path still gets validated on the real new conversation.
- ChatGPT project lifecycle + project-management CRUD is green on the authenticated managed WSL Chrome path: list/create/rename/delete, create-time `--memory-mode global|project`, `projects files add|list|remove --target chatgpt`, and `projects instructions get|set --target chatgpt`. Source add/remove now verify success against a fresh `Sources` reload rather than trusting only the first immediate post-picker row, and instructions writes verify by reopening the project settings sheet and confirming the persisted textarea value. The project surface is effectively complete for current native UI purposes; clone stays out of scope unless ChatGPT later exposes a real clone action. Historical closure notes now live in `docs/dev/plans/legacy-archive/0019-2026-04-08-chatgpt-conversation-surface-plan.md`.
- ChatGPT root conversation list/read/rename/delete are green on the authenticated managed WSL Chrome path, and the conversation context surface now includes more than sent user-turn file tiles. `auracall conversations files list <conversationId> --target chatgpt` still returns stable synthetic refs for real sent uploads, but `auracall conversations context get <conversationId> --target chatgpt --json-only` now also enriches ChatGPT context with `sources[]` from assistant citation/content-reference metadata plus `artifacts[]` for downloadable `sandbox:/...` outputs, generated `image_asset_pointer` artifacts, `ada_visualizations` table/spreadsheet artifacts, spreadsheet-like `.csv` / `.xlsx` markdown downloads, DOM-only assistant-turn `button.behavior-btn` artifacts, and canvas/textdoc blocks. Live proof on `69c3e6d0-3550-8325-b10e-79d946e31562` returns file-backed `sources[]` plus downloadable artifacts such as `updated skill.zip`, `combined JSON extraction`, and `combined BibTeX extraction`; live proof on image chat `69bc77cf-be28-8326-8f07-88521224abeb` returns four `image` artifacts with `sediment://...` asset pointers plus size/dimensions and generation metadata; live proof on CSV/table chat `bc626d18-8b2e-4121-9c4a-93abb9daed4b` returns two `spreadsheet` artifacts backed by ChatGPT `file_id`s; live proof on spreadsheet-download chat `69ca9d71-1a04-8332-abe1-830d327b2a65` returns `parabola_trendline_demo.xlsx` as a `spreadsheet` artifact; live proof on the DOCX + canvas chat `69caa22d-1e2c-8329-904f-808fb33a4a56` now fills `canvas.metadata.contentText` from the visible textdoc DOM; and live proof on the “vibe coding” chat `69bded7e-4a88-8332-910f-cab6be0daf9b` now returns `artifactCount = 86` from the assistant-turn button surface. The important implementation nuance is that direct in-page `fetch('/backend-api/conversation/<id>')` can return a JSON 404 even on a page that visibly hydrates correctly, so the adapter now falls back to CDP `Network.responseReceived` + `Network.loadingFinished` + `getResponseBody` on a reload of the already-open conversation route. Another important artifact nuance is that many inline binary download buttons do not use fetch/XHR at all; a native click programmatically triggers an anchor click to a signed `backend-api/estuary/content?id=file_...` URL. The root rename repair still matters because ChatGPT's current header `Open conversation options` menu is not a rename surface; rename must come from the sidebar-row `Open conversation options for ...` menu on the home/list page, the edit field that appears there is just a plain visible `input[type=\"text\"]`, and the authoritative completion signal is that the same conversation id reappears as the top root-list row with the new title after a short lag. Root delete now uses that same list-first row surface with header delete only as fallback, standalone `auracall delete <conversationId> --target chatgpt` accepts a raw fresh ChatGPT conversation id directly, and the full guarded `scripts/chatgpt-acceptance.ts` runner is now green end to end even when this account hits real ChatGPT cooldowns during rename/delete cleanup. For project chats, keep the project page conversation list as the authoritative surface; the abbreviated sidebar subset shown while a project is selected is not the full catalog. For real small-text upload validation, force native uploads with `--browser-attachments always`; under `auto`, ChatGPT can inline the file content into the prompt and never create a real attachment tile. Treat those conversation files as read-only after send: users can remove them from the composer before sending, but durable delete belongs to ChatGPT project `Sources`, not post-send conversation history.
- ChatGPT now has an opt-in artifact materialization path: `auracall conversations artifacts fetch <conversationId> --target chatgpt`. On the current managed WSL Chrome profile, serialized live runs materialize generated images into `conversation-attachments/<conversationId>/files/.../*.png`, inline `ada_visualizations` table artifacts into CSVs in the same cache tree, visible textdoc/canvas blocks into text files when `contentText` is present or can be filled from the DOM, and signed anchor-backed binary downloads into real files by capturing the generated `backend-api/estuary/content?id=file_...` URL and fetching it directly. Each run also writes a sidecar `conversation-attachments/<conversationId>/artifact-fetch-manifest.json` so operators can inspect per-artifact `materialized|skipped|error` results without changing the existing attachment manifest shape. Live proof:
  - `69bc77cf-be28-8326-8f07-88521224abeb` -> `artifactCount = 4`, `materializedCount = 4`
  - `bc626d18-8b2e-4121-9c4a-93abb9daed4b` -> `artifactCount = 2`, `materializedCount = 2`
  - `69caa22d-1e2c-8329-904f-808fb33a4a56` -> `artifactCount = 2`, `materializedCount = 2` (`comment_demo.docx` + `Short Document With Comments.txt`)
  - `69ca9d71-1a04-8332-abe1-830d327b2a65` -> `artifactCount = 1`, `materializedCount = 1` (`parabola_trendline_demo.xlsx`)
  - `69d04b50-3c88-8325-8240-0d838d47ee50` -> `artifactCount = 2`, `materializedCount = 1` (`auracall-artifact-smoke-oxmhrl.docx`)
  - `69d061ea-5098-8326-a2e4-70e38d845190` -> `artifactCount = 1`, `materializedCount = 1` (`auracall-identity-matrix-qmrqpe.xlsx`)
  - `69d06243-62f8-832f-8fc7-cba9e0148044` -> `artifactCount = 1`, `materializedCount = 1` (`Kitten enjoying ice skating fun.png`)
  The workbook case matters because ChatGPT exposes it through the embedded spreadsheet card's unlabeled header button rather than a filename-matching behavior button; Aura-Call now uses that fallback for `sandbox:/...xlsx` spreadsheet artifacts. The earlier canvas sample `69c8a0fc-c960-8333-8006-c4d6e6704e6e` no longer reproduces a live canvas artifact on this account, so do not use it as a current smoke. Also, do not run multiple live ChatGPT artifact fetches in parallel against the same managed browser; they share one active signed-in tab and can interfere with each other's navigation/state.
  One current side finding from the fresh generated-image proof: the direct browser-mode wrapper appeared to linger after the image artifact was already visible and materializable via `conversations context get` / `conversations artifacts fetch`. Record that as a later follow-up, not a current blocker.
- ChatGPT serialized full-context ingestion has now also been re-proven on a small representative chat set where each conversation was read first and then materialized:
  - `69bc77cf-be28-8326-8f07-88521224abeb` -> context `messages = 4`, `files = 1`, `sources = 0`, `artifacts = 4`; artifact fetch `materializedCount = 4`
  - `69caa22d-1e2c-8329-904f-808fb33a4a56` -> context `messages = 4`, `files = 0`, `sources = 0`, `artifacts = 2`, `canvasArtifacts = 1`; artifact fetch `materializedCount = 2`
  - `69ca9d71-1a04-8332-abe1-830d327b2a65` -> context `messages = 4`, `files = 0`, `sources = 0`, `artifacts = 1`, `spreadsheetArtifacts = 1`; artifact fetch `materializedCount = 1`
  During `conversations context get` and `conversations artifacts fetch`, the ChatGPT adapter now watches for a visible `Too many requests` / `...too quickly` dialog, dismisses it, waits about 15 seconds, and retries once before surfacing a real rate-limit failure. This particular serialized smoke set stayed below the throttle threshold, so the recovery path was present but did not have to fire live.
- ChatGPT project-scoped conversation list/rename/delete should now also be treated as live on the managed WSL Chrome path when `--project-id <g-p-...>` is supplied: the provider prefers the project page `Chats` tabpanel (`SECTION -> OL -> LI` in the main content area) over the sidebar subset when scraping project chats or verifying project-scoped rename/delete, and the phased guarded acceptance runner has now re-proven that slice live.
- ChatGPT browser-mode dialog selection now tracks the live composer surface: browser defaults resolve to `Instant`, `--browser-thinking-time` should use `standard|extended` (`light|heavy` still work as legacy aliases), and `--browser-composer-tool <tool>` applies ChatGPT add-ons like `web-search`, `canvas`, and `google-drive` from the `Add files and more` menu. Pro is a model-picker lane, not a Standard/Extended depth selector; Pro smokes should use `--model gpt-5.2-pro` with the default model strategy so AuraCall can verify the `Pro` row before selecting the depth. File upload remains the normal attachment flow (`--file` / composer upload), not a composer-tool selection.
- ChatGPT existing-conversation tool state is now an inspected runtime surface, not just a click side effect: browser runs persist the actual selected add-on in session metadata as `browser.runtime.composerTool` (for example `web search`), and final ChatGPT browser session metadata now also persists the normalized `conversationId` alongside `tabUrl`, which makes prompt-matched acceptance/debug lookups reliable.
- ChatGPT live browser work now carries a persisted profile-scoped guard under `~/.auracall/cache/providers/chatgpt/__runtime__/rate-limit-<profile>.json`: mutating ChatGPT llmservice CRUD operations are spaced apart automatically, ChatGPT browser-mode prompt runs consult the same guard before sending another live write, and both paths now also enforce a rolling per-profile write budget before ChatGPT has a chance to surface a visible `Too many requests` dialog. If the live UI still does expose a `Too many requests` / `...too quickly` failure, later ChatGPT live CRUD or browser-mode calls fail fast on that cooldown instead of continuing to hammer the account from fresh CLI processes.
- ChatGPT context/artifact read paths now also have local dialog recovery inside the provider adapter itself: if ChatGPT throws a visible rate-limit modal during `conversations context get` or `conversations artifacts fetch`, Aura-Call dismisses that modal, pauses briefly, and retries once before letting the higher-level persisted guard take over.
- Remaining Grok breadth work after the acceptance bar is archived in `docs/dev/plans/legacy-archive/0024-2026-04-08-grok-remaining-crud-plan.md`. Conversation-scoped file read/list/cache parity is now live for both project and non-project conversations via `auracall conversations files list <conversationId> --target grok [--project-id <id>]`; any resumed mutation follow-up should treat that archive note as background only.
- Interactive browser onboarding: `pnpm tsx bin/auracall.ts wizard` (preferred first-run path; detects candidate browser/profile sources, writes a browser-profile-backed `~/.auracall/config.json` entry using `browserFamilies.<name>` + `profiles.<name>.browserFamily`, then hands off to the normal setup/login/verification flow). On WSL, prefer the WSL Chrome choice first and keep that primary setup on the Aura-Call `default` profile; treat Windows Chrome as an advanced/manual-debug path in a separate named profile until a live DevTools endpoint is proven.
- Browser profile/setup inspection: `pnpm tsx bin/auracall.ts doctor --target grok --local-only --prune-browser-state` (reports the managed profile path, inferred source profile, Chrome-level Google-account state from the managed profile `Local State` plus `Default/Preferences`, and dead/legacy `~/.auracall/browser-state.json` entries without attaching to Chrome). Omit `--local-only` to also probe the live signed-in account on managed ChatGPT/Grok sessions. Add `--json` for a machine-readable `auracall.browser-doctor` contract; non-`--local-only` JSON reports embed the stable `browser-tools.doctor-report` contract when a managed browser instance is alive.
- Scriptable browser onboarding: `pnpm tsx bin/auracall.ts setup --target grok` (inspects the managed profile, opens the managed login profile if needed, refreshes it from the source Chrome profile when the source cookies are newer, then sends a real verification prompt through that same profile). The setup report now includes the detected signed-in account for managed ChatGPT/Grok sessions. Add `--force-reseed-managed-profile` if you want to rebuild the managed profile from the source profile before login. Add `--json` for a machine-readable `auracall.browser-setup` contract; it embeds the before/after `auracall.browser-doctor` reports plus explicit login/verification step status.
- Alternate-source bootstrap test: add `--browser-bootstrap-cookie-path <path>` to `auracall setup` / `auracall login` when you want to seed the managed Aura-Call profile from a different Chromium profile (for example Windows Brave) while still launching WSL Chrome at runtime.
- If the alternate source lives on Windows and the Chromium `Network/Cookies` DB is unreadable from WSL, expect the managed profile bootstrap to copy non-cookie auth state only; the browser can still launch, but CRUD/auth verification may stay guest-only until you sign in once in the Aura-Call-managed profile.
- Grok context sources smoke: `pnpm tsx scripts/verify-grok-context-sources.ts <conversationId> [projectId]` (validates `sources[]` extraction from inline links + Sources sidebar accordions).
- Grok context CLI source parity smoke:
  - live: `ORACLE_NO_BANNER=1 NODE_NO_WARNINGS=1 pnpm tsx bin/auracall.ts conversations context get <conversationId> --target grok --json-only | jq '.sources | length'`
  - cache: `ORACLE_NO_BANNER=1 NODE_NO_WARNINGS=1 pnpm tsx bin/auracall.ts cache context get <conversationId> --provider grok | jq '.context.sources | length'`
- Cache context list smoke (bounded + bannerless for automation): `pnpm tsx bin/auracall.ts cache context list --provider grok --limit 5 --json-only`
- Cache context keyword search smoke: `pnpm tsx bin/auracall.ts cache context search "oracle" --provider grok --limit 5`.
- Cache context semantic search smoke: `OPENAI_API_KEY=... pnpm tsx bin/auracall.ts cache context semantic-search "oracle" --provider grok --limit 5`.
- Cache-only commands such as `cache export`, `cache context list`, and
  `cache context get` should read provider cache state without resolving or
  launching a live browser target.
- Cache source catalog smoke: `pnpm tsx bin/auracall.ts cache sources list --provider grok --limit 10`.
- Cache artifact catalog smoke: `pnpm tsx bin/auracall.ts cache artifacts list --provider grok --limit 10`.
- Cache file catalog smoke: `pnpm tsx bin/auracall.ts cache files list --provider grok --limit 10`.
- Cache file pointer resolve smoke: `pnpm tsx bin/auracall.ts cache files resolve --provider grok --limit 20` (use `--missing-only` to focus orphan/missing local paths).
- Cache integrity doctor smoke: `pnpm tsx bin/auracall.ts cache doctor --provider grok --json` (use `--strict` to fail on warnings; JSON now includes aggregated conversation inventory summary counts).
- Cache repair smoke:
  - dry-run: `pnpm tsx bin/auracall.ts cache repair --provider grok --actions all --json`
  - apply single action: `pnpm tsx bin/auracall.ts cache repair --provider grok --identity-key <key> --actions rebuild-index --apply --yes --json`
  - parity drift actions:
    - `pnpm tsx bin/auracall.ts cache repair --provider grok --identity-key <key> --actions prune-orphan-source-links --json`
    - `pnpm tsx bin/auracall.ts cache repair --provider grok --identity-key <key> --actions prune-orphan-file-bindings --json`
    - `pnpm tsx bin/auracall.ts cache repair --provider grok --identity-key <key> --actions prune-orphan-artifact-bindings --json`
- Cache clear/compact/cleanup smoke:
  - clear dry-run: `pnpm tsx bin/auracall.ts cache clear --provider grok --identity-key <key> --dataset context --json` (JSON now includes `inventoryBefore` / `inventoryAfter`)
  - compact: `pnpm tsx bin/auracall.ts cache compact --provider grok --identity-key <key> --json`
  - cleanup dry-run: `pnpm tsx bin/auracall.ts cache cleanup --provider grok --identity-key <key> --days 30 --json` (JSON now includes `inventoryBefore` / `inventoryAfter`)
- Cache refresh hydration modes smoke:
  - conservative (existing IDs only): `pnpm tsx bin/auracall.ts cache --provider grok --refresh --include-history --history-limit 200`
  - opt-in project-only insertion: `pnpm tsx bin/auracall.ts cache --provider grok --refresh --include-history --history-limit 200 --include-project-only-conversations`
  - regression assertion script: `pnpm tsx scripts/verify-cache-refresh-modes.ts --provider grok --history-limit 200 [--project-id <id>]`
- Cache export SQL-first smoke:
  - standard: `ORACLE_NO_BANNER=1 NODE_NO_WARNINGS=1 pnpm tsx bin/auracall.ts cache export --provider grok --scope conversation --conversation-id <id> --format json --out /tmp/auracall-export-smoke/json`
  - no-index resilience: temporarily move `cache-index.json` aside for that identity, rerun the same export command, confirm output exists, then restore `cache-index.json`.
- Cache export parity matrix smoke (recommended): `pnpm tsx scripts/verify-cache-export-parity.ts --provider grok --conversation-id <id>` (runs `json|csv|md|html|zip` for conversation scope plus broader JSON scopes and performs a no-index SQL-first check).
- SQL catalog smoke: `pnpm tsx scripts/verify-cache-sql-catalog.ts --provider <grok|chatgpt> [conversationId]` (verifies `cache.sqlite` catalog tables and row counts; optional conversation drill-down).
- To start a DevTools session manually, run `pnpm tsx scripts/start-devtools-session.ts --url=https://grok.com` (prints the host/port and launches Chrome if needed).
- Verify scripts now auto-start a DevTools session via BrowserService; `AURACALL_BROWSER_PORT` is optional.
- Integrated WSL -> Windows Chrome runs now default to auto DevTools-port discovery. The normal product path is: launch Windows Chrome with `--remote-debugging-port=0`, read `DevToolsActivePort`, then attach through Aura-Call’s built-in `windows-loopback` relay. Firewall rules and `portproxy` are not part of the primary setup.
- WSL -> Windows Chrome smoke: if Windows Chrome is already running with `--remote-debugging-port=<port>` on Windows loopback, test the new relay path with `pnpm tsx bin/auracall.ts --engine browser --browser-target grok --remote-chrome windows-loopback:<port> --model grok --prompt "ping" --wait --verbose --force`.
- Integrated WSL -> Windows Chrome smoke: `AURACALL_WSL_CHROME=windows AURACALL_BROWSER_PROFILE_DIR='/mnt/c/Users/<you>/AppData/Local/AuraCall/browser-profiles/windows-smoke/grok' pnpm tsx bin/auracall.ts --engine browser --browser-target grok --browser-chrome-path '/mnt/c/Program Files/Google/Chrome/Application/chrome.exe' --browser-cookie-path '/mnt/c/Users/<you>/AppData/Local/Google/Chrome/User Data/Default/Network/Cookies' --browser-bootstrap-cookie-path '/mnt/c/Users/<you>/AppData/Local/Google/Chrome/User Data/Default/Network/Cookies' --model grok --prompt "Reply exactly with: windows chrome just works" --wait --verbose --force`. Aura-Call now lets Windows choose the DevTools port and discovers the real endpoint from `DevToolsActivePort` automatically.
- On WSL, browser/profile paths can now be supplied as `/mnt/c/...`, `C:\...`, or WSL absolute paths like `/home/<you>/.auracall/...`; Aura-Call normalizes them before resolving managed profile roots and Chrome `--user-data-dir` flags.
- Live API smokes: `AURACALL_LIVE_TEST=1 OPENAI_API_KEY=… pnpm test:live` (excludes OpenAI pro), `AURACALL_LIVE_TEST=1 OPENAI_API_KEY=… pnpm test:pro` (OpenAI pro live). Expect real usage/cost.
- Gemini API live smoke: `AURACALL_LIVE_TEST=1 pnpm vitest run tests/live/gemini-live.test.ts`
- Gemini web (cookie) live smoke: `AURACALL_LIVE_TEST=1 pnpm vitest run tests/live/gemini-web-live.test.ts` (requires a signed-in Chrome profile at `gemini.google.com`).
- Gemini team live smoke: `AURACALL_LIVE_TEST=1 AURACALL_GEMINI_TEAM_LIVE_TEST=1 pnpm vitest run tests/live/team-gemini-live.test.ts`
- ChatGPT team live smoke: `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_TEAM_LIVE_TEST=1 pnpm vitest run tests/live/team-chatgpt-live.test.ts`
- ChatGPT approval/resume/drain team live smoke:
  - `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-chatgpt-live.test.ts -t "human escalation"`
  - current acceptance bar:
    - initial `auracall-chatgpt-tooling` run returns:
      - `runtimeRunStatus = cancelled`
      - `finalOutputSummary = "paused for human escalation"`
    - `POST /status` then:
      - resumes the paused team run
      - drains the resumed team run through the real provider-backed path
    - final readback confirms:
      - `metadata.executionSummary.operatorControlSummary`
      - resumed execution timeline on `GET /status/recovery/{run_id}`
      - stored terminal step summary
        `= "AURACALL_CHATGPT_APPROVAL_TEAM_LIVE_SMOKE_OK"`
- ChatGPT cancelled-local-action team live smoke:
  - `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-chatgpt-live.test.ts -t "cancels auracall-chatgpt-tooling local action"`
  - current acceptance bar:
    - initial `auracall-chatgpt-tooling` run uses:
      - `--allow-local-shell-command node`
      - `--allow-local-cwd-root /home/ecochran76/workspace.local/auracall`
      - `--require-local-action-approval`
    - initial run returns:
      - `runtimeRunStatus = cancelled`
      - `finalOutputSummary = "paused for human escalation"`
    - the stored local action is durable before operator follow-through:
      - `status = requested`
    - `POST /status` then:
      - resolves the pending request as `cancelled`
      - resumes the paused team run
      - drains the resumed team run through the real provider-backed path
    - final readback confirms:
      - bounded `metadata.executionSummary.localActionSummary` with
        `cancelled = 1`
      - bounded `metadata.executionSummary.operatorControlSummary`
      - resumed execution timeline on `GET /status/recovery/{run_id}`
      - stored terminal step summary
        `= "AURACALL_CHATGPT_CANCELLATION_TEAM_LIVE_SMOKE_OK"`
- Cross-service team live smoke: `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_TEAM_LIVE_TEST=1 pnpm vitest run tests/live/team-multiservice-live.test.ts`
- Grok team live smoke: `AURACALL_LIVE_TEST=1 pnpm vitest run tests/live/team-grok-live.test.ts`
  - opt-in provider-backed approval/resume/drain case:
    - `AURACALL_LIVE_TEST=1 AURACALL_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-grok-live.test.ts -t "human escalation"`
    - current acceptance bar:
      - initial `auracall-tooling` run returns:
        - `runtimeRunStatus = cancelled`
        - `finalOutputSummary = "paused for human escalation"`
      - `POST /status` then:
        - resumes the paused team run
        - drains the resumed team run through the real provider-backed path
      - final readback confirms:
        - `metadata.executionSummary.operatorControlSummary`
        - resumed execution timeline on `GET /status/recovery/{run_id}`
        - stored terminal step summary
          `= "AURACALL_TEAM_APPROVAL_LIVE_SMOKE_OK"`
  - opt-in provider-backed rejected-local-action case:
    - `AURACALL_LIVE_TEST=1 AURACALL_REJECTION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-grok-live.test.ts -t "rejects auracall-tooling local action"`
    - current acceptance bar:
      - initial `auracall-tooling` run returns:
        - `runtimeRunStatus = cancelled`
        - `finalOutputSummary = "paused for human escalation"`
      - the stored rejected local action is durable before resume:
        - `status = rejected`
        - `resultSummary = "local action rejected because step policy forbids host actions"`
      - `POST /status` then:
        - resumes the paused team run
        - drains the resumed team run through the real provider-backed path
      - final readback confirms:
        - bounded `metadata.executionSummary.localActionSummary` with
          `rejected = 1`
        - bounded `metadata.executionSummary.operatorControlSummary`
        - resumed execution timeline on `GET /status/recovery/{run_id}`
        - stored terminal step summary
          `= "AURACALL_TEAM_REJECTION_LIVE_SMOKE_OK"`
  - opt-in provider-backed cancelled-local-action case:
    - `AURACALL_LIVE_TEST=1 AURACALL_CANCELLATION_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-grok-live.test.ts -t "cancels auracall-tooling local action"`
    - current acceptance bar:
      - initial `auracall-tooling` run uses:
        - `--allow-local-shell-command node`
        - `--allow-local-cwd-root /home/ecochran76/workspace.local/auracall`
        - `--require-local-action-approval`
      - initial run returns:
        - `runtimeRunStatus = cancelled`
        - `finalOutputSummary = "paused for human escalation"`
      - the stored local action is durable before operator follow-through:
        - `status = requested`
      - `POST /status` then:
        - resolves the pending request as `cancelled`
        - resumes the paused team run
        - drains the resumed team run through the real provider-backed path
      - final readback confirms:
        - bounded `metadata.executionSummary.localActionSummary` with
          `cancelled = 1`
        - bounded `metadata.executionSummary.operatorControlSummary`
        - resumed execution timeline on `GET /status/recovery/{run_id}`
        - stored terminal step summary
          `= "AURACALL_TEAM_CANCELLATION_LIVE_SMOKE_OK"`
  - live team chat hygiene now uses exact-id batched cleanup instead of
    immediate deletion:
    - successful ChatGPT, Grok, and Gemini team live tests enqueue disposable
      conversations into:
      - `~/.auracall/live-test-cleanup/chatgpt-team-conversations.json`
      - `~/.auracall/live-test-cleanup/grok-team-conversations.json`
      - `~/.auracall/live-test-cleanup/gemini-team-conversations.json`
    - once a provider ledger grows past `6` stored conversations, Aura-Call
      prunes toward the newest `3`
    - each enqueue now deletes at most the oldest `2` conversations so cleanup
      cannot dominate one live test turn
    - deletion stays exact-id only through:
      - `auracall delete <conversationId> --target <provider> --yes`
    - no fuzzy title matching is used for this cleanup path
 - Direct operator lifecycle regression:
   - `pnpm vitest run tests/http.responsesServer.test.ts -t "resume|drain|operator control summary"`
   - current acceptance bar:
     - seed one paused direct run
     - resume it through `POST /status`
     - drain it through `POST /status`
     - confirm `GET /v1/responses/{response_id}` exposes bounded
       `operatorControlSummary`
     - confirm `GET /status/recovery/{run_id}` timeline includes:
       - pause note
       - resume note
       - targeted drain note
  - optional bounded tooling case:
    - `AURACALL_LIVE_TEST=1 AURACALL_TOOLING_LIVE_TEST=1 pnpm vitest run tests/live/team-grok-live.test.ts`
    - keep this separate from the stable Grok baseline until the live
      tool-envelope path is consistently deterministic
  - current Grok guard posture:
    - browser-backed Grok runs now persist one bounded cooldown/spacing record
      per managed browser profile under:
      - `~/.auracall/cache/providers/grok/__runtime__/rate-limit-<browser profile>.json`
    - repeated live Grok runs may now briefly auto-wait before execution
    - if the remaining wait is larger than the bounded auto-wait window, the
      run should fail fast with:
      - `Grok rate limit cooldown active until ...`
      - or `Grok write spacing active until ...`
    - visible provider toasts such as:
      - `Query limit reached for Auto`
      - `Try again in 4 minutes`
      now count as Grok rate-limit signals and should seed that same cooldown
      instead of ending as a generic timeout
  - current baseline expected result:
    - `teamId = auracall-solo`
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - first step resolves to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
      - `service = grok`
    - `finalOutputSummary = "AURACALL_TEAM_LIVE_SMOKE_OK"`
  - current live follow-through:
    - uses returned `execution.runtimeRunId` to read the durable operator
      detail seam through `serviceHost.readRecoveryDetail(...)`
    - expected readback:
      - `runId = execution.runtimeRunId`
      - `sourceKind = team-run`
      - `taskRunSpecId = taskRunSpec.id`
      - non-empty `orchestrationTimelineSummary`
      - at least one `step-succeeded` timeline item
  - current HTTP follow-through:
    - starts a bounded local responses server against the same durable store
    - reads `GET /status/recovery/{run_id}` for the returned
      `execution.runtimeRunId`
    - expected HTTP payload:
      - `object = recovery_detail`
      - `detail.runId = execution.runtimeRunId`
      - `detail.sourceKind = team-run`
      - `detail.taskRunSpecId = taskRunSpec.id`
      - non-empty `detail.orchestrationTimelineSummary`
      - at least one `step-succeeded` timeline item
  - current response readback follow-through:
    - reads `GET /v1/responses/{response_id}` where
      `response_id = execution.runtimeRunId`
    - expected HTTP payload:
      - `object = response`
      - `id = execution.runtimeRunId`
      - `status = completed`
      - `metadata.runId = execution.runtimeRunId`
      - `metadata.taskRunSpecId = taskRunSpec.id`
      - `metadata.service = grok`
      - `metadata.runtimeProfile = auracall-grok-auto`
      - `metadata.executionSummary.stepSummaries`
        - bounded per-step routing projection from stored step state
        - use this when you need mixed-provider routing proof from response
          readback itself
      - contract split:
        - top-level `metadata.service` / `metadata.runtimeProfile` remain the
          compact response summary
        - `metadata.executionSummary.stepSummaries` is the mixed-provider
          routing projection
        - response `metadata.executionSummary` should not grow recovery-only
          status fields such as:
          - `activeLease`
          - `dispatch`
          - `repair`
          - `leaseHealth`
          - `localClaim`
        - recovery detail remains the orchestration timeline surface
        - recovery detail should not grow routing fields such as:
          - `runtimeProfile`
          - `service`
          - `stepSummaries`
      - non-empty `metadata.executionSummary.orchestrationTimelineSummary`
      - at least one `step-succeeded` timeline item
  - current broader-workflow expected result:
    - `teamId = auracall-two-step`
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - `stepSummaries.length = 2`
    - both steps resolve to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
      - `service = grok`
      - `teamStepStatus = succeeded`
      - `runtimeStepStatus = succeeded`
    - `finalOutputSummary = "AURACALL_TEAM_TWO_STEP_LIVE_SMOKE_OK"`
    - `sharedStateNotes` includes consumed-transfer evidence
    - durable host, HTTP recovery detail, and HTTP response readback each show:
      - at least two `step-succeeded` timeline items
      - at least one `handoff-consumed` timeline item
  - current multi-agent expected result:
    - `teamId = auracall-multi-agent`
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - `stepSummaries.length = 2`
    - both steps resolve to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
      - `service = grok`
      - `teamStepStatus = succeeded`
      - `runtimeStepStatus = succeeded`
    - `finalOutputSummary = "AURACALL_MULTI_AGENT_LIVE_SMOKE_OK"`
    - `sharedStateNotes` includes consumed-transfer evidence
    - durable host, HTTP recovery detail, and HTTP response readback each show:
      - at least two `step-succeeded` timeline items
      - at least one `handoff-consumed` timeline item
  - current bounded tooling expected result:
    - `teamId = auracall-tooling`
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - `stepSummaries.length = 2`
    - both steps resolve to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
      - `service = grok`
      - `teamStepStatus = succeeded`
      - `runtimeStepStatus = succeeded`
    - `sharedStateNotes` includes:
      - `local shell action executed: node`
      - local action outcome summary for the executed step
    - `finalOutputSummary = "AURACALL_TOOL_TEAM_LIVE_SMOKE_OK"`
    - current automation posture:
      - manual provider-backed CLI proof is green
      - the automated live case is still gated behind
        `AURACALL_TOOLING_LIVE_TEST=1`
      - do not fold it into the stable `AURACALL_LIVE_TEST=1` baseline until
        Grok reliably emits the expected local-action envelope shape
- Gemini local browser-profile doctor: `pnpm tsx bin/auracall.ts doctor --target gemini --local-only --json`
- Full live Gemini selector diagnosis is not implemented under `auracall doctor` yet; use the dedicated Gemini live smokes instead.
- Team CLI bridge smoke:
  - `pnpm tsx bin/auracall.ts teams run auracall-solo "Reply exactly with: AURACALL_TEAM_SMOKE_OK" --title "AuraCall team smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_TEAM_SMOKE_OK and nothing else." --max-turns 1 --json`
  - inspect the persisted linkage from that payload:
    - `pnpm tsx bin/auracall.ts teams inspect --task-run-spec-id <taskRunSpecId> --json`
    - `pnpm tsx bin/auracall.ts teams inspect --team-run-id <teamRunId> --json`
    - `pnpm tsx bin/auracall.ts teams inspect --runtime-run-id <runtimeRunId> --json`
  - review the persisted team-run sequence from that payload:
    - `pnpm tsx bin/auracall.ts teams review --task-run-spec-id <taskRunSpecId> --json`
    - `pnpm tsx bin/auracall.ts teams review --team-run-id <teamRunId> --json`
    - `pnpm tsx bin/auracall.ts teams review --runtime-run-id <runtimeRunId> --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - single step resolves to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
    - `teams review` returns a read-only ledger with:
      - `ledger.sequence`
      - `ledger.handoffs`
      - `ledger.artifacts`
      - `ledger.observations = []` until passive-monitoring slices start
      - `service = grok`
      - provider refs include stored conversation id, tab URL, configured URL,
        project id, runtime profile id, browser profile id, agent id, and
        selected model when present
      - provider cache path stays `null` unless stored metadata already carries
        a concrete path
      - `ledger.observations` includes:
        - durable hard-stop observations derived from failure metadata
        - stored ChatGPT passive observations for `thinking`,
          `response-incoming`, and `response-complete` when present on
          `browserRun.passiveObservations`
        - stored Gemini passive observations for `thinking`,
          `response-incoming`, and `response-complete` when present on
          `browserRun.passiveObservations`
        - on the current managed WSL Chrome path, live thinking-mode evidence
          is best recognized from the placeholder assistant turn
          `ChatGPT said:Thinking`; generic status-node scans are supplemental
        - Gemini evidence stays Gemini-owned:
          - web executor observations come from returned
            thoughts/text/images and successful completion
          - browser-native attachment observations come from prompt committed,
            answer first visible, and stable completion
        - stored Grok passive observations for `thinking`,
          `response-incoming`, and `response-complete` when present on
          `browserRun.passiveObservations`
        - Grok evidence stays Grok-owned:
          - prompt submitted
          - first new assistant content visible
          - stabilized result returned
    - `finalOutputSummary = "AURACALL_TEAM_SMOKE_OK"`
  - `pnpm tsx bin/auracall.ts teams run auracall-chatgpt-solo "Reply exactly with: AURACALL_CHATGPT_TEAM_LIVE_SMOKE_OK" --title "AuraCall ChatGPT team live smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_CHATGPT_TEAM_LIVE_SMOKE_OK and nothing else." --max-turns 1 --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - single step resolves to:
      - `runtimeProfileId = wsl-chrome-2`
      - `browserProfileId = wsl-chrome-2`
      - `service = chatgpt`
    - `finalOutputSummary = "AURACALL_CHATGPT_TEAM_LIVE_SMOKE_OK"`
  - automated live coverage now exists:
    - `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_TEAM_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-chatgpt-live.test.ts`
    - current expected result:
      - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - recovery detail and `GET /v1/responses/{response_id}` both read back the same run cleanly
    - response readback shows:
      - `metadata.service = chatgpt`
      - `metadata.runtimeProfile = wsl-chrome-2`
  - current inspect posture:
    - `teams inspect` should read back the same persisted `taskRunSpecSummary`
      and linked runtime run identity without creating a new execution surface
    - lookup should work by:
      - `taskRunSpecId`
      - `teamRunId`
      - `runtimeRunId`
  - automated provider-backed approval/resume/drain coverage now also exists:
    - `AURACALL_LIVE_TEST=1 AURACALL_CHATGPT_APPROVAL_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-chatgpt-live.test.ts -t "human escalation"`
    - current expected result:
      - initial `auracall-chatgpt-tooling` run is cancelled with
        `finalOutputSummary = "paused for human escalation"`
      - `POST /status` resumes the paused team run
      - `POST /status` drains the resumed team run through the real
        provider-backed path
      - final stored terminal step summary
        `= "AURACALL_CHATGPT_APPROVAL_TEAM_LIVE_SMOKE_OK"`
      - response readback shows bounded
        `metadata.executionSummary.operatorControlSummary`
  - `pnpm tsx bin/auracall.ts teams run auracall-cross-service "Reply exactly with: AURACALL_CROSS_SERVICE_LIVE_SMOKE_OK" --title "AuraCall cross-service team live smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_CROSS_SERVICE_LIVE_SMOKE_OK and nothing else." --max-turns 2 --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order across different providers
    - step 1 resolves to:
      - `runtimeProfileId = wsl-chrome-2`
      - `browserProfileId = wsl-chrome-2`
      - `service = chatgpt`
    - step 2 resolves to:
      - `runtimeProfileId = auracall-grok-auto`
      - `browserProfileId = default`
      - `service = grok`
    - durable host, HTTP recovery-detail, and HTTP response readback all show:
      - non-empty orchestration timeline
      - at least one `handoff-consumed` timeline item
    - `finalOutputSummary = "AURACALL_CROSS_SERVICE_LIVE_SMOKE_OK"`
  - `pnpm tsx bin/auracall.ts teams run auracall-cross-service-gemini "Reply exactly with: AURACALL_CROSS_SERVICE_GEMINI_LIVE_SMOKE_OK" --title "AuraCall cross-service Gemini team live smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_CROSS_SERVICE_GEMINI_LIVE_SMOKE_OK and nothing else." --max-turns 2 --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order across different providers
    - step 1 resolves to:
      - `runtimeProfileId = wsl-chrome-2`
      - `browserProfileId = wsl-chrome-2`
      - `service = chatgpt`
    - step 2 resolves to:
      - `runtimeProfileId = auracall-gemini-pro`
      - `browserProfileId = default`
      - `service = gemini`
    - durable host, HTTP recovery-detail, and HTTP response readback all show:
      - non-empty orchestration timeline
      - at least one `handoff-consumed` timeline item
    - `finalOutputSummary = "AURACALL_CROSS_SERVICE_GEMINI_LIVE_SMOKE_OK"`
  - automated live coverage now exists:
    - `AURACALL_LIVE_TEST=1 AURACALL_MULTISERVICE_TEAM_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-multiservice-live.test.ts`
  - mixed-provider readback nuance:
    - `execution.stepSummaries` are the authoritative per-step provider/runtime
      proof
    - `GET /v1/responses/{response_id}` metadata service/runtime fields are
      still shaped from the stored run response model and should not be treated
      as a per-step provider matrix
  - current live browser-profile rule:
    - if the runtime profile is bound to an existing managed browser profile
      through `manualLoginProfileDir`, the executor should reuse that browser-
      family-owned directory instead of launching a fresh runtime-profile-
      namespaced managed browser profile
  - current regression tell:
    - if Chrome launches on
      `~/.auracall/browser-profiles/auracall-grok-auto/grok` instead of
      `~/.auracall/browser-profiles/default/grok`, managed-profile ownership
      regressed and Grok project navigation may fall back to `issue finding id`
    - if the Grok page visibly renders `AURACALL_TEAM_SMOKE_OK` but the CLI
      does not exit promptly, Grok response completion detection regressed
    - if repeated Grok smokes now pause briefly or fail fast on a cooldown/
      spacing message, that is expected guard behavior rather than a prompt/
      transport regression
  - bounded broader-workflow smoke:
    - `pnpm tsx bin/auracall.ts teams run auracall-two-step "Reply exactly with: AURACALL_TEAM_TWO_STEP_LIVE_SMOKE_OK" --title "AuraCall two-step team live smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_TEAM_TWO_STEP_LIVE_SMOKE_OK and nothing else." --max-turns 2 --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order on the same Grok runtime profile
    - `sharedStateNotes` includes consumed-transfer evidence for step 2
    - `finalOutputSummary = "AURACALL_TEAM_TWO_STEP_LIVE_SMOKE_OK"`
  - bounded multi-agent smoke:
    - `pnpm tsx bin/auracall.ts teams run auracall-multi-agent "Reply exactly with: AURACALL_MULTI_AGENT_LIVE_SMOKE_OK" --title "AuraCall multi-agent team live smoke" --prompt-append "Do not use tools. Reply with exactly AURACALL_MULTI_AGENT_LIVE_SMOKE_OK and nothing else." --max-turns 2 --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order on the same Grok runtime profile
    - `sharedStateNotes` includes consumed-transfer evidence for step 2
    - `finalOutputSummary = "AURACALL_MULTI_AGENT_LIVE_SMOKE_OK"`
  - bounded tooling smoke:
    - `pnpm tsx bin/auracall.ts teams run auracall-tooling "Run one bounded node local shell action that emits AURACALL_TOOL_ACTION_OK, then reply exactly with: AURACALL_TOOL_TEAM_LIVE_SMOKE_OK" --title "AuraCall tooling team live smoke" --prompt-append "For the tool envelope, use a top-level localActionRequests array with exactly one shell action. Preserve the provided toolEnvelope unchanged. Use kind \"shell\" and command \"node\". Use args [\"-e\",\"process.stdout.write('AURACALL_TOOL_ACTION_OK')\"]. Use structuredPayload {\"cwd\":\"/home/ecochran76/workspace.local/auracall\"}. After the local action succeeds, the final answer must be exactly AURACALL_TOOL_TEAM_LIVE_SMOKE_OK." --max-turns 2 --allow-local-shell-command node --allow-local-cwd-root /home/ecochran76/workspace.local/auracall --json`
  - current expected result:
    - real `taskRunSpec` payload
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order on the same Grok runtime profile
    - shared state includes `local shell action executed: node`
    - the stored local action outcome for the tool step shows `command = node`
      and executed stdout for the bounded smoke
    - `finalOutputSummary = "AURACALL_TOOL_TEAM_LIVE_SMOKE_OK"`
  - current automation boundary:
    - the manual CLI smoke above is the authoritative proof right now
    - the matching live Vitest case exists, but remains gated behind
      `AURACALL_TOOLING_LIVE_TEST=1`
    - if Grok shows a visible Auto quota toast during that tooling case, treat
      it as provider throttling, not as a local-action transport regression
    - do not treat occasional Grok envelope drift as a transport regression on
      the stable baseline team suite
- Gemini bounded tooling team smoke on 2026-04-12:
  - `pnpm tsx bin/auracall.ts teams run auracall-gemini-tooling "Use the provided toolEnvelope structured context to request one bounded shell action, then use the resulting tool outcome to return the provided finalToken exactly." --title "AuraCall Gemini tooling team live smoke" --prompt-append "Requester must emit exactly one JSON object with top-level localActionRequests containing the provided toolEnvelope unchanged. Do not rename fields, add markdown fences, or add prose. Finisher must output only the final token after a successful executed tool outcome." --structured-context-json '{"toolEnvelope":{"kind":"shell","summary":"Run one bounded deterministic node command","command":"node","args":["-e","process.stdout.write('\''AURACALL_TOOL_ACTION_OK'\'')"],"structuredPayload":{"cwd":"/home/ecochran76/workspace.local/auracall"}},"finalToken":"AURACALL_GEMINI_TOOL_TEAM_SMOKE_OK"}' --max-turns 2 --allow-local-shell-command node --allow-local-cwd-root /home/ecochran76/workspace.local/auracall --json`
  - expected result:
    - `runtimeSourceKind = team-run`
    - `runtimeRunStatus = succeeded`
    - two steps succeed in order on `auracall-gemini-pro`
    - shared state includes `local shell action executed: node`
    - `finalOutputSummary = "AURACALL_GEMINI_TOOL_TEAM_SMOKE_OK"`
  - machine-specific prerequisite on this WSL pairing:
    - raw Chrome cookie reads currently return zero Google auth cookies plus
      `Failed to read Linux keyring via secret-tool; v11 cookies may be unavailable.`
    - export cookies first:
      - `pnpm tsx bin/auracall.ts login --target gemini --profile auracall-gemini-pro --export-cookies`
    - stored team execution now reuses:
      - `~/.auracall/browser-profiles/default/gemini/cookies.json`
      - then `~/.auracall/cookies.json`
      when Gemini browser auth cookies are not available from Chrome directly
  - automated live coverage now exists:
    - `AURACALL_LIVE_TEST=1 AURACALL_GEMINI_TEAM_LIVE_TEST=1 DISPLAY=:0.0 pnpm vitest run tests/live/team-gemini-live.test.ts`
    - current expected result:
      - `runtimeSourceKind = team-run`
      - `runtimeRunStatus = succeeded`
      - two steps succeed in order on `auracall-gemini-pro`
      - recovery detail and `GET /v1/responses/{response_id}` both read back the same run cleanly
      - response readback shows:
        - `metadata.service = gemini`
        - `metadata.runtimeProfile = auracall-gemini-pro`
        - executed local action summary for `node`
- Gemini login/export now treats a visible Gemini `Sign in` page state as a real login failure instead of waiting indefinitely for cookie export.
- Gemini web live-proof target surfaces:
  - text
  - attachment
  - YouTube
  - generate-image
  - edit-image
  - conversation context
  - conversation files list
  - conversation files fetch
- Recommended Gemini live-proof order:
  - text
  - attachment
  - YouTube
  - generate-image
  - edit-image
  - conversation context
  - conversation files list
  - conversation files fetch
- Run Gemini live proof against one explicit AuraCall runtime profile / browser
  profile pairing at a time so failures can be classified cleanly.
- Latest Gemini web proof on 2026-04-03:
  - pairing: AuraCall runtime profile `default` -> browser profile `default`
  - text: green
  - attachment: green
  - YouTube: green
  - generate-image: not green on this pairing
    - Gemini returned a provider/account capability response instead of an
      image:
      - `I can search for images, but can't seem to create any for you right now.`
  - edit-image: not green on this pairing
    - Gemini returned a provider/account capability response instead of an
      edited image:
      - `I can try to find an image like that for you, but can't create it right now.`
  - note: this machine required `auracall login --target gemini --export-cookies`
    plus `AURACALL_BROWSER_COOKIES_FILE=~/.auracall/browser-profiles/default/gemini/cookies.json`
    because `secret-tool` cookie decryption returned zero Google auth cookies
- Secondary Gemini pairing check on 2026-04-04:
  - pairing: AuraCall runtime profile `wsl-chrome-2` -> browser profile `wsl-chrome-2`
  - managed Gemini browser profile directory exists under:
    - `/home/ecochran76/.auracall/browser-profiles/wsl-chrome-2/gemini`
  - login/export state is now green:
    - `auracall --profile wsl-chrome-2 login --target gemini --export-cookies`
      now succeeds and writes:
      - `/home/ecochran76/.auracall/browser-profiles/wsl-chrome-2/gemini/cookies.json`
    - the current Gemini login flow can click a visible Gemini `Sign in` CTA
      once and wait through the Google handoff when that is sufficient
  - browser text proof is now green:
    - `AURACALL_BROWSER_COOKIES_FILE=~/.auracall/browser-profiles/wsl-chrome-2/gemini/cookies.json auracall --profile wsl-chrome-2 --engine browser --model gemini-3-pro --prompt 'Reply exactly with: WSL2 GEMINI TEXT GREEN 2' --wait --verbose --force`
    - returned exactly:
      - `WSL2 GEMINI TEXT GREEN 2`
  - browser file-input proof is now also green through Aura-Call's inline file
    bundling path:
    - `AURACALL_BROWSER_COOKIES_FILE=~/.auracall/browser-profiles/wsl-chrome-2/gemini/cookies.json auracall --profile wsl-chrome-2 --engine browser --model gemini-3-pro --prompt 'Read the attached file and reply exactly with its full contents, with no extra words.' --file /tmp/gemini-wsl2-attachment-proof.txt --wait --verbose --force`
    - returned exactly:
      - `WSL2 Gemini attachment proof 2026-04-04`
    - note:
      - verbose output reported `Browser will paste file contents inline (no uploads).`
  - native Gemini browser upload is now green for a real text-file upload:
    - `auracall --profile wsl-chrome-2 --engine browser --model gemini-3-pro --browser-attachments always --prompt 'Read the uploaded file and reply exactly with its full contents, with no extra words.' --file /tmp/gemini-native-upload-proof.txt --wait --verbose --force`
    - returned exactly:
      - `WSL2 NATIVE GEMINI UPLOAD GREEN 2026-04-04`
    - Aura-Call now takes that path through the live Gemini page itself for
      upload-mode runs, instead of relying on the earlier raw Gemini upload
      protocol path for ordinary attachment-backed prompts
  - the old raw Gemini upload transport investigation remains relevant
    background, but it is no longer the active path for standard browser upload
    prompts:
    - earlier forced-upload text proof returned:
      - `[NO CONTENT FOUND]`
    - earlier forced-upload image proof reached:
      - `Gemini accepted the attachment request but returned control frames only and never materialized a response body.`
  - native Gemini browser image-upload proof is still not freshly re-proven on
    this pairing after the browser-driven pivot
  - native Gemini browser image-upload is now green again on this pairing:
    - the key fix was to prefer Gemini's hidden image uploader over the generic
      hidden file uploader for image-only synthetic `fileSelected` dispatch
    - fresh live rerun:
      - pre-submit:
        - prompt still in composer
        - `visibleBlobCount = 1`
        - `Remove file gemini-native-upload-proof.png`
      - post-submit:
        - prompt committed to history
        - blob still visible
      - Gemini answer:
        - `An empty room features white walls, light wood flooring, and a large window overlooking a lush green landscape.`
    - that means the active image-association failure was in the uploader path,
      not in prompt commit or staged-ready timing
  - this pairing is now a real second text-green Gemini browser proof
  - Gemini browser provider list surfaces are now also live on this pairing:
    - `auracall --profile wsl-chrome-2 projects --target gemini`
      - returns real Gem rows through the generic browser provider path
    - `auracall --profile wsl-chrome-2 conversations --target gemini`
      - returns real `/app/<conversationId>` chat rows through the same path
      - now also writes cache under:
        - `~/.auracall/cache/providers/gemini/ecochran76@gmail.com/`
      - the earlier cache-identity warning is resolved on this pairing
  - Gemini conversation rename is now live on the active `default` pairing:
    - `pnpm tsx bin/auracall.ts rename dc7b095922577de3 'AuraCall Gemini Rename Smoke 1775466602' --target gemini --profile default`
    - returned:
      - `Renamed successfully.`
    - implementation note:
      - Gemini rename uses the direct `/app/<conversationId>` page action menu
        (`rename-button`), the rename dialog input
        (`edit-title-input`), and native keystroke submission through the
        shared browser-service `submitInlineRename(...)` helper
  - Gemini conversation context read is now minimally live on the active
    `default` pairing:
    - `auracall conversations context get 841b485bcb3819af --target gemini --profile default --json-only`
      - returns canonical `messages[]`
    - `auracall conversations context get ab30a4a92e4b65a9 --target gemini --profile default --json-only`
      - returns visible uploaded-image `files[]`
  - Gemini conversation files list/fetch are now also live on the active
    `default` pairing for direct chat upload chips:
    - text upload proof:
      - `auracall conversations files list 841b485bcb3819af --target gemini --profile default`
      - `auracall conversations files fetch 841b485bcb3819af --target gemini --profile default --verbose`
    - uploaded-image proof:
      - `auracall conversations files list ab30a4a92e4b65a9 --target gemini --profile default`
      - returns:
        - `gemini-conversation-file:ab30a4a92e4b65a9:0:uploaded-image-1`
      - `auracall conversations files fetch ab30a4a92e4b65a9 --target gemini --profile default --verbose`
      - current image materialization path can fall back to browser-native
        visible-preview capture when the signed image URL returns 403 outside
        the live page context
    - `pnpm tsx bin/auracall.ts conversations context get 841b485bcb3819af --target gemini --profile default --json-only`
    - returned canonical `messages[]`:
      - user:
        - `Read the uploaded file and reply exactly with its full contents, with no extra words.`
      - assistant:
        - `GEMINI NEW CHAT UPLOAD SMOKE 1775437518`
    - and the same direct chat surface now exposes a visible conversation file:
      - `pnpm tsx bin/auracall.ts conversations files list 841b485bcb3819af --target gemini --profile default`
      - returned:
        - `gemini-new-chat-upload-smoke.txt`
    - implementation note:
      - the extractor now reads ordered `user-query` / `model-response` turn
        containers from the direct `/app/<conversationId>` page and pulls text
        from the inner message nodes instead of the outer Gemini chrome wrappers
      - visible sent upload chips now also populate `context.files[]` and the
        shared `conversations files list` fallback
      - Gemini now also returns visible generated artifacts on the active
        `default` pairing:
        - `pnpm tsx bin/auracall.ts conversations context get 3525c884edae4fa4 --target gemini --profile default --json-only`
        - returned one `image` artifact with:
          - `uri: blob:https://gemini.google.com/...`
          - `width: 1024`
          - `height: 559`
        - `pnpm tsx bin/auracall.ts conversations context get 8e8e58b57ae544ea --target gemini --profile default --json-only`
        - returned one `generated` artifact with:
          - `title: Before The Tide Returns`
          - `mediaType: music`
          - `fileName: before_the_tide_returns.mp4`
        - `pnpm tsx bin/auracall.ts conversations context get 23340d1698de29b8 --target gemini --profile default --json-only`
        - returned one `generated` artifact with:
          - `title: Generated video 1`
          - `mediaType: video`
          - `fileName: video.mp4`
        - `pnpm tsx bin/auracall.ts conversations context get 59b6f9ac9e510adc --target gemini --profile default --refresh --json-only`
        - returned one `canvas` artifact with:
          - `title: AuraCall Canvas Route Probe`
          - `uri: gemini://canvas/59b6f9ac9e510adc`
          - `metadata.contentText`
          - `metadata.createdAt: Apr 6, 9:44 PM`
          - `metadata.hasShareButton: true`
          - `metadata.hasPrintButton: true`
      - earlier generic Canvas probe `c653ec3c84410829` still matters as a
        caution:
        - simply selecting the Canvas tool does not guarantee a first-class
          canvas artifact on every Gemini chat
      - Gemini `sources[]` and broader artifact parity beyond the proven
        image/music/video/canvas surfaces are still pending
      - Gemini artifact fetch is now also live for the proven conversation
        artifacts on the active `default` pairing:
        - `pnpm tsx bin/auracall.ts conversations artifacts fetch 59b6f9ac9e510adc --target gemini --profile default`
          - `artifactCount = 1`
          - `materializedCount = 1`
          - materialized `AuraCall Canvas Route Probe.txt`
        - `pnpm tsx bin/auracall.ts conversations artifacts fetch 8e8e58b57ae544ea --target gemini --profile default`
          - `artifactCount = 1`
          - `materializedCount = 1`
          - materialized `before_the_tide_returns.mp4`
        - `pnpm tsx bin/auracall.ts conversations artifacts fetch 23340d1698de29b8 --target gemini --profile default`
          - `artifactCount = 1`
          - `materializedCount = 1`
          - materialized `video.mp4`
      - Gemini conversation file fetch now also has a bounded shared CLI path:
        - `pnpm tsx bin/auracall.ts conversations files fetch <conversationId> --target gemini --profile default`
        - current implementation is intentionally limited to chat-uploaded files
          whose Gemini chat surface exposes either:
          - a direct preview/download URL
          - or a recoverable text preview after opening the chip
        - the known text-upload smoke conversation currently is not a clean live
          fetch proof because direct `/app/<id>` route open on this account can
          trip Google’s `sorry` interstitial before the file preview is reached
  - Gemini Gem create is now also live on this pairing:
    - `auracall --profile wsl-chrome-2 projects create 'AuraCall Gemini Gem CRUD Proof 2026-04-04 1854' --target gemini --instructions-text 'Reply helpfully about AuraCall Gemini CRUD proofs.'`
    - returned:
      - `Created project "AuraCall Gemini Gem CRUD Proof 2026-04-04 1854".`
    - refreshed list then surfaced the new Gem id:
      - `8206744c0568`
  - Gemini Gem rename is now also live on this pairing:
    - `auracall --profile wsl-chrome-2 projects rename 8206744c0568 'AuraCall Gemini Gem CRUD Proof 2026-04-04 1914' --target gemini`
    - returned:
      - `Renamed project 8206744c0568 to "AuraCall Gemini Gem CRUD Proof 2026-04-04 1914".`
    - authoritative follow-up read on:
      - `https://gemini.google.com/gems/edit/8206744c0568`
      - showed:
        - `AuraCall Gemini Gem CRUD Proof 2026-04-04 1914`
  - Gemini Gem delete is now also live on this pairing:
    - created disposable Gem:
      - `AuraCall Gemini Gem Delete Proof 2026-04-04 1935`
    - resolved id:
      - `525572997076`
    - deleted with:
      - `auracall --profile wsl-chrome-2 projects remove 525572997076 --target gemini`
    - returned:
      - `Removed project 525572997076.`
    - refreshed Gem list no longer included:
      - `525572997076`
  - deferred Gemini list-quality note:
    - some Gem manager rows still resolve abbreviated or repeated display
      names during list scraping
    - treat that as a later Gemini list-quality fix, not a blocker on the
      first create-path proof
  - operator safety rule:
    - `projects create <name>` should be treated as create-only, not
      create-or-reuse by side effect
    - AuraCall now blocks exact-name duplicates before provider creation; if a
      project might already exist, resolve/list first and reuse the existing id
- Until that matrix is re-proven in one fresh pass, treat Gemini as supported with inherited coverage, not as a freshly re-certified browser provider.
- ChatGPT guarded browser acceptance: `DISPLAY=:0.0 ORACLE_NO_BANNER=1 NODE_NO_WARNINGS=1 pnpm tsx scripts/chatgpt-acceptance.ts`.
  - The runner now aborts if the persisted ChatGPT cooldown is still materially active instead of sleeping for minutes and resuming later.
  - If `~/.auracall/cache/providers/chatgpt/__runtime__/rate-limit-<profile>.json` shows a long active cooldown, wait for it to clear before rerunning.
  - The current safer default guard is weighted rather than flat-count based:
    - lighter actions like rename/instructions count less than project create/upload/browser sends
    - each successful write also opens a post-commit quiet period before the next refresh-heavy or mutating step
    - the quiet period starts around 12-18 seconds and gets longer as recent weighted activity accumulates
  - On this account, prefer the phaseable path instead of one dense full burst.
  - Recommended resumable workflow:
    - `... scripts/chatgpt-acceptance.ts --phase project --state-file docs/dev/tmp/chatgpt-acceptance-state.json`
    - `... scripts/chatgpt-acceptance.ts --phase project-chat --resume docs/dev/tmp/chatgpt-acceptance-state.json`
    - `... scripts/chatgpt-acceptance.ts --phase root-base --resume docs/dev/tmp/chatgpt-acceptance-state.json`
    - `... scripts/chatgpt-acceptance.ts --phase root-followups --resume docs/dev/tmp/chatgpt-acceptance-state.json`
    - `... scripts/chatgpt-acceptance.ts --phase cleanup --resume docs/dev/tmp/chatgpt-acceptance-state.json`
  - `--state-file` writes a phase summary JSON after progress, success, and failure.
  - `--resume` reuses the prior summary's ids by default and now also keeps the same suffix/naming for a coherent disposable run.
  - Latest clean phased live sweep on the authenticated managed WSL ChatGPT profile:
    - `project` green
    - `project-chat` green
    - `root-base` green
    - `root-followups` green
    - `cleanup` green
  - Existing-conversation browser runs now reject reused assistant turns when a visible ChatGPT rate-limit modal blocks the new send, instead of returning the previous assistant answer as false success.
  - Post-MVP polish history is archived in [0021-2026-04-08-chatgpt-polish-plan.md](/home/ecochran76/workspace.local/auracall/docs/dev/plans/legacy-archive/0021-2026-04-08-chatgpt-polish-plan.md).
  - Broader hostile-state hardening history is archived in [0020-2026-04-08-chatgpt-hardening-plan.md](/home/ecochran76/workspace.local/auracall/docs/dev/plans/legacy-archive/0020-2026-04-08-chatgpt-hardening-plan.md).
- MCP focused: `pnpm test:mcp` (builds then stdio smoke via mcporter).
- MCP media/workbench service wiring:
  - `pnpm vitest run tests/mcp.server.test.ts tests/mcp.mediaGeneration.test.ts tests/mcp.runStatus.test.ts tests/mcp.workbenchCapabilities.test.ts --maxWorkers 1`
  - proves MCP media generation, media status, generic run status, and
    workbench capability tools share the configured browser-backed service
    bundle instead of default no-executor services
  - persistence-safe polling coverage now seeds response and media records,
    creates fresh service instances, and verifies MCP `run_status` plus
    `media_generation_status` read the stored ids without provider/browser
    re-invocation
- MCP team-run parity:
  - `pnpm vitest run tests/mcp/teamRun.test.ts tests/mcp.schema.test.ts --maxWorkers 1`
  - proves the `team_run` tool registration, bounded input/output schemas, and
    MCP provenance handoff into the configured team-run executor.
- Public prebuilt task-run-spec acceptance:
  - `pnpm vitest run tests/http.responsesServer.test.ts tests/mcp/teamRun.test.ts tests/cli/teamRunCommand.test.ts tests/teams.schema.test.ts --maxWorkers 1`
  - proves HTTP and MCP accept a prebuilt flattened `taskRunSpec`, reject
    compact/prebuilt assignment conflicts, and keep compact create behavior
    unchanged.
- If you are debugging a raw direct-CDP setup instead of Aura-Call’s integrated Windows path, you can still pin `AURACALL_BROWSER_PORT` / `AURACALL_BROWSER_DEBUG_PORT` and use firewall hints from `scripts/test-browser.ts`. That is now a fallback/debug workflow, not the primary Windows setup.
- Scoped browser runs can be smoke-tested by passing `--project-id` / `--conversation-id` to a browser command; they should not change default config behavior.
