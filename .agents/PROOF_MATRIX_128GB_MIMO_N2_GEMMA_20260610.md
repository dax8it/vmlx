# 128GB Checkpoint Proof Matrix - MiMo, N2, Gemma

Scope: current Python engine worktree
`/Users/eric/mlx/vllm-mlx-finite-launch-guard`. This file is for the
release/checkpoint lane. Do not use it to claim full release clearance; it
separates what was actually loaded and proven from what remains red.

## Latest Proof Additions

### Installed-App Parity After Responses `max_tokens` Alias Fix

Artifact:

- `build/current-installed-app-runtime-parity-after-responses-max-tokens-alias-20260610.json`

Action:

- Ran `bash panel/scripts/build-and-install.sh` from current source after
  commit `9aec5d6a1`.
- The script rebuilt bundled Python, ran the bundled Python verifier, packaged
  `release/mac-arm64/vMLX.app`, ad-hoc sealed the app, replaced
  `/Applications/vMLX.app`, and verified the local app signature.

Proven:

- Installed packaged source mirror and installed site-packages match current
  source hashes for:
  - `vmlx_engine/api/models.py`
  - `vmlx_engine/server.py`
- Both installed copies include `ResponsesRequest.max_tokens` and the
  `/v1/responses` `_responses_request_max_tokens` fallback to
  `request.max_tokens` when `max_output_tokens` is absent.
- Bundled Python import probe confirmed:
  `max_tokens=24`, `max_output_tokens=None`, and
  `fields_has_max_tokens=True`.
- `panel/scripts/verify-bundled-python.sh` passed all critical import and
  source-parity checks.
- `codesign --verify --deep --strict --verbose=2 /Applications/vMLX.app`
  passed.

Boundary:

- This is installed-app parity for a source/API fix, not a public release.
- `spctl --assess --type execute` rejects the local app as expected because it
  is ad-hoc signed and not notarized.
- No DMG, notarization, tag, upload, PyPI publish, updater JSON, or website
  update was performed.
- No installed-app live model launch was run for this alias fix yet.

### MiMo JANGTQ_2 Live Refresh + Responses `max_tokens` Alias Fix

Artifacts:

- `build/current-mimo-jangtq2-live-refresh-20260610/SUMMARY.json`
- `build/current-mimo-jangtq2-live-refresh-20260610/exact_b7_cat_09.json`
- `build/current-mimo-jangtq2-live-refresh-20260610/required_tool_blue_cat.sse`
- `build/current-mimo-jangtq2-live-refresh-20260610/sustained_decode_260.json`
- `build/current-mimo-jangtq2-live-refresh-20260610/max_tokens_alias_after_fix.json`
- `build/current-mimo-jangtq2-live-refresh-20260610/health_after_max_tokens_alias.json`

Fixed:

- `/v1/responses` now accepts `max_tokens` as a compatibility alias when
  `max_output_tokens` is absent. Root cause was
  `ResponsesRequest.model_config.extra="ignore"` dropping client-provided
  `max_tokens`, while the Responses endpoint resolved only
  `request.max_output_tokens`, falling back to the server default.
- Live pre-fix proof requested `max_tokens=260` and generated
  `output_tokens=2048`.
- Live post-fix proof requested `max_tokens=24`; server logs resolved
  `max_tokens: 24`, and response usage reported `output_tokens=24`.

Proven:

- Real local `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`
  loaded through current source with native TurboQuant text runtime,
  `mllm=False`, `mimo_v2_asymmetric_swa` / `mixed_swa_kv_v1`, paged prefix
  cache, block-disk L2, and generic TurboQuant KV disabled by contract.
- Final health after the patched request recorded `ram_tokens_cached=41`,
  `l2_block_tokens_on_disk=1092`, block-disk `disk_writes=1`, and active
  memory about `76.5GB`.

Red / not proven:

- MiMo JANGTQ_2 literal exactness remains red:
  `B7-CAT-09` generated as `B7ACAT-09`.
- MiMo JANGTQ_2 required-tool argument literal preservation remains red:
  `blue-cat` streamed/finalized as `blue cat`. The SSE transport shape was
  structurally green, but the value is wrong.
- Source-vs-quant first divergence remains blocked because the source endpoint
  `erics-m5-max2.local:8126` and prior local quant endpoint refused
  connections during this turn.
- Installed-app parity for this new API fix is not rebuilt/proven.

Verification:

- `.venv/bin/python -m py_compile vmlx_engine/api/models.py vmlx_engine/server.py`
  -> pass.
- `.venv/bin/python -m pytest -q tests/test_api_models.py -k
  'responses_max_output_tokens_rejected or responses_accepts_max_tokens_alias'`
  -> `2 passed`.

Boundary:

- This is a real Responses API compatibility fix discovered during MiMo live
  proof. It does not clear MiMo exactness, media, speed floor, installed-app
  parity, release signing, notarization, PyPI, updater JSON, or website
  release readiness.

### MiMo JANG_2L Screenshot Regression Classification

Proven:

- The installed app used in the screenshot is stale versus current source:
  `/Applications/vMLX.app/Contents/Resources/vmlx-engine-source` hashes differ
  from current source for `vmlx_engine/server.py`, `vmlx_engine/cli.py`,
  `vmlx_engine/api/tool_calling.py`, and `vmlx_engine/scheduler.py`.
- Current panel source detects the exact local MiMo JANG_2L text-runtime
  artifact `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L` as:
  `family=mimo_v2`, `cacheSubtype=mimo_v2_asymmetric_swa`,
  `toolParser=xml_function`, `reasoningParser=think_xml`,
  `supportsThinking=false`, `forceTextOnly=true`, and
  `isMultimodal=false`.
- Therefore current source should not append `--is-mllm` for that preserved
  media/text-runtime bundle. The screenshot's `--is-mllm` launch is an
  installed-app/runtime parity problem, not current source launch-policy proof.
- Added a focused panel regression guard for that exact local MiMo path in
  `panel/tests/model-config-registry.test.ts`.

Verification:

- `npm --prefix panel test -- --run tests/model-config-registry.test.ts -t
  "current local MiMo V2 JANG_2L"` -> `1 passed`.
- `npm --prefix panel test -- --run tests/model-config-registry.test.ts` ->
  `70 passed`.
- `npm --prefix panel run typecheck` -> pass.
- `git diff --check` -> pass.

Red / not proven:

- This does not solve MiMo JANG_2L decode speed, TTFT, user-visible quality, or
  media semantics.
- Installed app replacement/rebuild and real UI proof remain open before any
  checkpoint DMG/sign/notarize claim.

### MiMo JANG_2L Installed-App Rebuild + Text/Cache Proof

Artifacts:

- `build/current-installed-app-runtime-parity-audit-after-mimo-source-rebuild-20260611.json`
- `docs/internal/agent-notes/current-real-ui-installed-app-mimo-v25-jang2l-text-cache-after-rebuild-pass-20260611-proof.json`
- `docs/internal/agent-notes/current-real-ui-installed-app-mimo-v25-jang2l-text-cache-after-rebuild-pass-20260611-chat.png`

Proven:

- `/Applications/vMLX.app` was rebuilt and installed from current source using
  `panel/scripts/build-and-install.sh`.
- Installed-app runtime parity is green: `status=pass`, `missing_or_stale=[]`,
  bundled engine hash parity true, packaged engine-source hash parity true,
  installed `vmlx_engine 1.5.57`, and installed `jang_tools 2.5.30`.
- Current source and installed packaged mirrors match for `server.py`,
  `cli.py`, `api/tool_calling.py`, and `scheduler.py`; the stale-app drift from
  the screenshot investigation is cleared.
- Real installed-app UI proof passed on
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L` using installed
  bundled Python and `/v1/responses`.
- The server command did not include `--is-mllm`; server logs classified the
  bundle as `mimo_v2_preserved_text_runtime result=False`, and the UI request
  logged `chatIsMultimodal=false`.
- Visible output was exact twice: `SPEED_OK` then `SPEED_OK`; no raw parser,
  reasoning, or tool markup leaked into UI content.
- Native cache evidence: `mimo_v2_asymmetric_swa` / `mixed_swa_kv_v1`, generic
  TurboQuant KV disabled, scheduler cache `hits=1`, `tokens_saved=30`,
  `ram_tokens_cached=78`, block disk `blocks_on_disk=2`,
  `disk_writes=2`, and `l2_block_tokens_on_disk=78`.

Boundary:

- The locally installed app is ad-hoc signed/sealed; `codesign --verify --deep
  --strict` passes, but `spctl` rejects it because this is not a notarized
  Developer ID release artifact.
- MiMo JANG_2L speed remains open: short exact installed-app decode recorded
  about `2.0 t/s` then `1.7 t/s` with TTFT `1.52s` and `1.76s`.
- This does not clear MiMo JANGTQ_2 exactness/media, Gemma media/UI, Qwen
  deployed tunnel parity, N2 JANGTQ/non-JANG_1L, or any public release step.

### MiMo Panel `think_xml` Launch Parity Fix

Proven:

- Panel source now preserves MiMo `reasoningParser='think_xml'` from JANG
  capability detection while still forcing `supportsThinking=false`,
  `thinkInTemplate=false`, and `defaultEnableThinking=false`.
- Root cause fixed: `applyJangCapabilities()` previously erased MiMo's
  cleanup parser when JANG capability stamps were present, so some panel/app
  launches omitted `--reasoning-parser think_xml` despite the family registry
  declaring it.
- Verification passed: `npm --prefix panel run typecheck`,
  `npm --prefix panel test -- --run tests/model-config-registry.test.ts`
  (`69/69`), and `git diff --check`.

Boundary:

- This is parser-launch hygiene only. It does not clear MiMo JANG_2L speed,
  semantic quality, JANGTQ literal exactness, media, or installed-app release
  readiness, and it does not fake-enable MiMo thinking.

### MiMo JANG_2L Source Live Text/Cache + Shutdown Fix

Artifacts:

- `build/live-mimo-jang2l-after-thinkxml-20260611/chat_visible_what_are_u.json`
- `build/live-mimo-jang2l-after-thinkxml-20260611/chat_visible_what_are_u_repeat.json`
- `build/live-mimo-jang2l-after-thinkxml-20260611/responses_required_tool_bluecat.sse`
- `build/live-mimo-jang2l-after-thinkxml-20260611/health_after_requests.json`

Proven:

- Real source server loaded
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L` with
  `xml_function`, `think_xml`, native mixed-SWA paged cache, block-disk L2, and
  generic KV quantization disabled for MiMo.
- Screenshot-shape prompt `what are u? speak in one short sentence.` returned
  clean visible text twice:
  `I am an AI assistant created by Xiaomi's LLM Core Team.`
- Cache telemetry after the repeat showed `tokens_saved=35`,
  `ram_tokens_cached=300`, and `l2_block_tokens_on_disk=359`.
- The repeated Python 3.13 shutdown fatal is fixed in source:
  `vmlx_engine/scheduler.py` now shuts down the scheduler-owned
  `_step_executor` after disk-cache flush. Verification included
  `.venv/bin/python -m py_compile vmlx_engine/scheduler.py`, `git diff --check`,
  and a second real MiMo JANG_2L source start/stop that logged
  `Scheduler step executor shutdown complete` and exited without the prior
  `PyThreadState_Get` fatal.

Red / not proven:

- MiMo JANG_2L required Responses tool call for exact `blue-cat` produced no
  tool call and failed closed as `tool_calls_required`; no executable `{}` args
  were emitted. Required-tool/agentic loop remains red.
- This does not clear MiMo JANG_2L speed, long-run quality, media semantics,
  JANGTQ literal exactness, installed-app parity, or release readiness.

### MiMo JANGTQ_2 Thinking-On Proof Red + Native Cache UI Guard

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-mimo-v25-jangtq2-responses-thinking-tools-cache-deterministic-printf-bundled-python-20260610-proof.json`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`.
- Responses streaming, built-in `run_command`, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`, server launched with
  `--tool-call-parser xml_function --reasoning-parser think_xml`.

Result:

- Status `fail` for the requested reasoning-display row.
- UI request logs sent `enable_thinking=true`.
- vmlx-engine resolved `enable_thinking=False` because the current MiMo
  registry contract has `supports_thinking=False`.
- No reasoning deltas or persisted reasoning were recorded:
  `eventCounts.reasoningDone=0`, `persistedReasoningCount=0`.

Positive evidence:

- Tool/cache/content still worked under the attempted thinking-on run:
  exact visible outputs `MIMO_THINK_TOOL_ONE`,
  `MIMO_THINK_TOOL_TWO second UI turn.`, and `FOUR`.
- Native MiMo cache evidence stayed healthy:
  `mimo_v2_asymmetric_swa` / `mixed_swa_kv_v1`, 48 stored layers,
  9 full-KV layers, 39 rotating-KV layers, paged prefix cache, block-disk L2,
  3 cache hits, and `dequantized=false` on cache reconstruction.

Source fix:

- `vmlx_engine/cli.py`
- `panel/src/main/sessions.ts`
- `panel/src/renderer/src/components/sessions/SessionSettings.tsx`
- `panel/src/renderer/src/components/sessions/SessionConfigForm.tsx`

The engine CLI and panel now treat `mimo_v2_asymmetric_swa` as a native
stored-prefix cache owner:

- require paged prefix cache for the subtype;
- force stored cache quantization display to Auto/disabled;
- suppress generic `--kv-cache-quantization q4/q8` in launch args and command
  preview for MiMo's native mixed full/SWA cache.
- suppress auto or explicit generic CLI `--kv-cache-quantization q4/q8` for
  MiMo by default. The only bypass is the diagnostics-only env
  `VMLINUX_MIMO_ALLOW_GENERIC_KV_CACHE_QUANTIZATION=1`, which is not
  release-cleared.

Boundary:

- This is not a MiMo reasoning success. Current artifacts remain thinking-on
  red until a rebuilt/remade MiMo model/template proves visible final output
  with reasoning/tool interleaving.
- This is not a VL/audio/video semantic pass and not a release/sign/notarize/
  PyPI/updater/site action.

### Qwen35 Responses Raw-SSE Direct/Gateway/Tunnel Proof After XML Scalar Trim

Source fixes:

- `vmlx_engine/server.py`
  - invalid marker-bearing tool XML is stripped from fallback visible text when
    no parser/repair path yields a valid call.
- `vmlx_engine/api/tool_calling.py`
  - `_coerce_xml_tool_value` trims only pretty-wrapper newlines around one-line
    scalar XML parameter values.
- `vmlx_engine/tool_parsers/xml_function_tool_parser.py`
  - mirrors the same XML scalar-wrapper policy.

What this fixes:

- Required empty XML function calls do not become executable `{}` arguments.
- Invalid tool markup does not leak as visible fallback text after parser
  fallback.
- Pretty XML like `<parameter=value>\nblue-cat\n</parameter>` becomes
  `"blue-cat"` for scalar tool arguments, while same-line spaces, escaped
  entities, Unicode, and true multiline payloads are preserved.

Live proof:

- `build/current-responses-raw-sse-parity-qwen35-direct-gateway-tunnel-after-generic-xml-scalar-trim-current-tunnel-20260610.json`
- Status: `pass`.
- Model:
  `/Users/eric/models/JANGQ/Qwen3.6-35B-A3B-MXFP8-MTP`.
- Direct/gateway current-source captures plus current tunnel SSE.

Evidence:

- All surfaces parsed cleanly and advertised the same model.
- Authoritative function arguments matched across direct, gateway, and tunnel:
  `{"value": "blue-cat"}`.
- Direct and gateway output indices:
  message `0`, reasoning `1`, function_call `2`.
- Tunnel output indices:
  message `0`, function_call `1`.
- No conflicting output indices on any present surface.
- Reasoning events were present and not disabled:
  direct `5`, gateway `5`, tunnel `8`.
- Gateway argument stream passthrough guard passed.
- Local empty-XML fail-closed guard passed.

Verification:

- Parser/Responses/Qwen35 harness slice:
  `25 passed`.
- Changed-file `py_compile` and `git diff --check` passed.

Other-agent note:

- Do not revert the scalar-wrapper policy into blanket `.strip()` or blanket
  raw preservation. The contract is: trim only wrapper newlines for one-line
  scalar XML parameters, preserve same-line whitespace, escaped entities,
  Unicode, and true multiline strings.
- If recapturing public tunnel again, use a current tunnel SSE with valid
  indices; the older `20260609` tunnel file still demonstrates the historical
  duplicate-output-index failure.

Boundary:

- This is Qwen35 MXFP8 MTP Responses raw-SSE parser/API proof. It is not N2
  JANG_1L, MiMo media/exactness, Gemma MXFP, installed-app rebuild, DMG,
  notarization, PyPI, updater, website, or GitHub release work.

### Responses Empty-Args / Invalid XML Cleanup Fix

Source fix:

- `vmlx_engine/server.py`
- `_generic_parse_filtered` now strips native tool-markup residue when the text
  contains tool markers but no valid parser, instruction-echo repair, or
  required-single-tool bare-JSON repair produced a call.

What this fixes:

- The reported preamble plus empty XML function shape no longer falls through
  as visible raw tool markup in the shared nonstream parser cleanup path:
  `<tool_call><function=exec_command></function></tool_call>`.
- Required-tool streaming already failed closed in current source; this closes
  the remaining shared parser fallback gap.
- The fix does not synthesize missing arguments, rewrite function names, or
  accept `{}` for required schemas.

Verification:

- Focused slice:
  `6 passed`
  - empty required XML call fails closed
  - Responses preamble plus empty XML never emits `"arguments": "{}"`
  - auto mode keeps visible preamble while stripping invalid raw XML
  - nonstream/shared parser strips invalid XML residue
  - valid XML preserves escaped special characters and spacing
- Broader parser/Responses slice:
  `33 passed, 171 deselected`.
- Changed-file `py_compile` and `git diff --check` passed.

Boundary:

- This is source/API parser cleanup proof. It is not same-model live
  direct/gateway/tunnel raw SSE recapture, and it does not by itself close the
  output-index parity row.

### Gemma4 31B QAT JANG_4M Installed-App Bundled Video Proof

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-31b-jang4m-video-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-31b-jang4m-video-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/models/JANGQ-AI/gemma-4-31B-it-qat-JANG_4M`.
- Chat Completions streaming, `enable_thinking=false`, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`.
- Explicit `max_prompt_tokens=12000`.
- Media fixture: `build/media-fixtures/red-64x64-1s.mp4`, sent as base64
  `video_url`.

Proven:

- Status `pass`; app route used installed-app UI and bundled Python.
- Video attachment persisted and semantic check passed:
  `videoVerified=true`, `videoSemanticVerified=true`, expected regex
  `red|solid`.
- Visible video answer:
  `The provided image is a solid red square.`
- Server media evidence:
  request had `types={"video_url":1}`, base64 MP4 decoded, `25` total frames at
  `25.0 fps`, `4` frames extracted, and the Gemma media fallback processed the
  sampled video frames through the image-frame path.
- Runtime stayed on Gemma4 QAT JANG_4M VLM path:
  JANG v2 VLM mmap load, vision tower upcast to `bfloat16`, wired limit `44 GB`
  for a `27 GB` model, `affine_quantized_matmul`, `weight_format=jang_affine`,
  `profile=JANG_4M`, MLX affine quantized matmul dispatch, and Metal affine
  symbols active on Apple M5 Max.
- Native cache proof:
  `mixed_swa_kv_v1` with full-attention KV, sliding-window KV, preserved
  rotating-window metadata, prefix cache, paged cache, block-disk L2, and q4
  storage-boundary quantization applying only to full-attention KV.
- Cache/L2 metrics:
  `cache_detail=paged+mixed_swa`, second text turn `cached_tokens=20`,
  `ram_tokens_cached=62`, `l2_block_tokens_on_disk=62`,
  `l2_tokens_on_disk=62`, `blocks_on_disk=2`, and `disk_writes=2`.
- Live speed samples:
  text turns reported `19.5 tok/s` and `19.6 tok/s`; the video turn completed
  in `2.8s` with a single stream update, so the UI live-speed sample recorded
  `0.0 tok/s` while the server generated the visible media answer.

Boundary:

- This is a Chat Completions video/VL row, not a Responses API media row.
- This does not prove Gemma audio. Current Gemma QAT bundles still require
  weight-backed audio proof or honest gating before any audio claim.
- This is Gemma4 31B QAT JANG_4M only; MXFP variants remain separate rows.
- This is not a release/sign/notarize/PyPI/updater/site action.

### Gemma4 26B QAT JANG_4M Installed-App Bundled Video Proof

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-26b-jang4m-video-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-26b-jang4m-video-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/models/JANGQ-AI/gemma-4-26B-A4B-it-qat-JANG_4M`.
- Chat Completions streaming, `enable_thinking=false`, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`.
- Explicit `max_prompt_tokens=12000`.
- Media fixture: `build/media-fixtures/red-64x64-1s.mp4`, sent as base64
  `video_url`.

Proven:

- Status `pass`; app route used installed-app UI and bundled Python.
- Video attachment persisted and semantic check passed:
  `videoVerified=true`, `videoSemanticVerified=true`, expected regex
  `red|solid`.
- Visible video answer:
  `The video shows a solid, bright red square that remains static throughout the entire duration.`
- Server media evidence:
  request had `types={"video_url":1}`, base64 MP4 decoded, `25` total frames at
  `25.0 fps`, `4` frames extracted, and Gemma runtime processed the video as
  image frames.
- Runtime stayed on Gemma4 QAT JANG_4M VLM path:
  JANG v2 VLM mmap load, vision tower upcast to `bfloat16`, wired limit `36 GB`
  for an `18 GB` model, `affine_quantized_matmul`, `weight_format=jang_affine`,
  `profile=JANG_4M`, MLX affine quantized matmul dispatch, and Metal affine
  symbols active on Apple M5 Max.
- Native cache proof:
  `mixed_swa_kv_v1` with full-attention KV, sliding-window KV, preserved
  rotating-window metadata, prefix cache, paged cache, block-disk L2, and q4
  storage-boundary quantization applying only to full-attention KV.
- Cache/L2 metrics:
  `cache_detail=paged+mixed_swa`, second text turn `cached_tokens=20`,
  `ram_tokens_cached=72`, `l2_block_tokens_on_disk=72`,
  `l2_tokens_on_disk=72`, `blocks_on_disk=2`, and `disk_writes=2`.
- Live speed samples:
  text turns reported `87.3 tok/s` and `88.2 tok/s`; the video turn completed
  in `1.0s` with a single stream update, so the UI live-speed sample recorded
  `0.0 tok/s` even though the server generated the full visible video answer.

Boundary:

- This is a Chat Completions video/VL row, not a Responses API media row.
- This does not prove Gemma audio. Current Gemma QAT bundles still require
  weight-backed audio proof or honest gating before any audio claim.
- This is Gemma4 26B QAT JANG_4M only; Gemma 31B installed-app bundled video
  and MXFP variants remain separate rows.
- This is not a release/sign/notarize/PyPI/updater/site action.

### Nex/N2 Pro JANGTQ2 Installed-App Bundled Audio Honest Gate

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-audio-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-audio-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`.
- Chat Completions streaming, `enable_thinking=false`, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`.
- Media fixture: generated 1-second 16 kHz mono WAV, sent as `input_audio`.

Observed result:

- Status `fail` because requested audio was not supported.
- UI/session did send one audio attachment:
  `files=[{"kind":"audio","name":"real-ui-proof-audio.wav","mime":"audio/wav"}]`.
- Request body contained `input_audio`, `format="wav"`, and non-empty audio
  data.
- Server media diagnostic saw `types={"input_audio":1}` for family
  `qwen3_5_moe`.
- API returned HTTP 400:
  `/v1/chat/completions received unsupported media modality audio. Supported
  modalities: text, vision, video.`

Boundary:

- This is an honest current installed-app/bundled-runtime audio gate, not an
  audio success proof.
- Do not advertise N2 JANGTQ2 audio from token/config metadata. Current proved
  modalities for this bundle/runtime are text, vision, and video.
- Loader/runtime still proved JANGTQ2 VLM fast path, hybrid SSM cache,
  attention-only TurboQuant KV, q4 storage-boundary KV, block-disk L2, and SSM
  companion L2 before the audio request was rejected.
- This is not N2 JANG_1L and not a release/sign/notarize/PyPI action.

### Nex/N2 Pro JANGTQ2 Installed-App Bundled Video Proof

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-video-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-video-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`.
- Chat Completions streaming, `enable_thinking=false`, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`.
- Media fixture: `build/media-fixtures/red-64x64-1s.mp4`, sent as base64
  `video_url`.

Proven:

- Status `pass`; app route used installed-app UI and bundled Python.
- Video attachment persisted and semantic check passed:
  `videoVerified=true`, `videoSemanticVerified=true`, expected regex
  `red|solid`.
- Server media evidence:
  request had `types={"video_url":1}`, base64 MP4 decoded, `25` total frames at
  `25.0 fps`, `4` frames extracted, and runtime processed
  `num_images_processed=4`.
- Runtime stayed on N2 JANGTQ2 VLM fast path:
  MXTQ/JANGTQ VLM native TurboQuant fast path, `turboquant_codebook`,
  `weight_format=mxtq`, `profile=JANGTQ2`, 2-bit routed experts, group size
  64, `540` prestacked routed-expert TQ targets, `bfloat16` enabled for 512
  experts to prevent overflow, command-buffer split installed, full-model
  16-token prefill warmup complete.
- Native cache proof:
  hybrid SSM cache, attention-only TurboQuant KV, q4 storage-boundary KV,
  block-disk L2, SSM companion state, and async rederive policy.
- Media cache safety:
  prefix/paged store was skipped for the video prompt because media embeddings
  are path-dependent and must not be rebuilt from text-only tokens.
- Cache/L2 metrics:
  `ram_tokens_cached=50`, `l2_block_tokens_on_disk=50`,
  `l2_ssm_tokens_on_disk=68`, `l2_tokens_on_disk=118`, `blocks_on_disk=2`,
  `disk_writes=2`, `disk_hits=3`.
- Live speed samples:
  `30.0 tok/s`, `27.5 tok/s`, `29.4 tok/s`; video turn prompt path showed
  `vision_encoding_time=0.0063s`, generator `generation_tps=31.8`, peak memory
  `110.4GB`.

Boundary:

- This is a Chat Completions video/VL row, not a Responses API media row.
- This does not prove audio. Existing N2 audio installed-app evidence remains
  an honest unsupported-modality fail for this bundle/runtime path.
- This is not N2 JANG_1L and not a release/sign/notarize/PyPI action.

### Nex/N2 Pro JANGTQ2 Installed-App Responses Reasoning/Tool/Cache Proof

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-reasoning-tools-cache-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-reasoning-tools-cache-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`.
- Responses API streaming, `tool_choice=auto`, built-in `run_command`
  tools, `qwen` tool parser, `qwen3` reasoning parser,
  `enable_thinking=true`, deterministic `temperature=0`, `top_p=1`,
  `top_k=1`.

