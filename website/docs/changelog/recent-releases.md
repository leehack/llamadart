---
title: Recent Releases
description: Review recent llamadart release highlights and jump to the canonical changelog for full release notes.
---

For canonical full release notes, use:

- [`CHANGELOG.md`](https://github.com/leehack/llamadart/blob/main/CHANGELOG.md)

## Unreleased

- Throw `LlamaModelException` when native llama.cpp cannot find or load a
  multimodal projector, and `LlamaUnsupportedException` when the runtime lacks
  the mtmd functions; `LlamaEngine.supportsAudio` also throws the latter.
  Speech-to-text capabilities now say when no projector is loaded, using the
  new `LlamaEngine.hasMultimodalProjector`
  ([#325](https://github.com/leehack/llamadart/issues/325)).
- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@v0.4.1-1`, keeping the `v0.4.1` llama.cpp
  ABI/bindings while picking up wrapper-only native fixes. Refreshed the
  `llamadart_llama_cpp_flutter` Apple SwiftPM checksum and aligned current
  README/website native override docs.
- Honour `LlamaEngine.cancelGeneration()` issued right after listening to a
  `create`, `generate` or `ChatSession.create` stream, before it reaches the
  backend, instead of running the whole generation
  ([#602](https://github.com/leehack/llamadart/issues/602)).
- Cancel an active text-to-speech synthesis on `LlamaEngine.unloadModel()` and
  `dispose()` instead of waiting for it to finish
  ([#628](https://github.com/leehack/llamadart/issues/628)).
- Stop a Qwen3-TTS audio decode at its next chunk boundary when native
  text-to-speech is cancelled, instead of finishing the native step in
  progress first. This needs llamadart-native v0.4.1-1 or later; older
  runtimes keep the previous behaviour
  ([llamadart-native#86](https://github.com/leehack/llamadart-native/issues/86),
  [#322](https://github.com/leehack/llamadart/issues/322)).
- Add an experimental `DecisionEngine` for Laya-style decision models (a
  ModernBERT encoder GGUF plus a safetensors head) on native llama.cpp, with
  typed `ChoiceKey`, `ScoreKey` and `NoulKey` questions
  ([#604](https://github.com/leehack/llamadart/issues/604)).
- Add `example/basic_app/bin/llamadart_decision_example.dart`, a console demo
  that triages a support ticket with `DecisionEngine`
  ([#604](https://github.com/leehack/llamadart/issues/604)).
- Add `example/laya_tetris`, a Flutter app in which a Laya decision model
  plays real-time Tetris through `DecisionEngine`
  ([#604](https://github.com/leehack/llamadart/issues/604)).
- Add a notebook in `example/laya_tetris/training/` that fine-tunes a Laya
  decision head for the Tetris example and exports it for `DecisionEngine`
  ([#604](https://github.com/leehack/llamadart/issues/604)).
- Run `DecisionEngine` on WebGPU through the bridge decision API
  (apiVersion 1), which bridge assets `v0.1.47+` include
  ([#604](https://github.com/leehack/llamadart/issues/604)).
- Stop native image and audio requests from seeding the repeat penalty with
  leftover memory, which made output depend on the previous request
  ([#603](https://github.com/leehack/llamadart/issues/603)).
- After a failed native prompt decode, the next `reusePromptPrefix` request no
  longer runs on the wrong KV cache or keeps failing
  ([#601](https://github.com/leehack/llamadart/issues/601)).
- Reject `embed()` and `embedBatch()` on rank-pooled reranker GGUFs with
  `LlamaUnsupportedException` on native, instead of returning memory read
  past llama.cpp's classifier-score buffer
  ([#583](https://github.com/leehack/llamadart/issues/583)).
- Throw `LlamaInferenceException` from native `embed()` and `embedBatch()`
  when input to an encoder-only model or a model without a KV cache (such as
  BERT-family and ModernBERT GGUFs) does not fit one `microBatchSize` pass,
  instead of aborting the process or embedding only the last chunk
  ([#607](https://github.com/leehack/llamadart/issues/607)).
- Aligned default WebGPU bridge assets to `v0.1.49` for the decision API
  and the Web runtime fixes below, qualified against native `v0.4.1-1` and
  retaining Web/native llama.cpp
  `v0.4.1@b29c606e28a01b1bc8c1351026a0fa6e616bf6c4` parity and Web
  `@litert-lm/core@0.15.0`. Immutable Web asset manifest:
  `28d7b92d8d7a4406d2dd33f2d434f30f43bdbca82565914d9dfb6ff4a23bdddc`.
- On Web, an invalid GBNF grammar now fails generation with a
  `LlamaInferenceException` whose details contain `(invalid grammar)`, and the
  loaded model stays usable, instead of aborting the WebGPU bridge runtime
  ([llama-web-bridge#125](https://github.com/leehack/llama-web-bridge/pull/125)).
- On Web, when a bridge worker fails and the main-thread reload fails too, or
  a replacement worker cannot start, the bridge now forgets the model instead
  of being left broken with a `TypeError`. Later calls fail with
  `No model loaded. Call loadModelFromUrl first.`; call `unloadModel()`, then
  `loadModel()` and any projector again to recover
  ([llama-web-bridge#123](https://github.com/leehack/llama-web-bridge/pull/123),
  [llama-web-bridge#127](https://github.com/leehack/llama-web-bridge/pull/127)).
- On Web, a replacement bridge worker reloads the current model before its next
  request
  ([llama-web-bridge#126](https://github.com/leehack/llama-web-bridge/pull/126)).
- On Web, grammar-constrained generation no longer aborts the bridge runtime
  when top-k or top-p keeps only tokens the grammar rejects; it resamples as
  llama.cpp does, and fails with `Grammar rejected every candidate token` only
  when the grammar cannot continue
  ([llama-web-bridge#118](https://github.com/leehack/llama-web-bridge/pull/118)).
- On Web, an ordinary error from a healthy bridge worker, such as a prompt that
  overflows the context or empty embedding input, is now rethrown with the
  worker kept, instead of moving the session to the main thread for good and
  re-running the request
  ([llama-web-bridge#119](https://github.com/leehack/llama-web-bridge/pull/119),
  [llama-web-bridge#120](https://github.com/leehack/llama-web-bridge/pull/120)).
- Extend the GGUF speech-to-text validation pack with four synthetic edge
  fixtures built in-process, so no extra audio is stored: generated digital
  silence, plus a truncated RIFF, a stereo 44.1 kHz re-encode and a 33-second
  concatenation, the last three derived from the locked `jfk.wav`. Every GGUF
  STT pack run executes the four checks and each one gates `functional_pass`;
  the LiteRT-ASR and TTS packs pass no edge fixtures
  ([#325](https://github.com/leehack/llamadart/issues/325)).
- Raise every `stt`, `tts` and `litert-asr` speech validation pack run from 8
  to 15 lifecycle checks: an immediate cancel, three
  cancel/dispose/load/generate cycles, and bounds that fail the run when a
  cancellation takes over 500 ms to end its task or the peak resident set
  exceeds 1.10x the one sampled after the first generation
  ([#594](https://github.com/leehack/llamadart/pull/594)).
- Force greedy `topK: 1` for zero-temperature LiteRT-LM Web generation, matching
  the native clamp
  ([#548](https://github.com/leehack/llamadart/issues/548)).
- Log `Model … loaded from …; native engine creation is deferred until the
  first generation or tokenizer call` instead of `loaded successfully` when
  the native LiteRT-LM backend finishes `loadModel`, since it creates the
  engine lazily
  ([#569](https://github.com/leehack/llamadart/issues/569)).
- Require `dxcompiler.dll` and `dxil.dll` in the Windows x64 LiteRT-LM runtime
  cache and desktop validation bundle checks, matching the hook's v0.17.0-6
  inventory. The runtime does not preload them: Dawn's D3D12 backend loads the
  pair at GPU engine creation
  ([#570](https://github.com/leehack/llamadart/issues/570)).
- Document that Linux llama.cpp loads need the OpenMP runtime
  (`libgomp.so.1`; `libgomp1` on Ubuntu/Debian, `libgomp` on Fedora and Arch)
  and that Linux LiteRT-LM GPU needs a hardware Vulkan ICD: with only Mesa
  llvmpipe the runtime segfaults after model load instead of failing cleanly
  ([llamadart-native#82](https://github.com/leehack/llamadart-native/issues/82),
  [#572](https://github.com/leehack/llamadart/issues/572)).
- Record one startup diagnostic when every candidate of a native backend
  module family fails to load, or when a `ggml`/wrapper symbol is missing from
  both the primary FFI asset and every fallback library. Candidates are named
  by asset URI or file name only and loader errors are classified, never
  quoted, so no directory or loader search path reaches the diagnostic
  ([#416](https://github.com/leehack/llamadart/issues/416)).
- Forward llama.cpp and LiteRT-LM worker-isolate log records to the
  `LlamaEngine.configureLogging` handler. A worker takes the Dart logger level
  when it starts and `LlamaEngine.setDartLogLevel`/`setLogLevel` update a
  running worker; the default `none` sends nothing and `debug` records are
  capped at 1000 per worker. The LiteRT-LM program-cache pruning warnings are
  now ordinary `warn` records gated by that level instead of the native log
  level. Adds `LlamaLogger.level` and the `BackendDartLogLevel` capability
  ([#567](https://github.com/leehack/llamadart/issues/567)).
- Replace the token in `Bearer <token>` and the value in `token=`, `key=`,
  `secret=`, `password=`, `api_key=` and `apikey=<value>` outside HTTP URLs in
  native startup diagnostics with `<redacted-secret>`; URL and
  control-character handling is unchanged
  ([#551](https://github.com/leehack/llamadart/issues/551)).
- Add `ModelParams.liteRtLmCacheDir` to choose the native LiteRT-LM runtime
  cache directory and opt-in `ModelParams.liteRtLmMaxProgramCacheBytes`, which
  deletes `*_mldrift_program_cache.bin` files above the cap before each engine
  create and logs a warning per deleted file. Defaults are unchanged: the same
  per-platform directory and no pruning
  ([#552](https://github.com/leehack/llamadart/issues/552)).
- Force greedy `topK: 1` for zero-temperature
  `LiteRtLmRuntimeClient.createConversation` calls, which returned incoherent
  text on the LiteRT WebGPU sampler with the default top-k.
- Keep root-cause native startup diagnostics when the buffer or the rendered
  `startupDiagnostics=[...]` suffix overflows: teardown entries, now prefixed
  `teardown: `, are dropped first, duplicates are recorded once, entries are
  capped at 2048 characters, and each omitted run renders as `...`
  ([#415](https://github.com/leehack/llamadart/issues/415)).
- Skip the Windows altered-search-path preload for wrapper library candidates
  whose absolute path does not exist, so lazy wrapper API lookups no longer
  record a `Failed to preload Windows backend module` startup diagnostic per
  missing candidate
  ([#550](https://github.com/leehack/llamadart/issues/550)).
- Accept `promptTemplate` on the non-native
  `LiteRtLmRuntimeClient.createConversation` placeholder, so callers passing
  it compile for Web as they do on native
  ([#549](https://github.com/leehack/llamadart/issues/549)).
- Cache `TemplateCaps.detect` results in a per-isolate LRU keyed by exact
  template source and bounded at 16 entries, so repeated chat-template renders
  skip both Jinja parses and all four capability probes. Detections in which
  any analysis step failed are not cached and keep logging on every call
  ([#448](https://github.com/leehack/llamadart/issues/448)).
- Detect `supportsTools` and `supportsToolCalls` for chat templates that
  reject two tool calls in one assistant message (Llama 3.2) or a user turn
  directly after a tool call (Ministral 3). The tools capability probe now
  renders a single tool call, and a separate parallel probe clears only
  `supportsParallelToolCalls` when it throws
  ([#557](https://github.com/leehack/llamadart/issues/557)).
- Limit the Ministral tool-call grammar to a single `[TOOL_CALLS]` block unless
  parallel tool calls are enabled; it previously always allowed repeats while
  the parser kept only the first call
  ([#559](https://github.com/leehack/llamadart/issues/559)).
- Limit the Nemotron v3 tool-call grammar (Qwen3-Coder XML format) to a single
  tool call unless parallel tool calls are enabled; it previously always
  allowed repeats while the parser kept only one call
  ([#562](https://github.com/leehack/llamadart/issues/562)).
- Pin the WebGPU model-load retry ladder with browser tests for the ladder
  advance, the wasm64 BigInt restart on wasm32, the restart without the remote
  fetch backend, and forced remote-fetch chunk halving stopping on both its
  ten-restart cap and its 4 KiB minimum chunk, then collapse the duplicated
  attempt thread-count switch into one helper
  ([#361](https://github.com/leehack/llamadart/issues/361)).
- Apply the JSON Schema `pattern` keyword when generating GBNF, for anchored
  patterns built from literals, positive character classes, `(...)` groups
  nested at most 32 deep, grouped alternation and `*`/`+`/`?`/`{m,n}`
  repetition; any other pattern, including deeper nesting, falls back to the
  rule the schema would have produced without it, so `minLength` and
  `maxLength` still apply there. An applied pattern replaces
  `minLength`/`maxLength` as it does in llama.cpp, so a schema carrying both
  `pattern` and `maxLength` is no longer length-bounded. A schema carrying
  `pattern` but no explicit `type` now yields a string rule instead of
  throwing `Unrecognized schema`. Mistral Nemo and Magistral tool-call ids are
  now grammar-constrained to exactly nine alphanumerics
  ([#582](https://github.com/leehack/llamadart/issues/582)).
- Stop a cancelled llama.cpp image or audio prompt at the next prompt chunk,
  or between a media chunk's encode and its embedding decode, instead of after
  the whole prompt is ingested. The native call already running still
  finishes
  ([#599](https://github.com/leehack/llamadart/issues/599)).
- `SpeechToTextEngine` now fails a native Qwen3-ASR transcript that reaches
  the context size or `maxOutputTokens` with
  `LlamaSpeechTranscriptTruncatedException` instead of completing with
  truncated text, and `create()` reports `finishReason: 'length'` when native
  llama.cpp stops at either limit. The chat app caps Qwen3-ASR recordings at
  the validated 30 seconds
  ([#636](https://github.com/leehack/llamadart/issues/636)).
- Stop `ToolChoice.auto` on WebGPU from forcing a tool call: it now skips
  the lazy tool-call grammar and parses tool calls best-effort. WebGPU
  rejects `GenerationParams.grammarLazy` and a non-`root` `grammarRoot` with
  `LlamaUnsupportedException`; backends report this through the new
  `BackendLazyGrammarSupport`
  ([#654](https://github.com/leehack/llamadart/issues/654)).

## 0.8.24

- Align native `leehack/llamadart-native@v0.4.1` on upstream
  `b29c606e28a01b1bc8c1351026a0fa6e616bf6c4`, with matching Dart bindings
  and Apple companion `0.0.19`. This resolves the 0.8.23 grammar limitation:
  native `{2000}` repetitions are accepted again
  ([llamadart-native#76](https://github.com/leehack/llamadart-native/issues/76)).
- Aligned default WebGPU bridge assets to `v0.1.44` for matching
  Web/native `v0.4.1@b29c606e28a01b1bc8c1351026a0fa6e616bf6c4` parity.
  Immutable Web asset manifest:
  `8d61f453753ac7a7d839ac12318b70986a814748d86029993118c19454293aa9`.
- Update native LiteRT-LM to `v0.17.0-6` with Apple companion `0.0.11`,
  Qwen3 tokenizer compatibility, corrected Linux loading, and explicit Linux
  and Windows GPU selection while retaining CPU defaults. The Windows x64
  runtime bundles `dxil.dll` and `dxcompiler.dll`, which D3D12 GPU engine
  creation requires
  ([litert-lm-native#47](https://github.com/leehack/litert-lm-native/issues/47)).
  Web LiteRT-LM stays at `@litert-lm/core@0.15.0`.
- Preserve required iOS LiteRT-LM provider and Metal plugins, handle dependency
  ordering in companion libraries, and exclude metadata/import archives from
  runtime library inventories.
- Respect greedy sampling for zero-temperature native LiteRT-LM generation.
- Restore native Qwen3 chat text when thinking is disabled and preserve plain
  system instructions when seeding LiteRT-LM conversation history.
- Settle pending LiteRT-LM requests when a worker stops, close response ports,
  and report unverified native cleanup as an error.
- Preserve Unicode when detokenizing native GGUF tokens and suppress caller
  stop markers across chunk boundaries and speculative decoding.
- Restore native Qwen3-ASR file/encoded-byte transcription parity by keeping
  encoded audio out of string chat-template prompts.
- Render typed tool results as JSON text while preserving string results,
  validate Qwen XML argument types against schemas, and reject malformed or
  undeclared tool calls without exposing executable tool deltas.
- Prevent split MiniMax M3 thinking delimiters from leaking into reasoning.
- Discover Windows backend libraries in compiled CLI bundles and provide
  bounded diagnostics for unavailable native thinking-budget helpers.
- Fix fresh macOS Flutter dependency scanning while retaining Apple ABI and
  local-override guards.
- Add locked Gemma 4/Qwen3.5 validation profiles, explicit NPU coverage, and
  opt-in speech and voice-pipeline diagnostics.
- Preserve physical iOS speech-test failure-phase diagnostics and keep
  repository writer checks independent of generated website output.
- Retain open LiteRT-LM qualification gaps: macOS Qwen3.5 GPU reload latency
  ([#521](https://github.com/leehack/llamadart/issues/521)), Gemma exact-history
  behavior ([#513](https://github.com/leehack/llamadart/issues/513)), and
  Qwen3-0.6B arithmetic on Android CPU and iOS CPU/GPU
  ([#509](https://github.com/leehack/llamadart/issues/509)). The affected cases
  remain unqualified; these changes do not resolve the failures or establish
  their remaining owning layer.

## 0.8.23

- Fail Apple builds before native symbol lookup when the resolved llama.cpp
  companion does not match the core native runtime, with actionable upgrade
  guidance.

- Adopted native llama.cpp v0.4.0 with matching bindings and multimodal calls.
  Saved native sessions from older runtimes must be regenerated. Apple companion
  `0.0.18` supplies the matching native runtime.

- Aligned default WebGPU bridge assets to `v0.1.43` for Web/native
  llama.cpp `v0.4.0@5266f24da75dc449bd56cbed7addb9c8e4a6a73e` parity.
  Web `@litert-lm/core@0.15.0` and native LiteRT pins are unchanged. Immutable
  manifest: `111eefc3588842cebfe665b363378edca34924764610263e1eda5280dfcfaa27`.

- Known upstream limitation: llama.cpp v0.4.0 can reject large grammar
  repetitions, such as `root ::= "a"{2000}`. The post-v0.4.0 correction is
  tracked in [native #76](https://github.com/leehack/llamadart-native/issues/76)
  and is not included in this release.

## 0.8.22

- Updated `llamadart_llama_cpp_flutter` to `0.0.17` with the
  Apple SwiftPM `v0.3.0` runtime pin.

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@v0.3.0`, regenerated matching Dart FFI bindings,
  refreshed the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and
  aligned current README/website native override docs.

- Aligned default WebGPU bridge assets to `v0.1.41` for corrected
  TypeScript declarations and TTS recovery guidance, retaining Web/native
  llama.cpp `v0.3.0@c1d0e7a004015f23bc0233470b747b596f29b264` parity and Web
  `@litert-lm/core@0.15.0`. Immutable manifest:
  `fe97604daabaad6aefa223a8637d5fd9dcac09dd4a61b2ef19cd6aabb39392b9`.

- Consolidated native release tag grammar across Dart, Python, Bash, workflows,
  and documentation via a machine-readable fixture contract (`#404`).

## 0.8.21

- Aligned default WebGPU bridge assets to `v0.1.39` (immutable manifest
  `b355d01040604f6ae2c5c5fe5bb42b858101a96f03f67e4b27b32fe41ce3b2bf`),
  restoring Web and native llama.cpp upstream
  `v0.2.0@bb4caa7540188872173c44d161602d9271386413` parity with native
  anchor `llamadart-native@v0.2.0-1` while preserving Web
  `@litert-lm/core@0.15.0` packaging.

- Fixed native Qwen3-ASR transcription by applying the model chat template to
  audio turns, while preserving the validated raw-prompt Web bridge contract.
  Empty ASR output now fails explicitly instead of reporting an empty result.

- Fixed Qwen 2.5/3 LiteRT-LM `ToolChoice.required` requests silently running
  without their required-call grammar and finishing with no call. They now fail
  with an actionable `LlamaUnsupportedException` before generation when the
  backend cannot enforce the declared tool schema; Gemma 4 compatibility and
  `auto`/`none` tool routing are unchanged.

- Fixed Gemma 4 thinking-budget output so split channel controls and tool-call
  envelopes stay out of visible assistant content while preserving ordinary
  whitespace. The chat example now also validates custom tool declarations,
  executes declared host handlers exactly once, appends tool results, and
  performs a bounded continuation for both llama.cpp and LiteRT-LM backends.

- Patched the website's vulnerable `nanoid` and `uuid` dependency paths. Until
  Docusaurus replaces its unpatched image parser, automatic local Markdown
  images are rejected; website contributors should use static pathname URLs.

- Fixed `llamadart_native_runtimes` values `none`, `off`, and the string
  `false` selecting every runtime family instead of none;
  the build hook fails with its `No native runtimes selected` error again, as
  it did before 0.8.0. A YAML boolean `false` clears the selection too. Unset,
  empty, and all-unrecognised config still select every family.

- The published package no longer ships the `doc/` directory; that contributor
  and maintainer documentation is maintained on GitHub, and the packaged files
  that link to it now use absolute URLs.

- Fixed unanchored `docs/` and `website/` publish-exclusions that matched those
  directory names at any depth and dropped `tool/docs/` plus the
  `llamadart_server` example's OpenAPI spec and Swagger UI sources from the
  package, leaving the published example unable to analyze. Both patterns are
  now root-anchored.

- Narrowed the `dinja` dependency constraint to `>=1.0.0 <1.1.0` so chat
  template capability detection cannot silently resolve against an unverified
  Jinja parser minor. A 1.0.x patch can still reorganise the private sources
  the analyzer imports; a new coupling test turns that into a named failure.

- Fixed Command R7B, Hermes, and Hunyuan V3 tool grammars so distinct tool or
  parameter names cannot collide after conversion to internal GBNF rule names.

- Fixed DeepSeek V3.2 DSML tool calls using their upstream
  `<｜DSML｜function_calls>` envelope while preserving DeepSeek V4's distinct
  `<｜DSML｜tool_calls>` grammar and parser behavior.

- Fixed partial GLM 4.5, Poolside Laguna, and Muse Glimmer tool envelopes
  leaking into streamed assistant content, while preserving completed calls,
  malformed final output, and ordinary text surrounding Muse recipient
  channels.

- Fixed schema-constrained tool calls for Kimi K3, MiniMax M1/M3, DeepSeek
  V3.2/V4, and Muse Glimmer, including exact escaped names, required fields,
  declared value types, matching MiniMax M3 element tags, zero-argument calls,
  and strings containing delimiter characters. Required-tool mode now accepts
  each format's reasoning/content prefix while still requiring a call.
  MiniMax M3, DeepSeek DSML, Muse Glimmer, Poolside Laguna, and GLM 4.5 now
  reconstruct argument values from the declared tool schema instead of
  guessing from text. Added `ToolParam.nullType` for null-only JSON Schema
  properties.

- Made native video-input capability truthful without claiming end-to-end
  support. Explicit video content now receives a typed actionable rejection,
  public capability remains false, and the native probe calls
  `mtmd_helper_support_video` because helper symbols are exported even when
  video is compiled out. Full support still requires companion FFmpeg/ffprobe
  packaging and Dart frame-lifecycle wiring.

- Native release synchronization and build-hook overrides now accept stable
  `vMAJOR.MINOR.PATCH` artifacts and ordered `vMAJOR.MINOR.PATCH-N` wrapper
  rebuilds plus nightly `bNNNN-N` rebuilds, while preserving historical
  `bNNNN` and `bNNNN-llamadart.N` artifacts. Leading-zero nightly tags,
  rollback, wrapper/nightly `latest` results, missing bundles, and
  manifest/checksum/version skew fail closed; the default native pin is
  unchanged.

- Fixed Web/native backend API parity. `WebAutoBackend` now forwards grammar
  constraint support from its active runtime, so strict structured output fails
  early with an actionable error on unsupported Web backends, and the Web-safe
  `LiteRtLmRuntimeClient` stub now exposes the native client's thinking-tag
  configuration method.

- A failed llama.cpp model load now reports the startup diagnostics collected
  during native library discovery, so a missing or unloadable runtime library
  explains itself instead of surfacing as a bare load failure. Platforms that
  record no diagnostics keep their previous message unchanged.

- llama.cpp worker errors now keep their type. Every backend method routes an
  `ErrorResponse` through the file's own error mapper instead of rebuilding a
  bare `Exception`, `tokenize` and `detokenize` no longer discard the worker's
  error entirely, and a core `UnsupportedError` raised for an unavailable native
  capability is classified rather than flattened. State-file failures now throw
  `LlamaStateException`.

- Fixed multimodal media placeholders being normalized inconsistently. `<img>`,
  `<|img|>`, `<start_of_image>` and indexed markers such as `<|image_1|>` are now
  rewritten to the mtmd marker on every path, rather than depending on which
  layer rendered the prompt. MiniMax-M2 and MiniCPM-5 also now detect a
  forced-open thinking block using the same rule as every other handler.

- aLoRA adapters are now rejected with `LlamaUnsupportedException` instead of
  being applied like ordinary LoRA adapters. An aLoRA adapter must activate only
  after its invocation tokens appear in the prompt, so applying it from the
  start of generation silently changed output. Missing metadata-inspection
  symbols in custom native runtimes also fail closed with the same typed error,
  and rejected adapters are released when the cleanup ABI is available. LoRA
  errors from the worker keep their typed exception instead of arriving as a
  bare `Exception`, and a failed adapter load now throws
  `LlamaModelException`.

- Deprecated `LiteRtLmRuntimeClient.conversationTokenCount()` and
  `replaceConversationWithClone()`. Both are unused and are scheduled for
  removal in the next major release; open an issue if you depend on either.

- `NativeLlamaBackend.modelLoadFromUrl` now throws `LlamaUnsupportedException`
  instead of `UnimplementedError`, bringing it into the `LlamaException`
  hierarchy. It is the same exception type `LlamaEngine.loadModelFromUrl`
  already throws for this condition; each keeps its own message.

- Updated the default native llama.cpp runtime to the immutable
  `leehack/llamadart-native@v0.2.0-1` release (llama.cpp `v0.2.0`), adding LFM2
  DSpark support plus current upstream correctness and backend performance
  fixes. Matching Dart FFI bindings, including the new multimodal
  projector-device field, and the Apple SwiftPM artifact checksum were
  refreshed. Linux `libmtmd.so.0` now loads without the old
  `libmtmd.so.SOVERSION` compatibility alias.

- Removed the abandoned Dart-side MTP/n-gram speculative-decoding scaffolding
  from the llama.cpp backend; speculative decoding behavior is unchanged.

- Bumped `llamadart_llama_cpp_flutter` to `0.0.16` so the `v0.2.0-1` Apple
  SwiftPM pin actually publishes; `0.0.14` was already on pub.dev, so release
  automation skipped it and Apple builds would have kept the `b10514` runtime.

- Corrected the WebGPU bridge docs, which claimed the pinned `v0.1.37` bridge
  assets match the default native llama.cpp runtime. They embed `b10514` and now
  trail the native `v0.2.0-1` pin.

- Chat-template capability detection now logs a debug message naming the
  probe (`string-content`, `typed-content`, `system-role`, `tools`) when its
  render throws, so a template that fails to render is distinguishable from
  one that genuinely lacks the capability.

## 0.8.20

- Updated WebGPU bridge assets to `v0.1.37` (llama.cpp `b10514`), restoring
  native/Web parity and provisioning an explicit 1 MiB Wasm stack for wasm32
  and memory64 so Qwen3-ASR memory64 context construction does not overflow the
  default stack.

- Improved Web microphone transcription with browser-capture warmup trimming
  and early short, silent, and unsupported PCM WAV diagnostics.

- Added logical and micro-batch controls for llama.cpp/WebGPU models to the
  Flutter chat example.

- Made Android Auto probe the packaged Vulkan device before choosing GPU
  offload, avoiding unnecessary CPU fallback on capable models.

- Updated the native LiteRT-LM runtime to `v0.16.0-native.2`; the Apple companion
  packages the iOS Gemma constraint provider and Metal plugins required by the
  published runtime.

- Added an experimental `SpeechToTextEngine.liteRtLm` path with bounded mono
  16 kHz float PCM, partial/final transcript events, worker-isolated CPU
  inference, backpressure, and cancellation.

- Added experimental live English dictation to native Flutter chat models,
  including generic audio-chat models, using selectable checksum-pinned
  Moonshine Tiny (recommended, 54 MB) and Parakeet TDT 0.6B (optional, 615 MB)
  LiteRT sidecars. Live dictation is CPU-only, English-only, capped at five
  minutes, and unavailable on Linux and Web. Audio-chat models retain **Ask
  with voice** as a separate action.

- Improved Flutter chat example model downloads with bounded retries for
  transient network failures, safe resume after truncated responses, and a
  distinct integrity-verification state after transfer reaches 100%. The
  redesigned onboarding and Lab surfaces preserve model-card position while
  downloads reorder and keep streaming responses from pulling users away from
  chat history.

- Added experimental typed Qwen3-TTS synthesis on native llama.cpp and WebGPU
  with capability discovery, cancellation, speaker references, complete
  PCM/WAV output, and synthesis/playback/export controls in the Flutter chat
  example. Apple apps discover the TTS ABI in the embedded llama framework;
  current LiteRT-LM artifacts remain unsupported.

- Updated the native llama.cpp runtime to `b10514`, adding BailingMoE3,
  GraniteSWA/GraniteMoeSWA, speculators-format DSpark checkpoints, and current
  upstream multimodal/backend fixes and performance improvements. Matching Dart
  FFI bindings and the Apple SwiftPM artifact checksum were refreshed.

- Added an experimental typed Qwen3-ASR whole-file transcription workflow, a
  checksum-pinned Qwen3-ASR 0.6B native-and-Web chat-app preset, and file and
  microphone transcription. Web accepts WAV bytes only; native LiteRT-LM live
  dictation remains a separate implementation.

- Added **Ask with voice** to the native Flutter chat example for Gemma 4 E2B
  LiteRT-LM and audio-capable GGUF models. It sends a short microphone recording
  through normal multimodal chat so the model answers the spoken request, while
  remaining separate from typed speech-to-text.

## 0.8.19

- Updated the native llama.cpp runtime to `b10333` and WebGPU bridge assets to
  `v0.1.27` (llama.cpp `b10333`), including matching Dart FFI bindings and
  refreshed Apple SwiftPM artifacts.

- Fixed corrupt Qwen3.5 output on Android Vulkan by preserving the KQV
  offload required for correct hybrid model inference while retaining the
  remaining conservative Android context settings.

## 0.8.18

- Updated native llama.cpp to `b10276`, including Qwen3-TTS model-loading
  primitives, explicit bundled-MTP loading, automatic model-specific token
  suppression, recent model/runtime improvements, the matching load-mode and
  penalty-sampler ABI migrations, and refreshed Apple artifacts. Speech
  generation is not yet exposed through the public Dart API.

- Updated the default LiteRT-LM runtimes to native `v0.15.0-native.3` and Web
  `@litert-lm/core@0.15.0`. The native artifact includes a corrected v0.15
  streaming callback bridge and an Android Dawn rollback for Mali-G715 GPU
  device loss; incompatible callback runtimes now fail safely before
  generation, and concrete macOS app, framework, and cache libraries take
  precedence over process-linked assets.

- Updated WebGPU bridge assets to `v0.1.26` (llama.cpp `b10276`), refreshing
  both WebAssembly runtimes while preserving the existing bridge API.

- Disabled automatic WebGPU fetch-backed model loading by default. Streamed
  loading remains the safe default, with explicit opt-in available for
  controlled range-capable deployments.

## 0.8.17

- Updated the default llama.cpp native runtime to `b10075` with matching
  bindings and Apple artifacts.
- Added Tencent Hunyuan V3 chat-template, reasoning, and tool-call support.
- Fixed Gemma 4 LiteRT-LM text generation in the Web chat app after model
  loading completed successfully.
- Restored GGUF loading in deployed Web chat apps by packaging the pinned
  WebGPU runtime assets with Flutter Web builds.

## 0.8.16

- Updated the default llama.cpp native runtime to `b9982`, including safer
  multimodal UTF-8 prompt handling and refreshed Dart/SwiftPM bindings.
- Improved llama.cpp batching defaults and `ChatSession` context management for
  more predictable generation under constrained contexts.
- Added llama.cpp presence-penalty sampling and thinking-budget controls;
  unsupported WebGPU and LiteRT-LM paths now fail explicitly.
- Reworked the runnable TUI coding agent with a focused Pi-style workflow,
  Unsloth Qwen3.6 defaults, shared model-source loading, and clearer output.
- Improved the OpenAI-compatible server with standard client-managed tool-call
  transcripts, named `tool_choice`, configurable thinking behavior, and shared
  model-source loading.

## 0.8.15

- Added clipboard media attachments to the runnable chat app, including
  `Cmd/Ctrl+V` screenshots and copied image/audio files on desktop and web plus
  a **Paste attachment** action on mobile, while preserving normal text paste.
- Added an app-owned FIFO model-download queue to the runnable chat app, with
  per-card queue positions/cancellation and a responsive shell progress pill
  that remains visible after settings closes.
- Replaced the runnable chat app's broad built-in catalog with a focused
  Unsloth-first set. Added cross-platform Gemma 4 E4B plus native-desktop Gemma
  4 12B/26B-A4B/31B and Qwen3.6 35B-A3B presets. Added downloaded-first ordering,
  name/capability search, Mobile & Web/Desktop filters, clearer incompatible-model
  states, quieter model cards, and independent remove-from-library and
  downloaded-file actions for custom entries.
- Enabled Gemma 4 audio attachments in the runnable chat app for the current
  native GGUF projector and LiteRT-LM bundle while keeping LiteRT-LM Web
  text-only. Persisted capability settings now distinguish direct model media
  input from external `mmproj` input.
- Made native GGUF Auto tuning model- and memory-aware. **Max** now requests
  full llama.cpp offload, while Auto preserves the requested context when the
  model fits and reduces context before selecting partial offload under memory
  pressure. Auto intent persists separately from resolved values so each model
  load, including after an app restart, recalculates current device headroom.
- Fixed native LiteRT-LM response limits being misapplied as forced benchmark
  decode counts. Short answers now stream without waiting for the full token
  allowance, and the chat app flushes the first LiteRT-LM token immediately.
- Updated the default native LiteRT-LM runtime to `v0.14.0-native.2`, fixing
  Android GPU plugin symbol resolution and using the checksum-pinned official
  Apple XCFrameworks for Metal-capable iOS and macOS packaging.

## 0.8.14

- Improved the runnable chat app's web model-cache and loading experience by
  reusing cached GGUF and LiteRT-LM bundles, preserving browser model caches
  during app cache cleanup, allowing text-only downloads without a multimodal
  projector, and polishing download/load progress states.

- Updated the chat app's web runtimes to pinned WebGPU bridge assets `v0.1.18`
  (llama.cpp `b9915`) and `@litert-lm/core@0.14.0` for reproducible hosted and
  local inference.

- Updated the default native llama.cpp runtime to
  `leehack/llamadart-native@b9935`, regenerated matching Dart FFI bindings,
  refreshed the Apple SwiftPM companion checksum, and aligned current runtime
  documentation.

## 0.8.13

- Fixed load lifecycle guards so repeated model loads preserve the active
  model state, URL load unsupported-runtime diagnostics stay typed, and unload
  cancels active generation before freeing llama.cpp handles.

- Tightened LiteRT-LM runtime validation and local smoke coverage by requiring
  complete macOS arm64 runtime caches, adding the missing iOS-compatible
  SwiftPM Gemma provider target, and keeping Flutter macOS LiteRT-LM
  companion-package builds on hook-managed native assets while the current
  SwiftPM artifact set is incomplete.

- Reworked the README into a shorter entry point, fixed stale docs/examples
  found during the documentation review, and aligned release, Android smoke,
  WebGPU mem64, native sync, and capability-support wording with the current
  workflows and runtime behavior. WebGPU runtime LoRA calls now throw an
  unsupported-operation error instead of reporting no-op success.

- Fixed llama.cpp n-gram speculative configuration mapping so
  `draftTokenMax` no longer implicitly overrides upstream `ngramSizeM`, and
  documented upstream comparison commands plus measured n-gram benchmark
  results.

- Added llama.cpp upstream speculative decoding parity through
  `SpeculativeDecodingConfig` constructors for draft-simple, EAGLE3, MTP,
  DFlash, ngram-simple, ngram-map-k, ngram-map-k4v, ngram-mod, ngram-cache,
  and mixed n-gram plus one draft-model strategy, including generic native
  wrapper bindings, docs, and local benchmark matrix coverage. The benchmark
  tooling can generate a llama.cpp-compatible static n-gram cache file for
  `ngram-cache` E2E validation. Speculative benchmark prompts now render with
  configured or loaded GGUF chat templates before the generic fallback instead
  of silently falling back to a hard-coded Gemma prompt.

- Documented compatible DFlash GGUF metadata, a known-good public target/draft
  model pair, and troubleshooting guidance for incompatible `dflash-draft` or
  missing `dflash.target_layers` artifacts.

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9873-llamadart.2`, keeping the `b9873`
  llama.cpp ABI/bindings while picking up wrapper fixes for native release
  provenance and backend-selected speculative sampler acceptance. Refreshed
  the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum and aligned current
  README/website native override docs.

- Hardened LiteRT-LM generation validation so llama.cpp-only speculative
  decoding knobs fail loudly instead of silently degrading to LiteRT-LM's
  boolean speculative toggle.

- Added `LlamaStructuredOutput` and `LlamaEngine.createStructuredJson(...)`
  helpers for strict JSON-object / JSON-schema generation with final-output
  validation and typed decoding.

- Added `LlamaEngine.loadMultimodalProjectorSource(...)` so GGUF multimodal
  projector files can use the same `ModelSource` resolver and native
  download/cache options as `loadModelSource(...)`.

- Improved the runnable chat app's Manage Models cache UX so model and mmproj
  asset cache states are shown separately, missing multimodal projectors can be
  re-cached without re-fetching already cached model assets, and runtime media
  capability mismatches surface as user-readable warnings. Custom signed or
  tokenized Hugging Face URLs now require confirmation before they are saved.

## 0.8.12

- Updated the default LiteRT-LM native runtime pin to
  `leehack/litert-lm-native@v0.14.0-native.1`, refreshed native-assets and
  Apple SwiftPM checksums, and exposed the new native LiteRT-LM 0.14
  load/generation controls.

- Hardened LiteRT-LM 0.14 runtime packaging across Linux, Windows, Android,
  Apple SwiftPM, and macOS local runtime-prep paths.

- Hardened release automation by adding CODEOWNERS coverage for
  publication-sensitive files and making pub.dev/GitHub Release propagation
  waits configurable with longer defaults.

- Added post-merge release automation so a merged release-prep PR can publish
  missing companion package versions, push the core release tag, wait for
  pub.dev, and confirm the GitHub Release without a separate manual tag step.

- Added `LlamaEngine.getModelFileType()` for llama.cpp/GGUF models.

- Refreshed llama.cpp `b9860` native runtime pins and template parity for
  DeepSeek V4 and MiniCPM5, including MiniCPM5 XML tool-call handling.

## 0.8.11

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9829`, refreshed the
  `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and aligned current
  README/website native override docs for the release.

## 0.8.10

- **Potentially breaking behavior change:** native model cache defaults changed
  without breaking Dart source compatibility. `DefaultModelDownloadManager()` now
  prefers the platform shared cache on desktop/server instead of the process temp
  directory, and mobile `DefaultModelDownloadManager.auto()` without an explicit
  app-private directory now uses a best-effort temporary/cache fallback instead
  of throwing. Apps or tests that asserted the old temp path or mobile exception
  should pass an explicit cache directory or follow `MIGRATION.md`.

- Added optional `androidAppPrivateCacheDirectory` and
  `iosAppPrivateCacheDirectory` arguments to
  `DefaultModelDownloadManager.auto(...)` so apps can provide platform-specific
  mobile cache roots without constructor-level `Platform.isAndroid` /
  `Platform.isIOS` branching.
- Updated the default native `DefaultModelDownloadManager()` constructor to use
  the per-user shared model cache on desktop/server platforms and the mobile
  app-private cache fallback, so plain `LlamaEngine(...)` remote source loads use
  a platform-appropriate default while preserving a temporary fallback for hosts
  that cannot expose a desktop cache environment.

## 0.8.9

- Broadened the `hooks` dependency constraint to support both the existing
  build-hooks package family and the latest stable release, restoring the
  pub.dev dependency freshness score without breaking downstream packages that
  still resolve `hooks` 1.x.

- Made web-safe backend stubs the default conditional import/export targets,
  preserving native `dart:io` selection while avoiding false WASM compatibility
  deductions in pub.dev analysis.

## 0.8.8

- Added a CI release-doc version consistency check so current README/website
  install snippets and companion package READMEs stay aligned with package
  `pubspec.yaml` versions, and documented that companion/core package publishing
  happens only after release-prep merge with explicit maintainer approval for
  each tag.

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9803`, regenerated matching Dart FFI bindings,
  refreshed the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and
  aligned current README/website native override docs.

- Added `DefaultModelDownloadManager.auto(...)` plus explicit model cache root
  constructors for shared desktop caches, app-private mobile caches,
  user-selected model libraries, and App Group containers. Implicit shared cache
  resolution now fails loudly on mobile and web where the OS cannot provide a
  hidden cross-developer model folder.

## 0.8.7

- Fixed multimodal chat-template rendering so templates that force-open
  reasoning, such as Qwen3.5 VLM prompts ending with `<think>`, preserve
  `enable_thinking` and stream generated reasoning through `delta.thinking`
  instead of `delta.content`.

## 0.8.6

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9776`, regenerated matching Dart FFI bindings,
  refreshed the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and
  aligned README/website native override docs.

## 0.8.5

- Fixed the split-library mtmd fallback ABI for image and byte-buffer
  multimodal inputs so Windows `mtmd.dll` and other split mtmd native bundles
  use the same bitmap helper signature as the generated native binding path.
  This avoids corrupting the first mtmd bitmap-helper call for Gemma 4/MMProj
  style multimodal loads and adds native symbol regression coverage for the
  fallback ABI.

## 0.8.4

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9744`, regenerated matching Dart FFI bindings,
  refreshed the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and
  aligned current README/website native override docs.
- Expanded llama.cpp chat-template parity coverage for current upstream
  fixtures, including Cohere2 MoE, LFM2.5 tool-call, and Granite 4.1 templates.
  LFM2.5 prompts that use plain `List of tools: [...]` now route through the
  LFM2 handler, and `ToolChoice.required` uses grammar-constrained LFM2
  tool-call generation.
- Fixed streaming tool-call parsing so partial North/Cohere bare action arrays
  are not emitted as content before the complete tool call is parsed, and
  expanded the local GGUF feature smoke coverage for thinking, tool-call, and
  optional multimodal turns.

## 0.8.3

- Fixed Windows CUDA backend discovery when the native asset bundle directory is
  not on the app `PATH`. Apps using the CUDA llama.cpp backend can now resolve
  bundled CUDA redistributables beside `ggml-cuda.dll` without manually adding
  `.dart_tool/lib` or the native bundle path to `PATH`.

## 0.8.2

- Updated the default llama.cpp native runtime pin to
  `leehack/llamadart-native@b9694`, regenerated matching Dart FFI bindings,
  refreshed the `llamadart_llama_cpp_flutter` Apple SwiftPM checksum, and
  updated the default WebGPU bridge asset pin to
  `leehack/llama-web-bridge-assets@v0.1.17` (llama.cpp `b9699`). The WebGPU
  backend now caps unset large-model browser batches so Gemma 4 mem64 loads do
  not fall back to context-sized compute buffers.
- Added `BackendGpuEnumeration.listGpuDevices({probeBackends})` and
  `LlamaEngine.listGpuDevices` so apps can enumerate GPU-class devices and
  select llama.cpp offload targets by backend-specific `mainGpu` index.
- Added Cohere2 MoE / North Code chat-template detection and parsing so
  `<|START_TEXT|>` responses and `<|START_ACTION|>` tool-call arrays are
  handled separately from older Command-R templates.

## 0.8.1

- Fixed docs references that still pointed at
  `llamadart_litert_lm_flutter` `0.0.1` and
  the pre-`native.1` LiteRT-LM release after the 0.8.0 native pin sync moved
  LiteRT-LM Apple/runtime artifacts to `v0.13.1-native.1`.
- Routed native `.litertlm` image/audio chat parts through LiteRT-LM
  Conversation message JSON so bundles with native media processors can accept
  `LlamaImageContent` / `LlamaAudioContent` path and encoded-byte inputs without
  a separate `mmproj` projector.

## 0.8.0

- Split Flutter Apple SwiftPM runtime linking into companion packages:
  `llamadart_llama_cpp_flutter` for GGUF/llama.cpp and
  `llamadart_litert_lm_flutter` for `.litertlm`/LiteRT-LM. The core package
  remains a native-assets package without Flutter plugin metadata; the
  companion package sources live under `packages/` in this repository.
- Changed unset or empty `llamadart_native_runtimes` to mean all available
  runtime families. Flutter iOS/macOS companion packages decide Apple SPM
  runtimes when present; other builds continue to use
  `llamadart_native_runtimes`.
- Added opt-in native `.litertlm` `ModelParams` for activation data type,
  prefill chunk size, parallel file-section loading, and Android NPU LiteRT
  dispatch library directory, forwarding the pinned LiteRT-LM
  `v0.13.1-native.1`
  engine-settings C APIs while keeping defaults unchanged.
- Extended the LiteRT-LM engine smoke tool with matching environment variables
  and documented the support decision for each candidate runtime knob.
- Kept LiteRT-LM web rejecting these native-only settings explicitly.
- Added llama.cpp MTP benchmark diagnostics and local smoke/benchmark tools so
  baseline-vs-MTP runs can report decode timing, draft/accepted token counts,
  draft verification timing, and acceptance rate.
- Added `SpeculativeDecodingConfig.mtp(draftModelPath: ...)` for llama.cpp
  external draft-model MTP sessions.
- Removed the Android Vulkan MTP allow-list dart define and the model-name
  based Android Vulkan acceleration shortcut. Vulkan MTP now runs only when
  callers explicitly request Vulkan plus MTP in runtime parameters.

## 0.7.2

- Added explicit pub.dev platform metadata for Android, iOS, Linux, macOS, web,
  and Windows. This keeps the package listing aligned with the actual
  cross-platform runtime support even though Flutter plugin registration is
  only needed for Darwin app integration.

## 0.7.1

- Added Flutter iOS/macOS Swift Package Manager integration so Apple apps link
  pinned `leehack/llamadart-native` and `leehack/litert-lm-native`
  XCFramework artifacts through `darwin/llamadart/Package.swift`.
- Disabled the legacy hook-managed Apple bundle path for Flutter iOS/macOS
  builds, avoiding wrapper/framework `MinimumOSVersion` mismatches in App Store
  uploads.
- Raised the Flutter Apple runtime floors to iOS 16.4 and macOS 14.0 to match
  the published XCFramework artifacts.
- Kept Android native builds on both `llama_cpp` and `litert_lm` by default;
  iOS, macOS, Linux, and Windows now default to `llama_cpp` only. Non-Android
  `.litertlm` apps should opt in with `llamadart_native_runtimes`.
- Added native release pin automation for Apple SPM checksums, excluded local
  SwiftPM artifact caches from pub archives, and hardened main-branch CI against
  Hugging Face tiny-model download rate limits.
- Compatibility note: no Dart API breaking changes. Flutter Apple apps must
  target iOS 16.4/macOS 14.0 or newer.

## 0.7.0

- Added LiteRT-LM as a first-class backend for native `.litertlm` bundles and
  single-turn web-compatible `.litertlm` URLs, alongside the existing
  llama.cpp/GGUF path.
- Added `ModelParams.liteRtLmBackend` so callers can select LiteRT-LM CPU, GPU,
  or Android NPU execution where the pinned runtime supports it.
- Added native LiteRT-LM tokenization, detokenization, log-level control,
  runtime metrics, cached Hugging Face loading, and package hook overrides for
  testing compatible native runtime sources.
- Added `GenerationParams.speculativeDecoding` for native LiteRT-LM and wired
  the benchmark app so speculative runs are reflected in metrics.
- Fixed Gemma 4 `.litertlm` thinking and tool calling with canonical templates,
  thought-channel parsing, reasoning suppression, and a filename-keyed template
  registry for Gemma and Qwen LiteRT-LM bundles.
- Fixed iOS `.litertlm` loading by resolving embedded `LiteRtLm` and
  `StreamProxy` frameworks from the app bundle.
- Added WebGPU mem64 selection through `ModelParams.preferMemory64` and
  `ModelParams.modelBytesHint` so large GGUF models such as Gemma 4 E2B can
  choose the 64-bit bridge core.
- Fixed chat-app web downloads, LiteRT-LM web loading/generation, unsupported
  token-count refreshes, and misleading LiteRT-LM load progress.
- Hardened native and LiteRT-LM cancellation/disposal, multimodal cleanup,
  parser correctness, grammar generation, model download timeouts, and partial
  download resume behavior.
- Added Gemma 4 benchmark tooling, GGUF chat-feature smoke coverage, and the
  WebGPU Gemma 4 mem64 E2E scenario.
- Updated README and website docs for backend choice, capability limits,
  platform support, package-size controls, benchmark results, model templates,
  and pinned runtime artifacts.
- Compatibility note: no public API breaking changes for existing GGUF /
  llama.cpp callers. LiteRT-LM support is additive, with deprecated benchmark
  wrappers retained for compatibility; unsupported llama.cpp-only parameters are
  rejected for `.litertlm` loads instead of being silently ignored.

## 0.6.17

- Synced native hook pinning and regenerated bindings through
  `leehack/llamadart-native@b9371`, picking up llama.cpp `b9371`.
- Picked up the Apple mobile Metal stability fix that disables Metal residency
  sets on iOS/tvOS/visionOS native bundles, avoiding affected device
  context-creation failures such as `MTLLibraryErrorDomain Code=3`.
- Compatibility note: no public API breaking changes in `0.6.17`; existing
  `0.6.16` callers remain compatible.

## 0.6.16

- Fixed native `getVramInfo()` so llama.cpp GPU-class backend devices can
  report free/total VRAM when available, with Windows split-bundle registry
  fallback handling for backend-device symbols.
- Improved browser recovery for large remote WebGPU model/projector loads by
  retrying wasm32 model-staging aborts with the wasm64 core before surfacing
  memory-pressure failures.
- Improved the runnable chat app's web remote-model startup path so model assets
  are prefetched into browser cache when available, browser `CacheStorage`
  failures fall back to direct network loading, and credentialed/signed model
  URLs skip persistent browser cache storage.
- Improved the runnable chat app's mobile download behavior so lifecycle pauses
  no longer deliberately cancel active foreground downloads; the app now lets
  short screen-lock/background interruptions continue when the OS permits and
  still keeps explicit pause/dispose cancellation paths.
- Added in-app and docs guidance for mobile large-model downloads, including
  resumable partial files, foreground Dart lifecycle limits, and the need for
  opt-in native background download/model-store integrations for robust
  cross-app GGUF management.
- Compatibility note: no public API breaking changes in `0.6.16`; existing
  `0.6.15` callers remain compatible.

## 0.6.15

- Fixed GLM-OCR and other multimodal chat-template workarounds so image and
  audio content parts are preserved when tool-call normalization runs, system
  prompts are merged before leading media parts, and invalid tool-call
  serialization fails loudly instead of silently falling back to the wrong
  template shape.
- Added `tool/testing/run_local_e2e.dart` as a discovery and orchestration
  entry point for heavyweight local-only Dart E2E, Flutter device, and
  Web/Playwright smoke scenarios.
- Hardened the upstream llama.cpp chat/template E2E runner against current
  llama.cpp target renames, dynamic backend library lookup, and full
  `test-chat` server/mtmd build requirements.
- Documented that real-model/device/WebGPU scenarios remain skipped from
  default CI and should be opted into explicitly with `--list` and `--dry-run`
  first.
- Compatibility note: no public API breaking changes in `0.6.15`; existing
  `0.6.14` callers remain compatible. The chat-template changes fix
  multimodal serialization behavior for affected templates, and the local E2E
  runner is additive.

## 0.6.14

- Updated the default WebGPU bridge asset pin to
  `leehack/llama-web-bridge-assets@v0.1.16` (llama.cpp `b9165`), picking up
  the published JS bridge build, TypeScript declaration asset, and refreshed
  bridge docs.
- Added WebGPU readiness guidance covering browser capability checks,
  cross-origin isolation, bridge asset/version diagnostics, fallback behavior,
  model/configuration pressure, and the Flutter Web real-model smoke path.
- Added `ModelDownloadController`, a dependency-free helper that turns
  `ModelDownloadManager` cache/download work into app-facing lifecycle states
  for resolving, cache checks, downloads, verification, ready, failed,
  cancelled, and retry flows.
- Wired the runnable chat app example through a `ModelDownloadManager` adapter
  so its model-management UI demonstrates the controller while preserving the
  example's multi-asset and web-cache service behavior.
- Compatibility note: no public API breaking changes in `0.6.14`; the WebGPU
  bridge asset update and `ModelDownloadController` are additive, and existing
  `0.6.13` callers remain compatible.

## 0.6.13

- Added package-managed model source downloads and cache management:
  `ModelSource`, `ModelLoadOptions`, `ModelCachePolicy`, resolver targets,
  download/cache metadata, progress callbacks, cache inspection, removal,
  clearing, and age/size pruning.
- Added native/file-backed `DefaultModelDownloadManager` support for streaming
  HTTP downloads, `.part` files with atomic promotion, authenticated bearer and
  custom headers, cooperative cancellation, retry, HTTP Range resume, cache
  hit/refresh/cache-only/no-cache policies, SHA-256 verification, and persisted
  redacted metadata for signed URLs.
- Improved Hugging Face `hf://` ergonomics with `?revision=...` parsing for
  branch/ref names containing slashes, plus docs for private/gated bearer-token
  usage, separate `mmproj` assets, sharded-GGUF limitations, and redaction
  guarantees.
- Hardened download/cache correctness by serializing concurrent same-entry
  downloads, recovering missing or malformed cache metadata sidecars, treating
  mismatched byte-count/SHA-256 metadata as cache misses, and rejecting
  remote-only options for local `ModelSource.path(...)` inputs.
- Added `LlamaEngine.loadModelSource(...)` so local path sources keep using the
  existing native loader, remote HTTP(S)/Hugging Face sources download through
  the package-managed native cache before local loading, and URL-capable web
  backends keep using direct URL loading for simple unauthenticated requests.
- Added KV-cache state persistence APIs: `LlamaEngine.supportsStatePersistence`,
  `stateSaveFile(...)`, `stateLoadFile(...)`, backend support diagnostics, and
  WebGPU bridge forwarding for bridge assets `v0.1.15+`.
- Compatibility note: no public API breaking changes in `0.6.13`; existing
  `loadModel(...)` callers are unchanged.

## 0.6.12

- Synced default WebGPU bridge asset pinning to
  `leehack/llama-web-bridge-assets@v0.1.14` (llama.cpp `b9016`) to match the
  native runtime pin.
- Picked up bridge-side Qwen UTF-8 streaming stabilization and multimodal
  fallback narrowing while preserving control-token output for parser consumers.
- Picked up the bridge-side BERT embedding thread-pool sizing fix so automatic
  thread selection does not exceed the compiled WebAssembly pthread pool.
- Forwarded native-compatible `ModelParams` load tuning knobs through the
  WebGPU bridge path, including sequence slots, flash attention, KV cache type,
  RoPE overrides, split mode, and main GPU.
- Matched native batch defaults on WebGPU so unset `batchSize` and
  `microBatchSize` use `n_batch = n_ctx` and `n_ubatch = n_batch`, avoiding
  first-embedding aborts for BERT-class/non-causal encoder models while
  preserving model-specific Qwen3.5-0.8B WebGPU safety tuning.
- Filtered backend-owned runtime dependencies during native asset bundling so
  CUDA runtime DLLs and OpenBLAS runtime libraries are emitted only when their
  owning backend module is selected, while unknown runtime libraries stay
  bundled for forward compatibility.
- Compatibility note: no public API breaking changes in `0.6.12`.

## 0.6.11

- Synced native hook pinning and regenerated bindings through
  `leehack/llamadart-native@b8955`.
- Fixed Gemma 4 streaming so `<|channel>thought ... <channel|>` output is
  emitted as thinking deltas instead of content text, including when channel
  markers are split across streamed chunks.
- Tracked the chat app lockfile for stable generated Flutter plugin metadata in
  CI and release validation.
- Compatibility note: no public API breaking changes in `0.6.11`.

## 0.6.10

- Synced native hook pinning and regenerated bindings through
  `leehack/llamadart-native@b8638`.
- Hardened multimodal prompt overflow handling so native failures surface as
  Dart exceptions, and reduced staged chat-app image size to a `384px` max edge
  to lower multimodal context pressure.
- Added built-in Gemma 4 template detection/render/parse support, including
  thinking and tool-call handling.
- Added runtime projector capability gating so multimodal flows and the chat app
  respect actual `supportsVision` / `supportsAudio` results instead of
  model-family assumptions.
- Compatibility note: no public API breaking changes in `0.6.10`.

## 0.6.9

- Documented that iOS builds require a minimum deployment target of `16.4` or
  newer across the README, docs site, and example docs.
- Updated `example/chat_app` iOS Podfile and Runner project settings to use
  deployment target `16.4`.
- Honored `ggml_backend_score` during Android asset-based backend fallback so
  unsupported CPU variant libraries are skipped before initialization.
- Changed Android `auto` backend resolution to prefer CPU by default while
  keeping Vulkan available for explicit opt-in.
- Clarified that changing `hooks.user_defines` requires
  `flutter clean && flutter pub get` before rebuilding.
- Compatibility note: no public API breaking changes in `0.6.9`.

## 0.6.8

- Synced native hook pinning and regenerated bindings to
  `leehack/llamadart-native@b8480`.
- Refreshed generated low-level FFI bindings to match the synced upstream
  headers.
- Compatibility note: no public API breaking changes in `0.6.8`.

## 0.6.7

- Synced native hook pinning and regenerated bindings to
  `leehack/llamadart-native@b8373`.
- Hardened Linux bundle loading for packaged apps and improved versioned
  `libllamadart` dependency resolution.
- Fixed Hermes tool-call parsing when whitespace appears between `<tool_call>`
  and the JSON payload.
- Compatibility note: no public API breaking changes in `0.6.7`.

## 0.6.6

- Synced native hook pin to `leehack/llamadart-native@b8216`.
- Updated default web bridge asset pinning to
  `leehack/llama-web-bridge-assets@v0.1.10` (llama.cpp `b8216`).
- Switched bundled Qwen3.5 example presets to Unsloth `Q4_K_M` GGUFs.
- Added native perf diagnostics chips in the chat app (`p_eval`, `eval`,
  `sample`, `reuse`) and Android-specific Qwen tuning guidance.
- Restored a targeted Android Vulkan fast path for local Qwen3.5 `0.8B` / `2B`
  / `4B` models while keeping CPU as the recommended Android preset for
  `0.8B` / `2B`.
- Fixed local web chat app bridge/runtime handling for Qwen prompt streaming and
  multimodal fallback behavior.
- Compatibility note: no public API breaking changes in `0.6.6`.

## 0.6.5

- Added embedding APIs: `LlamaEngine.embed(...)` and
  `LlamaEngine.embedBatch(...)`.
- Added backend embedding capability interfaces for custom backend
  implementations.
- Added multi-sequence embedding batching support via
  `ModelParams.maxParallelSequences` (`n_seq_max`).
- Added native embedding benchmark tooling:
  `tool/testing/native_embedding_benchmark.dart` and
  `tool/testing/native_embedding_sweep.dart`.
- Added website docs for embeddings and updated basic-app docs with embedding
  examples.
- Added a Basic App SQLite vector retrieval example using
  `bin/llamadart_sqlite_vector_example.dart`.
- Updated default WebGPU bridge asset pinning to
  `leehack/llama-web-bridge-assets@v0.1.8`.
- Improved WebGPU runtime stability/tuning in chat app flows (backend switching,
  streaming smoothness, and multimodal regression gating).
- Added GPU-path multimodal image-size capping to reduce memory/runtime pressure
  on larger image inputs.
- Compatibility note: no public API breaking changes in `0.6.5`.

## 0.6.4

- Aligned multimodal projector offload with effective model-load settings,
  including CPU-only configurations.
- Added safer backend selection/discovery APIs and improved runtime backend
  status plus GPU-layer diagnostics accuracy.
- Improved web large-model handling with cache-prefetch download UX, bridge
  worker fallback paths, memory-pressure retries, and wasm64-core fallback
  wiring.
- Synced native hook tag to `b8157` and added Android arm64 CPU-profile and
  variant policy support with loader hardening.

## 0.6.3

- Synced native runtime to llama.cpp `b8138` and picked up Android arm64
  crash/compatibility hardening.
- Example app performance/UX polish and web model handling improvements.
- Added `example/tui_coding_agent`, a terminal coding agent example with
  default stable text-protocol tool mode.
- Added persisted settings log-level fallback handling with regression tests.

## 0.6.2

- Native inference performance improvements (request overhead, stream batching,
  and prompt-prefix reuse with parity-safe fallback).
- Added native benchmark and prompt-reuse parity tooling, plus CI parity
  coverage.

## 0.6.1

- Publishing compatibility fix for hook backend-config code paths.
- Continued parity hardening around template/parser behavior.

## 0.6.x line highlights

- Expanded llama.cpp template and parser parity.
- Stronger handling for tool payload fidelity.
- More deterministic behavior around template routing and fallback removal.

## 0.5.x line highlights

- Public API tightening and migration cleanup.
- Split Dart/native log controls.
- Example/runtime reliability improvements.

## Release usage guidance

- For upgrade planning, combine this page with
  [Upgrade Checklist](../migration/upgrade-checklist).
- For breaking changes, always validate against the exact release tag notes.