Proven:

- Status `pass`; app route used installed-app UI and bundled Python.
- Reasoning-enabled row produced `reasoning_display` in proven surfaces and
  `eventCounts.reasoningDone=5`.
- Built-in auto tool loop passed with `eventCounts.tool=124`, `stream=34`,
  `complete=3`; both tool turns executed real `run_command` calls and
  tool-result continuation.
- A no-tool reasoning probe was sent in the same proof (`Think briefly, then
  answer exactly: FOUR`) and final visible answer was `FOUR`.
- Proven surfaces included installed app UI, real loaded model, Responses API,
  Responses delta streaming/cache-detail usage, long tool loop,
  parser/language leak checks, settings persistence, server cache controls,
  cache endpoint stats, native cache status, L2 disk storage, and tool/L2 cache
  integration.
- Runtime/cache proof stayed on the N2 JANGTQ2 path:
  `turboquant_codebook`, `weight_format=mxtq`, `profile=JANGTQ2`,
  2-bit routed experts, group size 64, `540` prestacked routed-expert TQ
  targets, hybrid SSM native cache, attention-only TurboQuant KV, q4
  storage-boundary KV, SSM companion state, and async rederive policy.
- Cache/L2 metrics at end of proof:
  `ram_tokens_cached=7289`, `l2_block_tokens_on_disk=7289`,
  `l2_ssm_tokens_on_disk=26169`, `l2_tokens_on_disk=33458`,
  `blocks_on_disk=117`, `disk_writes=117`, `disk_hits=134`.
- Live speed samples: `45.5 tok/s`, `23.7 tok/s`, and `34.9 tok/s`; health
  memory about `103.8GB` active / `108.8GB` peak, generator peak `114.1GB`.

Boundary:

- This still excludes N2 JANG_1L.
- This is a no-media row; it does not prove N2 image/video/audio semantics.
- The artifact proves reasoning display/event behavior in the installed app
  proof, but it does not retain full raw SSE objects for direct output-index
  parity. Same-model raw SSE direct/gateway/tunnel output-index proof remains a
  separate row.
- `persistedReasoningCount=0` in this UI artifact, so it should not be cited
  as proof that reasoning text is persisted in chat history.
- MTP remains unavailable for this bundle because it reports
  `bundle_has_mtp=false` / `metadata_only_missing_weights`.

### MiniMax Legacy XML Raw Fallback Spacing Fix

- Source fix:
  `vmlx_engine/tool_parsers/minimax_tool_parser.py` no longer trims inner text
  when the legacy `<func_name>...</func_name>` fallback cannot parse JSON and
  serializes the schema-gated `{"raw": ...}` argument. It still uses trimmed
  text only for JSON detection/parsing.
- Regression:
  `tests/test_tool_parsers.py::TestMiniMaxToolParser::test_xml_function_raw_fallback_preserves_spacing`
  covers `<minimax:tool_call><legacy_raw>  alpha\nbeta  </legacy_raw>` with a
  request schema requiring `raw`.
- Audit correction:
  `tests/test_engine_audit.py` now checks the current Responses streaming
  invariants: parse candidates include `accumulated_content`,
  `accumulated_reasoning`, stripped full text, raw full text, and the final
  missing-required-args fail-closed guard.
- Verification:
  focused MiniMax slice passed `4 passed`; broad parser/Responses exactness
  slice passed `361 passed`; changed-file `py_compile` and `git diff --check`
  passed.
- Boundary:
  source/parser proof only. This is not a fresh MiniMax live model run and not
  a release/notarization/PyPI action.

### Nex/N2 Pro JANGTQ2 Installed-App Responses Tool/Cache Proof

Artifact:

- `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-tools-cache-bundled-python-20260610-proof.json`
- screenshot:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-tools-cache-bundled-python-20260610-chat.png`

Live setup:

- Installed app UI: `/Applications/vMLX.app`.
- Bundled runtime:
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`.
- Real model:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`.
- Responses API streaming, `tool_choice=auto`, built-in `run_command`
  tools, `qwen` tool parser, `qwen3` reasoning parser, deterministic
  `temperature=0`, `top_p=1`, `top_k=1`.
- Native hybrid cache path: paged cache, block-disk L2, SSM companion cache,
  and attention-only TurboQuant KV enabled.

Proven:

- Status `pass`; app route used installed-app UI and bundled Python, not the
  repo venv.
- Built-in auto tool loop executed both turns without empty `{}` arguments:
  `eventCounts.tool=106`, `stream=23`, `complete=2`.
- Tool-result continuation used `previous_response_id` with
  `function_call_output` follow-up items.
- Responses delta streaming, parser leak check, language leak check,
  settings persistence, server cache controls, cache endpoint stats, cache hit
  telemetry, L2 disk storage, and tool/L2 cache integration were all recorded
  in `provenSurfaces`.
- Runtime classified the bundle as `turboquant_codebook`, `weight_format=mxtq`,
  `profile=JANGTQ2`, 2-bit routed experts, group size 64, with `540`
  prestacked routed-expert TQ targets and custom TurboQuant kernels.
- Native cache status reported `family=qwen3_5_moe`,
  `schema=hybrid_ssm_v1`, components `attention_kv`,
  `ssm_companion_state`, and `async_rederive`.
- Attention KV TurboQuant was enabled for attention layers only; SSM companion
  state stayed native/full precision. Storage-boundary KV quantization used
  q4/group-64 with async clean-prefill rederive policy.
- Cache/L2 metrics at end of proof:
  `ram_tokens_cached=6833`, `l2_block_tokens_on_disk=6833`,
  `l2_ssm_tokens_on_disk=25265`, `l2_tokens_on_disk=32098`,
  `blocks_on_disk=109`, `disk_writes=109`, `disk_hits=134`.
- Live speed samples: `22.4 tok/s` and `27.0 tok/s`; TTFT was
  `18.35s`/`19.20s` while serving a 100GB-class model with hybrid cache.
- Health memory: about `103.8GB` active, `108.8GB` peak, with generator peak
  reported as `114.1GB`.

Boundary:

- This is not N2 JANG_1L proof; that row remains intentionally excluded here.
- This run had `enable_thinking=false`, so it does not clear N2 visible
  reasoning/interleaved reasoning-delta proof.
- It is a no-media row; it does not prove N2 image/video/audio semantics.
- MTP metadata was detected but runtime MTP was not available because the bundle
  reports `bundle_has_mtp=false` / `metadata_only_missing_weights`.
- Server logs still warn that the chat template needs fallback tool schema
  injection; the proof shows the fallback is usable for this row, not that the
  model artifact template is complete.

### DSML HTML-ish Repair Spacing Fix

- Source fix:
  `vmlx_engine/tool_parsers/dsml_tool_parser.py` no longer strips accepted
  string parameters in the DSV4/DSML degraded HTML-ish invoke repair path.
  The path now uses the schema-aware plain-param coercion/presence helpers.
- Regression:
  `tests/test_tool_format.py::TestFallbackToolPromptFormat::test_dsml_parser_htmlish_repair_preserves_string_spacing`
  covers a degraded `<invoke_write_file>` with path spaces, shell punctuation,
  XML-entity-like text, leading/trailing spaces, and a newline.
- Verification:
  focused DSV4/DSML repair slice passed `4 passed`; broad parser/Responses
  exactness slice passed `252 passed`; changed-file `py_compile` and
  `git diff --check` passed.
- Boundary:
  source/parser proof only. This is not a fresh live direct/gateway/tunnel raw
  SSE capture, not a MiMo JANGTQ model-exactness fix, and not release proof.

### MiniMax Raw Invoke Spacing Fix

- Source fix:
  `vmlx_engine/tool_parsers/minimax_tool_parser.py` preserves original raw
  invoke content when serializing fallback `{"raw": ...}` arguments. It still
  uses trimmed text for JSON detection/parsing.
- Regression:
  `tests/test_tool_parsers.py::TestMiniMaxToolParser::test_bare_invoke_raw_fallback_preserves_spacing`
  covers a schema-gated raw string payload with leading/trailing spaces and a
  newline.
- Verification:
  focused MiniMax slice passed `3 passed`; broad parser/Responses exactness
  suite passed `253 passed`; changed-file `py_compile` and `git diff --check`
  passed.
- Boundary:
  source/parser proof only. This is not a fresh live MiniMax model run, not a
  gateway/tunnel recapture, and not release proof.

### MiMo JANGTQ_2 Required Tool Raw SSE Exactness Red

Artifact:

- `build/current-mimo-jangtq2-required-tool-raw-sse-20260610.sse`
- rejected follow-up:
  `build/current-mimo-jangtq2-required-tool-after-toolchoice-propagation-20260610.sse`

Live setup:

- Direct source server only; no gateway/tunnel.
- MiMo JANGTQ_2 loaded from
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`.
- Responses API streaming, `tool_choice=required`, `xml_function` parser,
  `think_xml` reasoning parser, native MiMo mixed full/SWA cache, paged cache,
  block-disk L2, deterministic `temperature=0`, `top_p=1`.
- Tool schema required one string field: `value`.
- Prompt requested `record_fact` exactly once with value `blue-cat`.

Green:

- Structural raw SSE was valid.
- Message item used `output_index=0`; function call item used
  `output_index=1`.
- `response.function_call_arguments.delta`,
  `response.function_call_arguments.done`, final `response.output_item.done`,
  and `response.completed` agreed on the same argument object.
- No empty `{}` args, no parser exception, and no visible raw XML/tool-markup
  leak.
- Native JANGTQ/TurboQuant runtime remained active, and block-disk L2 wrote
  5 blocks / `288` cache-key tokens for the prompt.

Red:

- Required string exactness failed. The request asked for `blue-cat`, but the
  model/tool path streamed:
  - delta 1: `{"value": "blue `
  - delta 2: `cat"}`
  - final: `{"value": "blue cat"}`
- This is not the Qwen-style empty-arguments transport bug. It is a MiMo
  spacing/special-character tool-argument exactness failure.

Boundary:

- Do not clear this row by post-parse string repair, schema coercion, prompt
  wording only, or synthetic argument reconstruction.
- A temporary source prompt-injection hypothesis was tested and rejected:
  forcing XML-function required turns through the concrete fallback prompt
  changed the prompt (`289` to `364` tokens) but worsened the final argument to
  `{"value":"bluecat\n"}`. That source change was reverted and must not be
  used as release evidence.
- Still open: tool-result continuation, auto-tool/no-tool comparison,
  gateway/tunnel parity, installed-app parity, media semantics, and release
  readiness.

### MiMo JANG_2L vs JANGTQ_2 Post-Warm Direct Speed Boundary

Artifacts:

- `build/current-mimo-jang2l-postwarm-normal-no-trace-20260610.response.json`
- `build/current-mimo-jang2l-postwarm-cachehit-normal-no-trace-20260610.response.json`
- `build/current-mimo-jangtq2-postwarm-normal-no-trace-20260610.response.json`
- `build/current-mimo-jangtq2-postwarm-cachehit-normal-no-trace-20260610.response.json`

Live setup:

- Source server, not release/package work.
- Same port/settings per run: Responses API, `max_num_seqs=1`, continuous
  batching, `xml_function` tool parser, `think_xml` reasoning parser, paged
  cache, native MiMo mixed full/SWA cache, block-disk L2 enabled, no
  `VMLINUX_DECODE_TRACE`.
- Prompt: `Reply with exactly: SPEED_OK`, deterministic
  `temperature=0`, `top_p=1`, `max_output_tokens=8`.

Proven:

- MiMo JANG_2L loaded real
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L`, 112GB model,
  native mixed full/SWA cache, L2 enabled, `lm_head=True`, qkv `48/48`,
  switch proj `141/141`, dense MLP `3/3`. Sidecar inspection showed
  `lm_head.weight=(152576,1024)` uint32 and
  `lm_head.scales/biases=(152576,64)` float16, matching affine 8-bit group-64
  for hidden size 4096.
- JANG_2L startup paid the single-active MiMo decode graph warmup:
  `45.71s`. Post-warm exact response was `SPEED_OK`, 4 output tokens in
  `5.39s` server time (`0.7 tok/s`). Repeated same prompt found the expected
  short mixed-SWA cache hit and deliberate tiny-hit bypass, then exact
  `SPEED_OK`, 4 output tokens in `5.35s` (`0.7 tok/s`).
- MiMo JANGTQ_2 loaded real
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`, 83GB model,
  native TurboQuant path, 141 TQ groups/replacements, fused gate+up,
  native mixed full/SWA cache, L2 enabled, and single-active MiMo warmup
  `0.05s`.
- JANGTQ_2 post-warm exact response was `SPEED_OK`, 4 output tokens in
  `1.39s` server time (`2.9 tok/s`). Repeated same prompt found the expected
  short mixed-SWA cache hit and deliberate tiny-hit bypass, then exact
  `SPEED_OK`, 4 output tokens in `1.32s` (`3.0 tok/s`).
- Cache behavior is architecture-honest: generic TurboQuant KV stayed off for
  MiMo; native full/SWA/RotatingKVCache plus paged/L2 remained active. Short
  31-token hits are intentionally bypassed because reconstructing tiny
  mixed-SWA prefixes is slower than full prefill.

Boundary:

- This classifies the reported MiMo 0.3 tok/s-style issue as a real JANG_2L
  affine full-vocab lm_head/decode throughput blocker, not a prefix/L2 cache
  bug and not a loader upcast/mis-shape bug by current evidence.
- JANGTQ_2 is the viable fast MiMo checkpoint lane today; JANG_2L remains slow
  after warmup and should not be advertised as a high-throughput MiMo path.
- These short exact rows do not prove long-run 40 tok/s throughput, required
  tools, tool-result continuation, media semantics, source-vs-quant exactness,
  installed-app parity, package/sign/notarize, or release readiness.
- The JANG_2L shutdown emitted a Python 3.13 finalization/GIL fatal after clean
  app-layer shutdown; JANGTQ_2 shutdown did not. Track separately as a
  shutdown-runtime issue if it repeats.

### Qwen/Qwen-Coder Empty Required Tool Args Fail-Closed Guard

Source update:

- `vmlx_engine/server.py`
- `tests/test_engine_audit.py`

Proven:

- Current source now applies a final request-schema required-argument guard
  before Responses emits `function_call` SSE items.
- A malformed parsed call such as `exec_command` with `{}` is dropped when the
  request schema requires `cmd`; it will fall through to the existing
  `tool_choice=required` failed-response path rather than streaming
  `arguments: ""` / `{}` to Codex/opencode-style clients.
- Tools with no required arguments are not rejected merely because their
  argument string is empty.
- Existing Qwen parser cases still preserve valid schema-derived arguments for
  XML string arguments and plain tool-line output.

Verification:

- `.venv/bin/python -m py_compile vmlx_engine/server.py tests/test_engine_audit.py`
- `.venv/bin/python -m pytest -q tests/test_engine_audit.py -k 'qwen_issue_192 or xml_function_empty_required_args_fail_closed_at_server_boundary or responses_final_tool_emit_drops_empty_required_args'`
  passed `4/4`.
- `.venv/bin/python -m pytest -q tests/test_responses_raw_sse_parity_contract.py`
  passed `20/20`.
- `git diff --check` passed.

Boundary:

- This is a current-source parser/API fail-closed guard, not a new live model
  recapture.
- Direct/gateway/tunnel Qwen35 evidence still comes from existing artifacts
  such as
  `build/current-responses-raw-sse-parity-qwen35-direct-gateway-tunnel-after-missing-required-args-failclosed-20260610.json`.
- Still open: fresh same-model Qwen-coder-next and Qwen35 live recapture after
  this commit if release gating requires current-run artifacts, plus installed
  app/package parity and broader parser-family proof.

### Gemma4 12B QAT MXFP4 Responses Tool/Cache Leak Fix

Artifact:

- `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-qat-mxfp4-responses-tools-request-parser-fallback-20260610-proof.json`

Source update:

- `vmlx_engine/server.py`
- `tests/test_engine_audit.py`

Proven:

- Real local Gemma4 12B QAT MXFP4 loaded from
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`.
- Responses API dev-app proof used built-in tools and completed two tool-loop
  turns with visible assistant output:
  `The file has been created successfully. REAL_UI_LIVE_TOOL_ONE` and
  `The second UI turn is complete with REAL_UI_LIVE_TOOL_TWO.`
- The prior visible `thought\n...` leak is gone in this proof:
  `rawParserLeak=false`, `reasoningRawParserLeak=false`, and stream traces for
  both messages begin with visible `The` rather than `thought`.
- Cache proof remained active: `cache_hit_requests=3`,
  `cache_hit_tokens=3619`, `cache_detail=paged+mixed_swa`, and Gemma4
  mixed-SWA block-disk L2 recorded `3518` tokens on disk.
- Process cleanup was verified after the proof; no matching proof server,
  dev-app, or Electron process was left listening on the checked ports.

Root-cause/fix boundary:

- The source bug was the streaming Chat/Responses request path depending only
  on the global `_reasoning_parser`. CLI/app launch paths can leave that global
  unset even when the loaded model config resolves to `reasoning_parser=gemma4`.
- The fix adds a request-local reasoning parser fallback from the loaded model
  config when the global parser is missing and reasoning parser selection was
  not explicitly disabled.
- Explicit `--reasoning-parser none` remains a hard opt-out.
- No text was synthesized, no tool arguments were invented, no reasoning was
  disabled to hide the leak, and no broad output post-repair was added.

Verification:

- `.venv/bin/python -m py_compile vmlx_engine/server.py tests/test_engine_audit.py`
- `.venv/bin/python -m pytest -q tests/test_engine_audit.py -k 'request_reasoning_parser_falls_back_to_loaded_config or request_reasoning_parser_fallback_respects_explicit_none or loaded_gemma4_mxfp_sidecar_refreshes_auto_parsers or loaded_model_parser_refresh_preserves_explicit_disables or gemma4_supports_thinking_is_explicit_not_implicit'`
  passed `5/5`.
- Focused live proof command:
  `VMLINUX_REAL_UI_MODEL_PATH=/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4 VMLINUX_REAL_UI_SERVED_MODEL=gemma4-12b-qat-mxfp4-request-parser-fallback-20260610 VMLINUX_REAL_UI_PROOF_BASENAME=current-real-ui-live-model-gemma4-12b-qat-mxfp4-responses-tools-request-parser-fallback-20260610 VMLINUX_REAL_UI_WIRE_API=responses VMLINUX_REAL_UI_BUILTIN_TOOLS=1 VMLINUX_REAL_UI_ENABLE_THINKING=0 VMLINUX_REAL_UI_MAX_TOKENS=96 VMLINUX_REAL_UI_MAX_PROMPT_TOKENS=12000 VMLINUX_REAL_UI_MAX_TOOL_ITERATIONS=4 VMLINUX_REAL_UI_CHECK_SERVER_CACHE_CONTROLS=1 node panel/scripts/live-real-ui-model-proof.mjs`

Boundary:

- This clears the current-source Gemma4 12B QAT MXFP4 dev-app
  Responses/tools visible `thought` leak row.
- It does not prove installed-app parity, packaged/bundled Python parity,
  Gemma media/video/audio rows, every Gemma QAT size, direct/gateway/tunnel
  Qwen empty-args parity, MiMo JANGTQ_2 exactness, N2 rows, or release
  readiness.

### MiMo Source Combined-Media Splice Fix

Source update:

- `vmlx_engine/models/mllm.py`
- `tests/test_mimo_v2_media_runtime.py`

Proven:

- MiMo `Model.__call__` now splices all present image/video/audio modalities
  in one `get_input_embeddings(...)` call before clearing `input_ids`.
- The previous source flow handled `pixel_values` first, cleared `input_ids`,
  and could then fail or skip later video/audio splices in combined-media
  requests.
- Focused regression proves a single forward with both an image token and an
  audio token replaces both modal positions while text positions stay as text
  embeddings.

Verification:

- `.venv/bin/python -m py_compile vmlx_engine/models/mllm.py tests/test_mimo_v2_media_runtime.py`
- `.venv/bin/python -m pytest -q tests/test_mimo_v2_media_runtime.py -k 'image_and_audio_in_one_forward or model_splices_image_pixels_through_vision_tower or audio_projection_bridge_splices_audio_token'`
  passed `3/3`.

Boundary:

- This is a source contract fix for combined VL/audio/video requests. It does
  not clear MiMo JANGTQ_2 red-square/color semantics, literal exactness,
  required-tool argument exactness, live audio waveform semantics, live video
  semantics, Responses continuation, installed-app parity, package/sign/
  notarize, or release readiness.
- Source-vs-quant color first-divergence could not be rerun because
  `erics-m5-max2.local:8126` and `127.0.0.1:8897` endpoints were unavailable.

### MiMo JANGTQ_2 CLI Media + Block-Disk L2 Overlay Fix

Artifact:

- `build/current-mimo-v25-jangtq2-cli-media-l2-after-overlay-fix-20260610.json`
- `docs/internal/agent-notes/current-real-ui-dev-app-mimo-v25-jangtq2-icon-image-after-overlay-fix-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-dev-app-mimo-v25-jangtq2-icon-image-after-overlay-fix-20260610-chat.png`

Raw/live files:

- `build/mimo-jangtq2-cli-media-l2-after-overlay-fix-requests-20260610/image-request.json`
- `build/mimo-jangtq2-cli-media-l2-after-overlay-fix-requests-20260610/image-response.json`
- `build/mimo-jangtq2-cli-media-l2-after-overlay-fix-requests-20260610/cache-after-text-1.json`
- `build/mimo-jangtq2-cli-media-l2-after-overlay-fix-requests-20260610/cache-after-text-2.json`
- `build/mimo-jangtq2-cli-media-l2-after-overlay-fix-requests-20260610/cache-after-restart-text-request.json`

Source update:

- `vmlx_engine/server.py`
- `tests/test_engine_audit.py`

Proven:

- Root cause reproduced and fixed for the CLI path: `cli serve --is-mllm`
  previously loaded the promoted MiMo V2.5 JANGTQ_2 bundle text-only because
  `_mimo_v2_media_runtime_auto_enabled()` refused explicit
  `weights_preserved_text_runtime` metadata before checking complete local
  runtime sidecars.
- The fix allows the overlay only for MiMo JANG/JANGTQ/MXTQ runtime bundles
  with complete sidecars and source runtime classes. Generic preserved-media
  bundles still route text-only.
- Live CLI launch loaded `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`
  as `mllm=True`, auto-enabled preserved media runtime, bound `459` preserved
  media tensors, quantized `101` runtime modules, and kept native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`.
- Chat Completions image request reached the MLLM runtime and returned HTTP
  `200` with visible `vMLX`.
- Current Electron dev-app proof now accepts an image prompt override and
  passed with `panel/resources/icon.png`: the UI launched current source,
  adopted the MiMo server, sent the image through Chat Completions, recorded
  `MEDIA_DIAG engine_is_mllm=true`, and added `vl_image` to proven surfaces.
- MiMo generic TurboQuant KV stayed inactive; native MiMo asymmetric
  full/SWA/rotating cache remained the cache contract.
- Text cache proof wrote one block / `55` tokens to block-disk L2, repeated
  same-process with `cache_detail=paged`, then fresh-process restarted from
  the same L2 directory and restored with `cache_detail=paged+disk`,
  `cached_tokens=55`, and `disk_hits=1`.

Focused checks:

- `.venv/bin/python -m py_compile vmlx_engine/server.py tests/test_engine_audit.py`
- `.venv/bin/python -m pytest -q tests/test_mimo_v2_media_capability_gate.py -k 'mimo_v2_runtime_modalities_auto_enable_when_runtime_and_sidecars_are_complete or preserved_text_runtime_routes_text_only or runtime_modalities_fail_closed_for_preserved_text_runtime'`
  passed `3/3`.
- `.venv/bin/python -m pytest -q tests/test_engine_audit.py -k 'mimo_v2_text_runtime_metadata_auto_enables_complete_media_bundle'`
  passed `1/1`.

Boundary:

- This proves current-source CLI media routing plus text cache/L2 write and
  fresh-process restore, plus current-source dev-app image routing for a
  vMLX icon prompt. It does not clear MiMo semantic exactness, red-square image
  color quality, audio hygiene/exactness, Responses tool-result continuation,
  installed-app parity, package/sign/notarize, or release readiness.
- Media-context KV was intentionally not stored to L2; the server skipped media
  prompt cache storage because media embeddings are path-dependent.
- Older dev-app/installed-app image/video/audio rows that returned text-only
  `400` are stale relative to this source fix. Dev-app image and video now have
  current-source media-route proof, but installed-app media still needs rerun.
- The dev-app icon image answer still contained visible planning-style prose
  under `enableThinking=false`; keep MiMo no-thinking output hygiene open.

### MiMo JANGTQ_2 Quant-Only First-Divergence Side

Artifacts:

- `build/current-mimo-v25-jangtq2-source-vs-quant-first-divergence-quant-only-exact-probes-20260610.json`
- `build/current-mimo-v25-jangtq2-source-vs-quant-quant-only-health-after-20260610.json`

Proven:

- Real local MiMo JANGTQ_2 loaded as `mimo-v2-jangtq2` on `127.0.0.1:8897`.
- Runtime used native JANGTQ TurboQuant weights, native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`, paged cache, and block-disk
  L2. Generic TurboQuant KV stayed off by explicit isolation.
- The updated first-divergence harness now survives a missing source endpoint
  and still executes/captures the quant side.
- Quant endpoint returned HTTP `200` for all eight rows.
- ACK proxy rows pass, but the real exactness rows fail:
  `blue-cat -> blue`, `B7-CAT-09 -> B7CAT-09`,
  JSON `value` loses the hyphenated literal, and required tool args become
  `{"value":"blue cat"}`.
- Server logs recorded block L2 write-through for every quant-side prompt
  before clean shutdown.

Blocked:

- Source endpoint `http://erics-m5-max2.local:8126` is still absent. Current
  AdLab handoff says valid source truth requires a deliberate Swift MiMo TP4
  relaunch through `adlab-pair`; do not substitute a casual Python source load
  as source truth.

Boundary:

- This proves current quant-side mutation and cache/runtime behavior, not
  source-vs-quant causality. MiMo JANGTQ_2 exactness remains red until the
  Swift TP4 source endpoint runs and the same harness classifies whether source
  also fails or quant diverges.

### MiMo JANGTQ_2 Source-Vs-Quant First-Divergence Harness

Artifact:

- `build/current-mimo-v25-jangtq2-source-vs-quant-first-divergence-preflight-exact-probes-20260610.json`

Source update:

- `tests/cross_matrix/run_mimo_v2_source_vs_quant_first_divergence.py`

Proven:

- The existing first-divergence harness now defaults the quant served model to
  `mimo-v2-jangtq2` instead of the stale `mimo-v2-jang2l` name.
- The harness now includes the exact failing MiMo rows: plain `blue-cat`,
  plain `B7-CAT-09`, exact JSON with `blue-cat`, exact JSON with
  `B7-CAT-09`, plus the existing required tool-call `blue-cat` row.
- Preflight confirms both model paths exist:
  `/Volumes/EricsLLMDrive/jangq-ai/sources/MiMo-V2.5` on
  `erics-m5-max2.local` and
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2` locally.

Blocked:

- The source endpoint `http://erics-m5-max2.local:8126/health` and local quant
  endpoint `http://127.0.0.1:8897/health` were both connection-refused during
  this preflight, so no source-vs-quant generation rows were executed.

Next command once both endpoints are running:

```sh
.venv/bin/python tests/cross_matrix/run_mimo_v2_source_vs_quant_first_divergence.py \
  --source-base-url http://erics-m5-max2.local:8126 \
  --quant-base-url http://127.0.0.1:8897 \
  --source-model mimo-v2-source \
  --quant-model mimo-v2-jangtq2 \
  --out build/current-mimo-v25-jangtq2-source-vs-quant-first-divergence-exact-probes-20260610.json
```

Boundary:

- This is harness/proof-path correction and prerequisite evidence, not a MiMo
  runtime fix. Do not claim MiMo JANGTQ_2 exactness green until the updated
  source-vs-quant rows run and show whether source also fails or quant diverges.

### MiMo JANG_2L vs JANGTQ_2 Exactness A/B

Artifact:

- `build/current-mimo-v25-jang2l-vs-jangtq2-exactness-ab-20260610.json`

Raw probe:

- `build/current-mimo-v25-jang2l-exactness-variant-ab-20260610/result.json`

Proven:

- Real MiMo V2.5 JANG_2L loaded on the 128GB host with native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`, paged cache, block L2, and
  no generic TurboQuant KV.
- JANG_2L preserved `blue-cat` in plain completions, chat, JSON, and required
  tool-call arguments.
- JANG_2L preserved `B7-CAT-09` inside required tool-call arguments and had a
  paged cache hit of `192` tokens on the final tool request.
- The same eight-row probe remains fully red for MiMo JANGTQ_2, where
  `blue-cat` mutates to `blue` or `blue grass`, JSON values mutate, and tool
  args mutate to `{"value":"blue"}` / `{"value":"B7CAT-09"}`.

Boundary:

- This is not a MiMo release-clearance proof. JANG_2L still drifts visible
  sentinel text (`B7-CAT-09` -> `B7-CAD-09` / `B7-C44-09`) and omits `count`
  in the sentinel JSON row.
- JANGTQ_2 remains blocked on artifact/requant-profile/source-vs-quant
  first-divergence or decode/logit quality. Do not fix this by parser repair,
  JSON repair, string post-processing, sampling clamps, or cache changes.

### Gemma 12B MXFP8 CRACK Same-Model Public Responses SSE

Artifact:

- `build/current-responses-raw-sse-parity-direct-gateway-tunnel-gemma4-12b-mxfp8-crack-20260610.json`

Raw captures:

- `build/responses-sse-captures-20260610/direct-gemma4-12b-mxfp8-crack-tool-20260610.sse`
- `build/responses-sse-captures-20260610/gateway-gemma4-12b-mxfp8-crack-tool-20260610.sse`
- `build/responses-sse-captures-20260610/tunnel-gemma4-12b-mxfp8-crack-tool-20260610.sse`

Proven:

- Same model across direct source, panel gateway, and public tunnel:
  `models/Gemma-4-12B-it-MXFP8-CRACK`.
- Required tool arguments preserved as `{"value":"blue-cat"}` with
  `response.function_call_arguments.delta` and `.done`.
- Reasoning events present with no reasoning-disable workaround.
- Final response object is consistent with the stream.
- Output indices are valid on all three surfaces.
- Local source runtime used Gemma mixed-SWA paged cache plus block-disk L2 and
  hit 102 cached tokens on the gateway request.

Boundary:

- This supersedes the old `gemma4-e2b-sse` public tunnel blocker for the
  generic Responses raw SSE release row by targeting an actually advertised
  same Gemma model. It does not prove every Gemma QAT row, MiMo exactness/media,
  installed-app parity, release readiness, or N2 JANG_1L.

### Gemma JANG/MXFP Audio Modality Current State

Artifact:

- `build/current-gemma-jang-mxfp-audio-modality-current-state-20260610.json`

Proven:

- Current source and bundled Python agree for the local Gemma 12B QAT MXFP4,
  12B JANG_4M, 12B QAT JANG_4M, 26B QAT JANG_4M, 31B QAT JANG_4M, and native
  12B MXFP4 rows.
- Runtime modalities are `text`, `vision`, and `video`.
- Audio is not runtime-supported for these rows. The 12B unified/MXFP rows have
  `audio_config`, `audio_token_id`, and `embed_audio.embedding_projection`, but
  no `audio_tower.*` weights. The 26B/31B rows do not advertise `audio_config`
  and also have no `audio_tower.*` weights.
- Current bundled runtime matches source for `_bundle_declares_native_audio` and
  `_loaded_runtime_modalities`.
- Panel source now mirrors the same weight-backed audio boundary for local
  Gemma4/Gemma4-text chats. `detectModelConfigFromDir()` stamps
  `architectureHints.audioRuntimeAvailable=false` when a Gemma bundle has
  `audio_config`/audio tokens or projection-only `embed_audio.*` but no indexed
  `audio_tower.*` weights, while preserving `isMultimodal=true` for valid
  image/video routing. `chat.ts` uses that hint to omit only `input_audio`
  parts for known-no-audio local Gemma bundles instead of routing them to a
  server-side 400.
- Verification for the panel gate: `npm --prefix panel run typecheck` passed;
  `npm --prefix panel test -- --run tests/model-config-registry.test.ts`
  passed `69/69`, including config-only/projection-only audio false and
  `audio_tower.*` true cases.

Boundary:

- Do not use older Gemma audio semantic-red rows as evidence that audio is
  currently supported. Current source/bundled truth is honest unsupported-audio
  gating until a weight-backed `audio_tower.*` artifact exists and passes live
  audio E2E.
- This is not a release/sign/notarize/package/PyPI/updater action.

### Qwen35 Responses Raw SSE

Artifact:

- `build/current-responses-raw-sse-parity-qwen35-direct-gateway-tunnel-after-missing-required-args-failclosed-20260610.json`

Follow-up source/API fix:

- 2026-06-10 13:27 PDT: `vmlx_engine/server.py` now applies the missing-required
  argument guard inside `_parse_tool_calls_with_parser(...)` after request-tool
  filtering for both configured parser output and generic parser output. This
  extends the Qwen empty-args fail-closed rule to shared Chat/Responses parser
  paths, not only the Responses final SSE emitter.
- Regression:
  `tests/test_engine_audit.py::test_generic_parser_empty_required_args_fail_closed_at_shared_boundary`.
- Verification: focused engine-audit parser tests passed `5/5`, raw SSE parity
  contract passed `20/20`, py_compile passed, and `git diff --check` passed.
- Boundary: no local Qwen-coder-next artifact was found, so Qwen-coder-next
  remains not live-proven. This is a source fail-closed API/parser boundary fix,
  not a claim that every parser family live matrix is green.

Proven:

- Current-source direct, real panel gateway, and current public tunnel all
  preserve required `record_fact` arguments `{"value": "blue-cat"}` with
  reasoning enabled.
- All three surfaces parse cleanly, report the same served model
  `models/Qwen3.6-35B-A3B-MXFP8-CRACK-MTP`.
- Direct/gateway emit valid output indices:
  `message=[0]`, `reasoning=[1]`, `function_call=[2]`; tunnel emits
  `message=[0]`, `function_call=[1]`.
- All three surfaces have complete reasoning lifecycle, valid function-call
  argument delta/done, and final response consistency.
- Runtime health in the direct capture proves native MTP active, hybrid SSM
  cache, live attention TurboQuant KV, block-disk L2, and Qwen tool/reasoning
  parser defaults.
- Current-source focused guards passed on 2026-06-10 with `8 passed`, covering
  streamed preamble plus empty XML fail-closed behavior, no emitted
  `arguments: "{}"` executable tool calls, nonstream parser cleanup, Chat
  Completions fail-closed parity, next output-index allocation for function
  calls, duplicate-output-index classification, and interleaved
  content/reasoning/tool SSE classification.
- 2026-06-10 21:41 PDT focused refresh selected `6` current tests and passed
  `6/6`: Qwen streaming XML empty required args fail closed, empty
  `<function=exec_command></function>` fails closed with required schema,
  Responses streamed preamble plus empty XML never emits executable `{}`,
  function_call output indices advance past the message item, and the raw-SSE
  classifier flags output-index reuse. Command:
  `.venv/bin/python -m pytest -q tests/test_tool_parsers.py tests/test_server.py
  tests/test_responses_raw_sse_parity_contract.py -k "streaming_xml_empty_required_args_fail_closed or empty_function_with_required_schema_fails_closed or streaming_responses_preamble_empty_xml_tool_call_never_emits_empty_arguments or streaming_responses_tool_call_uses_next_output_index_without_text or classifier_flags_function_call_reusing_message_output_index or raw_sse_parity_fails_when_surface_reuses_message_output_index_for_tool"`.

Boundary:

- This clears Qwen35 same-model direct/gateway/tunnel raw Responses SSE for
  this required-tool request and closes the current source-side empty required
  args / duplicate output-index lane for that captured model. It does not
  clear every Qwen/Qwen-coder size, public deployment freshness, installed app
  UI, tool-result continuation for every profile, Gemma/MiMo/N2, or release
  readiness row.

### Qwen27 MXFP8 Responses Raw SSE

Artifact:

- `build/current-responses-raw-sse-parity-qwen27-mxfp8-direct-gateway-tunnel-20260610.json`

Raw captures:

- `build/responses-sse-captures-20260610/direct-qwen27-mxfp8-mtp-tool-20260610.sse`
- `build/responses-sse-captures-20260610/gateway-qwen27-mxfp8-mtp-tool-20260610.sse`
- `build/responses-sse-captures-20260610/tunnel-qwen27-mxfp8-mtp-tool-20260610.sse`

Proven:

- Same served model across current-source direct server, real panel gateway, and
  public tunnel: `models/Qwen3.6-27B-MXFP8-CRACK-MTP`.
- All three surfaces preserve required `record_fact` arguments
  `{"value": "blue-cat"}` with reasoning enabled and no reasoning-disable
  workaround.
- All three surfaces parse cleanly, emit valid function-call argument
  delta/done events, match the expected function/model/arguments, and keep final
  response consistency.
- Direct/gateway output indices are valid with
  `message=[0]`, `reasoning=[1]`, `function_call=[2]`; tunnel output indices
  are valid with `message=[0]`, `function_call=[1]`.
- Runtime health in the direct capture proves local
  `/Users/eric/models/JANGQ/Qwen3.6-27B-MXFP8-MTP` loaded with native MTP active
  at effective depth 3, `hybrid_ssm_v1` cache, `attention_kv`,
  `ssm_companion_state`, `async_rederive`, attention-only TurboQuant KV via
  `turboquant_kv_v1`, paged cache, and block-disk L2.
- Gateway log preserved request kwargs: stream, max output tokens, temperature,
  top_p, top_k, `enable_thinking=true`, `tool_choice=required`, one tool, and
  first tool `record_fact`.

Boundary:

- This clears Qwen27 MXFP8 same-model direct/gateway/public-tunnel raw
  Responses SSE for this required-tool request. It does not prove
  Qwen-coder-next, Qwen27 tunnel tool-result continuation, installed-app UI,
  media/VL/audio/video, all parser families, or release readiness.

### Qwen27 JANG_4M-MTP Direct/Gateway Tool-Result Continuation

Artifacts:

- `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-required-tool-after-visible-finalization-seed-fix-20260610.sse`
- `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-tool-result-continuation-after-visible-finalization-seed-fix-20260610.sse`
- `build/responses-sse-captures-20260610/gateway-qwen27-jang4m-mtp-required-tool-after-visible-finalization-seed-fix-20260610.sse`
- `build/responses-sse-captures-20260610/gateway-qwen27-jang4m-mtp-tool-result-continuation-after-visible-finalization-seed-fix-20260610.sse`
- `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-health-after-visible-finalization-seed-fix-20260610.json`
- `build/responses-sse-captures-20260610/gateway-qwen27-jang4m-mtp-health-after-gateway-continuation-20260610.json`

Proven:

- Earlier direct Qwen27 JANG_4M-MTP continuation was red because the model
  exhausted output budget in reasoning-only content after a tool result. Current
  seed-fix captures supersede that row.
- Direct required-tool SSE preserves `record_fact` arguments
  `{"value":"blue-cat"}` with reasoning-enabled startup and completed final
  object.
- Direct post-tool continuation SSE now emits visible `output_text.delta`
  chunks, completes with `status=completed`, and final `output_text` is
  `The fact "blue-cat" has been recorded.`.
- Gateway post-tool continuation SSE shows the same visible completed response
  through the real panel gateway path.
- Direct health proves real local
  `/Users/eric/models/JANGQ/Qwen3.6-27B-JANG_4M-MTP` / `JANGQ/Qwen3.6-27B-JANG_4M-MTP`
  loaded as MLLM, native MTP active, `hybrid_ssm_v1` cache, attention KV
  TurboQuant/storage boundary active, paged cache, block-disk L2, and SSM
  companion disk stores.

Boundary:

- This clears the current direct/gateway Qwen27 JANG_4M-MTP tool-result
  continuation red row from the older reasoning-only artifact. It does not prove
  public-tunnel JANG_4M-MTP continuation, Qwen-coder-next, installed-app UI,
  media/VL/audio/video, every parser family, or release readiness.

### Qwen35 Tool-Result Continuation And Hybrid Cache

Artifact:

- `build/current-qwen35-mxfp8-mtp-responses-tool-result-auto-no-tool-after-ssm-size-scale-20260610/SUMMARY.json`

Fix:

- `vmlx_engine/cli.py` now scales hybrid SSM companion entry capacity from the
  MB budget when a caller reserves more than the default SSM memory. Default
  remains conservative at `512 MB -> 8` entries; the 128GB-lane launch budget
  `8192 MB` now yields `64` entries.

Proven:

- Live health reported `ssm_companion.max_entries=64`, Qwen3.5 MoE native MTP,
  hybrid SSM cache, live attention TurboQuant KV, paged cache, block L2, and
  SSM companion L2.
- Responses gate passed with `overall_pass=true`: `tool_choice=auto`, two
  structured tool calls, two in-turn `function_call_output` continuations,
  `previous_response_id`, final no-tools visible answer, tool-result evidence,
  no raw tool markup leak, block L2 writes, SSM companion L2, and strict
  post-first cache hits (`cached_tokens=128`, then `256`).

Boundary:

- This green row uses final-turn `enable_thinking=false` as a compatibility
  control after reasoning-enabled tool turns. It does not clear full
  reasoning-enabled final no-tool synthesis; the earlier
  `build/current-qwen35-mxfp8-mtp-responses-tool-result-auto-no-tool-max1536-20260610/SUMMARY.json`
  stayed red because the final no-tool answer was reasoning-only before visible
  output.

### MiMo JANGTQ_2 Loader Contract

Artifact:

- `build/current-mimo-v25-jangtq2-load-module-contract-20260610.json`

Proven:

- The vMLX MiMo runtime registration is required; vanilla `mlx_vlm.load` does
  not support `mimo_v2`.
- With vMLX registration, MiMo JANGTQ_2 load completes in about `7.0s`.
- `config.quantization` reaches MiMo `text_config`.
- `lm_head` is q8 `QuantizedLinear`; `model.embed_tokens` is q8
  `QuantizedEmbedding`.
- Sampled attention projections are q4 `QuantizedLinear`.
- Sampled routed experts are 2-bit prestacked
  `jang_tools.turboquant.tq_kernel.TurboQuantSwitchLinear`.

Still red:

- This excludes the obvious sidecar-binding loader bug, but it does not clear
  exactness. The current dev-app exactness proof still shows
  `ACK-CB-742 -> ACKCB-742` and `blue-cat -> blue`.
- Parallel-lane action: either run source-vs-quant first-divergence/logit proof
  or compare TurboQuant selected-expert outputs/logits against dequant/reference.
  Do not patch semantic values in parser/JSON repair and do not chase cache/L2
  as the primary cause without contrary logits evidence.

## Proven Live On 128GB Host

### Current Release-Manifest Accounting

Artifact:

- `build/current-release-regression-manifest-after-mimo-jang2l-responses-l2-accounting-20260610.json`

Proven:

- The MiMo JANG_2L root-cause validator now points at current evidence for
  text/cache, SwitchGLU parity, metadata honesty, long-prompt OOM, Chat tool
  boundary, source-vs-quant preflight, fresh-process L2 restore, and Responses
  tools rerun.
- The MiMo row has `missing=[]`, so stale absent artifacts are no longer hiding
  the current proof surface.
- Green subchecks in that row: metadata truth, narrow text/cache,
  SwitchGLU selected-expert parity, direct Chat tool protocol, fresh-process
  block-disk L2 restore, and Responses transport/cache/L2.

Still red:

- `current_proof_sweep=fail`, `prepackage_ready=false`, `release_ready=false`.
- MiMo remains blocked by long-prompt first-request Metal OOM, JANGTQ_2
  artifact exactness, decode speed, JANG_2L live media/L2, JANG_2L
  Responses/tool semantic drift, UI/installed-app media parity after the CLI
  source fix, and source-vs-quant/no-source classification. Current-source CLI
  MiMo JANGTQ_2 media plus text L2 is now green in the artifact above, but that
  does not clear app/installed rows.

### Dev-App Detector and Settings Launch Parity

Artifacts:

- `build/current-panel-settings-contract-proof-20260610-mimo-n2-gemma-launch-parity.json`
- `build/current-panel-exact-local-model-detect-mimo-n2-gemma-20260610.json`
- `build/current-installed-app-runtime-parity-audit-after-june10-devapp-proofs-20260610.json`
- `build/current-installed-app-runtime-parity-audit-after-local-install-20260610.json`
- `build/current-release-regression-manifest-after-local-installed-app-parity-20260610.json`

Proven:

- Panel settings/launch contract is current-source green:
  `status=pass`, `missing_source_markers=[]`, panel settings tests passed
  `315`, model registry tests passed `66` in the contract artifact,
  engine model registry passed `140`, and CLI flag contract passed `9`.
- Exact local Gemma 12B MXFP4 and JANG4M directories now autodetect as
  `family=gemma4`, `cacheType=rotating_kv`, `usePagedCache=true`,
  `toolParser=gemma4`, `reasoningParser=gemma4`, and multimodal.
- Exact local MiMo JANG_2L and JANGTQ_2 directories now autodetect as
  `family=mimo_v2`, `cacheSubtype=mimo_v2_asymmetric_swa`,
  `usePagedCache=true`, `toolParser=xml_function`, and no automatic reasoning
  claim.
- Exact local N2 JANGTQ2 directory autodetects as `qwen3.5-moe`,
  `cacheType=hybrid`, paged, Qwen tools, Qwen3 reasoning, TurboQuant, and
  multimodal.
- Exact local N2 JANG_1L directory autodetects as `qwen3.5-moe`,
  `cacheType=hybrid`, paged, Qwen tools, Qwen3 reasoning, but
  `forceTextOnly=true` until VL and memory-safe runtime proof exist.

Fixes made:

- Added panel `gemma4_unified` and `gemma4_unified_text` model-type aliases so
  Gemma 4 unified bundles do not fall to `unknown`.
- Aligned panel MiMo detection with the Python registry: XML tools remain on,
  `mimo_v2_asymmetric_swa` cache subtype is exposed, paged cache is forced for
  that subtype, and MiMo reasoning is not auto-advertised without visible-final
  thinking proof.
- Installed-app runtime parity was stale before the local rebuild: the June 10
  audit found only `vmlx_engine/utils/jang_loader.py` mismatched in both bundled
  Python and packaged source mirrors. `/Applications/vMLX.app` was rebuilt and
  reinstalled with `panel/scripts/build-and-install.sh`; rerun audit
  `build/current-installed-app-runtime-parity-audit-after-local-install-20260610.json`
  is `status=pass`, `missing_or_stale=[]`, bundled engine hash parity true,
  packaged source hash parity true, `serve_help_runs=true`,
  `xml_function_tool_parser_cli=true`, parser/reasoning settings wired,
  model-owned generation defaults wired, max-output/max-context settings wired,
  Responses stream cache-detail metrics wired, and single-model gateway cache
  endpoint routing wired.
- The rebuilt `/Applications/vMLX.app` also passed
  `codesign --verify --deep --strict --verbose=2`; this was a local app-dir
  install, not a Developer ID notarized DMG release.
- Regenerated no-heavy release manifest
  `build/current-release-regression-manifest-after-local-installed-app-parity-20260610.json`
  remains `status=fail`, `prepackage_ready=false`, and `release_ready=false`,
  but its current proof sweep has `installed_app_runtime_parity_audit=true` and
  `staged_app_runtime_parity_audit=true`.

Not proven:

- Electron UI clicked chat transcript for every exact row. N2 JANGTQ2, Gemma
  12B MXFP4, and MiMo JANG_2L now have scoped installed-app rows below; other
  model/profile rows do not inherit those proofs.
- N2 JANG_1L memory-safe live startup. The latest high-free live attempt
  `build/current-n2-jang1l-live-chat-cache-ultrafree-20260610.json` started
  from `114.2 GiB` available with low-peak one-at-a-time knobs and still failed
  before health after `Wired limit set to 115 GB (model 119 GB)` with
  `[METAL] Command buffer execution failed: Insufficient Memory`.
- MiMo JANGTQ_2 exactness.
- Gemma audio/video semantic E2E.
- Same-model direct/gateway/tunnel raw SSE deployed parity.
- Full release/prepackage readiness; the regenerated manifest still has open
  blockers outside installed-app runtime parity.

### Gemma 4 12B MXFP4 and JANG4M

Artifacts:

- `build/current-gemma4-12b-mxfp4-jang4m-media-smoke-live-20260610.json`
- `build/current-gemma4-12b-mxfp4-jang4m-live-runtime-audit-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-qat-mxfp4-dev-app-proof-20260610.json`
- `build/current-real-ui-dev-app-gemma4-12b-mxfp4-exact-output-proof-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-qat-mxfp4-image-proof-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-qat-mxfp4-video-proof-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-qat-mxfp4-audio-proof-20260610.json`
- `build/current-real-ui-installed-app-gemma4-12b-mxfp4-responses-tools-cache-20260610.json`
- `build/current-real-ui-installed-app-gemma4-12b-mxfp4-image-proof-20260610.json`
- `build/current-real-ui-installed-app-gemma4-12b-mxfp4-video-proof-20260610.json`
- `build/current-real-ui-installed-app-gemma4-12b-mxfp4-audio-proof-20260610.json`

Proven:

- MXFP4 and JANG4M both loaded through current vMLX server.
- Image/media path returned correct visible color answer.
- Conservative text runtime passed for both rows.
- Visible answer, multi-turn recall, reasoning-on visible answer, required
  tool call, and cache endpoint sanity passed.
- Real Electron dev-app Gemma 12B QAT MXFP4 Responses/tools/cache proof is
  green. The app loaded `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`,
  executed the built-in `run_command` loop twice, used scoped Responses
  `function_call_output` follow-ups with `previous_response_id`, and created
  the expected probe files containing `REAL_UI_LIVE_TOOL_ONE` and
  `REAL_UI_LIVE_TOOL_TWO`.
- The MXFP4 app proof recorded content deltas for both assistant turns
  (`16` and `31` trace events), `responses_delta_streaming`,
  `responses_cache_detail_usage`, `long_tool_loop`, and
  `tool_l2_cache_integrated`.
- Runtime proof in the same app run: `weight_format=mxfp4`, `profile=MXFP4`,
  `weight_matmul_dispatch=mlx_affine_quantized_matmul`,
  `metal_na_active_on_host=true`, `passthrough_tensor_count=349`, active memory
  about `7773.6 MB`, and peak memory about `10518 MB`.
- Cache proof in the same app run: Gemma mixed-SWA cache,
  `cache_detail=paged+mixed_swa`, `cache_hit_tokens=3538`,
  final `cached_tokens=2688`, `l2_block_tokens_on_disk=3588`,
  block-disk `disk_hits=30`, and `disk_writes=58`.
- Current Electron dev-build exact-output proof is green for Gemma 12B QAT
  MXFP4: `GEMMA-ACK-742` returned exactly, and
  `{"status":"ok","value":"gemma-blue"}` returned exactly. The same run
  recorded no parser/reasoning leak, no persisted tools/reasoning,
  model-owned generation defaults, `weight_format=mxfp4`, Metal NA active,
  `mixed_swa_kv_v1`, generic TurboQuant KV correctly disabled for rotating
  mixed-SWA metadata, `cache_detail=paged+mixed_swa`, `cache_hit_tokens=22`,
  `l2_block_tokens_on_disk=61`, and block-disk writes `2`.
- Real Electron dev-app Gemma 12B QAT MXFP4 image/VL proof is green. The app
  persisted an image attachment, server `MEDIA_DIAG` observed one `image_url`,
  the Gemma media fallback ran with `1 image(s)`, and the assistant answered
  `Red` for the red-image semantic probe.
- The MXFP4 image proof also showed MXFP4 affine matmul with Metal NA active,
  mixed-SWA cache, `cache_detail=paged+mixed_swa`, `cached_tokens=20`,
  `l2_block_tokens_on_disk=64`, and block-disk `disk_writes=2`.
- Real Electron dev-app Gemma 12B QAT MXFP4 video/VL proof is green for the
  same 1-second 64x64 solid-red MP4 fixture used by the N2 proof. The app
  persisted a `video_url` attachment, server `MEDIA_DIAG` observed one
  `video_url`, the server decoded the base64 MP4, reported
  `25 total frames @ 25.0 fps`, extracted `4 frames`, and the assistant
  answered `The video shows a solid red screen.`
- The MXFP4 video proof also showed MXFP4 affine matmul with Metal NA active,
  mixed-SWA cache, `cache_detail=paged+mixed_swa`, `cached_tokens=20`,
  `l2_block_tokens_on_disk=65`, and block-disk `disk_writes=2`.
- Real Electron dev-app Gemma 12B QAT MXFP4 audio proof is red by explicit
  runtime guard, not by crash. The app attempted an audio turn, server
  `MEDIA_DIAG` saw `input_audio`, and the API returned `400`:
  `/v1/chat/completions received unsupported media modality audio. Supported
  modalities: text, vision, video.`
- Local rebuilt installed app proof is now green for Gemma 12B QAT MXFP4
  Responses/tool/cache. `/Applications/vMLX.app` launched as
  `uiLaunchMode=installed-app`, adopted the real server for
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`, used
  `/v1/responses`, executed two built-in `run_command` calls, and produced
  visible assistant turns containing `REAL_UI_LIVE_TOOL_ONE` and
  `REAL_UI_LIVE_TOOL_TWO`.
- The installed-app Gemma MXFP4 run verified the probe files exactly:
  `real_ui_tool_probe_1.txt=REAL_UI_LIVE_TOOL_ONE\n` and
  `real_ui_tool_probe_2.txt=REAL_UI_LIVE_TOOL_TWO\n`.
- The installed-app run recorded renderer content deltas (`count=16` and
  `count=24`), `eventCounts.tool=156`, `eventCounts.stream=40`,
  `eventCounts.complete=2`, server cache controls, settings persistence, and
  no raw parser/reasoning leak.
- Installed-app Gemma MXFP4 runtime/cache evidence: `weight_format=mxfp4`,
  `profile=MXFP4`, `weight_matmul_dispatch=mlx_affine_quantized_matmul`,
  `metal_na_active_on_host=true`, active memory about `7772.4 MB`, peak memory
  about `10512.9 MB`, native cache `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=3538`, `l2_block_tokens_on_disk=3584`,
  `l2_tokens_on_disk=3584`, block-disk `disk_hits=30`, and
  `disk_writes=58`.
- Local rebuilt installed app image/VL proof is also green for Gemma 12B QAT
  MXFP4. The app persisted the image attachment, the server `MEDIA_DIAG` saw
  one `image_url`, the Gemma media fallback ran with `1 image(s)`, and the
  assistant answered `Red` for the red-image semantic probe.
- The installed-app image run recorded `vl_image`, `installed_app_ui`,
  `server_cache_controls`, content deltas (`count=21`, `12`, and `1`), no raw
  parser/reasoning leak, `weight_format=mxfp4`, Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`, `cached_tokens=20`,
  `l2_block_tokens_on_disk=70`, `l2_tokens_on_disk=70`, and `disk_writes=2`.
- Local rebuilt installed app video/VL proof is now green for the same Gemma
  12B QAT MXFP4 row. The app persisted a video attachment, server `MEDIA_DIAG`
  saw one `video_url`, the server decoded the base64 MP4, reported `25 total
  frames @ 25.0 fps`, extracted `4 frames`, routed those frames through the
  Gemma media fallback, and the assistant answered `The video shows a solid red
  background with no movement or changes.`
- The installed-app video run recorded `video_where_supported`,
  `installed_app_ui`, `server_cache_controls`, content deltas (`count=21`,
  `12`, and `1`), no raw parser/reasoning leak, `weight_format=mxfp4`, Metal NA
  active, native `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cached_tokens=20`, `l2_block_tokens_on_disk=70`, `l2_tokens_on_disk=70`, and
  `disk_writes=2`.
- Local rebuilt installed app audio proof is red by explicit runtime guard, not
  by crash or cache failure. The installed app launched, completed two visible
  text turns, forced multimodal for one attached audio file, server
  `MEDIA_DIAG` saw one `input_audio`, and `/v1/chat/completions` returned
  `400`: `/v1/chat/completions received unsupported media modality audio.
  Supported modalities: text, vision, video.`
- The installed-app audio boundary run still recorded the Gemma runtime/cache
  surfaces before the failing audio turn: active memory about `7562.3 MB`, peak
  about `7872.4 MB`, `weight_format=mxfp4`, Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`, `cached_tokens=20`,
  `l2_block_tokens_on_disk=70`, `l2_tokens_on_disk=70`, and block-disk
  `disk_writes=2`. Generic TurboQuant KV remained correctly disabled for this
  mixed-SWA family.

Not proven:

- Installed-app audio support for the MXFP4 row. Installed-app image and video
  are green; installed-app audio is classified red by honest unsupported
  modality guard.
- Audio weight-backed E2E for the MXFP4 dev-app row is red; current source
  honestly rejects audio with supported modalities `text, vision, video`.
- Full larger Gemma QAT matrix through UI/installed app.
- Tunnel/gateway parity for these exact Gemma rows.
- Gemma 12B QAT MXFP4 dev-app audio support. Image and video are green in the
  source dev app; audio is honestly gated as unsupported.
- Older MXFP4 Responses/tool artifacts where visible text began with `thought`
  are superseded by
  `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-qat-mxfp4-responses-tools-request-parser-fallback-20260610-proof.json`.
  Do not carry the old visible-`thought` caveat into current release notes for
  the post-fix source row.

### Gemma 4 12B JANG4M Real Dev-App Proof

Artifact:

- `build/current-real-ui-live-model-gemma4-12b-jang4m-dev-app-proof-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-jang4m-video-proof-20260610.json`
- `build/current-real-ui-live-model-gemma4-12b-jang4m-audio-proof-20260610.json`
- `build/current-real-ui-dev-app-gemma4-12b-jang4m-exact-output-proof-20260610.json`
- `build/current-real-ui-installed-app-gemma4-12b-jang4m-responses-tools-cache-20260610.json`

Raw ignored proof captures:

- `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-jang4m-responses-tools-cache-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-jang4m-image-cache-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-jang4m-video-cache-max12k-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-jang4m-audio-cache-20260610-proof.json`

Proven:

- Real Electron dev app launched with `npm run dev`, connected to a real vMLX
  server loading `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-JANG_4M`.
- Responses UI rail passed with built-in `run_command` tools enabled.
- Two-turn tool loop executed real commands, wrote/read
  `REAL_UI_LIVE_TOOL_ONE`, wrote `REAL_UI_LIVE_TOOL_TWO`, and persisted tool
  execution/result phases in the chat UI state.
- Responses stream trace carried visible content deltas and server metrics.
  The two turns ended with `cachedTokens=2687` and `cachedTokens=2901`,
  `cacheDetail=paged+mixed_swa`, and live decode around `45 t/s`.
- Chat Completions UI rail passed with image attachment enabled.
- The attached red image reached the Gemma MLLM media path and returned visible
  `Red`; `media.imageSemanticVerified=true`.
- Server/cache controls were visible in the app session and matched the
  expected cache labels.
- Gemma native cache surfaced as mixed-SWA with prefix cache, paged cache, and
  block-disk L2 writes.
- No raw parser/tool markup leak and no hidden reasoning leak were observed in
  either dev-app run.
- Real Electron dev-app video pass is now green for a 1-second solid-red MP4
  when the session context cap is raised to `12000` prompt tokens. The app
  persisted a `video_url` attachment, the server decoded the base64 MP4,
  extracted frames, routed it through the MLLM media fallback, and the assistant
  answered `solid, dark red screen...`.
- The same video path with the default `4096` prompt cap failed honestly with
  `HTTP 413 prompt_too_long`, reporting about `8315` prompt tokens. Therefore
  Gemma 12B JANG4M video support is proven only with an adequately large context
  cap for this fixture, not with the 4k cap.
- The video pass also showed mixed-SWA cache/L2 surfaces:
  `cache_detail=paged+mixed_swa`, `cached_tokens=20`,
  `l2_block_tokens_on_disk=84`, and `disk_writes=2`.
- Real Electron dev-app audio attachment plumbing is now classified, but red:
  the app persisted an `input_audio` part, the server decoded the base64 WAV,
  and visible assistant output streamed, but the model did not transcribe the
  generated phrase `audio present`. The failed audio proof still shows cache
  and launch surfaces green: `cache_detail=paged+mixed_swa`,
  `cacheHitTokens=67`, `l2_tokens_on_disk=67`, `disk_writes=2`, and server
  cache controls verified.
- Current Electron dev-build exact-output proof is green for Gemma 12B JANG4M.
  The app loaded `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-JANG_4M`,
  returned exact text `JANG4M-ACK-742`, returned exact JSON
  `{"status":"ok","value":"jang4m-blue"}`, auto-detected Gemma4 tool and
  reasoning parsers, and recorded no raw parser/reasoning leak and no persisted
  tools/reasoning.
- Dev-build JANG4M exact-output runtime/cache evidence: active memory
  `9680.4 MB`, peak `9950.7 MB`, `weight_format=jang_affine`,
  `profile=JANG_4M`, Metal NA active, native `mixed_swa_kv_v1`,
  `cache_detail=paged+mixed_swa`, `cache_hit_tokens=24`,
  `l2_block_tokens_on_disk=66`, `l2_tokens_on_disk=66`, and block-disk
  `disk_writes=2`.
- Current Electron dev-build exact-output proof is also green for Gemma 26B
  A4B QAT JANG4M. The app loaded
  `/Users/eric/models/JANGQ-AI/gemma-4-26B-A4B-it-qat-JANG_4M`, returned exact
  text `GEMMA26-JANG4M-ACK-742`, returned exact JSON
  `{"status":"ok","value":"gemma26-jang4m-blue"}`, recorded no raw
  parser/reasoning leak, and persisted no tools/reasoning.
- Dev-build Gemma 26B JANG4M runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-26b-jang4m-exact-output-proof-20260610.json`
  records active memory `17650.5 MB`, peak `17842.9 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, Metal NA eligibility, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=29`, `l2_block_tokens_on_disk=81`,
  `l2_tokens_on_disk=81`, and block-disk `disk_writes=2`.
- Current Electron dev-build exact-output proof is green for Gemma 31B QAT
  JANG4M as well. The app loaded
  `/Users/eric/models/JANGQ-AI/gemma-4-31B-it-qat-JANG_4M`, returned exact text
  `GEMMA31-JANG4M-ACK-742`, returned exact JSON
  `{"status":"ok","value":"gemma31-jang4m-blue"}`, recorded no raw
  parser/reasoning leak, and persisted no tools/reasoning.
- Dev-build Gemma 31B JANG4M runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-31b-jang4m-exact-output-proof-20260610.json`
  records active memory `25333.1 MB`, peak `25778.7 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, Metal NA eligibility, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=29`, `l2_block_tokens_on_disk=81`,
  `l2_tokens_on_disk=81`, and block-disk `disk_writes=2`.
- Current Electron dev-build Responses/tool/cache proof is green for Gemma 31B
  JANG4M. The app used `/v1/responses`, executed built-in `run_command`,
  followed up with `previous_response_id` plus `function_call_output`, completed
  two visible assistant turns, and wrote exact probe files
  `REAL_UI_LIVE_TOOL_ONE` and `REAL_UI_LIVE_TOOL_TWO`.
- Dev-build Gemma 31B Responses/tool/cache evidence:
  `build/current-real-ui-dev-app-gemma4-31b-jang4m-responses-tools-cache-20260610.json`
  records active memory `28090.3 MB`, peak `34587.3 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=320`, `l2_block_tokens_on_disk=1960`,
  `l2_tokens_on_disk=1960`, block-disk `disk_writes=58`, and block-disk
  evictions `26` inside the 2 GB L2 cap.
- Current Electron dev-build Responses/tool/cache proof is green for Gemma 26B
  A4B QAT JANG4M. The app used `/v1/responses`, executed built-in
  `run_command`, followed up with `previous_response_id` plus
  `function_call_output`, completed two visible assistant turns, and wrote
  exact probe files `REAL_UI_LIVE_TOOL_ONE` and `REAL_UI_LIVE_TOOL_TWO`.
- Dev-build Gemma 26B Responses/tool/cache evidence:
  `build/current-real-ui-dev-app-gemma4-26b-jang4m-responses-tools-cache-20260610.json`
  records active memory `17782 MB`, peak `19943.9 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=3538`, `l2_block_tokens_on_disk=3559`,
  `l2_tokens_on_disk=3559`, block-disk `disk_hits=30`, and block-disk
  `disk_writes=58`.
- Current Electron dev-build image/VL proof is green for Gemma 26B A4B QAT
  JANG4M. The app persisted one image attachment, server `MEDIA_DIAG` saw
  `image_url`, the Gemma media fallback ran with `1 image(s)`, and the
  assistant answered `Red`; `imageSemanticVerified=true`.
- Dev-build Gemma 26B image/VL runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-26b-jang4m-image-proof-20260610.json`
  records active memory `17780.6 MB`, peak `18557.2 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=64`,
  `l2_tokens_on_disk=64`, block-disk `disk_writes=2`, and image-turn media
  prefix cache storage for `367` prompt tokens.
- Current Electron dev-build video/VL proof is green for Gemma 26B A4B QAT
  JANG4M at explicit `max_prompt_tokens=12000`. The app persisted one
  `video_url` attachment, server `MEDIA_DIAG` saw `video_url`, the server
  decoded the base64 MP4, extracted `4` frames, routed those frames through the
  Gemma media fallback, and the assistant answered `The video is a solid,
  static red square. REAL_UI_LIVE.`; `videoSemanticVerified=true`.
- Dev-build Gemma 26B video/VL runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-26b-jang4m-video-proof-20260610.json`
  records active memory `17779.1 MB`, peak `18557.2 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=64`,
  `l2_tokens_on_disk=64`, block-disk `disk_writes=2`, and video-turn media
  prefix cache storage for `357` prompt tokens.
- Current Electron dev-build audio proof is red for Gemma 26B A4B QAT JANG4M
  by explicit unsupported-modality guard. The app forced multimodal for one
  audio file and server `MEDIA_DIAG` saw `input_audio`, but
  `/v1/chat/completions` returned HTTP `400`: `unsupported media modality
  audio. Supported modalities: text, vision, video.`
- Dev-build Gemma 26B audio boundary runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-26b-jang4m-audio-proof-20260610.json`
  records active memory `17648.7 MB`, peak `17843.1 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=64`,
  `l2_tokens_on_disk=64`, and block-disk `disk_writes=2`.
- Current Electron dev-build image/VL proof is green for Gemma 31B QAT JANG4M.
  The app persisted one image attachment, server `MEDIA_DIAG` saw `image_url`,
  the Gemma media fallback ran with `1 image(s)`, and the assistant answered
  `Red`; `imageSemanticVerified=true`.
- Dev-build Gemma 31B image/VL runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-31b-jang4m-image-proof-20260610.json`
  records active memory `25850.6 MB`, peak `26233.1 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=62`,
  `l2_tokens_on_disk=62`, block-disk `disk_writes=2`, and image-turn media
  prefix cache storage for `365` prompt tokens.
- Current Electron dev-build video/VL proof is green for Gemma 31B QAT JANG4M
  at explicit `max_prompt_tokens=12000`. The app persisted one `video_url`
  attachment, server `MEDIA_DIAG` saw `video_url`, the server decoded the
  base64 MP4, extracted `4` frames, routed those frames through the Gemma media
  fallback, and the assistant answered `The provided image is a solid red
  square.`; `videoSemanticVerified=true`.
- Dev-build Gemma 31B video/VL runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-31b-jang4m-video-proof-20260610.json`
  records active memory `25842.8 MB`, peak `26233.1 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=62`,
  `l2_tokens_on_disk=62`, block-disk `disk_writes=2`, and video-turn media
  prefix cache storage for `355` prompt tokens.
- Current Electron dev-build audio proof is red for Gemma 31B QAT JANG4M by
  explicit unsupported-modality guard. The app forced multimodal for one audio
  file and server `MEDIA_DIAG` saw `input_audio`, but `/v1/chat/completions`
  returned HTTP `400`: `unsupported media modality audio. Supported
  modalities: text, vision, video.`
- Dev-build Gemma 31B audio boundary runtime/cache evidence:
  `build/current-real-ui-dev-app-gemma4-31b-jang4m-audio-proof-20260610.json`
  records active memory `25324.6 MB`, peak `25728.6 MB`,
  `weight_format=jang_affine`, `profile=JANG_4M`, Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=20`, `l2_block_tokens_on_disk=62`,
  `l2_tokens_on_disk=62`, and block-disk `disk_writes=2`.
- Local rebuilt installed app proof is now green for Gemma 12B JANG4M
  Responses/tool/cache. `/Applications/vMLX.app` launched as
  `uiLaunchMode=installed-app`, loaded
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-JANG_4M`, used `/v1/responses`,
  executed two built-in `run_command` calls, sent scoped tool-result
  continuations with `previous_response_id`, streamed visible assistant turns,
  and recorded content/tool deltas.
- Installed-app JANG4M runtime/cache evidence: `profile=JANG_4M`, JANG affine
  matmul with Metal NA active, active memory `9889.4 MB`, peak
  `12630.4 MB`, native `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=3538`, `l2_block_tokens_on_disk=3571`,
  `l2_tokens_on_disk=3571`, block-disk `disk_hits=30`, and block-disk
  `disk_writes=58`.
- Local rebuilt installed app image proof is now green for Gemma 12B JANG4M.
  `/Applications/vMLX.app` launched as `uiLaunchMode=installed-app`, loaded the
  same JANG4M artifact as MLLM, completed two visible text turns, persisted a
  red PNG image attachment, routed it through the Gemma media fallback with
  `1 image(s)`, and returned visible `Red`; `media.imageSemanticVerified=true`.
- Installed-app JANG4M image runtime/cache evidence: active memory `9892.5 MB`,
  peak `10450.3 MB`, JANG affine matmul with Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`, `cache_hit_tokens=20`,
  `l2_block_tokens_on_disk=77`, `l2_tokens_on_disk=77`, and block-disk
  `disk_writes=2`.
- Local rebuilt installed app video proof is now green for Gemma 12B JANG4M at
  `max_prompt_tokens=12000`. The app persisted a `video_url` attachment, server
  `MEDIA_DIAG` saw the video, decoded the base64 MP4, extracted `4` frames from
  the 25 fps fixture, routed it through the Gemma media fallback, and returned
  `The video shows a solid, static red screen with no movement or changes.`
- Installed-app JANG4M video runtime/cache evidence: active memory `9890 MB`,
  peak `10430.4 MB`, JANG affine matmul with Metal NA active, native
  `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`, `cache_hit_tokens=20`,
  `l2_block_tokens_on_disk=77`, `l2_tokens_on_disk=77`, and block-disk
  `disk_writes=2`.
- Local rebuilt installed app audio proof is classified red for Gemma 12B
  JANG4M. That older installed-app artifact attempted an `input_audio`
  attachment and recorded live runtime/cache state, but it did not prove audio
  support. Current source/bundled capability evidence in
  `build/current-gemma-jang-mxfp-audio-modality-current-state-20260610.json`
  and `build/current-gemma-audio-modality-source-boundary-20260610.json`
  supersedes the route classification: Gemma 12B JANG4M has `audio_config` and
  projection-only audio metadata but no `audio_tower.*` weights, so current
  runtime modalities are `text`, `vision`, and `video` only.
- Local rebuilt installed app Responses/tool/cache proof is now green for
  Gemma 26B QAT JANG4M. `/Applications/vMLX.app` launched as
  `uiLaunchMode=installed-app`, used bundled Python, loaded
  `/Users/eric/models/JANGQ-AI/gemma-4-26B-A4B-it-qat-JANG_4M`, used
  `/v1/responses`, executed two built-in `run_command` calls, recorded
  `long_tool_loop`, `reasoning_display`, `responses_delta_streaming`,
  `server_cache_controls`, `settings_persistence`, and visible chat screenshot,
  and wrote exact probe files `REAL_UI_LIVE_TOOL_ONE` and
  `REAL_UI_LIVE_TOOL_TWO`.
- Installed-app 26B QAT JANG4M runtime/cache evidence:
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-26b-qat-jang4m-responses-tools-cachecontrols-visible-chat-20260610-proof.json`
  records bundled Python
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`,
  native Gemma `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=7151`, `l2_block_tokens_on_disk=4884`, and no missing
  installed-app proof surfaces.
- Local rebuilt installed app Responses/tool/cache proof is now green for
  Gemma 31B QAT JANG4M using a narrower second-turn prompt that still required
  a real second `run_command` call. `/Applications/vMLX.app` launched as
  `uiLaunchMode=installed-app`, used bundled Python, loaded
  `/Users/eric/models/JANGQ-AI/gemma-4-31B-it-qat-JANG_4M`, used
  `/v1/responses`, completed two visible assistant turns, recorded
  `long_tool_loop`, `reasoning_display`, `responses_delta_streaming`,
  `server_cache_controls`, `settings_persistence`, and visible chat screenshot,
  and wrote exact probe files `REAL_UI_LIVE_TOOL_ONE` and
  `REAL_UI_LIVE_TOOL_TWO`.
- Installed-app 31B QAT JANG4M runtime/cache evidence:
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-31b-qat-jang4m-responses-tools-cachecontrols-visible-chat-short-second-tool-20260610-proof.json`
  records bundled Python
  `/Applications/vMLX.app/Contents/Resources/bundled-python/python/bin/python3`,
  native Gemma `mixed_swa_kv_v1`, `cache_detail=paged+mixed_swa`,
  `cache_hit_tokens=3408`, `l2_block_tokens_on_disk=2364`, and no missing
  installed-app proof surfaces.
- Boundary: the standard 31B installed-app long second-turn prompt failed at
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-31b-qat-jang4m-responses-tools-cachecontrols-visible-chat-20260610-proof.json`.
  That failed artifact proves load/cache/first-tool behavior but the second
  required-tool turn produced no tool call and correctly failed closed with
  `tool_calls_required`. Do not delete or mislabel that artifact; it documents
  prompt sensitivity rather than a parser/cache/app startup failure.

Not proven:

- Installed packaged app audio support for JANG4M; current installed-app proof
  is explicitly red.
- Installed packaged app JANG4M video at the default 4k prompt cap.
- Gemma 26B and 31B JANG4M public tunnel SSE and default 4k video behavior.
  Dev-app audio is tested and red by honest unsupported guard; installed-app
  text/tool/cache parity is now green for both rows.
- DMG package/sign/notarize/release readiness.
- Local panel session manager starting this exact model from launch args; these
  app proofs used a remote session connected to the server started by the proof
  harness.
- Gemma audio semantic E2E. Current source/bundled capability evidence gates
  this row as audio-unsupported before any semantic-support claim; do not treat
  older empty-output or semantic-fail audio attempts as support evidence.
- N2 or MiMo dev-app chat proof.
- Same-model public tunnel raw SSE parity.

### MiMo V2.5 JANGTQ_2

Artifacts:

- `build/current-mimo-v25-jangtq2-live-cb-cache-text-20260610.json`
- `build/current-mimo-v25-jangtq2-exactness-variant-probe-live-20260610/result.json`
- `build/current-real-ui-installed-app-mimo-v25-jangtq2-exact-output-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-responses-tools-cache-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-exact-output-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-exact-output-harness-assert-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-image-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-video-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jangtq2-audio-proof-20260610.json`
- `build/current-mimo-v25-jangtq2-cli-media-l2-after-overlay-fix-20260610.json`
- `docs/internal/agent-notes/current-real-ui-dev-app-mimo-v25-jangtq2-icon-image-after-overlay-fix-20260610-proof.json`
- `build/current-mimo-v25-jangtq2-disable-vmlx-fastpath-boundary-20260610.json`
- `build/current-mimo-v25-jangtq2-native-tq-allproj-contract-20260610.json`
- `build/current-mimo-v25-jangtq2-exactness-root-cause-boundary-20260610.json`

Proven:

- JANGTQ_2 bundle loaded and served on the 128GB host.
- Model footprint is about `79.45 GiB` on disk; final health showed about
  `76.4GB` active memory in the earlier cache/text row.
- Native MiMo mixed full/sliding attention cache surfaced as
  `mixed_swa_kv_v1`, subtype `mimo_v2_asymmetric_swa`.
- Prefix cache, paged cache, q8 storage-boundary KV quantization, and
  block-disk L2 were active.
- Live cache proof observed paged cache hit and L2 block writes.
- Exact HTTP requests completed without hidden think tags.
- Installed-app exact-output probe loaded the real 79 GiB JANGTQ_2 bundle in
  `/Applications/vMLX.app`, streamed Chat Completions turns, kept parser and
  reasoning leak checks clean, recorded no persisted tools/reasoning, hit paged
  mixed-SWA cache with `cache_hit_tokens=41`, and wrote block L2.
- Current Electron dev-build Responses/tool proof loaded the same real 79 GiB
  bundle through `npm run dev`, used `/v1/responses`, executed built-in
  `run_command`, sent `function_call_output` follow-ups with
  `previous_response_id`, recorded Responses delta/cache-detail surfaces, wrote
  exact probe files, hit paged mixed-SWA cache with `cache_hit_tokens=4548`,
  and wrote/read block L2 (`l2_block_tokens_on_disk=4225`, hits `36`, writes
  `68`).
- Current Electron dev-build exact-output proof also loaded the real bundle,
  streamed visible Chat turns, kept parser/reasoning leak checks clean, hit
  paged mixed-SWA cache with `cache_hit_tokens=41`, and wrote block L2.
- Current Electron dev-build exact-output proof is now also enforced by raw
  harness assertions. `panel/scripts/live-real-ui-model-proof.mjs` supports
  `VMLINUX_REAL_UI_EXPECT_ASSISTANT_1/2`; the refreshed raw proof failed
  directly on exact visible mismatches rather than relying on post-processing:
  `ACK-CB-742` became `ACKCB-742`, and
  `{"status":"ok","value":"blue-cat"}` became
  `{"status":"ok","value":"blue"}`.
- The hardened exactness run again shows cache/parser are not the primary
  blocker: no raw parser/reasoning leak, native `mixed_swa_kv_v1` /
  `mimo_v2_asymmetric_swa`, paged cache hit with `cache_hit_tokens=40`,
  `l2_block_tokens_on_disk=114`, `l2_tokens_on_disk=114`, and block-disk
  `disk_writes=3`.
- Older Electron dev-build image/VL, video, and audio proofs loaded the real
  bundle and reached `MEDIA_DIAG`, but they predate the current preserved-media
  overlay fix and returned text-only HTTP `400` guards. Treat those rows as
  stale for current-source image/video routing and as still useful only for the
  earlier runtime/cache boundary evidence.
- Current-source CLI proof after the overlay fix loaded the same bundle as
  `mllm=True` and proved image routing with HTTP `200` / visible `vMLX`.
  It also proved block-disk L2 write and fresh-process restore for a text prompt
  (`55` cached tokens, restart `cache_detail=paged+disk`, `disk_hits=1`).
- Current Electron dev-app icon image proof after the overlay fix passed with
  `vl_image`, `current_electron_dev_build`, `chat_completions`,
  `server_cache_controls`, `native_cache_status`, and `l2_disk_storage`.
  Treat earlier dev-app media `400` rows as stale for current source, but do
  not clear installed-app parity from CLI/dev-app proof alone.
- Current-source video/audio transport is also green after the media overlay
  fix in
  `build/current-mimo-v25-jangtq2-video-audio-source-proof-20260610.json`.
  The source server loaded the real JANGTQ_2 bundle as MLLM, bound preserved
  media weights, accepted a `video_url` red MP4 and OpenAI `input_audio`
  base64 request, returned HTTP `200` for both, logged frame reader use for
  the video fixture and base64 audio decode for the audio fixture, and kept the
  native MiMo mixed full/SWA cache contract with generic TurboQuant KV skipped
  by design.
- Current-source media runtime routing proof in
  `build/current-mimo-v25-jangtq2-media-runtime-source-proof-20260610.json`
  also proves the previous source image `400` route is cleared: `api_routes_mllm`,
  loader overlay, preserved media binding, and live image `200` are all true;
  media binding counts are `visual=364`, `audio_encoder=75`, and
  `speech_embeddings=20`.
- The no-fastpath A/B boundary proves `VMLINUX_DISABLE_MIMO_V2_SWITCHGLU_FAST_PATH=1`
  leaves the same exactness mutations, so the vMLX MiMo SwitchGLU fast path is
  not the primary cause.
- The native TQ all-projection contract proves `24` real-tensor gate/up/down
  selected-expert gather cases across sampled early/mid/late routed layers match
  explicit dequant reference with max absolute diff about `1.49e-08`. This
  closes the sampled native gather-shape/codebook/sign runtime gap for the
  current artifact.
- The dev-app audio run also proved the runtime/cache boundary before the media
  guard: active memory `76491.8 MB`, peak `77127.3 MB`, TurboQuant codebook
  routed experts, prestacked layout, native `mixed_swa_kv_v1` /
  `mimo_v2_asymmetric_swa`, generic TurboQuant KV correctly inactive,
  `ram_tokens_cached=132`, `l2_block_tokens_on_disk=132`,
  `l2_tokens_on_disk=132`, and block-disk `disk_writes=3`.

Red:

- Exact output fidelity is not release-green. The same live server mutated:
  `blue-cat -> blue`, `B7-CAT-09 -> B7CAT-09` / `B7 CAT-09`, and tool args
  likewise lost characters.
- Short cache/text row also returned `ACKCB-742` instead of `ACK-CB-742`.
- Installed-app exact-output probe confirmed the broader issue: it returned
  `ACKCB-742` for expected `ACK-CB-742` and only `{"` for expected
  `{"status":"ok","value":"blue-cat"}`.
- Dev-app exact-output proof reproduced the same failure: `ACK-CB-742` became
  `ACKCB-742`, and the JSON probe stopped at `{"`.
- Hardened raw-harness exactness proof reproduced a complete JSON-value
  mutation: expected `{"status":"ok","value":"blue-cat"}` became
  `{"status":"ok","value":"blue"}`.
- Source image/video/audio transport is green for current source after the
  overlay fix, but semantic quality and installed-app media parity remain open
  until rerun against the current bundled/runtime surface.
- Visual semantic quality is explicitly red in the current source
  video/audio artifact: the red video fixture was decoded as red (`254,0,0`)
  but the model answered black, and solid red/green/blue/white images all
  returned `Black.`. Audio transport is green, but transcript correctness is
  not independently verified by a labeled fixture.
- Source-vs-quant first divergence remains open: the source checkpoint exists
  on `erics-m5-max2.local`, but `http://erics-m5-max2.local:8126/health` timed
  out again during the 2026-06-10 14:06 PDT recheck.

Next implementation target:

- Do not chase cache/parser/JSON repair, sampling clamps, vMLX SwitchGLU
  fast-path, or native gather shape for this red row. The current evidence says
  MiMo JANGTQ_2 cache plumbing and sampled native TQ runtime binding work, but
  decode/artifact/logit exactness is wrong. Next useful work is source/dequant
  first-divergent logits or a corrected/lifted-precision artifact profile such
  as `gate=3/up=2/down=3` or `gate=3/up=3/down=3`, followed by the same
  exactness/media/API/UI proof rows.

### MiMo V2.5 JANG_2L

Artifact:

- `build/current-mimo-v25-jang2l-live-cb-cache-text-20260610.json`
- `build/current-real-ui-live-model-mimo-v25-jang2l-dev-app-proof-20260610.json`
- `build/current-mimo-v25-jang2l-chat-tool-boundary-20260610.json`
- `build/current-mimo-v25-jang2l-chat-tool-boundary-fulltools-20260610.json`
- `build/current-real-ui-live-model-mimo-v25-jang2l-dev-app-after-toolchoice-proof-20260610.json`
- `build/current-real-ui-live-model-mimo-v25-jang2l-dev-app-followup-proof-20260610.json`
- `build/current-real-ui-live-model-mimo-v25-jang2l-image-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jang2l-video-proof-20260610.json`
- `build/current-real-ui-dev-app-mimo-v25-jang2l-audio-proof-20260610.json`
- `build/current-real-ui-live-model-mimo-v25-jang2l-responses-tools-proof-20260610.json`
- `build/current-real-ui-installed-app-mimo-v25-jang2l-text-cache-proof-20260610.json`
- `build/current-real-ui-installed-app-mimo-v25-jang2l-tools-proof-20260610.json`
- `build/current-real-ui-installed-app-mimo-v25-jang2l-image-proof-20260610.json`
- `build/current-real-ui-installed-app-mimo-v25-jangtq2-text-cache-proof-20260610.json`
- `build/current-real-ui-installed-app-mimo-v25-jangtq2-image-proof-20260610.json`

Proven:

- 105 GiB local JANG_2L bundle loaded on 128GB host.
- Final health showed about `104997.8 MB` active and `105956.2 MB` peak.
- Uses `mlx_affine_quantized_matmul`; Metal NA active on host.
- Native MiMo mixed full/sliding cache surfaced as `mixed_swa_kv_v1`, subtype
  `mimo_v2_asymmetric_swa`.
- Prefix cache, paged cache, q8 storage-boundary KV quantization, and
  block-disk L2 were active.
- Paged cache hit observed: `cached_tokens=38`, `cache_detail=paged`.
- L2 block writes observed: `l2_tokens_on_disk=62`.
- Exact short output preserved: both repeats returned `ACK-CB-742`; first-token
  system probe returned `OK`.
- Direct source Chat tool boundary with only `run_command` passed for both
  `auto` and specific/required tool modes, with paged cache and L2 positive.
- Direct source Chat boundary with the full panel tool surface proved the
  failure shape: full auto mode is not green (`HTTP 413` nonstream and stream
  `prompt_too_long`, `4754` tokenized prompt tokens against max `4096`), while
  specific/required `run_command` still produced a tool call.
- Panel request assembly now sends a specific `tool_choice` only when the latest
  user message explicitly names exactly one available built-in tool. This is
  covered for both Chat Completions and Responses request bodies, and multiple
  named tools/no explicit tool names remain unpinned.
- Panel Chat Completions tool-result follow-ups now suppress the original
  explicit single-tool `tool_choice` after a tool call has executed. The
  follow-up proof no longer shows the earlier
  `tool_choice='required' was set but the model did not produce any tool calls`
  final-answer error.
- Post-fix real Electron dev-app MiMo attempts executed `run_command` tool calls
  and streamed visible content with cache/L2 telemetry. The best post-fix app
  run recorded `eventCounts.tool=90`, `eventCounts.stream=144`,
  `eventCounts.complete=2`, `cached_tokens=2344`, `cache_detail=paged`,
  `l2_block_tokens_on_disk=1074`, and `disk_writes=18`.
- The follow-up proof executed tool calls in the real dev app with
  `persistedToolCount=135`, `eventCounts.stream=239`,
  `eventCounts.complete=2`, `cacheHitTokens=8072`, verified server cache
  controls, and `l2_block_tokens_on_disk=4580`.
- Real Electron dev-app MiMo JANG_2L image/VL proof is now classified red by
  an explicit runtime text-only guard. The run requested `--is-mllm`, loaded the
  105 GiB artifact, completed text turns, and then the server `MEDIA_DIAG`
  observed one `image_url`, but `/v1/chat/completions` returned `400`:
  `received unsupported media modality image because the loaded runtime is
  text-only. Supported modalities: text.`
- The same image run proved MiMo JANG_2L runtime/cache surfaces in-app:
  `model_type=llm`, `JANG_2L_322_D3E16`,
  `mlx_affine_quantized_matmul`, Metal NA active, `mixed_swa_kv_v1`,
  `mimo_v2_asymmetric_swa`, `cache_detail=paged`, `cached_tokens=39`,
  `l2_block_tokens_on_disk=110`, and `l2_tokens_on_disk=110`.
- Real Electron dev-app MiMo JANG_2L video proof is now classified red by the
  same explicit runtime text-only guard. The run loaded the 105 GiB artifact,
  completed two visible text turns, and then the server `MEDIA_DIAG` observed
  one `video_url`, but `/v1/chat/completions` returned `400`: `received
  unsupported media modality video because the loaded runtime is text-only.
  Supported modalities: text.`
- The video run also proved the 128GB runtime/cache boundary in-app: active
  memory `105016.1 MB`, peak `106152.4 MB`, `JANG_2L_322_D3E16`,
  `mlx_affine_quantized_matmul`, Metal NA eligible, native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`, generic TurboQuant KV
  correctly inactive, `ram_tokens_cached=110`,
  `l2_block_tokens_on_disk=110`, `l2_tokens_on_disk=110`, and block-disk
  `disk_writes=3`.
- Real Electron dev-app MiMo JANG_2L audio proof is now classified red by the
  same explicit runtime text-only guard. The run loaded the 105 GiB artifact,
  completed two visible text turns, and then the server `MEDIA_DIAG` observed
  one `input_audio`, but `/v1/chat/completions` returned `400`: `received
  unsupported media modality audio because the loaded runtime is text-only.
  Supported modalities: text.`
- The audio run also proved the 128GB runtime/cache boundary in-app: active
  memory `105016.1 MB`, peak `106151.0 MB`, `JANG_2L_322_D3E16`,
  `mlx_affine_quantized_matmul`, Metal NA eligible, native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`, generic TurboQuant KV
  correctly inactive, `ram_tokens_cached=110`,
  `l2_block_tokens_on_disk=110`, `l2_tokens_on_disk=110`, and block-disk
  `disk_writes=3`.
- The server log explains the boundary: MiMo V2 preserved media weights
  override forced MLLM mode because bundle metadata marks vision/audio as
  `unwired weights_preserved_text_runtime`; the runtime routes this artifact
  text-only.
- Real Electron dev-app MiMo JANG_2L Responses tool proof is now classified.
  The app used `/v1/responses`, the first turn emitted a built-in
  `run_command` tool call, the app sent a scoped tool-result follow-up with
  `previous_response_id=resp_7aed9d6ca76f`, and the first tool loop completed.
- The same Responses run showed real MiMo runtime/cache pressure rather than a
  shallow API check: first response took `424` tokens in `289.0s`, live decode
  was about `1.2 t/s`, peak memory was `109374.2 MB`, paged cache hit tokens
  reached `1071`, last cache execution used `cached_tokens=687`,
  `l2_block_tokens_on_disk=3784`, block-disk `disk_hits=18`, and
  `disk_writes=60`.
- Local rebuilt installed app text/cache proof is green for MiMo JANG_2L with
  tools and media disabled. `/Applications/vMLX.app` launched, loaded
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L`, and completed two
  exact visible Chat Completions turns: `MIMO_INSTALLED_TEXT_ONE` then
  `MIMO_INSTALLED_TEXT_TWO`.
- The installed-app MiMo text/cache run recorded `installed_app_ui`,
  `chat_completions`, `server_cache_controls`, `generation_defaults_applied`,
  no raw parser/reasoning leak, `active_memory_mb=105017.5`,
  `peak_memory_mb=105961.1`, affine JANG_2L matmul with Metal NA active,
  single-active decode, native `mixed_swa_kv_v1` with
  `cache_subtype=mimo_v2_asymmetric_swa`, `cache_detail=paged`,
  `cached_tokens=41`, `l2_block_tokens_on_disk=114`, `l2_tokens_on_disk=114`,
  and block-disk `disk_writes=3`.
- The same run confirms the expected speed caveat: first-turn TTFT was
  `25.74s`, second-turn TTFT after paged cache hit was `1.57s`, and decode was
  about `1.9 tok/s`. This is installed-app text/cache evidence, not speed
  clearance.
- Local rebuilt installed app tool proof is classified red, but it proves the
  real installed tool surface was reached. The app launched the 105 GiB MiMo
  row with built-in tools enabled, server cache controls visible, and emitted
  tool events. It executed one `run_command` on the second turn and created
  `real_ui_tool_probe_2.txt` with `REAL_UI_LIVE_TOOL_TWO`.
- The installed-app tool proof failed the release `long_tool_loop` surface:
  the first requested marker mutated from `REAL_UI_LIVE_TOOL_ONE` to
  `REAL_UI_LAND_TOOL_ONE`, the expected first probe file was not created, the
  first visible content became repetitive tool-planning prose, and the final
  assertion was `requested real built-in tools but proof did not record
  long_tool_loop surface`.
- The same red tool run showed cache/L2 is not the blocker: active memory
  `105384.7 MB`, peak `109903.3 MB`, native `mixed_swa_kv_v1` /
  `mimo_v2_asymmetric_swa`, `cache_detail=paged`, `cache_hit_tokens=4552`,
  last cached tokens `3481`, and `l2_block_tokens_on_disk=4720`.
- Local rebuilt installed app image/VL proof is now classified red by the same
  text-only runtime guard as the source/dev app. The run requested forced MLLM,
  launched `/Applications/vMLX.app`, completed two visible text turns, attached
  one image, and server `MEDIA_DIAG` saw one `image_url`; `/v1/chat/completions`
  then returned `400`: `received unsupported media modality image because the
  loaded runtime is text-only. Supported modalities: text.`
- The installed-app image boundary run records why this is not a missing
  attachment or cache failure: server log says MiMo V2 preserved media weights
  override forced MLLM mode because bundle metadata marks vision/audio as
  `unwired weights_preserved_text_runtime`; runtime/cache evidence stayed live
  with active memory `105016.1 MB`, peak `105842.8 MB`,
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`, `cache_detail=paged`,
  `cached_tokens=39`, `l2_block_tokens_on_disk=110`, and block-disk
  `disk_writes=3`.
- MiMo JANGTQ_2 now has a green installed-app short exact text/cache row:
  local rebuilt `/Applications/vMLX.app` loaded the 79 GiB bundle, Chat
  Completions produced exact `MIMO_JANGTQ2_TEXT_ONE` and
  `MIMO_JANGTQ2_TEXT_TWO`, server cache controls were visible, no
  parser/reasoning leak was recorded, and the runtime stayed on native
  `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa` with TurboQuant codebook routed
  experts, `cache_detail=paged`, `cache_hit_tokens=42`,
  `l2_block_tokens_on_disk=120`, and block-disk `disk_writes=3`.
- MiMo JANGTQ_2 installed-app image/VL is red with the same honest text-only
  guard. The app attached one image and server `MEDIA_DIAG` saw one
  `image_url`, but `/v1/chat/completions` returned `400`: `received
  unsupported media modality image because the loaded runtime is text-only.
  Supported modalities: text.` Forced MLLM was overridden because the preserved
  media weights are `unwired weights_preserved_text_runtime`. Cache/L2 stayed
  live with `cache_detail=paged`, `cache_hit_tokens=39`,
  `l2_block_tokens_on_disk=132`, and block-disk `disk_writes=3`.

Red / not proven:

- Robust required/auto tool exactness in the dev-app row. The post-fix app run
  did call `run_command`, but MiMo mutated requested semantics:
  `REAL_UI_LIVE_TOOL_ONE` became `REAL_UI_LAND_TOOL_ONE`, and requested
  working-directory files became `/tmp/real_ui_land_tool_one.txt` /
  `/tmp/real_ui_land_tool_two.txt`; the expected probe files were not created.
- A stricter prompt using explicit `printf` / `cat` shell commands and a fixed
  working directory also failed: first assistant content was only
  `The user wants me to run run a specific command with the exact argument:`
  and the second assistant content was empty.
- The `long_tool_loop` release surface remains red for MiMo JANG_2L.
- The latest follow-up proof still fails `long_tool_loop`: MiMo mutated
  `REAL_UI_LIVE_TOOL_ONE` / `REAL_UI_LIVE_TOOL_TWO` into
  `REAL_UI_LAND_TOOL_ONE` / `REAL_UI_LAND_TOOL_TWO` and wrote `/tmp` files
  instead of the configured working-directory probe files.
- Responses stream/nonstream tool path for JANG_2L remains red for release. A
  real dev-app Responses run proved first-turn tool call plus
  `previous_response_id` follow-up, but the two-turn loop failed with
  `CDP timeout: Runtime.evaluate` while the second turn was still active; no
  final tool probe file semantics were verified.
- A current rerun removed the CDP-timeout ambiguity but remains red:
  `build/current-real-ui-live-model-mimo-v25-jang2l-responses-tools-rerun-20260610.json`
  proves real Electron dev app `/v1/responses`, Responses delta streaming,
  `previous_response_id` tool-result follow-up, two completed visible turns,
  paged cache hits, and block L2, but release assertions still fail because no
  `long_tool_loop` surface was recorded. Visible content drifted
  `REAL_UI_LIVE_TOOL_ONE` to `REAL_UI_LAND_TOOL_ONE`, and tool/file semantics
  did not satisfy the proof contract.
- Tool/Responses fresh-process L2 semantics beyond the source cache-restoration
  probe. The source cache-restoration row is now green, but it did not clear
  tool-loop or Responses semantics.
- VL/audio/video runtime. Image/VL is now explicitly red by a text-only runtime
  guard even when forced MLLM is requested; do not claim MiMo JANG_2L media
  support from preserved media weights.
- Installed-app tool loop, installed-app media, and MiMo JANGTQ_2 exactness are
  still red/open. The installed-app text/cache pass and partial second-turn
  tool execution do not clear those rows.
- Long context usability beyond the short cache proof.

Next implementation target:

- Keep the panel `tool_choice` fix; it reduces the app/full-tool-surface
  failure without faking a tool call. Do not generalize it beyond explicit
  single-tool user requests.
- Next MiMo work is model/artifact/decode/tool-argument exactness. Cache/L2 is
  not the current blocker: post-fix app attempts have paged cache hits and
  block-disk L2 writes.
- Continue JANG_2L into Responses/tool exactness. Fresh-process block-disk L2
  restore itself is now source-green, and Responses transport/cache/delta is
  live, but the tool-loop semantic drift remains release-red. Media honesty is
  now classified for image/VL: the current artifact is text-only at runtime
  despite preserved media weights.

Fresh-process L2 restore proof:

- Artifact:
  `build/current-mimo-v25-jang2l-restart-l2-restore-20260610-rerun/summary.json`
- Result: `status=pass`, `cache_status=pass`, `output_status=review`.
- First fresh process wrote one block / `48` tokens to block-disk L2.
- Second fresh process reopened the same block store and restored `48` cached
  tokens with `cache_detail=paged+disk`; block disk `disk_hits=1`, scheduler
  cache `disk_hits=1`, and `reconstruction_ok=true`.
- Native cache was `mixed_swa_kv_v1` / `mimo_v2_asymmetric_swa`; generic
  TurboQuant KV stayed inactive because flat TQ-KV would violate MiMo's mixed
  full/SWA rotating-cache contract.

### Nex/N2 Pro JANGTQ2

Artifact:

- `build/current-n2-jangtq2-live-chat-cache-responses-l2-20260610.json`

Proven:

- 101 GiB local JANGTQ2 bundle loaded and served on 128GB host.
- Final health showed about `104202.2 MB` active and `105212.9 MB` peak.
- Native cache is `hybrid_ssm_v1` with components:
  `attention_kv`, `ssm_companion_state`, `async_rederive`.
- Live attention TurboQuant KV is enabled only for attention KV layers;
  SSM companion state remains native.
- Tight-memory allocator drains occurred during prefill/decode.
- Chat cache proof passed with stable text `ACK`.
- Chat cache hit returned `cached_tokens=8`, `cache_detail=paged+ssm`.
- Required chat tool passed with args `{"query": "alpha"}`.
- Responses nonstream required tool passed.
- Responses tool-result follow-up with `previous_response_id` passed and
  returned `DONE`.
- Responses streaming required tool passed with args present across surfaces.
- Fresh-process L2 restart restore passed:
  `cache_detail=paged+ssm+disk`, block disk `disk_hits=1`, SSM companion disk
  `hits=1`.
- Final L2 totals: `l2_block_tokens_on_disk=271`,
  `l2_ssm_tokens_on_disk=271`, store sum `542`.

Not proven:

- Installed-app/UI path for this exact 20260610 proof.
- Dev-app image/video for this exact profile are proven in the app section
  below; audio remains red by explicit unsupported-modality guard.
- Same-model direct/gateway/tunnel public parity.
- JANG_1L profile.

Next implementation target:

- Treat JANGTQ2 as the N2 checkpoint candidate. It is the profile with real
  live 128GB cache/API/tool/L2 proof.

### Nex/N2 Pro JANGTQ2 Real Dev-App Proof

Artifact:

- `build/current-real-ui-live-model-n2-jangtq2-dev-app-proof-20260610.json`
- `build/current-n2-jangtq2-responses-stream-boundary-20260610.json`
- `build/current-real-ui-live-model-n2-jangtq2-dev-app-delta-proof-20260610.json`
- `build/current-real-ui-live-model-n2-jangtq2-dev-app-prevresp-proof-20260610.json`
- `build/current-real-ui-dev-app-n2-jangtq2-exact-output-proof-20260610.json`
- `build/current-real-ui-live-model-n2-jangtq2-image-proof-20260610.json`
- `build/current-real-ui-live-model-n2-jangtq2-video-proof-20260610.json`
- `build/current-real-ui-live-model-n2-jangtq2-audio-proof-20260610.json`
- `build/current-real-ui-installed-app-n2-jangtq2-responses-tools-cache-20260610.json`
- `build/current-real-ui-installed-app-n2-jangtq2-image-proof-20260610.json`
- `build/current-real-ui-installed-app-n2-jangtq2-video-proof-20260610.json`
- `build/current-real-ui-installed-app-n2-jangtq2-audio-proof-20260610.json`

Raw ignored proof captures:

- `docs/internal/agent-notes/current-real-ui-live-model-n2-jangtq2-responses-tools-cache-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-n2-jangtq2-responses-tools-cache-longdelta-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-n2-jangtq2-responses-tools-prevresp-default-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-live-model-n2-jangtq2-responses-tools-prevresp-longdelta-20260610-proof.json`
- `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-audio-20260610-proof.json`

Proven:

- Real Electron dev app launched with `npm run dev`, connected to a real vMLX
  server loading `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`.
- The 101 GiB N2 JANGTQ2 profile loaded in the app proof harness; final health
  showed about `103807.6 MB` active and `108294.9 MB` peak in the longer
  attempt.
- Real Electron dev-app image/VL proof is green. The app persisted an image
  attachment, the server classified the model as `mllm`, `MEDIA_DIAG` observed
  one `image_url` content part, the runtime processed `num_images_processed=1`,
  and the assistant answered `Red` for the red-image semantic probe.
- The N2 image proof showed hybrid SSM/TurboQuant/L2 state in the same run:
  `cache_detail=paged+ssm`, `cached_tokens=18`,
  `l2_block_tokens_on_disk=50`, `l2_ssm_tokens_on_disk=68`,
  `l2_tokens_on_disk=118`, block-disk `disk_hits=3`, and SSM companion stores
  `2`.
- For the media prompt itself, the server intentionally skipped prefix/paged
  cache store because media embeddings are path-dependent; this is the honest
  media cache boundary, not a cache failure.
- Real Electron dev-app video/VL proof is also green for a 1-second 64x64
  solid-red MP4. The app persisted a `video_url` attachment, the server decoded
  the base64 MP4, reported `25 total frames @ 25.0 fps`, extracted `4 frames`,
  processed `num_images_processed=4`, and the assistant answered
  `The video shows a solid red screen with no visible movement or change.`
- The N2 video proof showed the same hybrid cache/L2 shape as the image proof:
  `cache_detail=paged+ssm`, `cached_tokens=18`,
  `l2_block_tokens_on_disk=50`, `l2_ssm_tokens_on_disk=68`,
  `l2_tokens_on_disk=118`, block-disk `disk_hits=3`, and SSM companion stores
  `2`.
- Real Electron dev-app audio proof is red by explicit runtime guard, not by
  crash. The app attempted an audio turn, server `MEDIA_DIAG` saw
  `input_audio`, and the API returned `400`:
  `/v1/chat/completions received unsupported media modality audio. Supported
  modalities: text, vision, video.`
- Responses UI rail reached `/v1/responses` and completed two turns.
- Built-in `run_command` tool loop executed and wrote/read the expected probe
  files: `REAL_UI_LIVE_TOOL_ONE` and `REAL_UI_LIVE_TOOL_TWO`.
- Native cache surfaced as `hybrid_ssm_v1` / `hybrid_ssm_typed` with
  `attention_kv`, `ssm_companion_state`, and `async_rederive`.
- TurboQuant KV was active for attention KV layers only; SSM companion state
  stayed native.
- App/cache endpoints showed `paged+ssm` cache hits, block-disk L2 writes, and
  SSM companion disk stores. The longer attempt ended with
  `l2_block_tokens_on_disk=4626`, `l2_ssm_tokens_on_disk=23454`, and
  `l2_tokens_on_disk=28080`.
- Server cache controls were visible and verified in the dev app.
- No raw parser/tool markup leak and no hidden reasoning leak were observed.
- Separate real Electron dev-app Responses delta pass, without built-in tools,
  cleared the app renderer/content-delta surface. It loaded the same N2 JANGTQ2
  row, used `/v1/responses`, and produced two assistant messages with
  multi-event visible deltas:
  - first trace: `count=21`, `N` -> `N2_APP_DELTA_ONE is ready...`
  - second trace: `count=24`, `N` -> `N2_APP_DELTA_TWO is ready...`
- That delta pass recorded `responses_delta_streaming`,
  `responses_cache_detail_usage`, `cache_hit_telemetry`,
  `native_cache_status`, `l2_disk_storage`, and `server_cache_controls` in the
  proof surfaces. Runtime/cache evidence included `cache_detail=paged+ssm`,
  `cached_tokens=45`, `l2_block_tokens_on_disk=120`,
  `l2_ssm_tokens_on_disk=274`, and `l2_tokens_on_disk=394`.
- Current panel source now sends Responses in-turn tool-result follow-ups as
  scoped `function_call_output` input with `previous_response_id`, instead of
  replaying the whole input and re-applying the original explicit tool choice.
  The app proof logs this twice:
  `Responses tool follow-up using previous_response_id=... with 1 function_call_output item(s)`.
- After that fix, the default real Electron dev-app N2 JANGTQ2 Responses
  tool/cache/delta row is green:
  `build/current-real-ui-live-model-n2-jangtq2-dev-app-prevresp-proof-20260610.json`
  has `status=pass`.
- Current source inspection confirms the previous-response follow-up request
  builder is not re-sending the original explicit required tool choice for
  in-turn `function_call_output` continuations. `panel/src/main/ipc/chat.ts`
  sets `input` to the scoped `function_call_output` items, sets
  `previous_response_id`, and guards `obj.tool_choice` with
  `!isResponsesToolFollowup`. The green proof logs two
  `Responses tool follow-up using previous_response_id=...` lines, so the
  default N2 JANGTQ2 red row is not a replayed-tool-choice bug.
- The green combined app proof covers built-in `run_command`, tool-result
  continuation, visible markers, renderer deltas, cache/L2, and settings:
  assistant messages were `Done. REAL_UI_LIVE_TOOL_ONE` and
  `Done - this is the second UI turn. REAL_UI_LIVE_TOOL_TWO`; the tool probe
  files contained `REAL_UI_LIVE_TOOL_ONE` and `REAL_UI_LIVE_TOOL_TWO`.
- The same green proof recorded two multi-delta assistant traces (`count=8`
  and `count=15`), `responses_delta_streaming`,
  `responses_cache_detail_usage`, `long_tool_loop`, and
  `tool_l2_cache_integrated`.
- Runtime/cache evidence in the green combined app proof:
  `hybrid_ssm_v1`, attention-only TurboQuant KV, native SSM companion state,
  `cache_detail=paged+ssm`, `l2_block_tokens_on_disk=3579`,
  `l2_ssm_tokens_on_disk=17083`, `l2_tokens_on_disk=20662`,
  `block_disk_writes=59`, `block_disk_hits=110`, and `ssm_disk_hits=1`.
- Current Electron dev-build exact-output proof is green for N2 JANGTQ2:
  `N2-ACK-742` returned exactly, and
  `{"status":"ok","value":"n2-blue"}` returned exactly. The same run recorded
  no parser/reasoning leak, no persisted tools/reasoning, model-owned
  generation defaults, `hybrid_ssm_v1`, attention-only TurboQuant KV, native
  SSM companion state, `cache_detail=paged+ssm`, `cache_hit_tokens=21`,
  `l2_block_tokens_on_disk=59`, `l2_ssm_tokens_on_disk=80`,
  `l2_tokens_on_disk=139`, block-disk hits `3`, writes `2`, and SSM companion
  stores `2`.
- Local rebuilt installed app proof is now green for the same default N2
  JANGTQ2 checkpoint path. `/Applications/vMLX.app` launched as
  `uiLaunchMode=installed-app`, adopted the real N2 server, used
  `/v1/responses`, executed two built-in `run_command` calls, and produced
  visible assistant turns `Done. REAL_UI_LIVE_TOOL_ONE` and
  `Done - this is the second UI turn. REAL_UI_LIVE_TOOL_TWO`.
- The installed-app run verified the probe files exactly:
  `real_ui_tool_probe_1.txt=REAL_UI_LIVE_TOOL_ONE` and
  `real_ui_tool_probe_2.txt=REAL_UI_LIVE_TOOL_TWO`.
- The installed-app run also recorded renderer content deltas (`count=8` and
  `count=15`), `eventCounts.tool=106`, `eventCounts.stream=23`,
  `eventCounts.complete=2`, server cache controls, settings persistence, and
  no raw parser/reasoning leak.
- Installed-app runtime/cache evidence stayed architecture-correct:
  `hybrid_ssm_v1`, components `attention_kv`, `ssm_companion_state`,
  `async_rederive`, attention-only TurboQuant KV storage boundary, native SSM
  companion state, `cache_detail=paged+ssm`, `cached_tokens=384`,
  `l2_block_tokens_on_disk=3582`, `l2_ssm_tokens_on_disk=17086`,
  `l2_tokens_on_disk=20668`, `block_disk_writes=59`, `block_disk_hits=110`,
  and `ssm_disk_hits=1`.
- The installed-app proof originally recorded N2 MTP as
  `metadata_inconsistent` because `jang_config.drop_mtp=true` while config
  declares one MTP layer. Current source now treats this exact no-MTP-tensor
  JANGTQ2 shape as an honest dropped-MTP boundary:
  `status=dropped`, `issues=[]`, `runtime_active=false`; keep reporting MTP
  as unavailable, but do not surface it as artifact corruption unless indexed
  `mtp.*` tensors are also present.
- Local rebuilt installed app image/VL proof is green for N2 JANGTQ2. The app
  persisted the image attachment, server `MEDIA_DIAG` saw one `image_url`, the
  runtime processed `num_images_processed=1`, and the assistant answered `Red`.
- The installed-app image run recorded `vl_image`, `installed_app_ui`,
  `server_cache_controls`, no raw parser/reasoning leak, `hybrid_ssm_v1`,
  attention-only TurboQuant KV, `cache_detail=paged+ssm`, `cached_tokens=18`,
  `l2_block_tokens_on_disk=50`, `l2_ssm_tokens_on_disk=68`,
  `l2_tokens_on_disk=118`, block-disk `disk_hits=3`, `disk_writes=2`, and SSM
  companion disk stores `2`.
- Local rebuilt installed app video/VL proof is also green for N2 JANGTQ2. The
  app persisted the video attachment, server `MEDIA_DIAG` saw one `video_url`,
  the server decoded the base64 MP4, extracted `4` frames from a 25 fps
  one-second clip, processed `num_images_processed=4`, and the assistant
  answered `The video shows a solid red screen with no visible movement or
  change.`
- The installed-app video run recorded `video_where_supported`,
  `installed_app_ui`, `server_cache_controls`, no raw parser/reasoning leak,
  `hybrid_ssm_v1`, attention-only TurboQuant KV, `cache_detail=paged+ssm`,
  `cached_tokens=18`, `l2_block_tokens_on_disk=50`,
  `l2_ssm_tokens_on_disk=68`, `l2_tokens_on_disk=118`, block-disk
  `disk_hits=3`, `disk_writes=2`, and SSM companion disk stores `2`.
- Local rebuilt installed app audio proof is red by the same honest
  unsupported-modality guard as the source dev app, not by crash or cache
  failure. The installed app launched, completed two visible text turns, forced
  multimodal for one attached audio file, server `MEDIA_DIAG` saw one
  `input_audio`, and `/v1/chat/completions` returned `400`:
  `/v1/chat/completions received unsupported media modality audio. Supported
  modalities: text, vision, video.`
- The installed-app audio boundary run still recorded the N2 runtime/cache
  surfaces before the failing audio turn: active memory about `103805 MB`, peak
  about `104453.9 MB`, `hybrid_ssm_v1`, attention-only TurboQuant KV,
  `cache_detail=paged+ssm`, `cached_tokens=18`,
  `l2_block_tokens_on_disk=50`, `l2_ssm_tokens_on_disk=68`,
  `l2_tokens_on_disk=118`, block-disk `disk_hits=3`, `disk_writes=2`, and SSM
  companion disk stores `2`.

Red:

- A stricter custom long-delta prompt remains red:
  `docs/internal/agent-notes/current-real-ui-live-model-n2-jangtq2-responses-tools-prevresp-longdelta-20260610-proof.json`
  failed because the second turn did not create `real_ui_tool_probe_2.txt` and
  visible output degenerated into repeated `!` after a tool-choice-required
  error. Do not generalize the default checkpoint pass to that stricter prompt.
- Current source inspection confirms the Responses streaming fail-closed path
  for that stricter required-tool miss is contract-shaped: when
  `tool_choice='required'` produces no parsed tool calls, `vmlx_engine/server.py`
  emits empty `response.output_text.done`, an incomplete message
  `response.output_item.done`, an `error` event with
  `code=tool_calls_required`, and `response.completed` with `status=failed`,
  empty `output_text`, empty `output`, and usage/cache details. Do not replace
  this with argument synthesis or a placeholder tool call.
- Audio, public tunnel SSE parity, N2 JANG_1L, stricter custom long-delta prompt
  quality, and release readiness remain open. Image and video are green in both
  the source dev app and rebuilt installed app; audio is honestly gated as
  unsupported. Installed-app Responses/tool/cache and image/video media parity
  are green for the default checkpoint N2 JANGTQ2 path only; this is not a
  Developer ID notarized public DMG release claim.

Next implementation target:

- Raw direct server and panel gateway SSE are now proven green for N2 Responses
  tool plus tool-result continuation content deltas:
  `build/current-n2-jangtq2-responses-stream-boundary-20260610.json` is
  `status=pass`. Direct follow-up produced `16` output-text deltas and gateway
  follow-up produced `14` output-text deltas. Both completed on the same served
  model and returned `N2_DIRECT_DELTA_ONE` / `N2_DIRECT_DELTA_TWO`.
- N2 JANGTQ2 now has green default dev-app and rebuilt installed-app proof for
  built-in tool loop, Responses tool-result continuation, content-delta
  streaming, hybrid-SSM/TurboQuant KV cache, L2, and image/video media.
- 2026-06-10 13:14 PDT direct artifact inspection confirmed the direct/gateway
  SSE captures themselves contain valid `lookup` function-call argument
  delta/done events with `{"query": "alpha"}`, valid message/function output
  indices, final response consistency, and follow-up visible content deltas.
  Gateway cache telemetry shows `cache_detail=paged+ssm` with
  `cached_tokens=192` on the first-tool repeat and `cached_tokens=96` on the
  follow-up.
- The same inspection confirmed audio remains a red-but-honest unsupported
  modality row: current-source and installed-app audio artifacts reached the
  server with `input_audio`, then failed closed with HTTP 400 and supported
  modalities `text, vision, video`. Do not advertise N2 audio until a real
  weight-backed audio path exists.
- Remaining N2 rows are audio, public tunnel parity, N2 JANG_1L memory
  strategy, and the stricter custom prompt quality red row.
- 2026-06-10 13:23 PDT public tunnel availability check: current
  `https://testapi.adlabus.dev/v1/models` does not advertise any
  `Nex-N2-Pro-JANGTQ2` / N2 alias, and `/health` reports single-model gateway
  mode with Qwen27 standby. Treat N2 JANGTQ2 public tunnel parity as a deployed
  tunnel availability gap until the tunnel backend serves the N2 JANGTQ2 model;
  do not relaunch the 101 GiB local N2 row just to chase a tunnel surface that
  is not currently advertised.

## Red Live Attempts

### Nex/N2 Pro JANG_1L

Artifact:

- `build/current-n2-jang1l-live-chat-cache-responses-20260610.json`
- server log: `build/current-n2-jang1l-live-chat-cache-responses-20260610.server.log`
- `build/current-n2-pro-jang1l-local-memory-preflight-20260610-after-installed-app-proofs.json`
- `build/current-n2-jang1l-live-chat-cache-override-20260610.json`
- server log: `build/current-n2-jang1l-live-chat-cache-override-20260610.server.log`
- `build/current-n2-pro-jang1l-local-memory-preflight-launch-safe-20260610.json`
- `build/current-n2-jang1l-chat-cache-launch-safe-20260610.json`
- `build/current-n2-pro-jang1l-local-memory-preflight-after-mimo-exact-20260610.json`
- `build/current-n2-jang1l-chat-cache-after-mimo-exact-20260610.json`
- `build/current-n2-jang1l-deferred-eval-startup-proof-20260610.json`
- `build/current-n2-pro-jang1l-local-memory-preflight-deferred-eval-live-attempt-20260610.json`
- `build/current-n2-jang1l-live-chat-cache-deferred-eval-live-attempt-20260610.json`
- `build/current-n2-jang1l-live-chat-cache-deferred-eval-guard104-20260610.json`
- `build/current-n2-jang1l-live-chat-cache-forced-after-gemma-video-20260610.json`
- `build/current-real-ui-dev-app-n2-jang1l-bounded-chat-proof-20260610.json`
- `build/current-real-ui-dev-app-n2-jang1l-one-turn-visible-proof-20260610.json`
- `build/current-objective-proof-after-mimo-n2-dev-app-proof-refresh-20260610.json`
- `build/current-full-release-objective-checklist-after-mimo-n2-dev-app-proof-refresh-20260610.json`
- `build/current-release-regression-manifest-after-mimo-n2-dev-app-proof-refresh-20260610.json`

Observed:

- 110.59 GiB local bundle exists.
- Run was launched with `--jang1l-required-extra-headroom-gib 1`, so this was
  not a default preflight skip.
- Server startup began, model detection selected `qwen3_5_moe`, qwen parser,
  qwen3 reasoning parser, hybrid cache, and JANG text-only route.
- Quant shape inference patched 482 modules because config said uniform
  bits=2/group_size=128 while safetensors shapes required per-module overrides.
- Loader attempted 123 safetensors shards, bfloat16 for 512 experts, hidden
  4096.
- Loader set wired limit to the Metal cap: `Wired limit set to 115 GB (model
  119 GB)`.
- Process aborted before health with:
  `[METAL] Command buffer execution failed: Insufficient Memory`.
- Refreshed no-load preflight after the installed-app proofs still says
  `decision=do_not_launch`: indexed payload `110.57 GiB`, required available
  `118.57 GiB`, observed available `112.77 GiB`, gap `5.8 GiB`. Artifact
  metadata confirms `artifact_profile=JANG_1L`, `format=jang`,
  `model_type=qwen3_5_moe`, `architecture=Qwen3_5MoeForConditionalGeneration`,
  `vision_tensors=333`, and `audio_tensors=0`.
- Eric explicitly overrode the preflight gate and requested launch anyway. The
  override run used smaller live knobs (`max_tokens=16`, prefill batch `64`,
  prefill step `128`, completion batch `32`, SSM state cache `128 MB`, paged
  cache block size `64`, max cache blocks `256`, block L2 `2 GB`) and still
  failed during server startup before health. Before launch telemetry reported
  `available_gib=113.05`; server log again selected `qwen3_5_moe`, qwen tool
  parser, qwen3 reasoning parser, hybrid cache, attention-only TurboQuant KV
  policy, loaded 123 shards, enabled bfloat16 for 512 experts, set `Wired limit
  set to 115 GB (model 119 GB)`, then aborted with `[METAL] Command buffer
  execution failed: Insufficient Memory`.
- Fresh launch-safe refresh after MiMo installed-app image proof still skips
  before launch: no-load preflight observed `available_gib=114.23`, required
  `118.57`, gap `4.34`; chat/cache gate observed `available_gib=114.22`,
  required `118.57`, gap `4.35`, and recorded requested tool, Responses,
  Responses stream, and L2 restart probes. This safe run did not call `Popen`
  and did not create another Metal OOM.
- Fresh high-free launch attempt after the Gemma JANG4M installed-app image
  proof: `build/current-n2-pro-jang1l-local-memory-preflight-ultrafree-20260610.json`
  still had strict `decision=do_not_launch` at `available_gib=114.09`,
  required `118.57`, gap `4.48`. Per Eric's launch instruction, the live gate
  lowered JANG_1L headroom to `3 GiB` and ran one-at-a-time anyway:
  `build/current-n2-jang1l-live-chat-cache-ultrafree-20260610.json`,
  `status=fail`, `phase=server_startup`. Server log proves qwen3_5_moe/JANG_1L
  detection, qwen tool parser, qwen3 reasoning parser, hybrid cache,
  attention-only TurboQuant KV plus native SSM companion state, mmap JANG
  loader, `482` quant-shape patches, `123` shards, bfloat16 for `512` experts,
  and the same Metal OOM before health.
- Fresh after-MiMo exact-output refresh still skipped before launch: no-load
  preflight observed `available_gib=113.29`, required `118.57`, gap `5.28`;
  chat/cache gate observed `available_gib=113.28`, required `118.57`, gap
  `5.29`, recorded requested tool, Responses, Responses stream, and L2 restart
  probes, and left the cache directory empty because no weights were loaded.
- Deferred-startup-eval partial fix: qwen3_5_moe affine `JANG_1L` now defers
  eager startup eval through `load_jang_model(..., skip_eval=True)`. This moves
  the failure boundary from pre-health Metal OOM to post-first-request
  working-set pressure. The deferred-eval live attempt reached `/health`,
  loaded the real JANG_1L row in `6.7s`, initialized qwen parser, qwen3
  reasoning, hybrid SSM/cache, attention TurboQuant KV, paged cache, block L2,
  and SSM companion L2, then completed one bounded Chat Completions request
  with HTTP `200`.
- JANG_1L still is not a release-clear row: after that first bounded request,
  active Metal working set reached `102%` of the `107.5GB` cap; cache warm/hit,
  tool, Responses, Responses stream, and full L2 restart did not pass. A
  follow-up with `VMLINUX_METAL_WS_REJECT_PCT=104` plus wired-limit setup
  reproduced first-request Metal OOM (`server_exit=-6`), proving that simply
  bypassing the guard is not the next fix.
- Per Eric's direction, the after-Gemma-video proof forced JANG_1L again with
  `--jang1l-required-extra-headroom-gib 0` and low batches. This run again
  proves the 128GB host can load the model and serve one bounded Chat request:
  `/health` reached, first Chat Completions request returned HTTP `200`,
  native `hybrid_ssm_v1`, live attention TurboQuant KV, SSM companion state,
  async rederive, paged cache, block L2, and SSM companion L2 initialized. It
  still does not clear release use: cache warm and cache hit returned HTTP
  `503` at `102%` of the `107.5GB` Metal working-set cap after the first
  request, available memory fell to `6.41 GiB`, and the bounded first response
  had empty visible text.
- Current Electron dev-app bounded Chat proof reproduces the same release
  boundary in the user-facing app path. The app loaded the real JANG_1L row,
  completed one Chat Completions request with HTTP `200`, initialized
  `hybrid_ssm_v1`, live attention TurboQuant KV, SSM companion state, async
  rederive, paged cache, block L2, and SSM companion L2. The proof remains red:
  the first assistant content was whitespace/empty, and the second UI turn
  returned HTTP `503` at `102%` of the `107.5GB` Metal working-set cap.
- Current Electron dev-app one-turn visible-output proof isolates the first
  turn from the second-turn working-set guard. The proof harness now supports
  `VMLINUX_REAL_UI_SECOND_TURN=0` and records `secondTurnEnabled=false` in the
  artifact. With one turn only, the real app loaded JANG_1L, completed the Chat
  request without renderer send errors or Metal `503`, emitted `16` stream
  events and one completion event, but persisted empty visible assistant
  content. The stream trace was whitespace only (`" "` through sixteen spaces),
  with no hidden reasoning or raw parser leak.
- The one-turn proof keeps the runtime/cache evidence live: qwen3_5_moe/JANG_1L
  autodetect, qwen tool parser, qwen3 reasoning parser, native
  `hybrid_ssm_v1`, attention-only live TurboQuant KV, SSM companion state,
  async rederive, paged cache, block L2, SSM companion L2,
  `ram_tokens_cached=19`, `l2_block_tokens_on_disk=19`,
  `l2_ssm_tokens_on_disk=19`, `l2_tokens_on_disk=38`, active memory
  `112550.2 MB`, peak `112807.4 MB`, TTFT `46.44s`, and decode about
  `0.8 tok/s`.

Conclusion:

- JANG_1L is proven loadable on this 128GB host and can complete one bounded
  Chat request through current source and through the dev app. It is not
  release-clear usable yet: visible-output quality is red even in one-turn mode,
  and cache warm/hit, tool, Responses, and L2 restart proof remain red under
  working-set pressure.

Next implementation target:

- Implement the next 128GB runtime strategy for JANG_1L before claiming it:
  keep deferred startup eval, then reduce post-first-request working-set
  residency so cache warm/hit, tools, Responses, and L2 can run. Do not claim
  N2 JANG_1L support from JANGTQ2, and do not bypass the Metal working-set
  guard as a release fix.

## What To Tell The Other Agent

- Prioritize checkpoint release around proven rows: Gemma 12B MXFP4/JANG4M,
  MiMo JANG_2L short cache/text, and N2 JANGTQ2 full chat/cache/Responses/L2.
- Do not spend time proving generic cache. For MiMo use `mixed_swa_kv_v1`; for
  N2 use `hybrid_ssm_v1` with attention TQ KV plus native SSM companion.
- MiMo JANGTQ2 is loaded/cached and the installed-app default Chat Completions
  built-in tool loop is now green, but broader exactness remains red. New proof
  `build/current-real-ui-installed-app-mimo-v25-jangtq2-tools-proof-20260610.json`
  loaded the real 79 GiB bundle in `/Applications/vMLX.app`, executed
  `run_command`, created both expected probe files exactly, completed visible
  turns, kept parser/reasoning leak checks clean, and recorded paged
  mixed-SWA/L2 evidence (`cache_hit_tokens=4548`,
  `l2_block_tokens_on_disk=4225`, block-disk hits `36`, writes `68`). Responses
  tools are also green in
  `build/current-real-ui-installed-app-mimo-v25-jangtq2-responses-tools-proof-20260610.json`:
  `/v1/responses`, `previous_response_id` tool follow-ups,
  `function_call_output`, response/content delta surfaces, exact probe files,
  and the same paged mixed-SWA/L2 cache path are proven. Continue
  artifact/logit/decode diagnosis for literal/JSON/source-vs-quant exactness;
  do not reduce that to parser repair. The latest installed-app exact-output
  proof `build/current-real-ui-installed-app-mimo-v25-jangtq2-exact-output-proof-20260610.json`
  is red: `ACK-CB-742` became `ACKCB-742`, and the JSON probe stopped at `{"`,
  while parser/reasoning leak checks, paged mixed-SWA cache, and block L2 were
  clean. Current dev-build Responses tool/cache parity is also green in
  `build/current-real-ui-dev-app-mimo-v25-jangtq2-responses-tools-cache-20260610.json`,
  so the remaining MiMo JANGTQ2 blocker is not dev-app tool transport or cache
  plumbing. The matching dev-build exact-output proof
  `build/current-real-ui-dev-app-mimo-v25-jangtq2-exact-output-proof-20260610.json`
  reproduces the same exactness failure, so do not frame this as
  installed-app-only drift. Current source now also has a real visual-runtime
  contract fix: missing preserved visual sidecar biases
  `visual.merger.ln_q.bias`, `visual.merger.mlp.0.bias`, and
  `visual.merger.mlp.2.bias` are zero-filled instead of leaving initializer
  values in the media path. Visual-only Torch-vs-MLX parity is green in
  `docs/internal/agent-notes/current-mimo-v25-jangtq2-visual-torch-mlx-parity-20260610.json`
  (`max_mean_abs_diff=0.0008475283`, `min_cosine=0.9999996424`), but live
  patched-source color semantics remain red in
  `docs/internal/agent-notes/current-mimo-v25-jangtq2-direct-color-after-zero-bias-20260610.json`
  (`red -> Black`, `green -> White`, `blue -> Black`, `white -> Black`,
  `black -> White...`). Do not re-chase the stale text-only media gate or
  claim MiMo JANGTQ2 `vl_image` release clearance; next work is language-side
  multimodal splice/first-logit or artifact/source quant contract.
- MiMo JANG_2L is the stronger MiMo checkpoint candidate for load/cache/text,
  but post-fix app tool exactness is still red. The panel now pins
  `tool_choice` only for explicit single-tool user requests, and the app can
  execute MiMo-generated `run_command` calls, but MiMo still mutates filenames
  and sentinel text. Other agent should work artifact/logit/decode/tool-arg
  exactness before claiming app tool support.
- MiMo JANGTQ2 no-thinking visible-planning classification is now narrowed:
  `docs/internal/agent-notes/current-real-ui-dev-app-mimo-v25-jangtq2-icon-image-neutral-first-turn-20260610-proof.json`
  passes with neutral first turn (`OK.`) and image response `vMLX` under
  `enableThinking=false`, `persistedReasoningCount=0`, `rawParserLeak=false`,
  `reasoningRawParserLeak=false`, and app stream logs showing reasoning chars
  `0` for both turns. Treat the earlier planning-style prose in
  `current-real-ui-dev-app-mimo-v25-jangtq2-icon-image-after-overlay-fix-20260610`
  as proof-harness first-turn prompt contamination, not as a confirmed MiMo
  parser leak. Do not add arbitrary prose stripping. Still open: MiMo literal/
  JSON exactness, red-square color semantics, audio hygiene/semantics, video
  semantics, Responses tool-result continuation, installed-app parity for this
  exact media/no-thinking row, fresh-process L2 restore for media, and release
  readiness.
- N2 JANGTQ2 is the stronger N2 checkpoint candidate; it has live hybrid
  SSM/TQ/L2/tool/Responses proof.
- Qwen27 JANG_4M MTP direct Responses tool-result continuation is no longer
  the stale reasoning-only red row after `c468d9b17`. Current direct artifacts:
  required-tool
  `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-required-tool-after-visible-finalization-seed-fix-20260610.sse`
  and continuation
  `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-tool-result-continuation-after-visible-finalization-seed-fix-20260610.sse`.
  The required-tool turn preserves reasoning-enabled tool selection with valid
  function-call args `{"value":"blue-cat"}`. The terminal no-new-tools
  continuation completes with visible streaming deltas and final output
  `The fact "blue-cat" has been recorded.`. Health artifact
  `build/responses-sse-captures-20260610/direct-qwen27-jang4m-mtp-health-after-visible-finalization-seed-fix-20260610.json`
  shows native MTP active (`effective_depth=3`, text+vl), `hybrid_ssm_v1`,
  attention-only live TurboQuant KV, block L2, and SSM companion L2
  (`l2_block_tokens_on_disk=292`, `l2_ssm_tokens_on_disk=548`). Scope remains
  direct server only; gateway/tunnel, Qwen-coder-next, and broader family
  parser/API loops still need proof.
- N2 JANG_1L has a real startup/first-chat improvement from deferred startup
  eval, but the release blocker moved to post-first-request working-set
  pressure. Latest deferred-eval artifacts are
  `build/current-n2-jang1l-deferred-eval-startup-proof-20260610.json` and
  `build/current-n2-jang1l-live-chat-cache-deferred-eval-live-attempt-20260610.json`;
  they prove `/health` plus one bounded chat request, but full cache/tool/
  Responses/L2 remains red.
- Other agent should keep the new panel detector boundary: MiMo auto mode is
  XML tools + asymmetric-SWA paged cache, not auto reasoning; Gemma unified
  aliases must stay mapped to Gemma4 parsers and rotating mixed-SWA cache.
- Keep signed DMG release notes honest: say which profiles are checkpoint
  supported and which are experimental/red.

## Checkpoint DMG Release Proof - 2026-06-10

- Built local checkpoint DMGs for vMLX `1.5.56` from this worktree with an
  explicit override because the manifest is still red:
  `build/current-release-regression-manifest-checkpoint-dmg-override-after-n2-consumed-20260610.json`
  reports `status=fail`, `prepackage_ready=false`, and `release_ready=false`.
- Build command:
  `VMLINUX_CHECKPOINT_RELEASE_OVERRIDE=1 VMLX_PREPACKAGE_READY_MANIFEST_OUT=build/current-release-regression-manifest-checkpoint-dmg-override-after-n2-consumed-20260610.json panel/scripts/build-release-dmgs.sh all`.
- Notary command:
  `VMLINUX_NOTARY_KEYCHAIN=$HOME/Library/Keychains/vmlx-build.keychain-db panel/scripts/notarize-release-dmgs.sh`.
- Verify command: `panel/scripts/verify-release-dmgs.sh`.
- Both bundled app builds passed critical import/parity checks before DMG
  creation: local `vmlx_engine 1.5.56`, local `jang 2.5.30`, Gemma4 unified
  runtime, MiMo/N2 registration, JANG/JANGTQ loaders, TurboQuant kernels,
  audio/VLM imports, and source/bundled critical-file parity.
- Final Sequoia artifact:
  `panel/release/vMLX-1.5.56-sequoia-arm64.dmg`,
  `sha256=42c053cd2422e72ef74753cbc240a68a319d6c10ff60c105d5ed4c4c34f34a9c`,
  Apple notary id `d29a3974-4674-4812-8fa2-5a7e0da69269`.
- Final Tahoe artifact:
  `panel/release/vMLX-1.5.56-tahoe-arm64.dmg`,
  `sha256=b35e6cb55ca0f7e50a9a4a8733f111ea3df070ccf32caa87510c8027f16fb2f2`,
  Apple notary id `27ff0109-e023-469d-a634-5c410f37ac3c`.
- Verification status for both artifacts: valid disk image checksum, valid
  Developer ID signature from `ShieldStack LLC (55KGF2S5AY)`, stapled
  notarization ticket, stapler validation passed, and Gatekeeper accepted with
  `source=Notarized Developer ID`.
- Release-note boundary for other agent: this checkpoint can be described as a
  signed/notarized user-testing DMG with current proven checkpoint rows, not a
  production-ready release. Keep the open rows explicit: N2 JANG_1L, MiMo
  exactness/media, DSV4, public tunnel SSE parity, audio support, and full
  `release_ready` are still open.

## Gemma4 MXFP4 Parser Auto-Detect Fix - 2026-06-10 13:47 PDT

- Source fix: `vmlx_engine/server.py` now resolves registry keys through the local model resolver and refreshes auto-detected reasoning/tool parser state after `load_model()` records the loaded model path. This targets the Gemma4 MXFP4 Responses tools artifact where visible content started with `thought\n...` while parser state was null.
- Resolver fix: `vmlx_engine/api/utils.py` now resolves repo IDs from `~/models/<org>/<name>` before HF cache. Current Gemma4 MXFP4 proof bundles live at `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`, so repo-id launches now map to the local sidecar.
- Verification:
  - `.venv/bin/python -m py_compile vmlx_engine/server.py vmlx_engine/api/utils.py tests/test_engine_audit.py tests/test_api_utils.py`
  - `.venv/bin/python -m pytest -q tests/test_engine_audit.py -k 'loaded_gemma4_mxfp_sidecar_refreshes_auto_parsers or loaded_model_parser_refresh_preserves_explicit_disables or gemma4_supports_thinking_is_explicit_not_implicit'` -> `3 passed, 566 deselected`
  - `.venv/bin/python -m pytest -q tests/test_api_utils.py -k 'local_models_cache or existing_directory_returned_as_is or nonexistent_path_returned_as_is'` -> `3 passed, 55 deselected`
  - Direct local lookup: `JANGQ-AI/gemma-4-12B-it-qat-MXFP4` resolves to `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`, and registry returns `family=gemma4`, `tool=gemma4`, `reasoning=gemma4`.
- Proven: source parser-selection path for Gemma4 MXFP/JANG sidecar launches
  from repo IDs, app aliases with real loaded paths, and direct local paths.
- Current-source live proof is also green in
  `docs/internal/agent-notes/current-real-ui-live-model-gemma4-12b-qat-mxfp4-responses-tools-request-parser-fallback-20260610-proof.json`:
  real Gemma4 12B QAT MXFP4 loaded from
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`, Responses tools
  completed two built-in `run_command` turns, both visible stream traces begin
  with `The`, final visible text is
  `The second UI turn is complete with REAL_UI_LIVE_TOOL_TWO.`, parser leak
  flags are false, cache detail is `paged+mixed_swa`, and block-disk L2 stored
  `3518` tokens.
- Still open: installed-app bundled runtime must include this patch before a
  packaged checkpoint can claim the same MXFP4 parser fix; packaged DMG parity
  remains a release lane and was not performed here.

## MiMo JANG/JANGTQ Envelope Detection - 2026-06-11

- Green source row:
  affine MiMo V2.5 `JANG_2L` local bundles with explicit `format="jang"` are no
  longer classified as JANGTQ/MXTQ just because they carry affine `mxtq_bits`.
  True JANGTQ/MXTQ metadata and configless path/repo-name fallbacks still take
  the conservative JANGTQ/MXTQ MPP_NAX policy.
- Proof:
  focused CLI policy audit slice passed `3 passed`; direct local detector probe
  returned `False` for
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANG_2L` and `True` for
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`. `py_compile`
  and `git diff --check` passed.
- Still red before the follow-up row below:
  MiMo JANGTQ_2 literal and special-character exactness, MiMo real media
  semantics, thinking-on rows, speed/long-output quality, installed-app parity
  for this exact source commit, and signed/notarized release publication.

## MiMo JANG_2L Required Tool Loop - 2026-06-11

- Green source/runtime row:
  MiMo V2.5 affine `JANG_2L` now has a current-source live text/no-media
  Responses required-tool loop. The source fix is in
  `vmlx_engine/api/tool_calling.py`: XML-function/MiMo fallback prompts inject a
  compact hard `tool_choice=required` first-tool contract and concrete native
  XML example when the rendered prompt lacks that contract.
- Live proof artifacts:
  - `build/live-mimo-jang2l-required-contract-20260611/responses_required_tool_bluecat_after_required_contract.sse`
  - `build/live-mimo-jang2l-required-contract-20260611/responses_tool_result_continuation_after_required_contract.sse`
  - `build/live-mimo-jang2l-required-contract-20260611/health_after_required_tool.json`
  - `build/live-mimo-jang2l-required-contract-20260611/health_after_continuation.json`
- Proven:
  required-tool stream emitted `record_fact` with exact final arguments
  `{"value":"blue-cat"}` through argument delta/done/final function_call item,
  valid output index `1`, completed status, no visible prose/tool-markup leak.
  Tool-result continuation with `tool_choice=none` streamed exactly
  `STORED blue-cat.` and emitted no extra tool call.
- Cache/runtime evidence:
  affine JANG, native `mimo_v2_asymmetric_swa` cache, generic TurboQuant KV
  disabled, prefix+paged+block-L2 active, block L2 advanced from `637` to
  `740` tokens on disk.
- Shutdown evidence:
  after changing scheduler step-executor shutdown to
  `wait=False, cancel_futures=True`, a patched live restart/stop on port `8099`
  exited cleanly with `Scheduler step executor shutdown complete` and no
  Python 3.13 `PyThreadState_Get` fatal.
- Still red/open:
  MiMo JANGTQ_2 literal/special-character exactness and media semantics,
  thinking-on interleaved reasoning/tool rows, installed-app parity for this
  exact source commit, broader speed/long-output rows, and signed/notarized
  release publication.

## MiMo JANGTQ_2 Installed-App Media Overlay - 2026-06-11

- Green source/app rows:
  the explicit MiMo V2 media overlay no longer crashes on load. Source fixed
  the missing `os` import in `vmlx_engine/utils/jang_loader.py`, and the panel
  now clears `forceTextOnly` only under
  `VMLINUX_MIMO_V2_ENABLE_TEXT_RUNTIME_MEDIA_OVERLAY=1` when local indexed
  media weights and processor/token sidecars are present.
- Installed-app parity:
  `/Applications/vMLX.app` was rebuilt/reinstalled with
  `panel/scripts/build-and-install.sh`; local ad-hoc signature verification
  passed. Runtime parity artifact
  `build/current-installed-app-runtime-parity-audit-after-mimo-overlay-rebuild-20260611.json`
  is `status=pass` with no stale/missing files.
- Real UI route proof:
  `docs/internal/agent-notes/current-real-ui-installed-app-mimo-v25-jangtq2-image-overlay-red32-after-rebuild-20260611-proof.json`
  shows real installed app UI + Responses media transport for
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`: panel
  `modelForceTextOnly=false`, `chatIsMultimodal=true`, request body contains
  `image_url`, server `engine_is_mllm=true`, media weights bound
  `visual=364 audio_encoder=75 speech_embeddings=20`,
  `num_images_processed=1`, and `vision_encoding_time≈0.048s`.
- Cache proof:
  native `mimo_v2_asymmetric_swa` / `mixed_swa_kv_v1` cache remains active,
  generic TurboQuant KV remains disabled for MiMo, text turn paged cache hit
  saved `25` tokens, RAM cached `61` tokens, and block-L2 held `61` tokens.
  Media prompt cache storage was skipped by design because media embeddings
  are path-dependent.
- Red/open:
  image semantics are still wrong. Both the default 1x1 red PNG and a generated
  32x32 solid red PNG returned visible answer `Blue.`. Do not claim `vl_image`
  semantic pass, video pass, or audio pass from this overlay route proof. Treat
  MiMo JANGTQ_2 media semantics as an artifact/runtime visual-quality blocker.
- Release boundary:
  no DMG, Developer ID signing, notarization, tag, upload, PyPI, updater JSON,
  website, or N2 JANG_1L work was performed for this row.

## MiMo JANGTQ_2 Visual Trace And Video Segmentation - 2026-06-11

- Green source fix:
  MiMo-V2 local MLX vision `cu_seqlens` now matches the bundled PyTorch
  reference by segmenting attention per temporal frame. Old behavior grouped
  all frames in a media item into one segment, which can leak across video
  frames. Still images are unchanged because their observed grid is
  `grid_t=1`.
- Proof:
  `.venv/bin/python -m py_compile vmlx_engine/models/mllm.py` passed. A
  focused parity probe showed patched source-equivalent `cu_seqlens` for
  still image, multi-frame video, and mixed grids; old local behavior diverged
  whenever `grid_t>1`.
- Still-image semantic diagnosis:
  current direct source and installed-app media routes really process images,
  but solid-color semantics remain wrong. Processor trace ruled out RGB order
  and token expansion: red image produced `pixel_values=(16,1536)`,
  `image_grid_thw=[[1,4,4]]`, and four `<|image_pad|>` placeholders. Visual
  tower comparison against the bundled PyTorch reference loaded the same 364
  visual tensors and zeroed the same three missing merger biases; red-image
  embeddings matched with max abs diff `0.0136404`, mean abs diff
  `0.0004317`, cosine `0.99999964`.
- Red/open:
  do not claim MiMo JANGTQ_2 `vl_image`, video semantics, or audio green from
  this. The remaining solid-color failure is now classified outside local
  visual-tower math and should be investigated at artifact/model-quality,
  quant/logit bridge, or language-bridge level.
- Release boundary:
  no DMG, Developer ID signing, notarization, tag, upload, PyPI, updater JSON,
  website, or N2 JANG_1L work was performed for this row.

## Qwen-Coder-Next Served Surface Direct Responses SSE - 2026-06-11

- Green direct-source row:
  current source served `/Users/eric/models/Qwen3.6-35B-A3B-4bit` as
  `qwen3-coder-next` with Qwen tool parser and qwen3 reasoning parser. This is
  the available local served surface for the reported Qwen-coder-next style
  parser issue; no separate local Qwen-coder-next artifact was found.
- Proof:
  `build/current-qwen-coder-next-live-responses-sse-20260611/SUMMARY.json` is
  `status=pass`. Raw captures:
  `required_exec_command.sse`, `tool_result_continuation.sse`, and
  `adversarial_empty_xml_required.sse` in the same directory.
- Proven:
  required-tool streaming preserves `exec_command` args exactly as
  `{"cmd": "ls /tmp"}` across `response.function_call_arguments.delta`,
  `.done`, and the final `function_call` item; reasoning remains enabled; and
  output indices are valid (`message=0`, `reasoning=1`, `function_call=2`).
  Tool-result continuation via `previous_response_id` +
  `function_call_output` returns visible `alpha.tmp`/`beta.tmp` text and emits
  no second tool call. The adversarial preamble plus empty XML function body
  fails closed with `tool_calls_required`, emits zero function-call items, and
  never emits executable `{}` arguments.
- Cache/runtime:
  health after continuation is healthy with `ram_tokens_cached=277`,
  `l2_block_tokens_on_disk=277`, `l2_ssm_tokens_on_disk=533`, block disk
  writes `6`, and SSM companion disk stores `4`.
- Red/open:
  this is direct local source proof only, not gateway/tunnel or installed-app
  proof. The backing 4-bit artifact has no native MTP tensors and explicit q4
  KV was used, so do not treat this as native-MTP, calibrated TurboQuant speed,
  media, package, sign/notarize, or full release readiness proof.

## Qwen-Coder-Next Local Gateway Responses SSE - 2026-06-10

- Green local-gateway row:
  current source backend served
  `/Users/eric/models/Qwen3.6-35B-A3B-4bit` as `qwen3-coder-next`, then the
  real panel `ApiGateway` local proxy streamed a reasoning-enabled required
  `exec_command` Responses request.
- Proof:
  `build/current-qwen-coder-next-gateway-responses-sse-20260610/SUMMARY.json`
  is `status=pass`. Raw captures are
  `gateway_required_exec_command.sse`,
  `gateway_required_exec_command.log`, and `health_after_gateway.json`.
- Proven:
  the gateway returned `200` with SSE content type; reasoning events were
  present; `response.function_call_arguments.delta` fragments joined to
  `{"cmd": "ls /tmp"}`; `response.function_call_arguments.done` and the final
  function-call item matched exactly; no executable `{}` arguments were
  emitted; no raw XML tool markup leaked; and final output item order matched
  stream-added order.
- Output indices:
  stream-added indices are valid and sequential:
  `message=0`, `reasoning=1`, `function_call=2`. Done events covered the same
  indices in completion order, so reasoning can finish before the empty visible
  message without reusing index `0` for the tool call.
- Cache/runtime:
  post-gateway health is healthy with scheduler cached tokens `206`,
  block-disk L2 tokens `206`, four block-disk blocks, and q4 KV storage for
  this proof run.
- Red/open:
  this does not clear public tunnel parity, installed-app UI,
  every Qwen/Qwen-coder size, native MTP, calibrated TurboQuant speed, media,
  cross-family parser coverage, release packaging, sign/notarize, PyPI,
  updater JSON, website, or N2 JANG_1L.

## Qwen-Coder-Next Public Tunnel Availability - 2026-06-11

- Open tunnel row:
  `build/current-qwen-coder-next-tunnel-availability-20260611/SUMMARY.json`
  is `status=open`.
- Finding:
  `https://testapi.adlabus.dev/v1/models` is reachable and advertises 11 model
  IDs, but not the exact current-source served model `qwen3-coder-next`.
- Advertised Qwen-family IDs:
  `models/Qwen3.6-27B-MXFP8-CRACK-MTP`,
  `Qwen3.6-27B-MXFP8-CRACK-MTP`,
  `dealignai/Qwen3.6-27B-MXFP8-CRACK-MTP`,
  `models/Qwen3.6-35B-A3B-MXFP8-CRACK-MTP`, and
  `Qwen3.6-35B-A3B-MXFP8-CRACK-MTP`.
- Classification:
  same-model public tunnel raw SSE for `qwen3-coder-next` is a deployed
  tunnel/session-routing availability gap, not a local parser proof gap. Do
  not close this row from Qwen27/Qwen35 aliases unless an intentional alias
  mapping is deployed and documented.
- Other-agent next:
  route/deploy the public tunnel to the current-source `qwen3-coder-next`
  served surface, then recapture reasoning-enabled required-tool raw SSE with
  the same `exec_command`/`{"cmd":"ls /tmp"}` request and compare against the
  direct plus local-gateway artifacts.
- Red/open:
  public tunnel parity remains open. Installed-app UI, every-family parser
  coverage, native MTP, calibrated TurboQuant speed, media, release packaging,
  sign/notarize, PyPI, updater JSON, website, and N2 JANG_1L remain open or
  untouched here.

## MiMo V2.5 JANG_2L Speed/Cache Root Cause - 2026-06-11

- Open row:
  `build/current-mimo-jang2l-speed-cache-root-cause-20260611/SUMMARY.json` is
  `status=open`.
- Proven:
  classic JANG_2L native mixed full/SWA cache, paged reuse, and block-disk L2
  are active; full quantization coverage is logged for lm_head, embeddings,
  qkv, routed SwitchGLU, and dense MLP modules; and affine SwitchGLU body
  decode is active.
- Speed root cause:
  traces show the model body step is only around `2-3 ms`, while final logits/
  lm_head materialization dominates. Before SingleBatch warmup, token 1
  `logits_ms=34124.88`; after startup warmup, the first real user token still
  reports `logits_ms=2532.17` and token 2 `606.22`.
- Installed-app boundary:
  the older installed-app MiMo JANG_2L speed proof (`1.9 t/s`, first TTFT
  `25.74s`) is stale relative to the current rebuilt app. Current installed
  bundled Python matches source for the MiMo warmup/cache runtime files, so
  installed speed must be rerun before judging current package behavior.
- JANGTQ comparison:
  MiMo JANGTQ_2 remains the current high-speed MiMo path, with prior current
  source speed around `39 tok/s`.
- Red/open:
  classic JANG_2L steady-state high-speed decode is not release-cleared; the
  remaining optimization target is lm_head/logits materialization, not prefix
  cache, L2, RotatingKVCache metadata, or SwitchGLU body decode. Media,
  exactness, full agentic loops, release packaging, sign/notarize, PyPI,
  updater JSON, website, and N2 JANG_1L remain open or untouched.

## MiMo V2.5 Artifact Contract / Remake Guidance - 2026-06-11

- Proof:
  `build/current-mimo-artifact-contract-inspection-20260611/SUMMARY.json` and
  `build/current-mimo-artifact-contract-inspection-20260611/CONCLUSIONS.json`.
- Spacing/syntax:
  JANG_2L and JANGTQ_2 share identical chat template hash
  `3134ac101acd29d3ab41297707cc1a85699f5f0acb283fdeb0681e3750998403`,
  template length `8259`, `clean_up_tokenization_spaces=false`,
  `split_special_tokens=false`, and no `spaces_between_special_tokens`
  override. Current artifact evidence does not support spacing/template
  corruption between these two MiMo rows.
- Upcast/dtype:
  inspected hot text tensors are packed `U32` with `F16` sidecars. Both
  artifacts have shape-correct q8/group64 `lm_head` with packed
  `[152576,1024]`, scales `[152576,64]`, expanded input `4096`, hidden size
  `4096`. Current header evidence does not support a text-core BF16 upcast
  failure for this speed symptom.
- Quant/layout:
  classic JANG_2L: `format=jang`, profile `JANG_2L_322_D3E16`,
  `tq_packed=0`, `tq_norms=0`, layer0 qkv packed `[13568,1024]`, size
  `104.369GB`. JANGTQ_2: `format=jangtq`, profile `JANGTQ_2`,
  `tq_packed=141`, `tq_norms=141`, layer0 qkv packed `[13568,512]`, size
  `78.824GB`.
- Remake guidance:
  for a fast 128GB checkpoint, remake/prefer the JANGTQ_2-style prestacked
  TurboQuant routed-expert layout with `tq_packed/tq_norms` and smaller qkv
  footprint. Keep the current tokenizer/template spacing and native
  `mixed_swa_kv_v1` cache metadata. Do not remake solely to change cache
  type; generic TurboQuant KV is incompatible with MiMo's rotating/full
  mixed-cache contract.
- Red/open:
  this does not prove exactness/model quality is inherently bad; source/dequant
  logits or replacement-artifact A/B is still required for that. Current
  installed-app speed after rebuild, media, audio/video, full agentic loops,
  release packaging, sign/notarize, PyPI, updater JSON, website, and N2
  JANG_1L remain open or untouched.

## Gemma4 12B QAT MXFP4 Source Responses Video/Cache - 2026-06-11

- Proof:
  `docs/internal/agent-notes/current-real-ui-source-gemma4-12b-qat-mxfp4-responses-video-cache-20260611-proof.json`.
- Status:
  passed in current-source Electron dev UI with
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`,
  `wireApi=responses`, deterministic sampling, MLLM enabled, video enabled,
  audio disabled, and server cache controls enabled.
- Proven:
  `/v1/responses` streaming, video attachment preservation, base64 MP4 decode,
  25-frame ingestion with 4 extracted frames, frame-through-vision via Gemma4
  image fallback, semantic red/solid video answer, generation defaults,
  parser/language leak checks, Responses cache-detail usage, native Gemma4
  `mixed_swa_kv_v1` cache status, q4 storage-boundary KV quantization for
  full-attention KV only, paged/prefix cache reuse, cache endpoint stats, and
  block-disk L2 writes.
- Metrics:
  cache-hit requests `1`, cache-hit tokens `20`, L2 block tokens on disk `70`,
  disk writes `2`, text decode about `55-56 tok/s`, video prefill about
  `334 prompt tok/s`.
- No-claims:
  this is not audio proof; the artifact keeps `requestedAudio=false` and the
  runtime reports audio unavailable. This does not clear installed-app
  Responses video, 26B/31B Responses video, Qwen/N2/MiMo media, tunnel parity,
  full reasoning/tool stress, release packaging, sign/notarize, PyPI, updater
  JSON, or website release rows.

## MiMo V2.5 JANGTQ_2 Installed-App Exactness - 2026-06-11

- Proof:
  `docs/internal/agent-notes/current-real-ui-installed-app-mimo-v25-jangtq2-exact-output-harness-current-bundled-python-20260611-proof.json`.
- Status:
  failed honestly with installed `/Applications/vMLX.app`, bundled Python,
  `/Users/eric/.mlxstudio/models/JANGQ-AI/MiMo-V2.5-JANGTQ_2`,
  Chat Completions, deterministic sampling, no tools, no thinking, and strict
  exact-output assertions.
- Current failures:
  `ACK-CB-742` -> `ACKCB-742`; `{"status":"ok","value":"blue-cat"}` ->
  `{"status":"ok","value":"blue"}`.
- Positive runtime evidence:
  installed app and bundled runtime loaded the 79GB JANGTQ_2 artifact; runtime
  detected `turboquant_codebook`, profile `JANGTQ_2`, `423` routed-expert TQ
  targets, `141` prestacked TQ groups, native MiMo `mixed_swa_kv_v1` /
  `mimo_v2_asymmetric_swa` cache, and custom TurboQuant kernels. Block-disk L2
  wrote `117` tokens across `3` blocks. Live decode was about `42-43 tok/s`.
- Root-cause boundary:
  this replaces the older false-green installed exactness row after the proof
  harness fix. Existing A/B artifacts still exclude parser/JSON repair,
  tokenizer roundtrip, chat-template corruption, cache/L2, hidden sampling,
  and tool protocol shape as primary causes. The remaining primary class is
  artifact/logit/codebook/decode quality.
- Required next work:
  remake or A/B a replacement MiMo V2.5 JANGTQ_2 artifact against literal
  exactness probes (`ACK-CB-742`, `blue-cat`, JSON string values, tool argument
  values) before marking MiMo exactness release-clear. App/runtime proofs may
  continue for speed/tool/cache, but exactness stays red.

## Nex/N2 Pro JANGTQ2 Installed-App Runtime/API/Cache - 2026-06-11

- Local artifact:
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`, about `101G`.
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANG_1L` exists but
  remains off-limits for this lane.
- Green installed-app bundled-Python proofs:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-tools-cache-bundled-python-20260610-proof.json`
  and
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-reasoning-tools-cache-bundled-python-20260610-proof.json`.
- Proven:
  installed app UI, bundled Python, real N2 JANGTQ2 load, `/v1/responses`,
  built-in auto tool loop, long tool loop, tool-result continuation,
  `enable_thinking=true` reasoning display, content/Responses delta streaming,
  cache-detail usage, settings persistence, generation defaults, parser/
  language leak checks, native hybrid SSM cache, attention-only TurboQuant KV,
  q4 storage-boundary attention KV, async clean-prefill rederive policy, SSM
  companion L2, and block-disk L2.
- Runtime/cache details:
  health reports `turboquant_codebook`, `weight_format=mxtq`, profile
  `JANGTQ2`, `540` prestacked routed-expert TQ targets, `2725` indexed tensors,
  `hybrid_ssm_v1`, components `attention_kv`, `ssm_companion_state`, and
  `async_rederive`. The reasoning/tools proof recorded `7289` L2 block tokens,
  `26169` SSM tokens on disk, `33458` total L2 tokens, `117` disk writes, and
  `reasoningDone=5`.
- Media:
  installed-app image proof is green for `vl_image`; bundled video proof is
  green for video. Bundled audio proof fails at `audio_send_message`, which is
  the honest unsupported-audio boundary for this artifact.
- MTP:
  config/JANG metadata declares one MTP layer, but indexed weights contain zero
  MTP tensors. Current status is `dropped` /
  `metadata_only_missing_weights`; do not claim native N2 JANGTQ2 MTP active.
- Required next work:
  do not rerun these green rows unless app/source changed. Target missing
  proof instead: N2 JANGTQ2 direct/gateway/tunnel raw SSE parity, Responses
  media parity, or a fresh installed-app rerun after runtime changes. This does
  not clear N2 JANG_1L, audio, MTP, package/sign/notarize, PyPI, updater JSON,
  website, or public release rows.

## Gemma4 12B QAT MXFP4 Installed-App Responses Video/Cache - 2026-06-11

- Proof:
  `docs/internal/agent-notes/current-real-ui-installed-app-gemma4-12b-qat-mxfp4-responses-video-cache-bundled-python-20260611-proof.json`.
- Status:
  passed with installed `/Applications/vMLX.app`, bundled Python,
  `/Users/eric/models/JANGQ-AI/gemma-4-12B-it-qat-MXFP4`,
  `wireApi=responses`, deterministic sampling, MLLM enabled, video enabled,
  audio disabled, and server cache controls enabled.
- Proven:
  installed app UI, bundled Python, real Gemma4 12B QAT MXFP4 load,
  `/v1/responses`, Responses delta streaming, video attachment preservation,
  `video_url` request body, base64 MP4 decode, 25-frame ingestion with 4
  extracted frames, Gemma4 frame-through-vision path via image fallback,
  semantic red/solid video answer, generation defaults, parser/language leak
  checks, Responses cache-detail usage, native Gemma4 `mixed_swa_kv_v1` cache,
  q4 storage-boundary KV quantization for full-attention KV only,
  paged/prefix cache reuse, cache endpoint stats, and block-disk L2 writes.
- Metrics:
  cache-hit requests `1`, cache-hit tokens `20`, RAM cached tokens `70`, L2
  block tokens on disk `70`, disk writes `2`, text decode about `55-56 tok/s`,
  video prefill about `295 prompt tok/s`, memory about `7.8GB` active /
  `8.4GB` peak.
- No-claims:
  this is not Gemma audio proof; runtime reports audio unavailable. This does
  not clear 26B/31B Responses video, Qwen/N2/MiMo media, tunnel parity, full
  reasoning/tool stress, release packaging, sign/notarize, PyPI, updater JSON,
  or website release rows.

## Nex/N2 Pro JANGTQ2 Installed-App Responses Video/Cache - 2026-06-11

- Proof:
  `docs/internal/agent-notes/current-real-ui-installed-app-n2-jangtq2-responses-video-cache-bundled-python-20260611-proof.json`.
- Status:
  passed with installed `/Applications/vMLX.app`, bundled Python,
  `/Users/eric/.mlxstudio/models/JANGQ-AI/Nex-N2-Pro-JANGTQ2`,
  `wireApi=responses`, deterministic sampling, MLLM enabled, video enabled,
  audio disabled, and server cache controls enabled.
- Proven:
  installed app UI, bundled Python, real 101GB N2 JANGTQ2 load,
  `/v1/responses`, Responses delta streaming, video attachment preservation,
  `video_url` request body, base64 MP4 decode, 25-frame ingestion with 4
  extracted frames, N2 frame-through-vision path, semantic red/solid video
  answer, generation defaults, parser/language leak checks, Responses
  cache-detail usage, native `hybrid_ssm_v1` cache, attention-only TurboQuant
  KV, q4 storage-boundary attention KV, SSM companion state, async clean SSM
  capture/rederive policy, SSM companion L2, paged/prefix cache reuse, cache
  endpoint stats, and block-disk L2 writes.
- Runtime/cache details:
  health reports `turboquant_codebook`, `weight_format=mxtq`, profile
  `JANGTQ2`, `540` prestacked routed-expert TQ targets, `2725` indexed tensors,
  `15` attention layers, `45` SSM companion layers, and live attention
  TurboQuant KV. Cache totals: `50` RAM tokens cached, `50` L2 block tokens,
  `68` SSM tokens on disk, `118` total L2 tokens, `2` block disk writes, `2`
  SSM stores, and `3` block-disk hits. Cache-hit telemetry: `1` request / `18`
  tokens via `paged+ssm`.
- Metrics:
  load about `69.9s`; memory about `103.8GB` active / `105.3GB` peak; visible
  text turns about `27-29 tok/s`; video prefill about `125 prompt tok/s`.
- No-claims:
  this is not N2 audio proof, not native MTP proof, and not N2 JANG_1L proof.
  MTP remains `metadata_only_missing_weights` / `dropped` because indexed
  weights contain zero MTP tensors. This does not clear direct/gateway/tunnel
  raw SSE parity, package/sign/notarize, PyPI, updater JSON, website, or public
  release rows.

## Nex/N2 Pro JANGTQ2 Responses Raw SSE Direct/Gateway - 2026-06-11

- Proof artifacts:
  `build/current-n2-jangtq2-responses-stream-boundary-20260610.json` plus
  `build/responses-sse-captures-20260610/direct-n2-jangtq2-first-tool-20260610.sse`,
  `direct-n2-jangtq2-followup-20260610.sse`,
  `gateway-n2-jangtq2-first-tool-20260610.sse`, and
  `gateway-n2-jangtq2-followup-20260610.sse`.
- Status:
  direct and gateway raw SSE are green in current artifacts.
- Proven direct:
  first-tool capture emits message item `output_index=0`, function_call item
  `output_index=1`, `response.function_call_arguments.delta`,
  `response.function_call_arguments.done`, final function-call item with
  `{"query":"alpha"}`, and completed final object preserving the same output
  order. Followup capture streams `response.output_text.delta` events and
  completes the requested marker text.
- Proven gateway:
  first-tool and followup captures preserve the same output-index, argument
  delta/done, final-object, and content-delta shapes. Gateway usage records
  `cached_tokens` and `cache_detail=paged+ssm`.
- Remaining open:
  no N2 JANGTQ2 public tunnel SSE artifact exists in the current capture set.
  `build/current-n2-jangtq2-loopback-toolchoice-required-error-reduced-20260610.json`
  remains `status=open` for the strict long-delta/tool-adherence row because
  the model did not call the second tool and did not satisfy requested visible
  markers. The default/auto N2 JANGTQ2 tool/cache/delta row remains green.
- No-claims:
  this does not prove public tunnel parity, strict long-delta required-tool
  adherence, N2 JANG_1L, audio, MTP, package/sign/notarize, PyPI, updater JSON,
  website, or public release rows.
