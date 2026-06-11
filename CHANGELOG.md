# Changelog

All notable changes to NeoMind will be documented in this file.

The format is based on [Keep a Changelog](https://keepachangelog.com/en/1.0.0/),
and this project adheres to [Semantic Versioning](https://semver.org/spec/v2.0.0.html).

---

## [Unreleased]

### Dead Code Cleanup

Removed ~3000 lines of dead/superseded code across the agent crate. All removals verified: workspace builds clean, all tests pass.

**Removed subsystems:**

- **`agent/planner/`** (5 files, ~900 lines) — `KeywordPlanner`, `LLMPlanner`, `PlanningCoordinator` and their types. Designed for upfront multi-step plan generation before LLM tool-calling, but never wired into the execution pipeline. Superseded by the streaming tool-calling architecture (LLM picks tools at runtime) + Skills system (on-demand scenario guides). The associated `AgentEvent` variants (`ExecutionPlanCreated`, `PlanStepStarted`, `PlanStepCompleted`) were also removed from the enum, CLI handler, and API SSE handler — they were matched but never emitted.
- **`context/`** dead modules (5 files, ~2000 lines) — `business_context.rs`, `health.rs`, `meta_tools.rs`, `resource_resolver.rs`, `state_provider.rs`. These referenced old tool names (`list_devices`, `query_data`, `control_device`) and had zero production callers. `context/mod.rs` simplified from ~200 lines to ~25 (only `DeviceRegistry` and `ResourceIndex` remain).
- **`tools/event_integration.rs`** (~1030 lines) — `EventIntegratedToolRegistry` with zero references.

**Removed dead functions/fields:**

- `format_skill_matches()` from `skills/matcher.rs` — Skills are injected via the `skill` tool at runtime, not via prompt formatting. `match_skills()` retained (used by `/api/skills/match`).
- `AgentConfig.planning` field — serde-safe removal (unknown fields ignored on load).
- `AgentEvent::{ExecutionPlanCreated, PlanStepStarted, PlanStepCompleted}` variants + constructors.
- Dead semantic/smart wrapper methods in `agent/mod.rs` (6 methods).
- `llm.rs`: `context_manager` field, `set_context_manager()`, `build_business_context_section()`.
- `smart_conversation.rs`: unused `devices`/`rules` fields, `update_devices()`/`update_rules()`, `Rule` struct.
- `smart_followup.rs`: dead `refresh_devices()` method.
- **`agent/scheduler.rs`** (~320 lines, Round 11) — "Dependency-Aware Tool Scheduling (P2.1)" feature (`ToolExecutionPlan`, `ExecutionBatch`, `build_execution_plan`, `DependencyNode`, and 4 helper functions). Designed for parallel/sequential tool execution based on `ToolRelationships` metadata, but never wired into any execution path. The production executor uses `tool_loop.rs` (sequential) and `registry::execute_parallel` (parallel) directly. The module was declared `pub mod scheduler;` but had zero callers outside its own file/tests.
- **`smart_conversation::Device`** struct (Round 12) — 12-line struct with `Serialize`/`Deserialize` derives, commented "Shared between smart_conversation and smart_followup modules" but never used in either. `ConversationContext` uses its own `EntityReference` type for device tracking instead.
- **7 dead `Default` impls** (Round 12) — `ToolResultCache` (local, `agent/mod.rs`), `ToolNameMapper` (`tools/mapper.rs`), `DedupProcessor` (`memory/dedup.rs`), `ResourceIndex` (`context/resource_index.rs`), `AskUserTool`/`ConfirmActionTool`/`ClarifyIntentTool` (`tools/interaction.rs`). All constructors are only called via `::new()` or `::with_defaults()`, never via `::default()` or `Default::default()`.
- **Dead scheduler methods + error variants** (Round 13) — `AgentScheduler::get_tasks()`, `AgentScheduler::health_check()` (zero callers), `SchedulerError::SchedulerNotRunning`, `SchedulerError::SchedulerStale` (only used by `health_check`). Dead re-exports `ScheduledTask` and `SchedulerError` removed from `ai_agent/mod.rs` (nobody imports via the shortcut path).
- **`detect_ollama_capabilities()`** (Round 13) — public helper in `ollama.rs` with zero callers. The private `detect_model_capabilities()` it wraps is alive (4 call sites).
- **`register_builtin_backends()`** (Round 13) — in `backend_plugin.rs`, designed to populate the plugin registry during init but never called in production (only its own test called it). The `create_backend()` match arms handle backend creation directly.
- **`AgentExecutionResult`** struct (Round 14) — in `executor/mod.rs`, defined with 3 fields (`record`, `memory`, `success`) but never instantiated or returned by any function.
- **`ExtensionToolGenerator` + `ExtensionFilter`** (Round 14) — in `extension_tools.rs`, ~90-line struct/enum with `generate()`, `generate_definitions()`, `format_for_llm()` methods. Zero production callers (only tests). Superseded by `ExtensionToolExecutor` which takes a registry and is used by `ToolRegistry`.
- **`SkillRegistry::default()` impl** (Round 14) — all callers use `SkillRegistry::new()` or `SkillRegistry::load_all()`, never `::default()`.
- **3 dead `Default` impls in neomind-core** (Round 15) — `AggFunc` (`datasource/mod.rs`), `DataSourceCatalog` (`datasource/mod.rs`), `FrontendField` (`extension/package.rs`). All types are alive but `::default()` is never called — callers use `::new()` or construct explicitly.
- **`is_wasm_extension()`** (Round 15) — in `neomind-core/src/extension/mod.rs`, zero callers. WASM extension support was never implemented; `is_native_extension()` is alive (used by native loader).
- **6 dead `Default` impls across neomind-devices + neomind-agent** (Round 16) — `DeviceId` (`mdl.rs`), `DeviceRegistry` (`registry.rs`), `WebhookAdapterConfig` (`adapters/webhook.rs`), `MdlRegistry` (`mdl_format.rs`), `MqttAdapterConfig` (`adapters/mqtt.rs`), `ConversationContext` (`agent/conversation_context.rs`). All types are alive but `::default()` is never called — callers use `::new()` or construct explicitly.
- **`VectorStore::default()`** (Round 17) — in `neomind-storage/src/vector.rs`, zero callers. All callers use `VectorStore::new()`.
- **9 dead `Default` impls across rules + messages + cli-ops** (Round 18) — `GeneratorConfig` and `RuleHistoryStorage` and `CommandResultHistory` and `DependencyManager` and `UnifiedValueProvider` and `InMemoryValueProvider` (neomind-rules), `Message` and `ChannelRegistry` and `MessageManager` (neomind-messages), `ApiClient` (neomind-cli-ops). All types alive but `::default()` never called.
- **Dead LLM backend dynamic registration system** (Round 19) — Removed entire unused `BackendFactory` trait, `BackendRegistry` struct + impl + global registry singleton (`GLOBAL_REGISTRY`, `global_registry()`, `register_backend()`), `BackendRequirements` struct, and `DynamicLlmRuntime` struct + `LlmRuntime` impl from `neomind-core/src/llm/backend.rs`. These formed a complete but unused dynamic backend registration/factory system — the actual backend management uses the separate `LlmBackendInstanceManager`. Also removed dead `BackendCapabilities` convenience methods (`supports_all`, `supports_any`, `with_capability`, `with_streaming`, `with_multimodal`, `with_function_calling`, `with_max_context`), dead `BackendCapabilitiesBuilder::modality()` and `Default` impl. Cleaned up `DynamicLlmRuntime` re-exports from `llm/mod.rs` and `lib.rs`.
- **Dead `factories` module** (Round 19) — Deleted entire `neomind-agent/src/llm_backends/factories/mod.rs` (~400 lines): `OllamaFactory`, `CloudFactory`, `MockFactory` (all implementing the dead `BackendFactory` trait) and `MockRuntime`. None were instantiated outside their own tests.
- **Dead extension health monitoring + dead event factory methods** (Round 20) — Removed unused `ExtensionHealthInfo` struct, `ExtensionHealthStatus` enum + `as_str()` impl, and `get_health_info()` async method from `neomind-core/src/extension/isolated/process.rs` (~70 lines). These formed a health monitoring subsystem that was never wired into any API or consumer. Also removed dead `ProposedAction::new()`, `ProposedAction::create_rule()`, `ProposedAction::trigger_workflow()` factory methods and dead `MetricValue::string()`, `MetricValue::json()` factory methods from `neomind-core/src/event.rs`.
- **Dead event bus persistence + backpressure system** (Round 21) — Removed entire unused event persistence subsystem from `neomind-core/src/eventbus.rs`: `EventPersistence` trait, `PersistError` enum, `NoOpPersistence` struct + impl, and `test_no_op_persistence` test. Also removed dead `EventBusError` enum and `publish_with_backpressure` / `publish_with_backpressure_and_source` methods (never called — all callers use `publish` / `publish_sync` / `publish_with_source_sync`). Cleaned up re-exports from `lib.rs`.
- **Dead llm_backends config module + dead re-exports + dead factory method** (Round 22) — Deleted entire `neomind-agent/src/llm_backends/config.rs` (~306 lines): `LlmBackendConfig` enum, `LlmConfig` struct, `LlmRuntimeManager` struct, local `GenerationParams` type, `MAX_GENERATION_TOKENS` const — all had zero callers outside the file. Removed dead re-exports from `llm_backends/mod.rs`: `LlamaCppConfig`/`LlamaCppRuntime` (callers use full path), `BackendRegistry` (callers use `super::backend_plugin::BackendRegistry`), and the entire config re-export line. Removed dead `AgentEvent::intermediate_end()` factory method (variant constructed directly as `AgentEvent::IntermediateEnd`).
- `prompts/builder.rs`: deprecated `build_tool_calling_section()`, legacy `build_base_prompt()` wrapper.
- `toolkit/registry.rs`: dead `categories()` method.

**Critical bug fix (cache.rs):**

- `is_tool_cacheable()` now inspects shell command contents using a read-only action whitelist (`list`, `get`, `history`, etc.) instead of matching stale tool name aliases. Previously, mutation commands routed through `shell` (delete, control, send) were silently cached for 5 minutes.

**Renamed for clarity:**

- `format_aggregated_tool_result` → `format_cli_tool_result` (result_format.rs)
- Cleaned up "legacy"/"aggregated"/"virtual" terminology in mapper.rs comments and test names

### Dead Code Cleanup (Round 2)

Removed ~2500 lines of dead modules, functions, and legacy test files.

**Removed dead modules (zero production callers):**

- **`agent/formatter.rs`** (278 lines) — `format_tool_result` / `format_summary`. Production formatting uses `streaming/result_format.rs::format_tool_results` (plural).
- **`agent/cache.rs`** (311 lines) — A `ToolResultCache` that was never imported. The live caches are in `streaming/cache.rs` and `agent/mod.rs`.
- **`config/mod.rs`** (329 lines) — `StreamingConfig`, `get_default_config()`, `set_default_config()`. Defined but never called anywhere in the workspace.
- **`ai_agent/intent_parser.rs`** (294 lines) — `IntentParser` struct. The executor has its own `parse_intent` / `parse_intent_keywords` methods that don't use this type.
- **`memory_extraction.rs`** (~570 lines) — `MemoryExtractor`. Only referenced by `#[ignore]` integration tests. The production memory system uses `AgentMemory` (scheduled) and `MemorySnapshot` (chat).

**Removed legacy test files (all 100% `#[ignore]`, reference removed tool names):**

- `tests/test_multi_tool_inline.rs` — used `list_devices` / `list_rules`
- `tests/tool_calling_test.rs` (9 tests) — used `list_devices`
- `tests/tool_calling_evaluation.rs` — used `list_devices`, `query_data`, `device_discover`
- `tests/tool_calling_evaluation_real.rs` — used `device_discover`, `query_data`
- `tests/tool_chain_test.rs` — used `device_discover`, `get_device_data`
- `tests/memory_extraction_integration.rs` — tested removed `MemoryExtractor`
- `tests/memory_30rounds.rs` — tested removed `MemoryExtractor`

**Cleaned up dead re-exports in `lib.rs`:**

- `pub use tools::ToolNameMapper` — no external consumers
- `pub use ai_agent::IntentParser` — removed along with the module
- `pub use config::{get_default_config, set_default_config, StreamingConfig}` — removed along with the module
- `pub use memory_extraction::MemoryExtractor` — removed along with the module

### Dead Code Cleanup (Round 3)

Removed ~1540 lines of dead code from `semantic_mapper.rs`, `translation.rs`, and `agent/mod.rs`.

**Removed dead module:**

- **`translation.rs`** (1142 lines) — `MdlTranslator`, `DslTranslator`, `Language`, `DeviceDescription`, `RuleDescription`. Zero callers anywhere in the workspace.

**Removed dead SemanticToolMapper code (~400 lines):**

- 18 dead methods: `resolve_devices`, `register_rule(s)`, `resolve_rule`, `register_workflow(s)`, `resolve_workflow`, `register_device`, `get_rule_names_for_llm`, `get_workflow_names_for_llm`, `update_stats`, `get_stats`, `clear_caches`, `periodic_cache_cleanup`, `suggest_resolution`, `add_alias(es)`
- 4 dead types: `SemanticMapping`, `RuleMapping`, `WorkflowMapping`, `MappingStats`
- 3 dead struct fields: `rule_cache`, `workflow_cache`, `stats`
- **Key insight:** `rule_cache` and `workflow_cache` were never populated — all `register_*` methods had zero callers, so rule/workflow resolution always returned `None`. The caches and all dependent code were dead at runtime.
- `get_semantic_context()` simplified — removed rule/workflow context sections (always showed "暂无可用规则/工作流")
- `map_tool_parameters()` simplified — removed `resolve_rule` dead path and `update_stats` call

**Removed dead Agent methods (4):**

- `context_selector()`, `update_context_device_types()`, `update_context_rule_engine()`, `get_semantic_mapping_stats()` — zero callers

### Dead Code Cleanup (Round 4)

Removed ~770 lines of dead code from `context_selector.rs` and `smart_conversation.rs`.

**Removed dead module:**

- **`context_selector.rs`** (717 lines) — `IntentAnalyzer`, `ContextSelector`, `ContextBundle`, and all associated types. The entire module existed solely to produce a debug log: `analyze_intent()` was called via `tokio::join!` in the non-streaming `process_message` path, but `ContextBundle` was discarded (`_context_bundle`) and `IntentAnalysis` was only consumed by `tracing::debug!`. Removed the `context_selector` field from `Agent`, its initialization, the `analyze_intent()` method, all re-exports, and simplified the `tokio::join!` to a plain expression.

**Removed dead SmartConversationManager state:**

- `ConversationState` enum, `state` field, `state()` / `set_state()` methods — all had zero callers. The manager is now a unit struct (stateless interceptor for dangerous-operation detection and missing-info detection).

### Dead Code Cleanup (Round 5)

Removed ~76 lines of dead helpers from `prompts/builder.rs` and `conversation_context.rs`.

- 4 dead `PromptBuilder` methods: `build_system_prompt_with_time()`, `core_identity()`, `interaction_principles()`, `tool_strategy()` — superseded by the static `IDENTITY` / `PRINCIPLES` / `TOOL_STRATEGY` constants used by `build_system_prompt()`.
- Dead `CONVERSATION_CONTEXT_EN` constant and its re-export in `prompts/mod.rs` — only `CONVERSATION_CONTEXT_ZH` is consumed.
- Dead `ConversationContext::reset()` method — zero callers.
- 3 dead test functions that asserted on removed methods.

### Dead Code Cleanup (Round 5b)

Removed ~100 lines of dead methods, fields, and re-exports from `smart_followup.rs` and `agent/mod.rs`.

- 5 dead `SmartFollowUpManager` methods: `get_device_suggestions()`, `get_location_suggestions()`, `analyze_input_with_search()`, `clear_history()`, `record_asked()`.
- 2 dead struct fields: `asked_questions` (write-only, never read), `resource_index` (only readers were the removed methods above). `with_resource_index()` merged into `new()`.
- Dead `Default` impl (construction always uses `new()`).
- Trimmed 6 dead re-exports from `agent/mod.rs` (`FollowUpAnalysis`, `FollowUpItem`, `FollowUpPriority`, `FollowUpType`, `DetectedIntent`, `AvailableDevice`) — no code outside the module consumes them.

### Dead Code Cleanup (Round 6)

Removed ~250 lines of dead re-exports and dead types across 8 module files. All callers use full module paths (e.g., `memory::compressor::evict_to_limit`) rather than shortcut re-exports (e.g., `memory::evict_to_limit`); the shortcuts were dead.

**Deleted `memory/manager.rs` (186 lines):**
- `MemoryManager` was a dead abstraction wrapping `MarkdownMemoryStore`. Zero production callers — all code uses `MarkdownMemoryStore` directly. Removed after the `MemoryScheduler.manager` field (its last consumer) was cleaned up.

**Dead re-export trimming (37 re-exports removed):**

- `lib.rs` (8): `default_fallback_rules`, `process_fallback`, `AgentResponse`, `FallbackRule`, `SessionState`, `ToolCall`, `IntentCategory`, `IntentResult`
- `agent/mod.rs` (12): `NeoMindError` (pub use → private use), 3 conversation_context types, 3 semantic_mapper types, 4 streaming functions (shadowed or called via full path), 1 NeoMindError pub use
- `tools/mod.rs` (2): `get_mapper`, `ToolNameMapper`
- `toolkit/mod.rs` (5): `SharedToolRegistry`, `ToolResultList`, `ToolCallList`, `ExtensionFilter`, `ExtensionToolGenerator` + unused `Arc` import
- `memory/mod.rs` (12): `MemoryManager`, error types, compressor/dedup/extractor/security types
- `ai_agent/mod.rs` (2): `AgentExecutionResult`, `ExecutionContext`
- `skills/mod.rs` (3): `SkillMatch`, `SkillMetadata`, `SkillOrigin`
- `llm_backends/mod.rs` (6): `DynBackendPlugin`, `LlmBackendPlugin`, `register_builtin_backends`, `CloudFactory`, `MockFactory`, `OllamaFactory`
- `context/mod.rs` + `device_registry.rs` (2): `DeviceLocation` struct deleted (zero consumers), re-export removed

**Other dead code removed:**
- `MemoryScheduler.manager` field — stored but never read (also updated 3 tests + 1 production caller in `agent_state.rs`)

### Dead Code Cleanup (Round 7)

Removed ~200 lines of dead functions, dead builder methods, and a dead abstraction across 7 files. All removals verified: workspace builds clean, 435 agent tests + 40 extension-runner tests pass.

**Dead streaming functions removed (all callers use `_with_safeguards` variants):**
- `process_stream_events` (stream_core.rs, ~19 lines) — zero callers; Agent has its own method with same name
- `process_multimodal_stream_events` (stream_multimodal.rs, ~19 lines) — zero callers; Agent has its own method
- Cleaned up `streaming/mod.rs` re-exports (removed 2 dead re-exports)

**Dead StreamSafeguards builder methods (zero callers):**
- `fast_model()`, `reasoning_model()`, `with_interrupt()`, `new()` — all callers use `StreamSafeguards::default()` + `.with_interrupt_signal()`

**Dead functions in agent utility modules:**
- `tokenizer.rs`: `select_messages_within_token_limit` — superseded by `select_messages_with_importance` (zero callers)
- `tool_parser.rs`: `parse_tool_call_json` — zero callers
- `staged.rs`: `IntentClassifier::with_threshold` — all callers use `IntentClassifier::default()`

**Dead abstraction removed:**
- `fallback.rs`: `FallbackBuilder` struct + 4 methods + Default impl (~35 lines) — `process_fallback` constructs results directly; builder never used

**Dead methods on internal types:**
- `types.rs`: `LargeDataCache::{get, has, clear, entries}` — 4 methods with zero callers (only `store`, `resolve_reference`, `get_latest_image` are used)
- `types.rs`: `AgentInternalState::is_response_repetitive` — zero callers; made `hash_response` private (only used internally by `register_response`)
- `session.rs`: `SessionManager::validate_session` — zero callers (not used by `cleanup_invalid_sessions` which loads history directly)

**Extension-runner cleanup (pre-existing warnings fixed):**
- `resource_limits.rs`: moved platform-specific `libc` imports inside their `#[cfg]` blocks (fixed 2 macOS-only unused import warnings)
- `resource_limits.rs`: hoisted `hard_mb` computation out of cfg block (fixed field-never-read warning for `memory_limit_hard_mb`)
- `resource_limits.rs`: fixed 2 stale test assertions (`test_config_default` expected 2048 but Default sets 4096; `test_config_custom` set hard_mb=4096 but asserted 2048)

### Dead Code Cleanup (Round 8)

Removed ~120 lines of dead `LlmInterface` methods, `Agent` methods, and error helpers. All zero-caller removals verified: workspace builds clean, 434 tests pass.

**Dead `LlmInterface` methods removed (llm.rs):**
- `get_concurrent_limit()` — free function, zero callers
- `set_llm_from_box()` — broken stub that stored `None` (comment said "caller should use Arc directly")
- `switch_backend()` — zero callers
- `get_available_backends()` — zero callers
- `chat_without_tools()` — zero callers (use `chat()` or `chat_with_history()`)
- `chat_stream()` — zero callers (use `chat_stream_with_history()`)

**Dead `Agent` methods removed (agent/mod.rs):**
- `internal_state()` — zero callers (streaming code accesses the field directly)
- `is_llm_configured()` — zero callers (callers use `llm_interface().is_ready()`)
- `tool_definitions()` — zero callers
- `process_tool_result()` — zero callers (26-line stub that never called LLM)

**Dead error helpers removed (error.rs):**
- `from_memory_err()`, `from_tool_err()`, `from_device_err()` — zero callers
- `invalid_input()` — last caller (`parse_tool_call_json`) was removed in Round 7

### Dead Code Cleanup (Round 9)

Removed ~900 lines of dead public API methods, dead registry methods, dead dedup utilities, dead context modules, and dead skill index infrastructure across 12 files. All zero-caller removals verified: workspace builds clean, 469 tests pass.

**Dead `ToolNameMapper` methods removed (tools/mapper.rs):**
- `get_aliases()`, `has_alias()`, `has_simplified()` — zero callers
- `register_custom()`, `all_known_names()` — only test callers (runtime mapper is immutable behind `OnceLock`; custom registration was never used)

**Dead `ToolRegistry` methods removed (toolkit/registry.rs):**
- `definitions_json()` + `cached_definitions_json` field — zero callers (the cached `Vec<ToolDefinition>` via `definitions()` is the live path)
- `search()`, `search_with_category()` — zero callers

**Dead misc methods removed:**
- `ConfirmActionTool::requires_confirmation()` — only test caller (production uses `SmartConversationAnalysis.requires_confirmation` field)
- `Agent::available_tools()` — only test caller
- `ExtensionTool::command_descriptor()`, `ExtensionTool::extension_id()` — zero callers (field access used directly)
- `MemoryTool::session_id_handle()` — zero callers
- `available_backends()` (llm_backends/backends/mod.rs) + re-export — only test caller (the `neomind-storage` crate has its own unrelated `available_backends()`)

**Dead `DedupProcessor` code removed (memory/dedup.rs, ~100 lines + 10 tests):**
- `with_ngram_size()`, `similarity()`, `jaccard_similarity()` — zero production callers (production only uses `with_defaults()` + `find_similar()`)
- `dedup()`, `merge()`, `threshold()` — only test callers
- `DedupResult` struct + `has_duplicates()` — only used by dead `dedup()`
- Made `jaccard_similarity_with_ngram()` private (only called by `find_similar`)

**Dead memory modules deleted:**
- `memory/extractor.rs` (~255 lines) — `AgentExtractor`, `MemoryCandidate`, `MemoryAction`, `ExtractResult`, `parse_category()`. All types had zero production callers (only self-tests). The production memory system uses `AgentMemory` (scheduled) and `MemorySnapshot` (chat), not this LLM-based extractor.
- `memory/security.rs` (~185 lines) — `MemorySecurityScanner`, `SecurityScanResult`. Zero production callers (only self-tests). Memory injection/exfiltration scanning was never wired into the memory write path.

**Dead `context/device_registry.rs` deleted (~460 lines):**
- Entire module removed: `DeviceRegistry`, `DeviceAlias`, `DeviceCapability`, `SharedDeviceRegistry` type alias. All types had zero production callers (only self-tests). The production device system uses `neomind_devices::DeviceRegistry` (separate crate). `semantic_mapper.rs` uses `ResourceIndex`, not this module.

**Dead `ResourceIndex` methods + types removed (context/resource_index.rs):**
- `SearchQuery` builder methods (`new`, `with_resource_type`, `with_location`, `with_capability`, `with_min_score`, `with_limit`) — zero callers (only struct literal construction used internally)
- `SearchQuery` removed from `context/mod.rs` re-export (not used outside the module)
- `get()` — zero callers
- `list_channels()` — zero callers
- `stats()` + `ResourceIndexStats` struct — only test caller

**Dead `SkillRegistry` index infrastructure removed (skills/registry.rs):**
- `keyword_index` + `tool_action_index` fields + index-building code in `insert()` — built but never queried (the matching happens via `match_skills()` in `matcher.rs`, not registry lookups)
- `remove_indices()` method — only maintained dead indices
- `list_by_category()`, `find_by_keyword()`, `find_by_tool_action()` — zero/only-test callers

**Dead `Skill` method removed (skills/types.rs):**
- `estimated_tokens()` — zero callers

**Dead re-exports cleaned from mod.rs files:**
- `context/mod.rs`: removed 9 unused re-exports (`AccessType`, `AlertChannelResourceData`, `Capability`, `CapabilityType`, `DeviceResourceData`, `DeviceTypeResourceData`, `ResourceData`, `ResourceId`, `SearchResult`) + dead `SharedResourceIndex` type alias + unused `Arc`/`RwLock` imports
- `agent/mod.rs`: removed dead `SharedResourceIndex` type alias (duplicate, never used)
- `toolkit/mod.rs`: removed 10 dead re-exports (`NeoMindError`, `ToolCall`, `DynTool`, `Parameter`, `ExtensionTool`, `ExtensionToolExecutor`, `array_property`, `boolean_property`, `number_property`, `property`)
- `tools/mod.rs`: removed dead `map_tool_parameters` re-export (callers use full path `tools::mapper::map_tool_parameters`)
- `prompts/mod.rs` + `prompts/builder.rs`: removed dead `CONVERSATION_CONTEXT_ZH` constant + re-export (stale comment said "used by memory.rs" but zero actual references)
- `agent/streaming/mod.rs`: removed dead `build_context_window_with_config` re-export (callers use `super::context::` directly)

**Dead methods removed from `llm.rs`:**
- `LlmInterface::instance_manager()` — only test caller (field access used directly where needed)
- `LlmInterface::set_instance_manager()` — placeholder stub (`let _ = manager;`), zero callers
- `LlmInterface::max_concurrent()` — only test callers (`available_permits()` covers production needs)

**Dead methods removed from `session.rs`:**
- `SessionCleanupConfig::new()` — zero callers (`Default::default()` used everywhere)
- `SessionCleanupConfig::disabled()` — zero callers
- `SessionManager::with_config()` — zero callers (builder method never chained)
- `SessionManager::set_cleanup_config()` — zero callers
- `SessionManager::cleanup_config()` getter — zero callers

### Dead Code Cleanup (Round 10)

Removed ~220 lines of dead test-only APIs and never-populated device-aware followup infrastructure.

**`Agent::with_fallback_rules()` removed (agent/mod.rs):**
- Test-only builder method, zero production callers. The `fallback_rules` field and `process_fallback()` remain alive (6 production call sites in streaming code).
- Removed sole caller `test_custom_fallback_rules` test.
- Removed `MockGreetTool` struct + `impl Tool` (only invoked by the removed test).

**Dead `available_devices` infrastructure removed (agent/smart_followup.rs, ~180 lines):**
- `set_available_devices()` — pub method, only test caller. The `available_devices` field was never populated in production.
- `available_devices` field + initialization.
- `AvailableDevice` re-export (`pub use crate::smart_conversation::Device as AvailableDevice`).
- `has_location_info()` private method — sole caller was the removed "设备控制类" branch.
- `get_available_locations()` private method — sole callers were dead branches in `detect_missing_info_aware()`.
- Simplified `detect_missing_info_aware()`: removed `context` parameter (no longer needed), removed 2 dead branches that generated `MissingLocation` followups (the guard `!self.available_devices.is_empty()` was always false).
- Removed `create_manager_with_devices()` test helper.
- Removed 4 dead/vacuous tests: `test_context_aware_missing_info`, `test_missing_info_without_context`, `test_followup_priority_ordering` (vacuous after cleanup), `test_fallback_suggestion_with_context`.

## [0.8.11] - 2026-06-11

### Agent Module Architecture Refactor

Major decomposition of two oversized source files into focused, maintainable sub-modules. Pure structural refactoring — zero logic changes, all public APIs preserved via re-exports. 4 rounds of code review, 540/540 tests pass.

**`streaming.rs` (4,231 lines → 12 sub-modules):**

- `intent.rs` — "List-only dead end" detection (action verb matching, read-only tool detection, action hint extraction)
- `cache.rs` — `ToolResultCache` with TTL, size limits, and key normalization
- `thinking.rs` — Thinking content cleanup and repetition removal
- `tool_detect.rs` — JSON tool call detection in LLM response buffer
- `sanitize.rs` — Base64 stripping, data image URL replacement, UTF-8 safe truncation
- `dedup.rs` — Cross-round tool result deduplication with entity ID extraction
- `result_format.rs` — Tool result formatting for shell, device, agent, rule, extension outputs
- `context.rs` — Context window building with tiered compaction, token estimation, message priority
- `resolve.rs` — Cached argument resolution, tool name mapping, image auto-injection
- `tool_exec.rs` — Tool execution with retry and caching
- `stream_core.rs` — Main text-only streaming loop (ReAct pattern)
- `stream_multimodal.rs` — Multimodal (text + image) streaming loop

**`executor/mod.rs` (3,169 → 1,450 lines + 4 sub-modules):**

- `tool_loop.rs` — Multi-round tool execution loop with deduplication, duplicate round detection, and Phase 2 summary generation
- `tool_prompt.rs` — System prompt construction (resource sections, tool messages, knowledge injection)
- `tool_result.rs` — Tool result processing, Phase 2 summary via LLM, and final decision building
- `compact.rs` — Message compaction for context window management

### Testing

- **17 new boundary tests** covering cross-module interfaces:
  - `intent`: 4 tests (Chinese/English action verbs, read-only detection, action hints)
  - `cache`: 5 tests (key consistency, TTL expiration, insert/get, cacheability)
  - `dedup`: 4 tests (latest-keep, entity separation, JSON/non-JSON key generation)
  - `resolve`: 4 tests (passthrough, missing references, HTTP URL handling, tool name resolution)

### CLI Domain Tool Consolidation

Unified all CLI domain tools (device, agent, rule, message, transform, alert) to route through the `shell` tool, eliminating duplicate tool definitions in the registry and simplifying the LLM's tool surface.

- **Mapper routing** — `ToolNameMapper` now maps CLI domains (`device`, `agent`, `rule`, etc.) to `shell` instead of standalone tool names. `build_cli_command()` converts structured arguments into `neomind <domain> <action> --flag value` CLI commands
- **Registry fallback** — `ToolRegistry::execute()` and `execute_parallel()` detect CLI domain tool names and fall back to shell execution when the tool isn't directly registered
- **tool_exec integration** — `execute_with_retry_impl()` converts CLI domain calls to shell commands before execution, handling timeout inheritance correctly
- **Removed `format_for_llm`** — No longer needed; tool descriptions now come from the shell tool's embedded CLI reference

### Fixed

- **Re-export completeness** — Added missing `cleanup_thinking_content` and `format_tool_results` re-exports in `agent/mod.rs`
- **Focused+ tool guidance** — Updated to use `shell` commands (`neomind device history`, `neomind device control`) instead of removed `device(action=...)` pattern

## [0.8.10] - 2026-06-11

### Agent Native Tool Calling

Complete overhaul of the tool-call parsing pipeline — agent executor now uses native structured tool calls from the LLM API response directly, instead of parsing them from freeform text.

- **Native `tool_calls` field** — Added `LlmOutput.tool_calls: Option<Vec<Value>>` in `neomind-core::llm::backend`. All three backends (OpenAI, Ollama, llama.cpp) now populate this field with structured JSON from the API response, preserving tool call IDs
- **Priority-based parsing** — Tool loop uses native `tool_calls` first → text parsing fallback → thinking field fallback. Eliminates fragility of regex-based extraction for models that support native tool calling
- **`FinishReason::ToolCalls`** — New finish reason variant for tool-call stop conditions. OpenAI (`tool_calls`), Anthropic (`tool_use`), Ollama, and llama.cpp all map to this instead of `Stop`
- **Continuation mechanism** — When the LLM is still making tool calls at `max_rounds`, up to 10 additional rounds are allowed so the agent can finish its work instead of being cut off mid-task
- **Vision tool exclusion** — Vision tool is excluded from the tool list when the multimodal LLM already receives images inline, avoiding redundant image analysis

### Agent Data Collection

- **Device info block** — `build_resource_table()` now renders a separate `**Devices:**` section above the metrics table, showing device ID, name, and type for each bound device
- **Resource display names** — Resource table shows both `resource_id` and `name` when they differ (e.g. `device-001 (Temperature Sensor)`)
- **Image metric child-path skip** — Data collector skips child paths of already-collected image metrics (e.g. `values.image.image_base64` under `values.image`) to prevent duplicate image data
- **Event-triggered device metadata** — Event-triggered executions now include device metadata (ID, type, name, adapter) in the data context, so the LLM knows which device triggered the event
- **Image metric extraction guard** — If an event metric is recognized as an image but extraction fails (no URL, no base64), execution is skipped instead of producing an empty analysis

### AI Analyst

- **WS/API dedup** — Invoke response now uses execution ID for message dedup with WebSocket events, preventing duplicate AI messages when both WS and HTTP API return results
- **Streaming placeholder cleanup** — Properly cleans up streaming placeholders and polling intervals when invoke resolves or errors, including error/timeout paths
- **Agent name dedup** — Agent name now includes component ID prefix (`AI Analyst [a1b2c3d4]`) to prevent name collisions across multiple analyst instances
- **Device info filter** — History message loader skips `device_info` entries (device metadata, not sensor data) when building AI analyst context

### Device Data

- **JSON key trimming** — `UnifiedExtractor` now trims whitespace from JSON object keys before processing. Handles devices that send keys with leading/trailing spaces (e.g. `" values.image"`) which would break downstream metric lookups
- **Empty key skip** — JSON keys that are empty after trimming are skipped entirely

### Fixed

- **CI release uploads** — Added `contents: write` permission to GitHub Actions workflow for release asset uploads

## [0.8.9] - 2026-06-10

### Image History Performance Overhaul

Complete end-to-end optimization of the image telemetry data pipeline — from API response to rendered `<img>`. Cuts first meaningful paint from ~12s to ~1-2s for dashboards with camera image history widgets.

- **Two-phase loading** — ImageHistory now loads 3 latest images (1h range) within ~1-2s, then fetches full 200-image history in the background. User sees images immediately instead of waiting for the entire 6MB+ payload
- **Pre-normalized base64 pipeline** — Raw base64 from the database is converted to `data:image/...;base64,...` data URLs once at fetch time (fetch layer, WS events, store merge path), eliminating expensive per-render normalization (`isPureBase64` regex + `atob` + string copies on 50KB strings × 200 images)
- **Fast-path rendering** — `toImageHistoryItems()` detects pre-normalized data URLs via `startsWith()` (no regex/atob) and skips `normalizeImageUrl()` entirely — zero string copies per image
- **Fingerprint-based tracking** — Replaced full base64 URL storage in source tracking Sets/arrays with lightweight fingerprints (length + charCode + last 32 chars), reducing tracking memory from ~10MB to ~8KB
- **O(n) source comparison** — Replaced O(n²) `filter+includes` on 50KB strings with Set-based O(n) intersection using fingerprints
- **Removed cache busting** — Eliminated pointless `#timestamp` fragment appended to data/blob URLs (no effect on inline content, only created 50KB string copies)
- **mergeLiveData O(k) optimization** — Fetched data is already sorted by `sortTelemetryResults`; only live WS points need individual insertion — eliminates O(n²) array copies (was 20,100 intermediate arrays per merge)
- **Raw cache limiting** — Telemetry cache for image sources stores only the last 5 raw items instead of all 200, reducing in-memory cache from ~30-50MB to ~1.5MB
- **Phase reset on source change** — Fixed bug where switching image data source kept `phase='full'`, causing stale data to display while the new source loaded

### DataSource Pipeline Optimization

- **Single-pass source categorization** — Replaced 5 separate `useMemo` + `.filter()` calls in `useDataSource` with a single loop that extracts telemetry/polling/extension sources + device ID sets + WS flag in one pass
- **Stable setDataAdapter** — Eliminated 3 identical per-render closures (one per sub-hook) with a single `useCallback` adapter, reducing re-render cascade
- **Shared `getTs` utility** — Extracted timestamp accessor from `useExtensionSource` into `eventProcessors` shared module, deduplicating identical local functions
- **Backward scan for extension events** — Changed `findIndex` (forward scan) to backward loop in event dedup, which is cache-friendly and stops at first match
- **Extension cache key** — Reused `effectiveTimeWindow` computed during fetch instead of recomputing per-source in cache step
- **findDevice O(1) cache** — Module-level `Map` cache in `deviceUtils.ts` shared across all callers, replacing O(n) `.find()` scan; used by `deviceSlice` telemetry flush path

### AI Analyst Enhancement

- **Config panel** — Added settings dialog (gear button) with model selector, system prompt editor, and context window size control
- **Model selector** — Uses design-system `Select` component with Auto (default) option, vision capability indicator (Eye icon), and per-backend model grouping
- **Model name persistence** — Config now saves both `modelId` and `modelName` to survive page refresh
- **Streaming indicator** — Input bar shows streaming state during LLM response generation
- **Icon picker** — Replaced raw `lucide-react` barrel import with `dynamicIconMap` for tree-shaking in icon picker, component library, community registry, and dynamic registry
- **Barrel import cleanup** — Removed `import * as lucideReact` from 6 files (ComponentLibrarySidebar, InstallComponentDialog, VisualDashboard, componentLibraryUtils, CommunityRegistry, DynamicRegistry), replaced with individual imports or `dynamicIconMap`

### Backend

- **Image data extraction** — Added `image_base64` and `image_mime_type` field support in `data_collector.rs::extract_image_data`, covering more extension output formats
- **Qwen 3.7 multimodal** — Added `qwen3.7` to heuristic vision match for native multimodal detection
- **Agent error message** — LLM failure path now produces actionable conclusion ("check model availability and capabilities") instead of generic fallback
- **Agent API handlers** — Fixed agent CRUD and execution endpoints in `neomind-api`
- **Agent storage query** — Fixed agent list query in `neomind-storage`

### Agent Memory & Context

- **Agent focused-path simplification** — Removed ~1300 lines of dead code from `analyzer.rs` and `response_parser.rs` (dead `insight` field, 5 unused JSON parsing functions, `build_focused_system_prompt`, `build_available_commands_description`, etc.)
- **Tool result hard limit** — Consolidated duplicate `TOOL_RESULT_MAX_LEN` constants into single 128KB module-level limit
- **Knowledge inline injection** — `build_tool_system_prompt()` now receives pre-fetched knowledge file contents, eliminating per-execution tool-call overhead
- **Context compaction refinement** — Adjusted priority-based token compaction thresholds for 128K context models
- **Context-aware history** — `build_history_context()` updated with knowledge content parameter and improved data freshness display
- **Memory journal** — Relaxed action_taken truncation to 150 chars/action, improved learning guidance language
- **Streaming dedup cleanup** — Reduced `MAX_TOOL_ITERATIONS` from 100 to 30 (matches scheduled executor max_rounds)

### Fixed

- **Component config save** — Added loading spinner and disabled state to save buttons in `ComponentConfigDialog` (both desktop and mobile layouts), prevents double-submit
- **Duplicate toast on agent save** — Removed redundant toast from `AgentsPage`, now handled by `AgentEditorFullScreen`

### Frontend

- **Font loading** — Switched Google Fonts to async load (`media="print" onload`) to eliminate render-blocking, added italic 400/800 weights
- **Rules list** — Added `Created` and `Last Triggered` columns with execution count display
- **Transforms list** — Added `Created` and `Last Executed` columns, replaced Transform Code with description subtitle, mobile cards show last executed time
- **Agent editor** — Added Max Chain Depth slider control
- **ResponsiveTable** — Fixed row hover to use `bg-muted-30` for consistency with design tokens
- **MapDisplay** — Removed unused center point indicator
- **Device detail** — Minor UI fixes

## [0.8.8] - 2026-06-09

### Visual Quality & Brand Identity

- **Brand color system** — Added `--brand` CSS variable (NeoMind orange #E05727) with light/dark variants, registered in Tailwind config
- **Enhanced Aurora background** — Doubled aurora gradient opacity for more visible ambient lighting in both light and dark modes
- **Card hover lift effect** — ResponsiveTable mobile cards and DeviceList cards now lift with shadow on hover (`hover:shadow-md hover:-translate-y-0.5`)
- **Table row brand-tinted hover** — Desktop table rows highlight with subtle brand color on hover instead of plain gray
- **Unified loading states** — Replaced 11 raw `Loader2` spinners across page-level and dialog contexts with consistent `LoadingState` component
- **Extension marquee brand color** — Empty state marquee cards use brand color for icon backgrounds and hover borders
- **EmptyState consistency** — Unified icon container styling across `EmptyState` and `EmptyStateCompact`

### Fixed

- **AiAnalyst JSX structure** — Fixed unclosed div tag in initializing state render
- **AgentDetailPanel stale closure** — Used ref to avoid stale closure over agent ID in event handlers

---

## [0.8.7] - 2026-06-08

### Agent Memory & Context Engineering Overhaul

Complete rewrite of the agent memory system — replacing a complex hierarchical model (ShortTermMemory, LongTermMemory, TaskProfile, fingerprint-based dedup, LLM reflection) with a simple and effective ExecutionJournal + KnowledgeFileRef design.

### Added

- **ExecutionJournal** — FIFO ring buffer of `ExecutionRecord` (max 10 entries). Each execution logs outcome, actions taken, success status, and timestamp
- **KnowledgeFileRef** — Index entries for agent-scoped knowledge files created by the LLM via the `memory` tool. Replaces TaskProfile + Baselines
- **Agent-scoped knowledge files** — `custom:{name}` files now isolated per agent at `agents/{agent_id}/custom/{name}.md`
- **Rule creation metric discovery enforcement** — Three-layer defense to prevent LLM from creating rules with guessed device IDs or metric names
- **Smart tool result compaction** — `compact_messages()` now uses `smart_summarize_tool_result()` to preserve key data instead of blind truncation
- **Agent knowledge file initialization at creation** — `task-understanding.md` is created immediately when an agent is created
- **Knowledge file content API field** — `KnowledgeFileRefDto` now includes optional `content` field
- **Complex MetricValue in Extension transforms** — `TransformedMetric.value` upgraded from `f64` to `MetricValue` (Float/Integer/Boolean/String/Json)
- **Extension input/output mapping resolution** — Automatic dot-path extraction, URL fetch, base64 encoding for transform parameters
- **Dynamic output type detection** — Transform output registry detects MetricValue variant instead of hardcoding Float
- **Image metric click-to-view** — Map and CustomLayer metric popups detect image values and display thumbnails
- **`window.neomind` API** — `callExtension()`, `fetchDeviceValues()`, `createTransform()`, `updateTransform()`, `deleteTransform()`, `listTransforms()` for community components
- **Dashboard Advanced tab** — Component config dialog supports custom `AdvancedPanel` from community/extension bundles
- **Community component `config` prop** — `ComponentRenderer` passes full config object to community components
- **Dashboard SSE self-sync echo suppression** — Prevents stale server data from overwriting in-progress edits
- **Transform `input_raw` and `__imageData` variables** — JS transform context for vision workflows

### Frontend Visual Polish

- **Stagger fade-in-up animations** — List rows, card grids, and skeletons animate in with staggered delays
- **Chart entrance animations** — LineChart, BarChart, PieChart animate on first render with gradient fills
- **Shimmer skeleton effect** — Skeleton loading upgraded from pulse to shimmer sweep animation
- **Page-level fade-in transition** — Pages wrapped in `PageLayout` fade in smoothly on mount
- **Chat message entrance animation** — New chat messages animate in as they appear
- **Theme switch transition** — Theme toggle has color transition and icon rotation animation
- **Card hover effects** — Cards lift with shadow on hover
- **Component library sidebar** — Flat grid layout with post-install highlight animation

### Changed

- **Time context** — Reduced to single concise line
- **HistoryConfig mode-aware** — Focused mode uses `HistoryConfig::focused()`
- **Frontend Memory tab** — Knowledge Files cards + Execution Journal timeline
- **Extension default memory limit** — Raised from 2048MB to 4096MB for ML model workloads
- **Cross-platform library search path** — `LD_LIBRARY_PATH` / `DYLD_LIBRARY_PATH` / `PATH` for shared libraries
- **Extension IPC channel initialization** — Event channel created before stdin reader, preventing race conditions

### Removed

- **ShortTermMemory, LongTermMemory, MemorySummary, ImportantMemory, TaskProfile** — Deleted from `AgentMemory`
- **Complex memory write logic** — ~260 lines removed
- **Context fingerprint functions** — ~60 lines removed
- **System prompt editor** — Removed custom system prompt textarea from agent editor

### Fixed

- **Vision tool mis-invocation** — System prompt no longer tells LLM to "Use the vision tool" when images are already embedded. Changed to "(included in message)" label
- **Vision tool incomplete data URL handling** — `resolve_image()` correctly parses `image/jpeg;base64,...` without `data:` prefix
- **Agent base64 image cleaning** — URL-safe char conversion, whitespace stripping, padding fix, decode+re-encode validation
- **Gradient ID collisions** — LineChart and BarChart gradient fills use unique IDs per chart instance
- **O(n²) stagger index** — Reduced to O(1)
- **Extension memory limit** — RLIMIT_AS raised to 4GB to accommodate ONNX Runtime + rayon thread pools
- **Cargo.lock tracked** — Removed from .gitignore for reproducible CI builds
- **CI build fallback** — Platform-specific bundle type fallback (deb+rpm / app / nsis) when full build fails
- **Transform `extensions.invoke()` JS API** — Properly creates `extensions` object with `invoke` method
- **Extension health state display** — Distinct colors for Error/Warning/Stopped states
- **Extension crash recovery error reporting** — All failure paths write error status to storage
- **Extension list filter** — Added Stopped/Failed filter option
- **Device telemetry image normalization** — Normalized on initial fetch
- **Dashboard drag jump** — Freeze container width during drag/resize
- **Component `_raw` telemetry parsing** — Parses JSON string telemetry for flat key access
- **Component render error isolation** — Per-cell ErrorBoundary prevents cascade failures
- **Extension `hasDeviceBinding` metadata** — Correctly propagates through registries
- **Agent knowledge file auto-init on update** — Legacy agents get `task-understanding.md` on first update
- **Timeseries default timeRange** — Changed from 1h to 24h
- **Agent card status glow** — Removed excessive ring effects
- **Error messages for 400/422** — Shows actual server error message
- **Metric tag extraction** — Expanded exclusion list for timeline
- **Dynamic config multi-data-source** — Respects `max_data_sources` from widget manifest
- **IPC event channel error logging** — Prevents silent message drops
- **NE101 ROI canvas** — Fixed React error #310 (conditional hook), image from device store, canvas layout fix

### Backward Compatibility

- All new `AgentMemory` fields use `#[serde(default)]` — old redb data deserializes gracefully
- No data migration required

---

## [v0.8.5] - 2026-06-03

### Added

- **MQTT broker TLS certificate generation** — Self-signed certificate generation with proper X.509 extensions (Key Usage, Extended Key Usage, Subject Alternative Names including system hostname). 1-hour clock skew tolerance for date validation. Certificate paths respect `NEOMIND_DATA_DIR` environment variable
- **MQTT broker restart API** — `PUT /api/mqtt/broker-config` now triggers automatic broker restart when port, listen address, or TLS settings change. Includes rollback logic: if the new broker fails to start, automatically restarts with the previous configuration and rebuilds the internal MQTT adapter
- **MQTT TLS status in API** — `GET /api/mqtt/status` now returns `tls_enabled` field indicating whether TLS is active on the embedded broker
- **Credential cache for MQTT authentication** — In-memory `CredentialCache` with `Arc<RwLock>` avoids redb lookups on every MQTT CONNECT packet. Cache auto-refreshes when credentials are added or deleted via the API. Custom `Debug` impl redacts sensitive fields (system password)
- **Restart lock for embedded broker** — `tokio::sync::Mutex` prevents concurrent restart operations from racing against each other
- **Environment variables documentation** — New `docs/guides/en/16-environment-variables.md` and `docs/guides/zh/16-environment-variables.md` covering server, auth, LLM, extension, CLI, and Docker configuration
- **Brotli compression** — HTTP response compression now supports both Gzip and Brotli encoding

### Changed

- **Extension command timeout increased** — Default FFI command timeout raised from 30s to 300s (configurable via `NEOMIND_FFI_TIMEOUT_SECS`). In-flight request timeout aligned to match. Prevents timeout errors for long-running extensions (YOLO, video processing)
- **Extension memory limit** — Default memory limit for isolated extensions raised from 512MB to 2048MB, accommodating ML model workloads
- **Dashboard desktop layout** — Desktop sidebar is now always expanded (removed collapsible toggle). Simplified navigation with fixed sidebar layout. Tab bar mode remains available as an alternative
- **Telemetry data fetching** — Optimized caching strategy with 10s fetch timeout (up from 5s) for better reliability over slow connections. 60s bucket alignment and 30s TTL maintained for cache freshness
- **MQTT broker config validation** — Listen address must be a valid IP. TLS cannot be enabled without pre-configured certificates. Credential uniqueness check before adding duplicates
- **Deploy configuration** — Updated nginx example with improved WebSocket proxying and Docker-specific port mappings

### Fixed

- **MQTT broker restart Send safety** — Fixed `Box<dyn StdError>` held across `.await` boundary in restart rollback path, which caused handler trait resolution failure. Store data is now extracted before any async operations
- **Telemetry test data integrity** — Fixed `test_image_retrieval_performance` and `test_telemetry_concurrent_write_performance` flaky failures by adding explicit `flush()` calls before querying. Tests were reading from redb while data was still in the write buffer
- **Extension test timeout assertion** — Updated `test_command_descriptor_dto` assertion to match the new 120s default timeout value
- **Dashboard component rendering** — Fixed extension component loading in `ComponentRenderer` by removing interfering `ErrorBoundary` wrapper
- **Dashboard mobile edit mode** — Fixed state reset when toggling mobile edit mode
- **Extension IPC routing** — Fixed stale reference in extension stream routing after process restart
- **Native confirm dialogs** — Replace `window.confirm()` with styled custom confirm dialog for dashboard widget removal and LLM instance deletion
- **Dashboard widget drag jumping** — Freeze container width measurement during drag/resize operations to prevent layout reset from stale store positions

### Changed

- **Component library and marketplace grids** — Replaced fixed responsive breakpoints with auto-fill columns (max 6) for better use of screen width on large displays

---

## [v0.8.4] - 2026-06-02

### Changed

- **System prompt slim-down (73% token reduction)** — Reduced AI agent system prompt from ~7,500 to ~1,800 tokens, freeing ~5,700 tokens per request for conversation history (+32% available context). Three-layer architecture: (1) system prompt for core decision rules, (2) CLI `--help` for command details loaded on demand, (3) skill tool for complex workflows loaded on demand. Removed redundant CLI reference table (already in shell tool JSON description), few-shot examples (modern tool-calling models don't need them), and consolidated duplicate rules across PRINCIPLES/RESPONSE_FORMAT/THINKING_GUIDELINES. Added Typical Workflows table, response format patterns, error handling hint, and vision hint. Integrated vision capability detection so multimodal models automatically receive image analysis instructions.

### Added

- **Vision tool** — AI agent can now analyze images from HTTP URLs, local files, data URLs, or raw base64 using a vision-language model (VLM). Auto-detects VLM backends via `supports_multimodal` capability and registers the tool automatically. Security hardened: SSRF protection with per-redirect validation, symlink-safe file reads via canonicalize-then-validate, MIME allowlist for data URLs, file extension whitelist with magic bytes validation, 10MB size limit. VLM backend selection follows priority: explicit config → active backend → first multimodal instance
- **4 new bridge extensions** — Home Assistant Bridge, LoRaWAN Bridge, Modbus Bridge, and Uink-RMS Bridge added to the extension marketplace for broader IoT protocol coverage
- **Layered multimodal capability detection** — Replace hardcoded heuristic with 3-tier resolution: LiteLLM registry (2,748 embedded model entries) → conservative heuristic → false. Add user override endpoint (`PATCH /api/llm-backends/:id/capabilities`), background refresh loop for Ollama instances (hourly `/api/show` polling), and source tracking (`user_override` > `runtime_api` > `registry` > `heuristic`). HTTP images pre-encoded to base64 for Ollama compatibility
- **i18n comprehensive standards** — Added section 12 to DESIGN_SPEC.md covering namespace rules, key naming convention (`{page}.{section}.{field}`), cross-namespace references, and common mistakes checklist
- **Dashboard tab bar layout mode** — Alternative to the left sidebar: a horizontal scrollable tab bar rendered inline in the toolbar header, freeing the full content width for the dashboard grid. Toggle via `PanelTop` button in the sidebar header or `PanelLeft` button on the tab bar; preference persisted in `localStorage` (`neomind_dashboard_layout_mode`). Active tab has a distinct `bg-muted` style with an elastically-expanding `⋮` action menu (cubic-bezier overshoot easing, 200ms) that reveals Rename/Delete on hover — no floating overlay. Left side has `[≡ sidebar][+]` controls; tab names truncate at 200px with full-name tooltip on hover. Layout mode is independent from the existing sidebar collapse state and fullscreen mode
- **Tooltips on dashboard toolbar action buttons** — Edit/Done, Add Component, Share, and Fullscreen buttons now use Radix `Tooltip` (300ms delay) instead of native `title=` attribute, matching the hover-label pattern used elsewhere in the dashboard chrome
- **i18n keys for tab bar** — Added `sidebar.switchToTabs` and a new `tabBar.*` namespace (`newDashboard`, `namePlaceholder`, `deleteTitle`, `deleteDescription`, `delete`, `rename`, `switchToSidebar`) in both `en` and `zh`

### Changed

- **Extensions page empty state redesign** — Replaced generic "No extensions found" with a rich ecosystem showcase: horizontal marquee scrolling 12 real extension preview cards (YOLO Video, Face Recognition, BACnet, Modbus, LoRaWAN, ONVIF, Home Assistant, Stream Player, Weather, OCR, OPC-UA, Image Analyzer), 8 category tags matching actual extension types, and CSS-only animation with edge fade and hover-pause

- **Messages page filter redesign** — Replaced heavy Sheet side-drawer with a lightweight Popover dropdown filter panel. Compact pill-style buttons replace bulky collapsible sections for Severity, Status, and Category filters. Removed CollapsibleSection component and unused Sheet/Separator/ChevronDown imports

- **Multimodal image upload avoids redundant vision tool call** — When a user uploads an image to a multimodal-capable model (e.g., GPT-4o, qwen-vl), the image is sent directly as native `Content::Parts` and the `vision` tool is filtered from the tool list. This prevents the model from calling the vision tool on images it can already see, eliminating a redundant LLM round-trip (following industry best practice: OpenAI, Anthropic, CrewAI all recommend native multimodal over tool-mediated vision)

- **Dashboard telemetry data split** — Separated real-time device telemetry (`deviceTelemetry` Record) from the `devices` array to eliminate cascading re-renders. Previously, every WebSocket metric update mapped over the entire `devices` array, causing all dashboard components to re-render. Now high-frequency metric writes only update a per-device telemetry map, while the `devices` array reference stays stable. Dashboard components use targeted selectors with `shallow` equality to re-render only when their bound device's telemetry changes. This reduces re-renders from O(n) per metric update to O(1).

- **Clippy cleanup** — Fixed 45 clippy warnings across 4 crates (`neomind-cli-ops`, `neomind-storage`, `neomind-agent`, `neomind-api`). Introduced `CredentialValidator` type alias for complex closure types, replaced `iter().cloned().collect()` with `to_vec()`, used `strip_prefix` instead of manual slicing, and resolved `await_holding_lock` in shutdown by cloning `Arc` before dropping the read guard
- **Dashboard list sorted by creation time** — Both sidebar and tab bar now display dashboards ordered by `createdAt` ascending (oldest first, newest at end), independent of backend fetch order or sync remapping. Newly created dashboards always appear at the end of the list
- **Sidebar collapsed-mode cleanup** — Removed the `+` (new dashboard) button and its divider from the collapsed sidebar view. The collapsed column now shows only the dashboard icon list; creation requires expanding the sidebar first or using the tab bar's `+` button
- **Sidebar item always shows component count** — Removed the `count > 0` guard so dashboards with 0 components display "0 components" instead of hiding the count row entirely

### Fixed

- **i18n ZH translations** — Batch translated 422 missing Chinese keys across 15 namespace files. Achieved EN/ZH parity (5,370 keys each, 17 active namespaces)
- **i18n reference consistency** — Fixed `ConfigFieldComponents.tsx` using default namespace instead of explicit `dashboardComponents`. Fixed 6 files using `t('common.xxx')` anti-pattern in default namespace context (`DeviceBindingConfig`, `MessageChannelsTab`, `MessagesTab`, `messages.tsx`). Fixed `settings.tsx` listing unregistered namespaces (`llm`, `connections`)
- **Create-dashboard navigation race** — `handleDashboardCreate` now `await flushSync()` and reads the final `currentDashboardId` from the store before navigating, so the URL receives the stable post-remap dashboard id. Previously the URL would hold the local temporary id while the store later updated to the backend-assigned id, causing the URL ↔ Store sync to bounce the user off the newly created dashboard

### Removed

- **~8,900 lines of dead frontend code** — Removed 30+ unused components, hooks, and utility modules that were superseded by page-level implementations:
  - `components/automation/` — AlertsTab, AutomationCreatorDialog, AutomationsTab, TransformsTabContent, TransformExecutionHistory (replaced by `pages/automation-components/`)
  - `components/devices/` — DeviceControl, DeviceRealtime, TemplatePreview (replaced by `pages/devices/`)
  - `components/extensions/` — ExtensionDataSourceSelector, ExtensionMetricSelector, ExtensionToolSelector, ExtensionTransformConfig (inlined into pages)
  - `components/shared/` — BulkActionBar, FullScreenEditor, KeepAlive, MonitorStatsGrid, SearchBar, SearchResultsDialog (unused)
  - `components/layout/` — SubPageHeader (unused)
  - `hooks/` — useApiData, useComponentPerf, useDialog, useInterval, useLoadingButton, useMessages (replaced by store-level fetchCache pattern)
  - `lib/` — extension-stream-hooks, fetch-with-timeout, react-query-hooks, status/utils, validation/utils, related test
- **Dead i18n namespaces** — Removed `commands.json` (58 keys, 0 references), `navigation.json` (12 keys, duplicated by `common.json` `nav`/`navShort`), `tools.json` (11 keys, unused), and orphaned camelCase `dashboardComponents.json` (merged into hyphenated version)
- **245 duplicate i18n keys from common.json** — Removed sections that existed identically in `dashboard-components.json`: visualDashboard, sizes, imageDisplay, imageHistory, layerDisplay, mapDisplay, markdownDisplay, placeholders, range, searchBar, videoDisplay, webDisplay, common

---

## [v0.8.3] - 2026-06-01

### Added

- **Docker deployment** — Production-ready multi-stage Dockerfile (Node 20 frontend + Rust 1.85 backend + Alpine runtime), docker-compose.yml with named volume persistence, health check, and `.env.example` configuration template. Single container includes API server, Web UI, embedded MQTT broker, and extension runner


- **Agent experience learning** — New per-execution insight extraction and LLM-driven task profile reflection. Agent memory now accumulates actionable knowledge over time instead of just recording what happened:
  - `MemorySummary.insight` — Inline insight from main LLM output (focused mode) or deterministic extraction (free mode: failure reasons, alert/command triggers, >20% baseline deviation, anomaly keywords). Zero extra LLM calls
  - `TaskProfile` — Evolving task-level knowledge summary (max 500 chars) generated by LLM reflection when ≥5 insights accumulated (first time) or 6-hour staleness (updates). Includes version, execution count, and freshness tracking
  - Task Knowledge injected as highest-priority section in `build_history_context()` for LLM decision-making
  - Short-term summary cards now display insights with lightbulb icon in agent detail panel
  - API DTOs (`MemorySummaryDto`, `AgentMemoryDto`) expose `insight` and `task_profile` fields
  - i18n support for Task Knowledge and Recent Key Findings (en/zh)
- **`web_fetch` tool** — AI agent can now fetch URL content directly. Returns cleaned text (HTML stripped) or raw content with configurable max length (default 5000, max 50000 chars). Security: SSRF protection blocks private/local IPs (localhost, 10.x, 192.168.x, 172.16-31.x, IPv6 unique local, link-local, IPv4-mapped IPv6), validates redirect targets, enforces 15s timeout and 1MB response limit. Content-Type media type parsing prevents binary bypass via parameter injection
- **`file_write` tool** — AI agent can create or overwrite files within allowed directories (data dir + `NEOMIND_ALLOWED_WRITE_DIRS` env var). Atomic writes via temp-file-then-rename. Supports all text file types (.rs, .toml, .py, .js, .json, .md, .conf, etc.). Blocks binary extensions (.so/.dll/.exe/.sys) and .env files. Content limit: 1MB. Auto-creates parent directories by default. Preserves file permissions on overwrite
- **`file_edit` tool** — AI agent can perform precise string replacement in existing files. Parameters: `old_string`/`new_string` with optional `replace_all`. CRLF/LF line ending normalization for cross-platform matching. File size limit: 10MB. Error messages include file preview for context when old_string not found. Atomic write preserves file permissions
- **`path_validator` module** — Shared security layer for file tools. Symlink escape prevention via `find_existing_ancestor()` + canonicalization. Path traversal (`..`) detection at component level. `NEOMIND_ALLOWED_WRITE_DIRS` env var for extension development directories
- **Memory tool 2-file API** — New file-based memory endpoints: `GET/PUT /memory/file/{category}` for direct file read/write. Memory tool now supports custom category files (`custom/{name}.md`) and per-request session binding via shared handle
- **Device list grouped by type** — `neomind device list` now groups devices by `device_type`, shows metric schema with example values from online devices (parallel enrichment), and truncates large lists (>50 devices) for token budget protection
- **LLM backend create via CLI** — `neomind llm create` registers new LLM backend instances from the command line
- **Thinking model loop detection** — Ollama backend detects and cuts off runaway thinking (loops, excessive length) for qwen3/deepseek-r1 models
- **Chat page context injection** — When the global chat FAB is opened from a page (dashboard, devices, automation, etc.), a short neutral context string (`[context] page:dashboard "name", N components`) is automatically prepended to the first user message so the AI knows which page the user is on. Context is reactive to route changes, injected only on the first message per session, and resets on new conversation
- **Dashboard community components split** — Component library now separates "My Components" (locally created / AI-generated) from "Marketplace" (installed from registry). Added `source` field to distinguish origins, with reinstall support for local components to refresh updated bundles
- **System context resource inventory** — Periodic background task gathers device/agent/extension/dashboard names and writes to KNOWLEDGE.md `<!-- system-context -->` marker section (800 char limit, 10min interval). AI now knows what resources exist without tool calls
- **LLM chat/agent summarization** — Periodic background task uses LLM to summarize recent chat sessions → `<!-- chat-summary -->` in USER.md (200 chars) and active agent execution patterns → `<!-- agent-summary -->` in KNOWLEDGE.md (300 chars). Configurable backend selection and 2h interval

### Changed

- **Agent context builder optimized** — Merged duplicate Execution History + Short-term Memory sections into single "Recent Execution History". Filtered low-value learned patterns. Baselines now show human-readable device names from resources instead of raw metric IDs
- **Agent reflection prompt language** — All LLM reflection prompts use English for consistency
- **Focused mode LLM fallback** — Deterministic fill from `situation_analysis` when small models omit `reasoning_steps`/`conclusion`/`decisions` fields. Uses `serde_json::Value` for `insight` to tolerate non-string LLM output (true, 0, null). No extra LLM calls, no circular risk
- **Memory system refactor** — Replaced old LLM-based chat extraction (`POST /api/memory/extract`) with marker-based periodic summarization. Removed dead extraction pipeline (compat stubs, category files). Memory writes are now: (1) user via memory tool, (2) background periodic summaries. Old `user_profile.md`/`task_patterns.md`/`domain_knowledge.md` files (417KB of noise) replaced by clean USER.md/KNOWLEDGE.md
- **Memory config defaults** — `agent_char_limit`: 500→1000, `summary_interval_secs`: 3600→7200, `system_context_interval_secs`: 300→600. Added `summary_backend_id` field for selecting LLM backend for summarization (defaults to active backend)
- **Agent short-term memory** — Capacity increased from 10→20 entries. `summarize_agent_context()` now includes both situation and conclusion for richer context. Learned patterns get time-based confidence decay (10%/week, removed after 28 days). Baselines pruned when data sources no longer present
- **Memory config dialog** — Replaced manual toggle switch with Radix UI Switch component. Added LLM backend selector for summarization. Removed Extract button from toolbar
- **Tool prompt architecture** — `builder.rs` now includes structured tool descriptions (Type 1: shell, Type 2: skill, Type 3: file/web) with parameter docs, security notes, and usage examples in the system prompt. `TOOL_STRATEGY` section guides LLM on when to use each tool type
- **Memory tool actions expanded** — Added `read_file`, `write_file`, `list_files` actions for direct file manipulation alongside existing category-based actions
- **Memory panel unified** — Custom memory files merged into the same table as user/knowledge files. Single unified dialog for view/edit. "Add File" button in tab actions bar. Eliminated ~200 lines of duplicate state and dialogs
- **Memory stats API unified** — `GET /api/memory/stats` now returns `{ files, custom_files }` using the new `store.stats()` API instead of deprecated `all_stats()`. Fixed stats display (was always showing 0 chars due to key mismatch)
- **Code formatting cleanup** — `cargo fmt` applied across agent, storage, API crates for consistent formatting
- **Table vertical alignment** — ResponsiveTable cells now use flex centering for consistent vertical alignment across rows with varying content heights
- **Global chat floating window** — Replaced full-screen backdrop overlay with a fixed-size floating window (380×560 desktop, 70vh mobile) anchored to bottom-right. Users can now chat while viewing Dashboard/device pages behind the window
- **Memory scheduler cleanup** — Removed system resource summary job that wrote stale "System Resources" sections to KNOWLEDGE.md every schedule interval, wasting the char budget on transient data queryable live via CLI tools

### Removed

- **`ai_metric` tool** — Removed the AI Metric tool and all related infrastructure. This tool allowed LLM agents to write custom time-series metrics (`ai:{group}:{field}`), but had no reliable use case — the Memory system already covers cross-session knowledge persistence. Full cleanup across backend, frontend, i18n, and docs:
  - **Rust**: Deleted `crates/neomind-agent/src/toolkit/ai_metric.rs` (614 lines). Removed `AiMetricsRegistry` from `AgentState`, `init_tools()`, `refresh_extension_tools()`. Removed `DataSourceType::Ai` enum variant and `DataSourceId::ai()` from `neomind-core`. Removed `collect_ai_sources()` from data handler. Removed `"ai:"` from `KNOWN_PREFIXES` in telemetry migration
  - **Frontend**: Removed `'ai-metric'` from `DataSourceType` union, `AIMetricDataSource` interface, `aiGroup` field. Cleaned all 6 config schema files, `UnifiedDataSourceConfig`, `DataSourceIndicator`, `DualModeSourceField`, `ComponentConfigBuilder`, `componentDataApi`
  - **i18n**: Removed `aiMetric`, `aiMetricDesc`, `noAiMetrics`, `aiGroupPlaceholder` from en/zh locales
  - **Docs**: Removed ai_metric references from agent (en/zh), tools (en/zh), storage (en/zh), and web dashboard (en/zh) documentation
- **`session_search` tool** — Removed conversation history search tool. LLM already has full conversation context in its prompt window, making self-search redundant. Memory system handles cross-session knowledge persistence. Deleted `crates/neomind-agent/src/toolkit/session_search.rs` (127 lines)
- **`think` tool** — Removed the explicit thinking tool (338 lines). Thinking models now handle reasoning internally via streaming. The `think` namespace removed from LLM tool routing and staged agent filter
- **`ToolFilter` dead code** — Removed unused `ToolFilter` struct, `filter_by_intent()`, `intent_prompt()` from `staged.rs` (~130 lines). Removed dead `classify_intent()`, `get_intent_prompt()`, `filter_tools_by_intent()` methods and `tool_filter` field from `LlmInterface` in `llm.rs` (~140 lines including tests). Removed unused `IntentCategory::namespace()` and `IntentClassifier::classify_category()`
- **5 unused agent components** — Deleted `AgentMemoryDialog`, `AgentExecutionsList`, `AgentListPanel`, `AgentLogicPreview`, `AgentsList` (0 references, ~1626 lines of dead code)
- **Chat memory toggle** — Memory is now always enabled (configurable via settings). The per-session toggle was redundant since the memory tool provides on-demand access regardless of snapshot preload
- **Chat skill selector** — LLM already auto-selects skills via the `skill` tool based on user intent. Manual preloading was redundant and added UI clutter
- **Memory extract endpoint** — Removed `POST /api/memory/extract` and frontend Extract button. Old LLM-based chat extraction produced 417KB of noisy data (3551 entries, mostly duplicates). Replaced by background periodic summarization
- **Dead memory modules** — Removed `compat.rs` (empty stubs), `lifecycle.rs` (unused hooks), `short_term.rs`, `mid_term.rs`, `long_term.rs`, `tiered.rs`, `bm25.rs`, `embeddings.rs` (all unused after refactor)
- **Unused `write_last_resource_summary_time`** — Removed dead method from `MarkdownMemoryStore`

### Fixed

- **Custom Layer background image UI redesign** — Merged awkward two-field layout (URL + separate file upload) into a single inline field with URL input + Upload button, matching ImageSourceField pattern
- **LayerEditorDialog save button i18n** — Added missing `common.save` translation key so save button shows localized text instead of raw key
- **Missing zh translations for spatial config** — Added `backgroundType`, `backgroundImageUrl`, `layerItemBinding`, `manageLayerItems` and related keys to Chinese locale
- **Memory tool write lock** — Write operations (add/replace/remove/create) now use `store.write().await` instead of `store.read().await` to prevent read-modify-write race conditions
- **Memory tool first-match-only** — `replace`/`remove` actions now use `.replacen(..., 1)` instead of `.replace()` to prevent multi-replace data corruption
- **Memory tool chars vs bytes** — All "X chars" messages now use `.chars().count()` instead of `.len()` for correct UTF-8/Chinese text reporting
- **Memory tool list action** — `target` parameter is now optional for `list` action (was incorrectly required)
- **Memory snapshot budget** — Added hard truncation fallback when user content alone exceeds 5000 char budget
- **Refresh extension tools** — Memory tool is now re-registered during `refresh_extension_tools()` to prevent it from disappearing after extension refresh
- **All compiler warnings resolved** — Zero warnings across neomind-storage, neomind-agent, neomind-api crates
- **Session file path traversal** — Added `validate_session_id()` to block `../` and `/` in session IDs, preventing arbitrary file access
- **Char counting consistency** — Fixed `write_file()`, `stats()`, and agent stats to use `.chars().count()` instead of `.len()` for correct UTF-8/Chinese text handling
- **Extraction lock resilience** — Extraction guard now uses `Drop` pattern to ensure lock is released even on panic, preventing permanent lock-out
- **Missing i18n keys** — Added `systemMemory.extract` and `systemMemory.custom.description` to en/zh locales
- **Session sidebar card overflow** — Fixed Radix ScrollArea Viewport injecting `display:table` + `min-width:100%` causing cards to overflow. Added CSS override to Viewport component and proper `min-w-0` flex constraints for text truncation
- **Session action buttons** — Edit/delete buttons now compact (`h-4 w-4`) and absolutely positioned floating on card right side with hover reveal, instead of inline layout
- **Dashboard stuck skeleton screens** — Fixed three root causes: loading counter leak on telemetry-only sources, retry storm (reduced to 1 retry at 500ms), and added 3s hard deadline force-clear
- **Dashboard cross-tab sync** — Emit `DashboardUpdated` event on CRUD operations. VisualDashboard subscribes for real-time sync across browser tabs
- **Dashboard chart tooltip crash** — Fixed crash when rendering telemetry point objects `{timestamp, time, value}` as React children. LineChart now correctly extracts numeric values
- **Community widget data flow** — Fixed `fetchData` prop not reaching community widgets due to missing `installedComponents.length` dependency in rendering useMemo. Removed 2.5s fetch delay for immediate registry sync
- **Data source editor binding** — Fixed `dataSourceToSelectedItems` not recognizing `type:"telemetry"` and `type:"device"` with metric fields, causing editor to not show bound state for AI-created data sources

---

## [v0.8.2] - 2026-05-29

### Changed

- **DataSource unified Source+Mode architecture** — Replaced 12 legacy `type`-based routing with 4 unified fields (`source`/`id`/`field`/`mode`). New `DataSourceSource` (device/extension/system/transform/ai) and `DataSourceMode` (latest/timeseries/command/info/list) types provide clean orthogonal dimensions. `migrateToUnified()` bidirectionally populates both old and new fields for zero-migration backward compatibility. Removed 14 type guard functions, legacy switch statements across 6 sub-hooks. All routing now uses mode-based logic with fallback to legacy fields
- **usePollingSource replaces useSystemSource** — New generic HTTP polling hook supporting latest, list, and timeseries accumulation modes. System metrics now support client-side historical accumulation (pruned by `timeRange`/`limit`). Deleted `useSystemSource.ts` entirely. `pollDataSource()` dispatch in fetch.ts provides extensible source routing for future data sources (rule lists, message lists, external APIs)
- **Config UI outputs unified fields** — `selectedItemsToDataSource` now outputs `source`/`id`/`field`/`mode` alongside legacy `type`. `suggestedMode` prop enables per-component mode hints (LED→latest, Chart→timeseries, Toggle→command, Map→info). Eliminates sourceTransform round-trips for new configurations
- **isImageDataSource refactored** — Changed from 3-arg `(params, transform, metricId)` to single-arg `(ds)` pattern. Updated 8 call sites across 4 files
- **Community/extension component fetchData API** — New `resolveDataSourceData()` utility and `fetchData` prop injection in ComponentRenderer for community/extension components. Provides mode-aware data fetching without React hook dependency

### Fixed

- **Instant telemetry initial rendering** — Telemetry-bound components (LED, ValueCard, ProgressBar, etc.) now read initial values from `store.current_values` instead of waiting for HTTP API. New `readTelemetryInitialValues` in `useStoreSource` creates synthetic data points from store, eliminating loading flash on dashboard open
- **Enhanced telemetry retry** — `useTelemetrySource` now retries with exponential backoff on transient failures instead of showing permanent error state
- **Dashboard component count mismatch** — Removed destructive `isDataSourceValid` filter in `fetchDashboards` that silently deleted components with incomplete data sources
- **Camera hardware lock leak** — `VideoDisplay` CameraAccess now properly stops MediaStream tracks on unmount via `streamRef` + cleanup
- **Dual/triple fullscreen rendering** — VideoDisplay, MapDisplay, CustomLayer no longer render content inline AND via portal simultaneously (`{!isFullscreen && content}` pattern)
- **useTelemetrySource timer leaks** — Retry setTimeout and fetch timeout promise now tracked via refs and cleaned up on unmount
- **LayerEditorDialog cancel data loss** — Cancel button now calls `onOpenChange(false)` instead of `onSave(undefined)` which wiped all layer bindings
- **Config save dataSource priority** — Simplified `handleSaveConfig` to 2 authoritative locations instead of 5, preventing restoration of intentionally-cleared data sources
- **Duplicate dashboard creation** — `HybridDashboardStorage.syncToApi` now only syncs dashboards with existing server ID mapping
- **Stack overflow on large telemetry arrays** — Replaced `Math.min(...array)` / `Math.max(...array)` with `.reduce()` pattern across 10 files to handle arrays >100K elements
- **createStableKey stack overflow** — Added depth limit (MAX_DEPTH=10) to prevent infinite recursion on deep/circular references
- **Sparkline crash on sparse data** — Added guard for `< 2` data points before rendering
- **getLinearGradient OKLCH handling** — Now uses proper `colorWithAlpha()` helper instead of raw string concatenation
- **normalizeDataSource empty array** — `[]` input no longer wrapped as `[[]]`
- **imageUtils cache memory bloat** — Inputs >10KB (base64 camera frames) skip caching to avoid multi-MB string retention
- **SharedDashboard i18n** — Replaced 6 hardcoded English error messages with `t()` calls
- **Video display config i18n** — Replaced hardcoded Chinese strings with `t()` calls
- **Chart useMemo stale data** — LineChart, BarChart, PieChart now include `sources`, `getSeriesName`, `getDeviceName` in dependency arrays
- **Renderers missing builtIn types** — Added `counter` and `metric-card` to builtInTypes Set and builtInComponentMap
- **DashboardGrid redundant data-grid** — Removed `data-grid` attribute from child elements (layouts prop is authoritative)
- **ImageDisplay fullscreen portal** — Fullscreen overlay now uses `getPortalRoot()` instead of inline rendering
- **Dashboard switch state cleanup** — `mobileSelectedId` and `mobileEditBarOpen` reset on dashboard switch
- **Deep clone on template apply** — `applyTemplate` now uses `JSON.parse(JSON.stringify())` for proper deep clone
- **configComponentId reset on delete** — `deleteDashboard` now clears `configComponentId` and `configPanelOpen`

### Fixed (Round 10)

- **Error Boundary for dashboard components** — Extension/community component runtime errors no longer crash the entire dashboard page; graceful error card with localized message
- **localStorage quota recovery** — `LocalStorageDashboardStorage.save()` now catches `QuotaExceededError`, clears stale data, and retries write
- **Hybrid storage sync race condition** — Rapid edits to a local dashboard before first server sync now preserve latest changes instead of overwriting with stale server state
- **Position validation** — `moveComponent` now clamps negative x/y to 0 and dimensions to minimum 1; `positionFromDTO` applies same validation to API responses
- **Registry validation** — Dynamic and community component registries reject types that shadow built-in widget types (e.g. registering `"line-chart"` as extension)
- **Missing type guards** — Added `isExtensionMetricSource()` and `isExtensionCommandSource()` type guards for discriminated union coverage

### Fixed (Round 11)

- **Mobile edit mode state leak** — Exiting edit mode on mobile now resets `mobileSelectedId` and `mobileEditBarOpen` instead of leaving stale mobile UI
- **Mobile drag/resize disabled** — Grid drag and resize disabled on touch devices to prevent conflicts with scrolling and touch interactions
- **Extension uninstall cleans all dashboards** — Unregistering an extension now removes its components from ALL dashboards, not just the current one
- **ComponentRenderer unmounted state updates** — Added mountedRef guard to prevent React warnings from async state updates after component unmount
- **Mobile touch targets** — Action buttons in mobile edit mode increased to 44px height (was 32px) for proper touch accessibility
- **Mobile selection overlay** — Split overlay into separate selected/unselected states; component content is now interactive when selected

### Changed

- **Dashboard configSchemas registry pattern** — Replaced 2982-line monolithic `configSchemas.tsx` switch statement with a modular registry pattern. Schema generators are now organized into `builtIn/` sub-modules (indicators, charts, controls, display, spatial, business) plus a `dynamic.tsx` handler for extension/community/custom components. No user-visible behavior changes
- **Dashboard store: eliminated slice circular dependencies** — Removed module-level `_scheduleSync`/`_flushSync` variable exports from `dashboardCrudSlice`. `scheduleSync()` and `flushSync()` are now proper slice methods accessed via `get()`, eliminating fragile module-level getter pattern
- **DataSource discriminated union types** — Added 12 type-specific interfaces (`DeviceDataSource`, `CommandDataSource`, `SystemDataSource`, etc.) with type guards (`isDeviceSource()`, `isRealtimeSource()`, `isPolledSource()`, etc.). Legacy flat `DataSource` interface preserved for backward compatibility. Updated `useDataSource` pipeline and `dashboardHelpers` to use type guards
- **useDataSource simplified state management** — Replaced 12-action `useReducer` state machine with flat `useState` + loading ref counter. Removed `activeFetchSource` tracking, `FETCH_EMPTY_RETRY`, and `FORCE_CLEAR_LOADING` actions. Loading state is now a simple counter (loading = counter > 0) managed by `startLoading`/`finishLoading` callbacks

---

## [v0.8.1] - 2026-05-27

### Added

- **Embedded MQTT broker auth & TLS management** — Redesigned `EmbeddedBroker` with `external_auth` callback for redb-backed credential validation, stop/restart lifecycle, and TLS support (cert/key paths). Broker now loads config from redb at startup and validates connections against stored credentials
- **MQTT credential storage** — New redb tables (`mqtt_credentials`, `mqtt_credentials_by_username`) for MQTT username/password management. Full CRUD methods with automatic index maintenance in `neomind-storage`
- **Embedded broker config API** — New endpoints `GET/PUT /api/settings/broker` for reading and updating embedded broker configuration (auth mode, TLS, credentials). Changes take effect on broker restart
- **Embedded broker config UI** — New `EmbeddedBrokerConfigDialog` component with auth mode toggle (anonymous/credential), credential management (add/delete), and TLS configuration (cert/key paths). Full en/zh i18n support
- **CLI: device drafts commands** — New `neomind device drafts` subcommand group (`list`, `get`, `approve`, `reject`, `config`) for managing auto-discovered device drafts. Full workflow: list pending → inspect samples → approve with name/type → or reject
- **CLI: device webhook-url** — New `neomind device webhook-url <ID>` command to retrieve the HTTP push URL for webhook adapter devices
- **CLI: extension config** — New `neomind extension config <ID>` to view config, `--set '<JSON>'` to update. Replaces manual API calls for extension configuration
- **CLI: API client auth retry** — All API client methods (GET/POST/PUT/DELETE/multipart) now automatically retry on 401 with refreshed API key from redb. API key stored in `RwLock` for thread-safe refresh
- **CLI: health check via API** — `neomind health` now queries actual LLM backend status via API instead of checking environment variables. Shows backend count, active backend ID, and setup hints
- **CLI: system info with TLS/auth/credentials** — `neomind system info` now exposes MQTT broker TLS status, auth mode, and credentials for AI agent onboarding guidance
- **Broker connection guide in Add Device dialog** — New step showing embedded broker connection details (host, port, credentials) to simplify device onboarding

### Changed

- **CLI: shell tool reference updates** — `transform test` renamed to `test-code`, `extension get` aliased to `info`, agents created as `active` by default (no longer need `control <ID> active`), push target type auto-detected from config
- **CLI: shell operator fallthrough** — Commands containing pipes (`|`), redirects (`>`), or stderr redirects (`2>`) now fall through to real shell execution instead of internal routing
- **CLI: DSL parser validation** — Rule engine now rejects function-call syntax (e.g., `device.metric(temperature)`) and empty source/metric with clear error messages
- **Session preview auto-extraction** — Session list now includes preview text auto-extracted from the first user message (50-char limit), improving session sidebar display
- **User guide improvements** — Updated documentation with Skills tab references, Data page guidance, and content fixes
- **Embedded broker migrated to rmqtt** — Replaced rumqttd with rmqtt for improved stability, plugin support, and standards compliance. Broker restart uses system credentials from redb

### Fixed

- **Storage lifetime issue** — Fixed lifetime annotation in `delete_mqtt_credential` preventing compilation
- **macOS resource limits** — Fixed macOS file descriptor limits for stable operation under high connection counts
- **MQTT InvalidAuth loop** — Resolved broker authentication loop caused by credential mismatch; parallelized broker startup for faster initialization
- **MQTT broker restart credentials** — Broker restart adapter now correctly uses system credentials from redb instead of stale values
- **Backend base64 image stripping reverted** — Reverted commit 49c1086 which stripped `data:image/...;base64,` prefix from metric/telemetry API responses, breaking all image consumers (dashboard widgets and external extensions). Backend now returns string values as-is
- **Base64 image detection** — Fixed `/9j/` (JPEG) rejection in `isPureBase64`/`isBase64Image` across ImageDisplay, ImageHistory, AgentMonitorWidget, and helpers. All components now correctly detect JPEG base64 data
- **Image URL normalization** — Fixed double-prefixed data URL handling and non-standard `data:` prefix cases using magic bytes detection in normalizeImageUrl
- **Image dynamic refresh** — Device→telemetry conversion in ImageDisplay and ImageHistory now includes `refresh` interval for live image updates
- **External placeholder SSL error** — Replaced external `via.placeholder.com` with local empty state, eliminating SSL errors for missing images
- **React setState-during-render warning** — Fixed `UnifiedDataSourceConfig` calling `onChange()` inside `setSelectedItems` updater; moved to useEffect
- **Floating chat session isolation** — PanelChatView and GlobalChatFab now share session key constant; added new conversation button; fixed session history loading on mount
- **Floating chat panel redesign** — Complete overhaul of the global floating chat panel: independent session with local state (no longer shares global store with chat page), proper LLM backend loading with "not configured" empty state, skeleton loading when reopening panel, session not found auto-recovery (silently creates new session)
- **AI response tool call rendering fixed** — `ToolCallVisualization` was deprecated (returned `null`), causing tool calls and execution process to be invisible in `MergedMessageList` and `MessageItem`. Replaced with `ToolProcessBlock` to match the main chat page's rendering
- **Floating panel card-style AI responses** — Added `assistantCard` prop to `MessageItem`/`MergedMessageList` for wrapping AI responses (thinking + tool calls + content) in a subtle card background, improving readability over the glass morphism panel background
- **Streaming cursor positioning** — Fixed floating cursor in streaming content caused by `relative inline` CSS on the wrapper; now uses proper `align-text-bottom` alignment
- **Streaming-to-saved message flash fix** — Panel's `"end"` handler now uses `currentStreamMessageId` as the saved message ID, enabling smooth transition from streaming block to persisted message without visual flash
- **Session cleanup on delete** — `deleteSession` in sessionSlice now clears the panel's persisted session ID from localStorage when the deleted session matches, preventing "Session not found" errors on next panel open
- **Missing i18n translations** — Added translations for "Edit Dashboard", "Internal Broker", "Built-in" labels in en/zh locales

---

## [v0.8.0] - 2026-05-26

### Added

- **Messaging system delivery retry** — Failed message deliveries are now automatically retried up to 3 times with a 2-minute interval scheduler. The existing `DeliveryLog` infrastructure (`can_retry`/`increment_retry`/`max_retries`) is now fully wired to a background retry loop in `AppState`
- **Webhook timeout configuration** — Webhook channels now support configurable request timeout (`timeout_secs`, default 30s) with a 10s connect timeout. Field exposed in the channel creation dialog in the UI, with en/zh i18n labels
- **Message deduplication** — Messages with the same title+source+severity within a 60-second window are automatically deduplicated. The message is still stored but channel delivery is skipped, preventing message bombing from high-frequency rule triggers
- **Automatic delivery log cleanup** — A background task now runs every 6 hours to clean up delivery logs older than 1 day and messages older than 30 days. Runs on startup and periodically via `tokio::select!` alongside the retry scheduler
- **Automatic updater fixes** — Fixed app restart and version placeholder replacement after in-app updates. Fixed service config, sudo handling, and upgrade support for the install/update flow
- **Global AI chat entry (FAB)** — Floating action button on all non-chat pages opens a full-screen glass-morphism chat overlay with smooth scale-up animation. Panel uses an independent session persisted via localStorage, shares WebSocket with the main `/chat` page. Brand orange styling, Bot icon for AI messages, i18n empty state
- **5 new notification channels** — Telegram (Bot API), WeCom (robot webhook), DingTalk (custom robot with HMAC-SHA256 sign), Slack (Incoming Webhook), Feishu (custom bot with HMAC-SHA256 sign). Each channel is feature-gated in `Cargo.toml` and registered via `ChannelFactory`. All use platform-native message formats (markdown, Block Kit, HTML)
- **Channel editor FullScreenDialog** — Replaced inline `UnifiedFormDialog` with dedicated `ChannelEditorDialog` component using `FullScreenDialog` + Sidebar layout. Left sidebar shows all 7 channel types with icons and descriptions; main area shows dynamic config form. Mobile-friendly with horizontal tab bar
- **Data push module** — New `neomind-data-push` crate for pushing device telemetry and extension output to external systems. Supports Webhook and MQTT targets with event-driven and interval-based scheduling, configurable retry with exponential backoff, data filtering, and Jinja-like template rendering. Full REST API and frontend management UI with `PushTargetDialog` and `DeliveryHistoryPanel`
- **Channel type registry** — Backend now exposes channel type schemas via `GET /api/messages/channels/types/:type/schema` with per-type JSON Schema for config validation. Frontend auto-discovers available types

### Changed

- **Email SMTP connection reuse** — `EmailChannel` now builds and caches the `SmtpTransport` at creation time via `Arc<Mutex>`, eliminating per-send SMTP connection setup overhead
- **Email recipients atomicity** — `add_recipient`/`remove_recipient` now recreate the email channel before persisting to storage, with automatic rollback on failure. Previously a failed recreation could leave `state.recipients` and `EmailChannel.to_addresses` out of sync
- **Chat message styling** — AI messages use Bot icon instead of logo image. User message bubbles use neutral black/white. User avatar uses brand orange accent. Streaming text internationalized
- **Messages page refactored** — Extracted ~500 lines of channel create/edit logic from `messages.tsx` into standalone `ChannelEditorDialog` component. Main page reduced by 40%
- **Delivery log removed** — Removed monolithic `delivery_log.rs` (591 lines). Delivery tracking now handled by channel-level retry in `ChannelFilter` with simpler dedup logic

### Fixed

- **Email TLS configuration dead code** — The `use_tls` field in `EmailChannel` was stored but never read in `send()`, which always used `Tls::Required`. Now correctly uses `builder_dangerous` when `use_tls` is false, enabling support for local mail servers (MailHog, etc.)
- **CLI robustness** — Fixed widget install multipart mismatch, added border styling to widget scaffolds, aligned CLI docs/skills/prompts with actual system behavior
- **CI build** — Fixed Tauri externalBin by building `neomind-cli` alongside `neomind-extension-runner`
- **Device auto-discovery** — Fixed `adapter_type` when registering auto-discovered devices
- **Channel config field alignment** — Email config now sends `smtp_server`/`username`/`password` (was `smtp_host`/`smtp_username`/`smtp_password`). Webhook timeout field now sends `timeout_secs` (was `timeout`). All fields match backend factory expectations
- **Channel edit form initialization** — Edit mode now correctly populates form via `useEffect` watching `open`/`editingChannel` instead of relying on `onOpenChange` callback which only fires on user actions
- **DingTalk dead code** — Removed unused `webhook_url` method that caused Rust compiler warning

---

## [v0.7.9] - 2026-05-25

### Added

- **Widget development skill** — New builtin skill `widget-development.md` with complete IIFE templates (ValueCard, Clock, Gauge, DevicePanel), jsxRuntime pattern documentation, props interface guide, manifest.json reference, and Tailwind styling rules. Based on patterns from real NeoMind-Dashboard-Components repository
- **Extension development skill** — Rewritten `extension-development.md` with complete working DataProcessor template, state management patterns (AtomicU64, RwLock, Mutex), Builder API reference, Cargo.toml requirements, and `ureq` sync HTTP guidance. Based on patterns from real NeoMind-Extensions repository
- **Transform metric discovery guidance** — Enhanced `transform-management.md` with "Discover Metrics Before Writing Code" section, auto-unwrap semantics documentation, `extensions.invoke()` usage, and three discovery paths (device metrics, extension metrics, existing transforms)
- **Extension reload command** — New `neomind extension reload <ID>` command in CLI, cli-ops, and shell.rs routing. Calls `POST /api/extensions/:id/reload` for hot-restarting extension processes
- **Agent create advanced flags** — Help text now documents all flags: `--resources`, `--metrics`, `--commands`, `--event-filter`, `--timezone`, `--enable-tool-chaining`, `--max-chain-depth`, `--priority`, `--context-window-size`
- **Shell help for extension/widget/transform** — Added detailed help entries for `extension create/build`, `widget create`, and `transform create` with workflow steps, parameter tables, and examples

### Changed

- **Dashboard add-components** — Shell help and tool description now prominently recommend `add-components` over `update --components` to prevent accidental full replacement of dashboard components
- **Rule DSL quotes** — Fixed tool description to use `RULE "<name>"` (quoted) matching the actual DSL parser requirement
- **Rule engine improvements** — Enhanced DSL parsing, validation, and generator for more robust rule creation
- **CLI error recovery** — Transform test command now flattens API error responses for clearer error messages

### Fixed

- **Webhook adapter auto-discovery** — Webhook adapter now emits `DeviceDiscovered` on every POST for unregistered devices (previously only on first POST), enabling proper sample collection for auto-onboarding
- **Webhook auto-onboarding single-trigger** — `create_draft_with_topic()` now triggers analysis immediately when `MIN_SAMPLES_FOR_ANALYSIS` samples are collected (was 1 but analysis only triggered in `add_sample_to_draft`). One webhook POST now creates draft + triggers analysis
- **Webhook URL format** — Fixed all frontend webhook URL generation from `/api/devices/webhook/{id}` to correct route `/api/devices/{id}/webhook` across 6 components
- **Webhook handler refactor** — Rewrote webhook handler from 650+ lines to ~200 lines, delegating to `WebhookAdapter.process_webhook()` instead of duplicating token verification, metric extraction, and event publishing
- **Webhook shared device registry** — Webhook adapter now receives the shared `DeviceRegistry` via `set_shared_device_registry()`, fixing token verification and device type lookup
- **Webhook token display** — Fixed `config_to_device_instance()` in compat.rs to include `connection_config.extra` fields (webhook_token, json_path, etc.) so tokens display correctly in Device Connections
- **Pending Devices WebSocket auto-update** — Fixed event handler to use correct field names (`custom_type`, `data.event_type`, snake_case values). Added `Custom` event arm in `extract_event_data()` to avoid double-wrapped serialization
- **Webhook routes** — Added 3 webhook routes to router.rs: `POST /api/devices/:id/webhook`, `POST /api/devices/webhook`, `GET /api/devices/:id/webhook-url`
- **Webhook token input** — Added webhook token generation and input to both AddDeviceDialog and ManualAddForm (AddDeviceGlobalDialog)
- **Webhook URL with real IP** — Device Connections webhook URLs now show server's real IP instead of localhost
- **Device Information webhook display** — DeviceDetail page now shows webhook URL and token for webhook adapter devices
- **Extension status/logs 500→404** — Fixed API returning 500 "IPC error" for non-existent extensions. Added existence check before IPC calls, returning proper 404
- **Boolean flag parsing** — Fixed `--tls` flag silently failing when it's the last argument. Changed from `get_flag_value()` to `args.iter().any()` for boolean flags
- **Severity level mismatch** — Fixed message send recovery hint from "error" to "emergency" to match actual API accepted values (info|warning|critical|emergency)
- **Transform auto-unwrap** — Single-key JSON input like `{"value": 42}` is now auto-unwrapped to scalar `42` for simpler transform code. Multi-key objects remain as-is
- **Extension reload routing** — `neomind extension reload` no longer falls through to `__FALLTHROUGH__` but properly calls the API endpoint
- **Marketplace dialog flickering (Windows)** — `ExtensionListContent` and `DetailContent` were defined as inline components inside `MarketplaceDialog`, causing React to unmount/remount the entire DOM subtree on every render. Replaced with stable inline JSX. Also removed duplicate `fetchExtensions()` call after install
- **EntityIconPicker flickering** — `IconPreview` was defined inside the component body, moved to module level to prevent React remounting
- **UnifiedDataSourceConfig flickering** — `ItemBadge` (2 instances) and `DataIndicator` defined inside component bodies caused unnecessary remounts. Extracted to module-level components with `t` passed via props

---

## [v0.7.9] - 2026-05-23

### Added

- **CLI command system (neomind-cli-ops)** — New shared library crate with typed API client, unified output formatting, and full CLI commands for all 8 domains: device, dashboard, rule, extension, widget, transform, agent, message. Each domain supports list/get/create/update/delete plus domain-specific actions (device control, rule testing, agent invocation, extension marketplace, etc.)
- **AI Build Mode foundation** — `neomind-cli` packaged as Tauri external binary, enabling the agent to execute CLI commands via shell tool. Full CLI command reference injected into agent system prompt for discoverability
- **System CLI** — New `system info` command aggregating MQTT broker status, network info, and webhook URL. Broker management and help modules added
- **Telemetry stats API** — New endpoint for telemetry statistics with improved telemetry handling in backend
- **Dashboard rewrite (Phase 1–4)** — Complete frontend dashboard architecture overhaul:
  - Phase 1: New type system, API client, and Zustand store slices (CRUD + data source)
  - Phase 2: Query hooks, data source abstractions, real-time event bridge
  - Phase 3: Grid layout, widget shell, config panel, component registries
  - Phase 4: Widget adapters for all chart types, feature module barrel export

### Changed

- **useDataSource pipeline rewrite** — Refactored from 16 files to 4 focused sub-hooks (useTelemetrySource, useExtensionSource, useStoreSource, useSystemSource). Fixed extension event dynamic updates and data flow bugs
- **Agent CLI integration** — Unified flag names between shell.rs and CLI for consistency. Improved CLI completeness and token efficiency in agent prompts

### Fixed

- **Dashboard scroll white screen** — Multiple fixes: debounced Recharts ResponsiveContainer, staggered chart rendering with memoization, skipped unchanged device updates, removed overflow-anchor suppression
- **Dashboard multi-widget performance** — Fixed lag, blank widgets, and unresponsive mouse in dashboards with many components
- **Dashboard config preview** — Fixed live preview not reflecting config changes, removed forced grid aspect ratio causing component distortion, preserved component aspect ratio
- **Dashboard data source config** — Improved data source selector and configuration UI
- **Extension crash diagnostics** — Improved error reporting and fixed Windows DLL search path
- **CLI compatibility** — Fixed short option conflicts in device commands, added `--json` flag, fixed output printing, added API key auth support
- **Extension runner** — Bumped to 0.7.5 with improved crash protection

## [v0.7.8] - 2026-05-16

### Changed

- **Extension marketplace dialogs** — Converted extension detail and install dialogs to `FullScreenDialog` for better layout on all screen sizes
- **Transform Builder toolbar** — Redesigned Code step toolbar, removed step titles for cleaner UI
- **Data Explorer detail view** — Optimized list layouts and detail panel styling
- **Telemetry storage identifiers** — Unified all storage source IDs with `device:` prefix for consistency

### Fixed

- **Dashboard telemetry data sorting** — Fixed time-series data returning oldest points instead of newest when storage limit push-down was used. Added `query_range_rev()` for efficient descending-order queries. Applied stable sort across all telemetry transform paths to prevent JavaScript's unstable `Array.sort` from shuffling equal-timestamp points
- **Image history cross-metric interference** — Tightened `eventMetricMatches()` to prevent `foo.image` matching `bar.image` via last-segment comparison. Image data sources in the store change path now use content-only deduplication (same image content at any timestamp is treated as duplicate) instead of timestamp+value pair matching
- **Image history stale data injection** — Added time range validation to WebSocket and SSE event merge paths — events with timestamps outside the component's configured time range are now rejected. Fixed `findMetricValue` step 4 to require structurally similar key names instead of matching any image-like value
- **Store merge data misalignment** — `fetchTelemetryData` now only merges store values when API returns empty, preventing stale `current_values` from being stamped with `now` and displacing real latest data
- **Timestamp consistency** — All telemetry paths now use `Math.floor(Date.now() / 1000)` (integer seconds) instead of `Date.now() / 1000` (float). Fixed `extractTimestamp` in `ImageHistory` to correctly normalize seconds↔milliseconds
- **Extension marketplace install timeout** — Increased HTTP request timeout from 30s to 120s and extension startup timeout from 30s to 120s to allow heavy extensions (e.g. stream-player with 70+ FFmpeg dylibs) to complete installation
- **Update dialog reappearing after restart** — Prevented version update dialog from showing again after the app has been restarted following an update
- **AI chat message flicker** — Eliminated brief content flash when AI streaming completes and the final message replaces the streaming state
- **CI build warnings** — Resolved event capability test timeout and remaining build warnings

## [v0.7.7] - 2026-05-15

### Added

- **Data retention configuration** — New `GET/PUT /api/settings/retention` and `POST /api/settings/retention/cleanup` endpoints for automatic telemetry cleanup. Configurable retention period (never–90 days), image data retention, cleanup interval, and manual trigger
- **Preferences UI — Data Management** — New data management section in Settings > Preferences with auto-cleanup toggle, retention period selector, image data retention selector, and manual cleanup button
- **Extension FFI timeout protection** — Added `safe_ffi_call_with_timeout` with 30-second limit for all extension FFI calls, preventing hung extensions from blocking the runner
- **Extension event queue backpressure** — Event queue now capped at 1000 entries; oldest events dropped with warning log when queue is full

### Changed

- **Server startup parallelization** — Split initialization into Phase A (parallel store opening via `spawn_blocking`) and Phase B (background services). All redb stores (rule, agent, dashboard, instance, extension) open concurrently, reducing cold-start time
- **Concurrent extension loading** — Extension loading now uses bounded parallelism (`Semaphore(4)`) instead of sequential loading
- **Lazy GPU detection** — GPU info collected on first `/api/stats` request instead of at startup, eliminating startup delay on systems without GPU
- **Frontend cache eviction** — `useDataSource` now enforces max cache sizes with FIFO eviction for system stats, telemetry, and extension data caches
- **Extension stream lifecycle** — Added `destroy()` method for complete client cleanup; proper subscription handler cleanup on reconnect
- **Robust dashboard conversion** — `positionFromDTO` returns safe defaults for missing/malformed position data; better validation of component DTOs

### Fixed

- **Integration test redb lock conflict** — `ExtensionStore::open` now supports `:memory:` mode (isolated temp DB per call); `new_for_testing()` uses `:memory:` to eliminate parallel test file lock failures (87/87 tests passing)
- **Backend switching race condition** — `set_active` now holds a DashMap guard to prevent concurrent instance removal during active backend switch
- **Channel handler error handling** — Replaced `expect("Just created")` / `expect("Just updated")` with proper `ok_or_else` error responses in channel CRUD handlers
- **Dashboard scroll white screen** — `ChartContainer` replaced ResizeObserver + useState with pure CSS (`minHeight: 120`), eliminating the first-frame blank render. Grid items use `content-visibility: auto` with `contain-intrinsic-size: 300px` to prevent GPU texture exhaustion during fast scrolling
- **Chart component deduplication** — Extracted shared `toTelemetrySource`, `getDeviceName`, `getPropertyDisplayName`, `getSeriesName`, and `ChartTooltip` from LineChart/BarChart/PieChart into shared modules (~300 lines removed)
- **Cache implementation unified** — `useDataSource` telemetry cache migrated from raw Map + manual TTL/eviction to `TypedCache` with metadata support, unified with system stats and extension caches (~70 lines removed)

### Removed (Dead Code Cleanup)

- **Legacy `LlmBackend` trait** — Removed unused trait from `neomind-core` along with `LlmConfig`, `GenerationResult`, `StopReason`, `GenerationStream` types (0 implementations, fully replaced by `LlmRuntime`)
- **`TokenizerWrapper`** — Removed empty placeholder module (`llm_backends/tokenizer.rs`), never had a real implementation
- **`ContextRelevance::Low`** — Removed unused enum variant that was never constructed or matched
- **`StorageResult.source`** — Removed unused `'local' | 'api' | 'cache'` field from frontend persistence types (set 28 times, never read)
- **Dead functions/constants** — Removed 10 `#[allow(dead_code)]` items: `filter_simplified_tools`, `AsyncThinkStorage`, `AggressiveMockLlm`, `COMPOUND_SEPARATORS`, `MAX_TOOL_CALLS_PER_REQUEST_DEFAULT`, `DEFAULT_CONTEXT_TOKENS`, `extract_conversation_entities_topics`, `build_memory_injection_hint`, `detect_complex_intent_with_llm`, `is_complex_multi_step_intent_fallback`
- **Dead struct fields** — Removed `MessageManager.data_dir`, `MqttMapping.capabilities`, `HttpPollingTask.error_count`, `ExtensionStreamEvent::Heartbeat` variant
- **Unused example files** — Removed 5 dead examples from `crates/neomind-devices/examples/`
- **Incorrect `#[allow(dead_code)]` annotations** — Cleaned from `IsolatedExtensionLoader.native_loader` (actively used), `StreamEvent`, `CloudDeviceTypesIndex`

### Fixed

- **Integration test redb lock conflict** — `ExtensionStore::open` now supports `:memory:` mode (isolated temp DB per call); `new_for_testing()` uses `:memory:` to eliminate parallel test file lock failures (87/87 tests passing)
- **Clippy warnings** — Auto-fixed ~57 clippy issues: unnecessary `to_string`, redundant closures, `and_then→map`, `filter_map→map`, `map_or` simplification, `strip_prefix`, `is_multiple_of`, empty lines after doc comments

## [v0.7.6] - 2026-05-14

### Performance

- **WKWebView dashboard rendering** — Replaced `translate3d(0,0,0)` with `content-visibility: auto` + `isolation: isolate` + `contain: layout paint` to prevent GPU compositing layer exhaustion during loading/scrolling, eliminating white screen flash on Tauri macOS
- **Sparkline render optimization** — Extracted `SparklineContent` to top-level `memo`-wrapped component to prevent remount on each parent render; wrapped `Sparkline` export in `React.memo` to skip reconciliation when props unchanged
- **DashboardGrid render optimization** — Removed `devicesLength` from `gridComponents` useMemo dependency to prevent 3-second full rebuild on unrelated device changes
- **Limit push-down to storage** — Added `limit: Option<usize>` parameter through `query_telemetry` → `query_limited` → `query_range` chain, capping data allocation at the storage layer instead of filtering after full read
- **N+1 query elimination** — Replaced per-metric `latest()` loops with single-transaction `latest_batch` in `get_current_metrics`, reducing storage transactions linearly with metric count
- **Cold-start metrics warmup** — `list_metrics` now caches results in `metrics_info` DashMap after the first cold-start range scan, skipping full-table scans on subsequent calls
- **Debounced dashboard persistence** — `storage.sync` debounced to 500ms trailing window to coalesce rapid drag/resize events into a single API call
- **HTTP timeout layers** — Added `RequestBodyTimeoutLayer(20s)` nested inside `TimeoutLayer(30s)` to prevent slow-client DoS while preserving proper LIFO semantics
- **Code deduplication** — Extracted `createStableKey` utility from 3 duplicate implementations into shared `@/lib/stable-key.ts`

### Fixed

- **Timeout layer ordering** — Swapped `TimeoutLayer(30s)` and `RequestBodyTimeoutLayer(60s)` so the body timeout (20s) fires before the overall request timeout (30s), per Tower LIFO middleware semantics
- **Cold-start `list_metrics` returning empty** — Removed early-return guard that prevented the fallback range scan from running after server restart; added `metrics_initialized = true` after both `list_metrics` and `list_all_metrics_grouped` fallback scans
- **`moveComponent` stale closure** — Replaced separate `moveDebounceTimer` with shared `scheduleSync()` mutable-ref pattern to capture latest dashboard state during rapid drag operations
- **`handleIdChange` dashboard overwrite** — Added `activeDashboardId` guard to only update `currentDashboard`/`currentDashboardId` when the user hasn't switched away during sync
- **Sparkline const between import blocks** — Moved `SVG_OVERFLOW_VISIBLE` style constant to after all imports to satisfy linter
- **LoadingState animation** — Restored missing `animate-pulse` on loading skeleton placeholder
- **Removed unused `AlertCircle` import** from `DefaultStates.tsx`
- **Flaky test** — Added `flush()` method to `TimeSeriesStorage`/`ExtensionMetricsStorage` and call it in `test_extension_storage_write_query` to drain write buffer before asserting query results

### Chore

- **Gitignore** — Added `.worktrees/` for git worktree isolation

## [v0.7.5] - 2026-05-13

### Added

- **Unified execution engine: Focused / Focused+ / Free** — Focused mode agents can now opt into tool calling via the `enable_tool_chaining` toggle, creating a "Focused+" mode that combines pre-collected data with multi-round tool queries. The `run_tool_loop` engine is shared across Free (30 rounds, full autonomy) and Focused+ (configurable rounds, recommended tool guidance). Original Focused JSON path preserved as fallback when tool chaining is disabled
- **ToolLoopConfig** — New configuration struct driving the tool loop with mode-specific parameters: `max_rounds` (30 for Free, `max_chain_depth` for Focused+) and `recommended_tools` (prompt guidance extracted from bound resources for Focused+, unrestricted for Free)
- **Focused mode tool chaining toggle** — Agent editor shows an "Enable Tool Chaining" switch under Focused mode, persisted via `enable_tool_chaining` field. Hidden when Free mode is selected
- **Focused+ grouped resource prompt** — Focused+ system prompt groups bound resources by type (metrics with current values, commands) and provides a lightweight snapshot table instead of dumping raw pre-collected JSON. LLM is guided to use `device(action="history")` for historical queries, eliminating the need for manual `time_range` / `include_history` configuration
- **Data Collection config hidden for Focused+** — When tool chaining is enabled, the per-resource Data Collection config panel (time range, include history) is hidden since the LLM queries what it needs via tools
- **Adaptive time-series compression for device history** — `device(action="history")` now returns one of two formats, automatically picking the smallest: compact values array (`{"values": [...]}`) or adaptive series (`{"series": [{"range": "...", "kept": 12.0}, {"range": "...", "fluctuated": [12.5, ...]}]}`). Stable periods compress to single `"kept"` entries, significantly reducing token usage for the LLM
- **Mid-task context compaction** — When agent memory exceeds 70% of the context budget during long ReAct loops, old tool execution rounds are automatically summarized into a structured progress summary. Keeps recent rounds intact, preventing context overflow mid-task
- **Actual prompt overhead measurement** — Context window budget now measures real system prompt + tool definition tokens instead of using fixed percentage heuristics. Allocates `model_capacity - overhead - 1024` for history with a 20% safety floor
- **Agent summary API** — New `GET /api/agents?view=summary` endpoint returning lightweight `{id, name, status}` for dashboard dropdowns, replacing full agent payload
- **LargeDataCache eviction** — Cache now enforces max 20 entries and 50MB total. Oldest entries evicted automatically when limits are exceeded
- **Release build profile** — Added LTO thin, codegen-units=1, strip, opt-level=3 for smaller optimized binaries

### Changed

- **Time-series write buffering** — Single-point writes are now batched in an in-memory buffer (200 points, 500ms flush interval) and flushed to redb as batched transactions, significantly improving high-frequency device telemetry throughput. Flush is offloaded to `spawn_blocking` to avoid blocking the async runtime
- **Async storage I/O** — `MessageStore` operations (`insert`, `update`, `delete`, `list`) now have `*_async` wrappers that offload blocking redb I/O to `spawn_blocking`, preventing tokio runtime stalls
- **Batch delivery log writes** — Message delivery logs are collected per send cycle and written in a single lock acquisition, reducing lock contention
- **Tool response ID naming** — All aggregated tool responses now use explicit field names (`device_id`, `agent_id`, `rule_id`, `message_id`, `extension_id`) instead of generic `"id"`, improving LLM clarity
- **Token estimation consolidation** — Unified `estimate_tokens` and `estimate_message_tokens` into `tokenizer` module. Thinking content is correctly excluded from token counts (not sent to LLM)
- **Tool result compaction thresholds** — Increased keep threshold from 4KB→8KB, data-action preview from 300→2048 chars, and `CompactionConfig.max_message_length` from 8K/6K→32K/16K to preserve compact time-series format intact
- **Ollama thinking timeout guard** — Added `!skip_remaining_thinking` check to prevent repeated timeout warnings. Added 180s hard limit after timeout — terminates stream if model is stuck in thinking loop
- **ExtensionStore singleton** — `ExtensionState` now holds a shared `Arc<ExtensionStore>` instead of opening the database per call in `load_from_storage` and error handling paths
- **Error handling improvements** — `IsolatedExtension::new` uses `ok_or_else()` instead of `expect()` for child process stdin/stdout/stderr. API handlers use `From` conversion with `?` instead of `.map_err()`
- **InFlightRequests lock optimization** — Send response outside the mutex critical section, reducing lock hold time
- **Shared `ExtensionStore` in state** — `ExtensionState` constructors now accept `Arc<ExtensionStore>`, eliminating redundant `open()` calls in `load_from_storage` and auto-discovery
- **Image insight extraction** — Rewritten to use char-level operations for UTF-8 safety. Image analyses deduplicated by content fingerprint to prevent memory bloat
- **Agent panic protection** — `execute_agent` now catches panics via `catch_unwind` and converts them to Failed execution records instead of crashing the scheduler

### Fixed

- **Dashboard widget loading flash** — All 8 generic dashboard components (ValueCard, LineChart, BarChart, PieChart, Sparkline, ProgressBar, LEDIndicator, AgentMonitorWidget) now use `showLoading = loading && !hasData` pattern, preventing skeleton flash during periodic telemetry refreshes
- **DashboardGrid blank first frame** — Initial container width measurement now uses `useLayoutEffect` instead of `useEffect`, eliminating the blank frame caused by width 0 → measure → re-render
- **Dashboard DTO type safety** — Refactored `fromDashboardDTO` / `toDashboardDTO` to eliminate all `any` casts. Proper `ComponentDTO` interface, discriminated `GenericComponent`/`BusinessComponent` handling via `isGenericComponent()`
- **i18n fallback** — Removed hardcoded `lng: 'en'` default, allowing proper browser language detection. Settings tab labels now correctly use `settings:` namespace prefix
- **Agent config state injection** — Removed fragile `_agentsList`/`_visionModelsList` injection pattern in `componentConfig`. Dashboard now reads agent/model lists directly from component state
- **Extension sync consolidation** — Merged three separate extension sync effects in `App.tsx` into two cleaner effects (immediate on auth + periodic 60s timer)
- **Pending devices broker check** — Now checks both built-in MQTT broker (`connected`) and external brokers, instead of only external
- **Export dialog tree-shaking** — `xlsx` and `jszip` now loaded via dynamic `import()`, reducing initial bundle size
- **useDataSource cache leak** — Added `beforeunload` cleanup for the telemetry cache interval, preventing HMR interval accumulation in development
- **UTF-8 safe truncation** — Text truncation in agent prompts now correctly handles multi-byte characters at sentence boundaries, preventing panics on non-ASCII content
- **Agent editor state reset** — Creating a new agent now correctly resets `enableToolChaining` to prevent stale state from previous edits

## [v0.7.4] - 2026-05-11

### Added

- **Extension device management API** — Extensions can now register device type templates and device instances via new capabilities `DeviceTemplateRegister`, `DeviceRegister`, `DeviceUnregister`. Enables extensions to act as virtual device adapters
- **Extension command routing** — `DeviceService` now routes commands for extension-registered devices (adapter_type="extension") back to the owning extension via an `ExtensionCommandRouter` callback
- **Extension log viewer** — New `GET/DELETE /api/extensions/:id/logs` endpoints. Extensions capture stderr into a ring buffer (500 lines) with structured log entries (timestamp, level, message), viewable from the frontend details dialog
- **Extension crash recovery with config restore** — After crash recovery restart, the system automatically re-applies the extension's saved configuration from the extension store
- **Extension config_parameters support** — Extension runner now parses `config_parameters` from metadata JSON, enabling extensions to declare their configuration schema
- **Device metric update sets last_seen** — Reporting metrics from an extension now updates the device's `last_seen` timestamp, preventing "Never Connected" false status
- **Extension details full-screen dialog** — `ExtensionDetailsDialog` redesigned as `FullScreenDialog` with sidebar navigation: Overview, Configuration, Logs, Metrics, Commands — replacing the old tabbed modal
- **Extension SDK v0.6.3** — New `register_template()`, `register_device()`, `unregister_device()` functions for device management from extensions
- **Dashboard sharing system** — Full-featured share link management for dashboards: create links with read-only or interactive permissions, set expiration (1h–30d), copy/revoke links. Backend proxy forwards API requests via `x-internal-proxy` header for auth bypass. Shared dashboards render using the same component pipeline as the main dashboard
- **ShareManagerDialog** — New full-screen dialog for managing share links with "Add Share" dashed card pattern. Creation form in nested `UnifiedFormDialog` (z-[110])
- **Dashboard DualModeSourceField** — New dual-mode data source selector supporting both extension metrics and device metrics. Video-display component supports device-metric binding
- **Component library FullScreenDialog** — Replaced Sheet-based component library picker with `FullScreenDialog` for better space and consistency
- **Community component marketplace** — Backend API for browsing, installing, and managing community dashboard components. Manual install via file upload supported. New `FrontendComponentStore` for filesystem-based component storage
- **Marketplace browser & import UI** — `ComponentMarketplace` full-screen dialog for browsing and installing marketplace components with one-click install/uninstall. `InstallComponentDialog` for manual component import via file upload (manifest.json + bundle.js)
- **Frontend component runtime** — `CommunityRegistry`, `ComponentRenderer`, Zustand store slice for frontend components. WebSocket event system and lifecycle hooks for community components
- **Device binding for components** — Dashboard components can bind to devices via `deviceBinding` config. Bound components receive `deviceContext` (device info, current values) and `sendDeviceCommand` function. `DeviceBindingConfig` panel for selecting bound device and command parameters
- **Extension `has_device_binding` flag** — Extension components declare device binding support via `has_device_binding` in component definition

### Changed

- **Migrate to parking_lot locks** — Replaced `std::sync::RwLock`/`Mutex` with `parking_lot` equivalents across all backend crates (~80 lock `.unwrap()` calls eliminated). parking_lot locks never poison, removing a class of potential panics
- **Replace ExtensionStats API with ExtensionLogs API** — Removed `GET /api/extensions/:id/stats` and `ExtensionStatsDto`. Replaced with the new log viewer endpoints. Frontend store updated accordingly
- **ExtensionCard redesign** — Simplified from 570-line component to 148 lines by extracting details into `ExtensionDetailsDialog`
- **Fix unsafe error handling** — `shell.rs` now checks return values of `killpg` (Unix) and `TerminateProcess` (Windows) with logging on failure
- **Fix business logic unwrap()** — Replaced ~25 `unwrap()` calls in production code with `expect()`, `unwrap_or()`, or proper error propagation
- **Fix agent semaphore panic** — Tool concurrency semaphore closure now returns an error instead of panicking
- **Fix clippy -D warnings** — Resolved `is_multiple_of`, `Default` impl, `or_insert_with`, `map_or`, wildcard pattern, and `from_str` → `parse_category` naming issues
- **Fix broken test** — `test_cursor_decode_invalid_utf8` assertion corrected
- **Fix extension uninstall dialog** — Uninstall confirmation now correctly shows the extension name instead of literal `{{name}}`
- **Fix extension grid props** — Corrected `onConfigure` → `onDetails` prop name to match `ExtensionGrid` API
- **Bump version to 0.7.4** — Updated workspace, extension-runner, web, Tauri versions. Bumped extension-sdk to 0.7.0
- **Dashboard header buttons reordered** — Edit → Add Component → Share (Share moved to rightmost position). All buttons use `rounded-md` for consistent smaller border radius
- **"Add" button label** — Changed from "Add" to "Add Component" for clarity
- **Device re-registration** — `DeviceRegistry::register()` now updates existing devices in-place instead of returning `AlreadyExists` error, enabling idempotent extension re-registration
- **Fix last_seen timestamp unit** — Extension metric updates now use seconds instead of milliseconds for `last_seen`, matching device registry expectations
- **Device command dialog spacing** — Increased spacing between form fields in command control dialog for better readability
- **Dashboard sidebar alignment** — Fixed header alignment and markdown content padding in dashboard sidebar
- **Security: protected routes** — Moved sensitive APIs (LLM backends list, etc.) from public to protected routes. Removed `skipAuth` from frontend API calls that should require authentication

## [v0.7.3] - 2026-05-08

### Added

- **Relative Time Range for Tool Queries** — New `time_range` parameter for device, rule, message, and ai_metric tools. Supports human-readable strings like `"30min"`, `"1h"`, `"1d"`, `"1w"`, `"2w"` instead of Unix timestamps, solving small model timestamp calculation errors
- **Guided Error Messages** — All tool errors now include natural language guidance (e.g., entity not found → suggest list action, unknown action → show valid actions, operation failures → suggest next steps)
- **Time-Range Query Prompt** — Prompt builder now includes explicit time-range guidance to help small models correctly choose `history` action with `time_range` for time-based queries

### Changed

- **Tighter ReAct Loop Duplicate Detection** — Stop after 1 consecutive duplicate round (was 2), lower already-executed threshold to 50% (was 60%), add message_id/extension_id to signature checks
- **Stronger Inter-Round Context** — Multi-round context prompt now uses "STOP AND THINK" pattern to prevent small models from re-calling same tools with identical arguments
- **Device Tool Description** — Enhanced with stronger time-range keywords and examples to improve small model action selection accuracy

### Fixed

- **Repeated Tool Calls** — Fixed small models repeatedly calling same tool (e.g., `message(list)` 3 times in a row) by tightening loop detection and improving inter-round prompts
- **Wrong Action for Time Queries** — Fixed models using `device(list)` instead of `device(history)` when user asks about trends or time ranges

### Removed

- **Dead Code** — Removed unused `ToolOutput::error_with_data()` method
- **Chinese Hardcoding** — Replaced all hardcoded Chinese text in code with English (aliases, error messages, examples, test assertions)

---

## [v0.7.2] - 2026-05-06

### Added

- **Multi-Instance Management** — Connect to and switch between multiple NeoMind backends (local + remote) with full-screen instance manager dialog, instance selector pill in navigation bar, and animated switch overlay
- **Instance CRUD API** — REST endpoints (`/api/instances`) for creating, listing, updating, deleting, and testing remote backend instances with API key authentication
- **Instance Storage** — Persistent storage for remote instance metadata in `instances.redb` (redb-backed)
- **Unified Auth Verification** — New `GET /api/auth/verify` endpoint that accepts both JWT and API key authentication, used for pre-switch key validation
- **API Key Pre-Validation** — Instance switching validates API keys against the remote backend before switching, preventing broken states with clear error messages
- **API Key Form Validation** — Instance add/edit form validates API keys in real-time against the remote instance before saving, with visual feedback (check/error icons)
- **Remote Instance UX** — Instance manager hides management actions (add/edit/delete) when connected to a remote instance, shows contextual hint banner
- **CLI API Key Management** — `neomind api-key create/list/delete` commands for managing API keys from the command line with custom data directory support
- **Auth Data Dir Support** — `AuthState::new_with_data_dir()` for CLI tools to use custom data directories for API key storage
- **Persistent Encryption Key** — Encryption key for API key storage auto-generated and persisted to `data/encryption_key` file, survives server restarts without needing `NEOMIND_ENCRYPTION_KEY` env var
- **Encryption Key Fallback Chain** — `CryptoService` now follows priority: env var → persistent file → generate + save, ensuring API keys remain valid across restarts

### Fixed

- **Infinite API Loop on Devices Page** — TransformsBadge and DeviceTransformsDialog fetched devices, device types, and transforms on every mount, causing N×3 redundant API calls per page load. Fixed with conditional dialog rendering (`{open && <Dialog />}`) and shared `fetchCache` for transform list queries
- **Mobile Content Top Padding** — Extensions and Settings pages had inconsistent top spacing compared to other pages. Unified mobile content padding to `pt-2` in PageLayout
- **Mobile Action Button Inconsistency** — Page action buttons used different sizes (`h-8 text-xs` vs `h-9 text-sm`) on mobile. Unified all page action buttons to use standard `size="sm"` for consistent appearance
- **Extensions Page Header Layout** — Moved Extensions page action buttons into `headerContent` slot for consistent fixed positioning with other tabbed pages
- **WebSocket Infinite Reconnect Loop** — Switching to a remote instance with an invalid API key caused WebSocket to repeatedly fail auth → reload page → fail again. Fixed by separating API key errors (disconnect without reload) from JWT errors (reload to re-login)
- **WebSocket Close Code for Auth** — Server now sends close code `4001` for WebSocket auth rejections, allowing the client to distinguish auth failures from normal disconnects
- **API Key Not Clearing on Edit** — Clearing the API key field in instance edit form didn't remove the key (empty string was sent as `undefined`). Fixed: frontend sends empty string, backend treats it as `api_key = None`
- **Stale Zustand Persist Cache** — Old `currentInstanceId` from Zustand persist could override localStorage-based instance selection after page refresh. Fixed with persist version bump (v2) and migration that removes the stale field
- **Validation Icon Layout Shift** — API key validation icon (checkmark/error/spinner) caused input field width to shift. Fixed by reserving space with `pr-8` padding on the input
- **Remote Instance Shows Offline** — Instance selector always showed offline for remote instances because `isAuthenticated` only checked JWT token, not API key. Fixed `checkAuthStatus` to recognize API key as valid authentication, enabling WebSocket connections for remote instances
- **Login Page Stuck on Remote Instance** — Switching to a remote instance with API key from login page stayed on login instead of redirecting to dashboard. Login page now detects API key auth and redirects immediately
- **Stale Instance Cache After Edit** — Editing an instance (e.g. clearing API key) updated the Zustand store but not the localStorage cache (`neomind_instance_cache`), causing login page to use stale data. Fixed: all instance CRUD operations now sync to localStorage cache immediately
- **API Key Stored in Plaintext in Browser** — Backend now returns masked API keys (e.g. `nmk_abc1****`) in list/get/update responses. Full keys are held only in JavaScript memory during the add/edit session and never persisted to localStorage. Edit form shows masked key with option to clear or replace
- **Failed Switch Doesn't Revert** — Dismissing the error overlay after a failed instance switch left `currentInstanceId` pointing to the unreachable target, causing reconnection attempts on next refresh. Fixed: `clearSwitchingError` now reverts to the previous instance
- **revertSwitch Could Get Stuck** — If the instance list was empty after switching to a remote instance, reverting failed silently. Fixed: `revertSwitch` now falls back to `getCachedInstances()` when the in-memory list is empty
- **Duplicated localStorage Key Constants** — Instance-related localStorage keys were defined independently in `instanceSlice.ts` and `login.tsx`. Extracted to shared `instance-constants.ts` module

### Changed

- **Dynamic API Base URL** — Refactored `getApiBase()` to support runtime URL switching via `setApiBase()` for multi-instance support, extracted URL/key utilities to `urls.ts`
- **WebSocket/SSE/Extension Stream Auth** — All real-time connections support both JWT token and API key authentication. API key sent as query parameter for WebSocket/SSE, enabling passwordless access to remote instances
- **ProtectedRoute Accepts API Key** — Frontend route guard allows access when either JWT token or API key is present, enabling passwordless remote instance access
- **Connection Status → Instance Selector** — TopNav connection status indicator replaced with instance selector pill showing current instance name and connectivity status
- **Instance Manager Full-Screen Dialog** — Instance list opens as full-screen dialog (replacing dropdown) for better usability on mobile and desktop
- **Login Page Instance Selector** — Login page includes instance selector dropdown using cached instance list, allowing connection to remote backends before authentication
- **Setup Wizard Split** — Setup wizard pages extracted into separate files under `web/src/pages/setup/` for maintainability

---

## [v0.7.1] - 2026-05-04

### Added

- **BLE Provisioning** — Zero-touch device setup via Bluetooth Low Energy with dual transport support (Tauri native BLE via btleplug + Web Bluetooth API)
- **BLE Device Config Read** — Read device info (MAC, SN, model, netmod type) from BLE characteristic on connect for pre-filling configuration
- **BLE Netmod Support** — Adapt provisioning UI based on device network module type (WiFi / HaLow / Cat.1 cellular), hide WiFi config for Cat.1 devices
- **BLE Re-provisioning** — Update existing device info (name, broker, MQTT config) when re-provisioning via BLE; show "Configuration Updated" success message
- **BLE Device Name Sync** — Write user-specified device name to firmware storage during BLE provisioning
- **BLE Preparation Guide** — Step-by-step instructions on scan page to guide users through the provisioning flow
- **Auto Discovery Broker Guidance** — Contextual empty state in Pending Devices that guides users to add MQTT broker in Settings
- **Network Info API** — `GET /api/system/network-info` returns WiFi SSID and LAN IP for BLE provisioning

### Fixed

- **Device Type Dropdown Loading** — Add Device dialog now fetches device types on open instead of relying on stale cache
- **WebSocket Not Auto-Recovering** — Added missing `online` event listener for network recovery and reset `isManualDisconnect` flag in `connect()`
- **WebSocket Disconnected After Page Refresh** — Auth state initially false caused disconnect flag to stick, blocking reconnect
- **About Page Memory Progress Bar** — Used `bg-*` classes instead of `text-*` for progress bar fill color
- **Layout Flicker on Page Switch** — Responsive hooks (`useIsDesktop`, `useIsMobile`, `useIsTouchDevice`, `useDeviceType`) now read `window.innerWidth` synchronously on first render
- **Focus Ring on Click** — Suppressed `:focus-visible` ring on mouse clicks in Tauri/Chromium
- **BLE WiFi SSID 404** — Fixed frontend calling non-existent `/system/wifi-ssid` endpoint → use registered `/system/network-info`
- **BLE Success Screen** — Deferred `onComplete` callback to done phase close button instead of closing dialog immediately on apply
- **BLE MQTT Characteristic Optional** — Handle older firmware without MQTT characteristic gracefully
- **BLE Empty WiFi Password** — Allow empty password for open WiFi networks

### Changed

- **BLE Two-Phase Provisioning** — Split into resolve-only (get MQTT config) → BLE write → register device, preventing phantom devices on BLE failure
- **BLE Scanned Device Cards** — Display MAC address instead of model name for easier device identification
- **Pending Devices Table** — Removed column header icons for cleaner appearance
- **Add Device Dialog Icons** — Updated tab and header icons for better semantic meaning

---

## [v0.7.0] - 2026-04-28

### Added

- **API Input Validation** — All POST/PUT endpoints validate parameters before processing
- **Settings Persistence** — Settings saved to redb database, survive server restarts
- **MQTT Topic Unsubscription** — Custom MQTT topics can be unsubscribed via API
- **Empty State Guidance** — All list pages show helpful guidance when empty
- **Confirmation Dialogs** — Destructive operations require explicit confirmation
- **Form Validation** — Agent, device, and rule editors validate input with inline error messages
- **Error Boundaries** — React Error Boundaries for graceful page failure handling
- **User-Friendly Error Messages** — Toast notifications show clear messages instead of raw errors
- **AI Analyst Display Title** — Agent name in dashboard widget linked to Display Title from agent config
- **JWT-Based Rate Limiting** — Per-user rate limiting with JWT client identification
- **Backend-Ready Event** — Tauri desktop startup uses event-based ready detection instead of polling
- **Aurora Background & Glass Morphism** — App-wide aurora gradient background layer with glass-style TopNav and PageLayout footer
- **OKLCH Color System** — CSS color tokens migrated from HSL to OKLCH for perceptually uniform color scales
- **Harmonized Accent Tokens** — OKLCH-based category accent colors (purple, orange, teal, rose) with consistent light/dark variants
- **Design System Tokens** — Centralized Tailwind config tokens for borders, radius, shadows, and layout spacing
- **Frontend Design Specification** — Comprehensive `DESIGN_SPEC.md` documenting all UI patterns, tokens, and conventions
- **Plus Jakarta Sans & Noto Sans SC Fonts** — New typography with Latin and CJK support
- **UnifiedFormDialog** — Centralized dialog component handling mobile/desktop, portal, escape key, backdrop click, and z-index extraction for backdrop sync
- **Chart Color Palette Redesign** — Visually distinct, accessible chart colors with better contrast

### Changed

- **Error Handling** — Replaced 1000+ hot-path `unwrap()` calls with safe error propagation across 8 crates
- **Pagination** — Standardized default page size to 10 across all pages
- **Loading States** — All page-level loading uses skeleton screens instead of spinners
- **Notifications** — Replaced `alert()` with toast notifications throughout the UI
- **Event Trigger Cooldown** — Default changed from 5s to 60s (configurable)
- **Frontend Visual Unification** — Unified visual style and component consistency across 109 frontend files
- **Centralized API Layer** — Standardized all frontend API calls through centralized `api.ts`, eliminating scattered `fetch()` calls
- **DashMap for Device Registry** — Replaced `RwLock<HashMap>` with `DashMap` for lock-free concurrent device operations
- **Lazy Telemetry Loading** — Telemetry data fetched on demand (detail view) instead of eagerly on page load
- **Rate Limit** — Raised to 5000/min for edge device workloads; frontend retries on 429
- **Design Token Migration** — All hardcoded Tailwind palette colors (blue-500, green-600, etc.) replaced with semantic design tokens (text-success, bg-error-light, text-accent-orange, etc.) across entire frontend
- **Dialog Consolidation** — 29 form dialogs migrated from raw Radix Dialog to UnifiedFormDialog with consistent behavior
- **Chat Welcome Page** — Redesigned welcome screen with improved layout
- **Checkbox Unification** — All checkbox components consolidated to use shared `Checkbox` from `ui/checkbox`
- **Vertical Stepper Redesign** — Improved step indicator with better visual hierarchy
- **Map Component** — Device icon click no longer navigates away; shows toast notification instead
- **Shared Layout Tokens** — Extracted reusable tokens for dashboard cards, dialog headers, and section layouts

### Performance

- **API Polling Storms** — Eliminated continuous polling from data explorer (debounced events), telemetry hooks (retry limit + throttle), and extension components (conditional polling)
- **N+1 Telemetry Queries** — Replaced N+1 pattern with single table scan in data sources API
- **Message Manager Lock Contention** — Write locks released before disk I/O, reducing p99 latency from 700ms
- **Session RwLock Contention** — Session resolution clones data and drops lock before async operations
- **Agent Execution Query** — Direct lookup by ID instead of fetching 100 records + linear search
- **Device Registry Concurrency** — `DashMap` eliminates lock contention for concurrent device reads/writes
- **Agent Editor Responsiveness** — Dialog opens immediately; resources loaded in background; validation on submit only
- **Blocking Call Chain Elimination** — Removed 25 blocking patterns across 28 files (frontend and backend)
- **Batch API Requests** — Frontend batches telemetry and data source requests to reduce HTTP overhead
- **Extension Polling** — YOLO device inference extension only polls when device binding is active
- **Fetch Deduplication** — TTL-based cache (10s) in Zustand store prevents redundant API calls on page remount; WebSocket device status events use optimistic updates instead of full refetch

### Fixed

- **Rule Engine** — Catch-all error recovery prevents scheduler crashes
- **Console Cleanup** — Removed 130+ non-essential console statements from frontend
- **Extension Runner** — Improved crash loop detection and panic handling
- **Session Flicker & Tab Jumping** — Fixed race conditions in chat session switching and tab state sync
- **Focus Management** — Proper auto-focus on dialog open, search input sync, CLS (Layout Shift) prevention
- **Delete Confirmation** — Consistent border-radius and confirmation dialogs for destructive actions
- **JWT Expiration** — Client-side token expiration check prevents 401 error storms from expired tokens
- **Base64 Image Handling** — Robust cleaning with re-encoding for Ollama compatibility
- **Thinking Model Compatibility** — Disabled thinking mode in agent analyzer; made `importance` field optional in memory compression response
- **Agent Editor Input Lag** — Validation runs on submit instead of every keystroke
- **Automation Page Duplicate Loading** — Prevented duplicate resource loading on automation page navigation
- **Recharts Console Warnings** — Suppressed width/height -1 warnings from responsive charts
- **Startup Health Check** — Uses HEAD method instead of GET; increased timeout for reliability
- **Telemetry Time Range** — Frontend time range aligned with backend 30-day limit
- **User Prompt Length** — Lowered minimum from 10 to 1 character for short messages
- **Dashboard First-Load Race Condition** — Components no longer show "Failed to Load Data" on initial load; deferred data fetching waits for device list to be available before showing error state
- **Nested Dialog Z-Index** — All dashboard child dialogs (Map Editor, Layer Editor, Center Picker, AI Analyst, Agent Monitor, Command Button) now render above FullScreenDialog (z:100) using z-[110]
- **Dialog Backdrop Z-Index** — UnifiedFormDialog extracts z-index from className and applies to backdrop, fixing misaligned layering
- **Dark Mode Dialog Border** — Added visible border to UnifiedFormDialog for clear edge distinction in dark mode
- **Tailwind v3 Opacity Modifiers** — Fixed all broken CSS variable opacity modifiers (bg-primary/10 silently fails); replaced with pre-defined tokens (bg-muted-30, bg-success-light) and inline styles
- **Select Text Alignment** — Fixed text alignment in Select/Combobox components
- **Dropdown Z-Index** — Fixed dropdown menus appearing behind other UI elements
- **Nav Z-Index Conflict** — Fixed TopNav layering conflict with content below
- **Aurora Background Rendering** — Fixed CSS selector issues and glass surface rendering

### Removed

- **Swagger/OpenAPI (utoipa)** — Removed unused utoipa dependencies and auto-generated spec code

### Testing

- Added comprehensive unit tests to neomind-storage (42+ new tests)
- Added comprehensive unit tests to neomind-agent (125+ tests in tools module)
- Added comprehensive unit tests to neomind-rules (93+ new tests for DSL parser and engine)
- Added comprehensive unit tests to neomind-messages (118+ total tests)
- Added comprehensive unit tests to neomind-extension-runner (79+ new tests)
- Added comprehensive unit tests to neomind-api (24 validation tests)

---

## [v0.6.12] - 2026-04-26

### Added

- **VLM Vision Dashboard Component** — New `vlm-vision` dashboard component for real-time visual analysis using VLM (Vision Language Model) models. Streams camera/video frames to LLM backends for scene understanding, object detection, and visual Q&A directly on the dashboard.
  - `useVlmSession` hook with WebSocket streaming for low-latency frame-by-frame analysis
  - `useVlmQueue` hook with drop-intermediate-frame strategy to keep only the latest frame
  - `useVlmModels` hook for listing available LLM backends as vision models
  - `VlmMessageBubble`, `VlmTimeline`, `VlmInputBar`, `VlmConfigPanel` UI components
  - Full Zustand slice for VLM session state management
  - Registry-based component library with automatic category grouping
  - Config dialog with data source binding (device metrics, extensions, AI metrics), model selector, system prompt, and context window settings
  - i18n support (English/Chinese)

- **Event-Driven Agent Triggers for Extensions** — Agents can now be triggered by extension output events, not just device metrics. This enables agents to react to AI analysis results, external API data, and custom extension outputs.
  - Unified `DataSourceRef` model (`source_type`, `source_id`, `field`) replaces device-only `EventTriggerData`
  - `check_and_trigger_data_event()` as unified entry point for all data source types
  - `matches_data_source_filter()` supporting `Device`, `Metric`, `ExtensionMetric`, `ExtensionTool` resource types
  - ExtensionOutput feedback loop prevention with source exclusion dispatch

- **Agent Status Sync** — Agent pause/activate actions now properly sync with the scheduler (pause → unschedule, activate → reschedule), ensuring UI state matches backend execution state.

- **Extension Push-Metrics API** — New `POST /api/extensions/:id/push-metrics` endpoint for device-initiated data push that immediately stores telemetry and publishes `ExtensionOutput` events to trigger downstream agents.

### Changed

- **Dashboard Component Registry** — Replaced hardcoded `getComponentLibrary()` with registry-driven approach using `groupComponentsByCategory()`, making it easier to add new component types.
- **Tauri Updater Version Comparison** — Version check now normalizes `v` prefix and whitespace before comparison, preventing duplicate update prompts when remote JSON uses `v0.6.12` format.
- **Data Source Loading Optimization** — Added `skip_telemetry` param to `/api/data/sources` to skip expensive telemetry population for bulk listing; frontend uses server-side `source_type` filtering and parallel requests; eliminated N+1 query pattern.
- **Event-Triggered Agent Cooldown** — Changed from 5s to 60s to prevent excessive LLM calls while keeping data fresh (collection stays at 60s).
- **API Retry Policy** — Frontend now retries only gateway errors (502/503/504), not 500 application errors.
- **Unified Data Source Config** — Migrated `UnifiedDataSourceConfig` from local state to Zustand store for consistency.
- **AI Analyst Session** — Enhanced `useAnalystSession` with improved data processing, multi-source value extraction, and unmount protection for API calls. Removed `useAnalystQueue` (merged into session hook).
- **Default Image Format** — Changed default camera frame format from PNG to JPEG for better bandwidth efficiency.

### Fixed

- **Recharts Chart Rendering** — Fixed "width(-1) and height(-1)" console warnings by introducing `ChartContainer` with `ResizeObserver` and explicit pixel-sized inner container, ensuring `ResponsiveContainer` always receives valid dimensions.
- **Race Condition in Agent Execution** — Fixed `get_latest_execution` querying by ID instead of potentially stale cache. Added atomic check-and-insert for scheduler concurrency. Handled `RwLock` poison gracefully instead of panicking.
- **MQTT Lock Contention** — Fixed `last_seen` read-write lock race with `try_write`; scoped dual write lock releases to prevent contention.
- **Event Bus CPU Busy-Loop** — Added `yield_now()` in `EventBusReceiver` to prevent CPU spinning.
- **Rule Engine Deadlock** — Reduced lock scope in rule engine to prevent potential deadlock.
- **Storage Consistency** — Cache updates now happen after successful DB commit, not before. LRU cache eviction optimized from O(n) to O(1).
- **Input Size Limits** — Added limits for push-metrics (100), telemetry metrics (50), extension queries (10K), agent input (100KB), and telemetry time range (30 days max).
- **Memory Leak Prevention** — Auto-cleanup for delivery logs exceeding 1000 entries. Clean empty skill index entries on removal. Extension stream clients properly cleaned on unregister.
- **Error Handling** — Return proper HTTP 500/504 for agent execution failures. Log data collection, AI metric event, and WebSocket handler errors instead of silently dropping. Handle closed semaphore gracefully.
- **AI Analyst Data Display** — Strip "produce:" prefix from extension metric field names for correct backend key matching. Extract per-metric values instead of showing raw arrays for multi-source data.
- **Data Explorer Crash** — Guard telemetry API response to prevent crash on 502/401 when `res.data` is undefined.
- **Metric Value Parsing** — Fix fallback from 0.0 to string for non-numeric metric values.
- **Console Log Cleanup** — Removed 63+ unnecessary `console.log/info/debug` calls across frontend.
- **Dead Code Removal** — Removed `DataSourceSelector`, `DataSourceSelectorContent` components, and unused system memory extraction code from agent executor.

---

## [v0.6.11] - 2026-04-21

### Added

- **Generic Telemetry API** — New `GET /api/telemetry` endpoint for querying time-series data from any source type (devices, AI metrics, transforms, extensions) using a unified interface. Accepts `source`, `metric`, `start`, `end`, `limit`, and `aggregate` (avg/min/max/sum/count) parameters. Returns data in a consistent format with `"source_id"` key. Independent of the device-specific `/api/devices/:id/telemetry` routes.
- **Server-side Pagination for Data Sources** — `GET /api/data/sources` now supports `offset`, `limit`, `source_type`, `source`, and `search` query parameters. `populate_latest_values` runs only on the paginated subset, significantly reducing DB queries for large deployments.
- **Data Explorer Redesign** — Frontend Data Explorer rewritten with server-side pagination, filtering by source type and source name, and search. Replaced client-side filtering with API-driven filtering for better performance.
- **Extension Push Mode** — Extensions can now push data to the host via a native FFI callback (`PushOutputWriterFn`), bypassing the JSON FFI round-trip. New `send_push_output()` SDK function and `neomind_extension_register_push_writer` FFI export.
- **Extension Instance Reset** — New `neomind_extension_reset_instance()` FFI export allows the runner to re-initialize extensions without restarting the process. Extension instance storage changed from `OnceLock` to `RwLock<Option<...>>` with double-checked locking.
- **CString Memory Safety** — `json_ptr()` now tracks the last 4 allocations per thread, automatically freeing the oldest when the buffer is full. Prevents memory leaks when the host doesn't call `free_string`.
- **IPC Event Subscription** — Extension runner now supports event subscription via IPC. New `event_handler.rs` and `ipc_routing.rs` modules provide channel-based stdin message routing and event state management.
- **IPC ConfigUpdate Message** — New `ConfigUpdate` IpcMessage and `ConfigUpdated` IpcResponse support hot-reloading extension configuration.
- **Extension Health & Config Metadata** — Extensions now expose `health_status`, `last_error`, `last_error_at`, and `config_parameters` fields. Frontend types updated accordingly.

### Changed

- **`device_id` → `source_id` Telemetry Renaming** — Renamed the first-level key in the telemetry time-series storage from `device_id` to `source_id` across the entire stack. This reflects the actual usage where telemetry stores data from multiple source types (devices, AI agents, transforms, extensions), not just devices. The rename covers 5 Rust crates and 20+ frontend files.
  - **Storage Layer** (`neomind-storage`): All `TimeSeriesStore` method parameters (`write`, `query_range`, `query_latest`, `delete_range`, `list_metrics`, etc.), struct fields (`BatchWriteRequest`, `TimeSeriesResult`), and internal DashMap keys renamed.
  - **Devices Wrapper** (`neomind-devices/telemetry`): `TimeSeriesStorage` and `MetricCache` methods updated. Method renames: `list_devices()` → `list_sources()`, `get_device()` → `get_source()`, `clear_device()` → `clear_source()`, `device_count()` → `source_count()`.
  - **Core Bridge** (`neomind-core/datasource`): `DataSourceId::device_part()` → `source_part()`, `from_storage_parts(device_id, ...)` → `from_storage_parts(source_id, ...)`. All internal tests updated.
  - **API Layer** (`neomind-api`): Extension metrics handlers, data source handlers, capability providers updated. Internal variable names aligned with new terminology.
  - **Agent Layer** (`neomind-agent`): AI metrics tool uses `source_id = format!("ai:{}", group)`. Tool output JSON key changed to `"source_id"`. Data collector uses `source_part()`.
  - **Extension State** (`extension_state`): `ExtensionMetricsStorage` method parameters and `ExtensionMetricsStorageAdapter` local variables renamed.
  - **Frontend Gradual Migration**: Added `sourceId` field to `DataSource` and `MapMarker` types (with `deviceId` deprecated). Introduced `getSourceId()` helper that prefers `sourceId` with `deviceId` fallback. All 20+ dashboard and config components updated to read via `getSourceId()` and write both fields.
- **Extension SDK Unified Trait** — Removed `wasm_extension` module. The `Extension` trait is now identical across native and WASM targets, simplifying cross-platform extension development.
- **IPC InFlightRequests: Sync Mutex** — Replaced `tokio::sync::Mutex` with `std::sync::Mutex` in `InFlightRequests` so `complete()`, `cancel()`, etc. can be called from synchronous contexts (receiver thread) without `block_on`.
- **Extension State Enum Simplified** — `ExtensionStateEnum` reduced to 4 states: `Running`, `RunningIsolated`, `Stopped`, `Error`. Removed unused `Discovered`, `Loaded`, `Initialized` states and `ExtensionTypeEnum`.
- **Extension Execute Response Simplified** — `ExtensionExecuteResponse` changed from a structured interface to `Record<string, unknown>` — the raw JSON result from the extension is returned directly.
- **SDK Version Bumped** — `neomind-extension-sdk` updated to v0.6.1.

### Removed

- **HTTP_REQUEST & KV_STORAGE Capabilities** — Removed `HttpRequest` and `KvStorage` from `ExtensionCapability` enum, SDK bindings, API providers (`HttpCapabilityProvider`, `KvCapabilityProvider`), and storage layer (`ExtensionKvStore`). Extensions can make HTTP calls and manage key-value data natively.
- **PermissionDenied Error** — Removed `CapabilityError::PermissionDenied` and `required_capabilities` from `ExtensionContextConfig`. Capability access is now determined solely by provider registration.
- **Dead IPC Forwarder** — Removed `start_ipc_forwarder` thread (~150 lines) and `SyncIpcRequest`/`SyncIpcResponse` types. The stdin reader thread handles all IPC routing.

### Fixed

- **SDK Macro Compilation Error** — Fixed `expected *mut i8, found Option<_>` in `neomind_export!` macro. `Vec::remove()` returns `T`, not `Option<T>` — changed `if let Some(old) = buf.remove(0)` to `let old = buf.remove(0)`.
- **Debug Logging Cleanup** — Converted 47 `eprintln!` calls to structured `tracing` macros across extension runner (`main.rs`, `ipc_routing.rs`) and core (`process.rs`). Only the panic handler retains `eprintln!` for safety.
- **Extension Upload Dialog Animation** — Fixed Loader2 spinner jittering during upload by converting inline component function to a JSX variable, preventing React unmount/remount cycles on every progress update.
- **Extension Bundle Cache Stale Issue** — Fixed browser loading old UMD bundles after extension reinstall/update. Three fixes applied:
  - Store's `unregisterExtension` now clears `DynamicRegistry` caches and global variables.
  - Upload dialog clears extension caches before re-syncing component registry.
  - `syncComponents` detects `bundle_url`/`global_name`/`export_name` changes and clears stale module caches.
- **Loading State Improvements** — Skeleton screen patterns improved across `LoadingState` and `ResponsiveTable` components.
- **Tauri Version Mismatch** — Fixed `tauri.conf.json` showing stale version while Cargo.toml was already updated.

### Preserved (Not Changed)

- **Extension SDK Wire Protocol**: JSON parameter key `"device_id"` unchanged — avoids breaking external extensions.
- **Device Management Code**: Device register/unregister/status/config/command handlers use `device_id` semantically and correctly.
- **API URL Routes**: All existing HTTP routes (`/api/devices/:id/telemetry`, etc.) unchanged.
- **redb File Format**: Binary storage format unaffected — only variable names changed.
- **`device_type` Fields**: Retention policy fields in storage layer correctly preserved as a separate concept.

---

## [v0.6.10] - 2026-04-20

### Added

- **AI Metrics Tool** — New `ai_metric` tool enables LLM agents to create and query custom time-series metrics (anomaly scores, predictions, derived indicators). Actions: `write` (persist data point + metadata), `read` (list all metrics with latest values or query time-series for a specific metric). Metrics appear in the Data Explorer via `ai:{group}:{field}` data source IDs. Metadata persists across restarts via JSON file.
- **AI Metrics Registry** — `AiMetricsRegistry` provides shared metadata storage between `AiMetricTool` (writes) and the data sources handler (reads), with disk persistence in `data/ai_metrics_metadata.json`.
- **Dynamic Data Explorer Tabs** — Frontend Data Explorer now dynamically creates tabs for all registered data source types, including AI Metrics. Tab content auto-refreshes when new sources are discovered.
- **Unified Data Sources Collector** — `collect_ai_sources` handler collects AI metric data sources alongside device, extension, and transform sources for the unified data API.

### Changed

- **Agent Execution Mode Redesign** — Renamed Chat Mode → **Focused Mode** and React Mode → **Free Mode** with clear differentiation across all layers (backend, API, frontend, LLM tools).
  - **Focused Mode**: User binds resources (required), LLM works within defined scope using structured data tables and decision templates. Single-pass, token-efficient. Best for monitoring, alerts, data analysis.
  - **Free Mode**: LLM freely explores with all 8 tools (device, agent, rule, message, extension, transform, skill, shell), no resource binding needed. Multi-round reasoning. Best for complex automation and device control.
- **Structured Prompt for Focused Mode** — Focused Mode prompt now uses structured Markdown tables (data table + command table + decision template) instead of loose text, improving LLM reliability for command execution.
- **Scope Validation** — Focused Mode command execution validates that commands are within bound resources, rejecting out-of-scope commands with warning logs.
- **Data Collection Config UI** — Focused Mode metric resources now show configurable data collection settings (time range, include history, trend analysis, baseline comparison) in the agent editor.
- **Notification/Alert in Focused Mode** — Focused Mode can send notifications and alerts without binding, as inherent agent capabilities.
- **Focused Mode API Validation** — Create/update agent API returns 400 error if Focused Mode has no resource binding.
- **ExecutionMode Enum** — `Chat`/`React` renamed to `Focused`/`Free` with serde aliases for backward compatibility. Old values (`"chat"`, `"react"`) still accepted via deserialization.
- **Frontend Mode Cards** — Agent editor mode selection updated with new names, icons, descriptions, and "Required" badge for Focused Mode.
- **Free Mode Resource Binding Removed** — Free Mode no longer shows resource binding section. Resources cleared when switching to Free Mode.
- **LLM Tool Descriptions** — Agent tool parameter descriptions (`execution_mode`, `resources`, `enable_tool_chaining`) in both `aggregated.rs` and `simplified.rs` updated to reflect Focused/Free semantics and resource binding rules.
- **Internal Naming Unified** — `AnalysisResult` enum variants, all doc comments, tracing messages, and log strings updated from Chat/React to Focused/Free across `neomind-agent`, `neomind-storage`, and `neomind-api`.
- **Shell Tool** — New `shell` tool enables AI agents to execute system commands on the host. Features: login shell (`$SHELL -l -c`) for full user environment (PATH, aliases), cross-platform support (Unix/macOS/Windows), configurable timeout (max 600s), output truncation (10K chars), UTF-8 safe truncation, process group isolation for clean timeout kill. Parameters: `command` (required), `timeout`, `working_dir`, `description` (audit log).
- **Agent Skill System** — User-defined skill management via the `skill` tool. Actions: `search`, `list`, `get`, `create`, `update`, `delete`. Skills are YAML frontmatter + Markdown files that provide scenario-driven operation guides for the AI agent. Includes keyword matching, token budget injection, and persistence.
- **Skills Panel UI** — Frontend panel in agent settings for creating, editing, and deleting user skills with a code editor. Supports YAML frontmatter syntax highlighting.
- **Action Enum Constraints** — LLM tool definitions now include `enum` constraints on the `action` parameter for all aggregated tools, so the LLM knows exactly which actions are available (e.g., `device` supports `list|latest|history|control|write_metric`).
- **Removed Builtin Skills** — Removed 8 hardcoded builtin skills (753 lines) that duplicated tool descriptions. The skill system now focuses on user-defined multi-tool workflow skills only.
- **Enhanced Tool Descriptions** — All 6 aggregated tool descriptions (device, agent, rule, message, extension, transform) enhanced with critical workflow hints (confirm flow, list-first pattern, required fields) to compensate for removed builtin skills.
- **Login Shell for Shell Tool** — Uses `$SHELL` environment variable with `-l` flag for full user environment; falls back to `/bin/sh -c` without `-l` in minimal environments (Docker, IoT edge).
- **Adaptive Tool Timeout** — Outer tool execution timeout in `execute_with_retry_impl` now adapts to shell tool's internal timeout (`shell_timeout + 5s` buffer) instead of hardcoded 30s.
- **Tool Name Mapper** — Added `skill` and `shell` with Chinese/English aliases (命令行, 终端, bash, cli, 技能, 指南, etc.) for fuzzy tool name resolution.
- **Non-Simplified Tool Registration** — `update_tool_definitions` now registers ALL tools from the registry (not just extension tools) that aren't already in simplified definitions, fixing shell tool not being visible to the LLM.
- **Automation Simplified** — Removed complex automation modes, simplified to transform-only workflow. Unified loading states across frontend components.

### Fixed

- **Tool Result Compaction Echoing** — The old `[Called: tool(args) → result]` compaction format was being echoed verbatim by smaller LLMs instead of generating new tool calls. Replaced with natural language sentences that clearly indicate past results and instruct the model not to repeat them.
- **AI Metric Discoverability** — `ai_metric` `read_list` returned empty when metrics were written without optional `unit`/`description` fields because metadata was only registered conditionally. Now always registers metadata on write so all metrics are discoverable.
- **AI Metric Tool Description** — Improved `ai_metric` tool description with clear examples for write and read actions, making it easier for LLMs to use correctly.
- **AI Metric Metadata Persistence** — AI metrics metadata now persists to `data/ai_metrics_metadata.json` across server restarts via `AiMetricsRegistry` disk persistence.
- **Shell Timeout Parameter** — `timeout` parameter now accepts both number (`30`) and string (`"30"`) forms, fixing LLM passing string values through simplified schema.
- **Simplified Tool Description Accuracy** — Fixed `device` tool description: `get` → `latest`, added missing `write_metric` action. Fixed `message` tool: added missing `get` action.
- **Cross-Platform Shell Dependencies** — `libc` moved to Unix-only target dependency, `windows-sys` added as Windows-only dependency for proper cross-compilation.

### Added

- **Agent Execution Mode Redesign** — Renamed Chat Mode → **Focused Mode** and React Mode → **Free Mode** with clear differentiation across all layers (backend, API, frontend, LLM tools).
  - **Focused Mode**: User binds resources (required), LLM works within defined scope using structured data tables and decision templates. Single-pass, token-efficient. Best for monitoring, alerts, data analysis.
  - **Free Mode**: LLM freely explores with all 8 tools (device, agent, rule, message, extension, transform, skill, shell), no resource binding needed. Multi-round reasoning. Best for complex automation and device control.
- **Structured Prompt for Focused Mode** — Focused Mode prompt now uses structured Markdown tables (data table + command table + decision template) instead of loose text, improving LLM reliability for command execution.
- **Scope Validation** — Focused Mode command execution validates that commands are within bound resources, rejecting out-of-scope commands with warning logs.
- **Data Collection Config UI** — Focused Mode metric resources now show configurable data collection settings (time range, include history, trend analysis, baseline comparison) in the agent editor.
- **Notification/Alert in Focused Mode** — Focused Mode can send notifications and alerts without binding, as inherent agent capabilities.
- **Focused Mode API Validation** — Create/update agent API returns 400 error if Focused Mode has no resource binding.

### Changed

- **ExecutionMode Enum** — `Chat`/`React` renamed to `Focused`/`Free` with serde aliases for backward compatibility. Old values (`"chat"`, `"react"`) still accepted via deserialization.
- **Frontend Mode Cards** — Agent editor mode selection updated with new names, icons, descriptions, and "Required" badge for Focused Mode.
- **Free Mode Resource Binding Removed** — Free Mode no longer shows resource binding section. Resources cleared when switching to Free Mode.
- **LLM Tool Descriptions** — Agent tool parameter descriptions (`execution_mode`, `resources`, `enable_tool_chaining`) in both `aggregated.rs` and `simplified.rs` updated to reflect Focused/Free semantics and resource binding rules.
- **Internal Naming Unified** — `AnalysisResult` enum variants, all doc comments, tracing messages, and log strings updated from Chat/React to Focused/Free across `neomind-agent`, `neomind-storage`, and `neomind-api`.

- **Shell Tool** — New `shell` tool enables AI agents to execute system commands on the host. Features: login shell (`$SHELL -l -c`) for full user environment (PATH, aliases), cross-platform support (Unix/macOS/Windows), configurable timeout (max 600s), output truncation (10K chars), UTF-8 safe truncation, process group isolation for clean timeout kill. Parameters: `command` (required), `timeout`, `working_dir`, `description` (audit log).
- **Agent Skill System** — User-defined skill management via the `skill` tool. Actions: `search`, `list`, `get`, `create`, `update`, `delete`. Skills are YAML frontmatter + Markdown files that provide scenario-driven operation guides for the AI agent. Includes keyword matching, token budget injection, and persistence.
- **Skills Panel UI** — Frontend panel in agent settings for creating, editing, and deleting user skills with a code editor. Supports YAML frontmatter syntax highlighting.
- **Action Enum Constraints** — LLM tool definitions now include `enum` constraints on the `action` parameter for all aggregated tools, so the LLM knows exactly which actions are available (e.g., `device` supports `list|latest|history|control|write_metric`).

### Changed

- **Removed Builtin Skills** — Removed 8 hardcoded builtin skills (753 lines) that duplicated tool descriptions. The skill system now focuses on user-defined multi-tool workflow skills only.
- **Enhanced Tool Descriptions** — All 6 aggregated tool descriptions (device, agent, rule, message, extension, transform) enhanced with critical workflow hints (confirm flow, list-first pattern, required fields) to compensate for removed builtin skills.
- **Login Shell for Shell Tool** — Uses `$SHELL` environment variable with `-l` flag for full user environment; falls back to `/bin/sh -c` without `-l` in minimal environments (Docker, IoT edge).
- **Adaptive Tool Timeout** — Outer tool execution timeout in `execute_with_retry_impl` now adapts to shell tool's internal timeout (`shell_timeout + 5s` buffer) instead of hardcoded 30s.
- **Tool Name Mapper** — Added `skill` and `shell` with Chinese/English aliases (命令行, 终端, bash, cli, 技能, 指南, etc.) for fuzzy tool name resolution.
- **Non-Simplified Tool Registration** — `update_tool_definitions` now registers ALL tools from the registry (not just extension tools) that aren't already in simplified definitions, fixing shell tool not being visible to the LLM.

### Fixed

- **Shell Timeout Parameter** — `timeout` parameter now accepts both number (`30`) and string (`"30"`) forms, fixing LLM passing string values through simplified schema.
- **Simplified Tool Description Accuracy** — Fixed `device` tool description: `get` → `latest`, added missing `write_metric` action. Fixed `message` tool: added missing `get` action.
- **Cross-Platform Shell Dependencies** — `libc` moved to Unix-only target dependency, `windows-sys` added as Windows-only dependency for proper cross-compilation.

---

## [v0.6.9] - 2025-04-16

### Added

- **Transform Aggregated Tool** — New `transform` tool enables LLM agents to manage JavaScript-based data transforms through natural conversation. Actions: `list`, `get`, `create`, `update`, `delete`, `test`. Supports scope-based targeting (global, device type, specific device), extension invocation via `extensions.invoke()`, and custom output prefixes. Full multilingual support (English/Chinese).
- **TransformStore Trait Abstraction** — `TransformStore` trait in `neomind-agent` with async CRUD methods using `serde_json::Value` for cross-crate data transfer, implemented for `SharedAutomationStore` in `neomind-api`. Avoids circular dependency between crates.
- **Virtual Metrics in Device Tool** — `device(action="list")` (detailed mode) now includes `virtual_metrics` field showing metrics from Transform/extension writes not in the device template. `device(action="latest")` appends virtual metrics with latest values into the metrics array, so the LLM can see and query all available metrics.
- **Device Write Metric Action** — New `device(action="write_metric")` action allows the AI agent to write values to device metrics. Accepts `device_id`, `metric`, `value` (string/number/boolean/null), and optional `timestamp`. Enables calibration values, status flags, computed results, and any AI-generated data to be persisted on devices.
- **Dynamic Context Compaction** — Context compaction parameters (`keep_recent`, `history_share`, `message_length`) now adapt to model capacity (>16k/8k-16k/<8k). Large models get 95% effective context allocation.
- **LLM Default Context Length** — Default max context token increased from 4096/8192 to 128000 across all backends (Ollama, llama.cpp, mock), matching modern model capabilities.
- **GLM & MiniMax Model Detection** — Added context length detection for GLM (128k) and MiniMax/abab (512k) models.

### Changed

- **Keyword Planner** — Rule intent planner now distinguishes transform-related queries from rule queries, routing to the correct tool (transform vs rule) based on message keywords (convert, transform, data processing, 数据转换, 数据解析, etc.).
- **Unified Alert/Message Tools** — Alert tool merged into message tool with consistent descriptions and examples.
- **Anti-Hallucination Tool Formatting** — Tool result summaries now use structured markers (`**[ToolResult:agent]** preview...`) instead of predictable "✓ tool executed successfully" patterns, making it harder for the LLM to memorize and hallucinate responses in long conversations.

### Fixed

- **Tool Result Cache Invalidation** — Cache not invalidated on write actions (create/update/delete/control) across all tools, causing stale data on subsequent reads. Now properly invalidated after all mutations.
- **`_raw` Metric Filtering** — `_raw` and `*_raw` metrics (containing large base64 images, full MQTT payloads) now replaced with `[raw payload, {size}]` in tool output, preventing token waste in LLM context. Virtual metrics discovery also skips these noise fields.
- **Duplicate Round Content** — Last tool-call round's content was displayed twice: once in the tool round block and once as the final message. Fixed in both backend (no longer storing `final_response_content` in `round_contents_map`) and frontend (no longer saving last round content on stream end).
- **Message List Detection** — `message(list)` output was misidentified as "Conversation Log". Added message-object detection (title/level/read fields) for correct formatting.
- **User Message Preservation** — User messages now always preserved in context window (User priority >= System), preventing critical context loss during compaction.

---

## [v0.6.8] - 2025-04-15

### Added

- **Per-Round Thinking Persistence** — Backend now tracks and stores thinking content per tool-call round (`round_thinking` field on `AgentMessage`), enabling grouped rendering in the frontend with visual round labels and color-coded badges.
- **Thinking Deduplication** — Frontend detects and hides thinking content that duplicates the final response (Phase 2 LLM echo), avoiding redundant display.
- **Streaming Loading Indicator** — Consistent loading dots shown during streaming when content hasn't arrived yet, replacing the previous empty-gap behavior after tool calls or thinking blocks.

### Changed

- **LLM Pipeline Optimization** — Removed deprecated `is_likely_thinking` filter in Ollama paths (Ollama already separates content/thinking correctly); removed keyword-based thinking control overrides — thinking now respects user/instance `thinking_enabled` setting directly (`Instance setting → LlmInterface → Ollama backend`).
- **Unified LLM Defaults** — Standardized parameters across configs: temperature 0.3, top_p 0.7, top_k 40, repeat_penalty 1.05 for better tool-calling determinism.
- **Prompt Cleanup** — Removed Quick Reference table and tool description double-injection from system prompts (~284 lines of deprecated constants removed from `builder.rs`); tool definitions now handled entirely by `PromptBuilder`.
- **Unified Chat Text Sizing** — All chat message block font sizes unified to 13px (thinking content, tool call content, markdown body, round content), with labels at 11px. Previously ranged from 10px–14px across different blocks.
- **Softer Block Styling** — Thinking and tool-call blocks now use borderless rounded backgrounds (`bg-muted/30`) instead of hard borders, for a cleaner visual appearance.
- **Tool Call Block Spacing** — Tool call block uses `mb-4` bottom margin to create clear separation from the final response content below.

### Fixed

- **Multi-Round Thinking Display** — Thinking content now accumulates across all tool-call rounds instead of resetting on each round transition, so all rounds' thinking is visible during streaming.
- **Duplicate Loading Indicators** — Removed legacy standalone loading dots that conflicted with the new inline loading, preventing double indicators on empty streaming messages.
- **Rule Builder Extension Support** — Fixed validation in rule creation that blocked "Next" when selecting an extension as data source (only checked `device_id`, ignored `extension_id`). Fixed trigger building for extension conditions (was always empty `device_id`). Fixed `RuleAction::Set` on backend not routing to extension executor — Set actions targeting extensions now correctly execute via `ExtensionActionExecutor`.
- **Model Selector Overflow** — Added `max-h-[50vh] overflow-y-auto` to LLM model dropdown to prevent long model lists from overflowing the viewport.
- **Embedded Tool Call JSON in Display** — Small models (e.g. 4B) often output tool call JSON (`[{"name":"device",...}]`) as plain text mixed with markdown code blocks. Three-layer fix:
  - **Backend hold-back**: Streaming buffer now also detects `{"`, `{"name"`, and ```json``` patterns — not just `[` — to prevent partial JSON fragments from being yielded to the frontend.
  - **Backend storage cleaning**: `remove_tool_calls_from_response` applied at all 4 message storage points (main tool path, multimodal path, no-tool paths) and enhanced with ```json code block regex cleaning. `content_before_tools` is also cleaned before storing as round content.
  - **Frontend display cleaning**: `cleanToolCallJson()` applied to both `round_contents` and message content during rendering, covering streaming and persisted messages.

### Changed

- **Dead Chinese Prompt Code Removed** — Removed 481 lines of unused Chinese prompt constants (`*_ZH`) and associated methods from `builder.rs`. The `LANGUAGE_POLICY` header already instructs models to respond in the user's language, making separate Chinese prompts unnecessary. Only `CONVERSATION_CONTEXT_ZH` retained (still used by agent executor memory system).

---

## [v0.6.7] - 2025-04-14

### Added

- **Ollama Capabilities-Based Vision Detection** — Vision detection now prioritizes the Ollama API `capabilities` array (authoritative source) over `model_info` heuristic, with fallback for older Ollama versions.
- **qwen3.5 Multimodal Support** — Full qwen3.5 series (including `qwen3.5:4b` local models) now correctly detected as multimodal across all detection paths.
- **Agent Thinking Panel Collapsible** — Agent thinking panel now supports collapse/expand with a preview line, reducing visual clutter during execution monitoring.
- **Tauri Keyboard Fix** — Prevent Backspace/Delete from triggering browser back navigation in Tauri WebView.

### Changed

- **Agent Card Layout** — Simplified footer layout; executing status shown inline with spinner instead of separate thinking block.
- **Agent Detail Panel** — Executions are preloaded on agent selection instead of waiting for history tab; auto-reload on execution completion.
- **Unified Vision Detection** — All backend vision detection now uses `neomind-core`'s `detect_vision_capability()` for consistency.
- **Capability Upgrade Logic** — Backend capability detection only upgrades (false→true), never downgrades API-detected values that are already persisted.

### Fixed

- **Dashboard LineChart Stale Data** — Removed React.memo from LineChart component that prevented data updates.
- **DevicesPage Performance** — Grouped selectors with `shallow` equality to reduce unnecessary re-renders.
- **Telemetry Query Concurrency** — Added semaphore to limit concurrent telemetry queries to 16, preventing resource exhaustion.
- **Storage Performance** — Single DB query for device state instead of double lookup; paginated scan avoids loading all results; range query replaces full table scan.
- **UTF-8 Key Safety** — Safe `increment_prefix` for UTF-8 keys in storage, with semaphore error logging.

---

## [v0.6.6] - 2025-04-14

### Added

- **Token Usage Reporting & Context Summarization** — Agent streaming now reports token usage per turn. Sessions auto-summarize when context exceeds model limits, preserving conversation continuity across long sessions.
- **Context Summarization API** — New `POST /api/sessions/:id/summarize` endpoint for manual context compression.

### Changed

- **Agent Toolkit Consolidation** — Merged and simplified tool definitions, removed unused system tools (DSL, MDL, rule-gen) for cleaner agent context and faster tool resolution (~3400 lines removed).
- **Streaming Refactor** — Agent streaming handler restructured for better error recovery and token tracking.

### Fixed

- **Memory Compression Safety** — Compression now preserves high-importance entries instead of sending all entries to LLM. Only entries exceeding category limits are compressed, and the top half is always kept intact.
- **Over-Aggressive Merge Protection** — New safety threshold blocks compression when LLM returns fewer than 20% of the entries it was given, preventing catastrophic memory loss from small models over-merging.
- **Extract/Compress Decoupling** — `POST /api/memory/extract` no longer auto-triggers compression on all categories. Compression runs only via the scheduler or manual `POST /api/memory/compress` trigger.
- **Default Context Length** — Use 8192 as default `max_context` instead of 0, preventing context overflow on backends that don't report model limits.
- **Ollama Model Context Detection** — Correct context size detection for ministral and other models that report context length differently in the Ollama API.
- **Tauri Updater CI** — Fixed artifact paths and auto-generation of `latest-update.json` in GitHub Actions workflow.

---

## [v0.6.5] - 2025-04-13

### Added

- **Token-Based Context Management** — Conversation history managed using token counting instead of message count, with automatic context overflow retry for resilience across LLM backends.
- **Dashboard Grid Rewrite** — Ref-based `react-grid-layout` integration eliminates feedback loops between layout state and re-renders, fixing jitter and positioning bugs.
- **Config Data Refresh** — Component data updates immediately when editing data binding in config dialog, with `configVersion` tracking for live re-renders.
- **Chart Responsive Resize** — Chart components (LineChart, BarChart, PieChart, AreaChart) properly fill their container via flex-based layout.
- **New Component Default Size** — Dashboard components appear at correct default sizes instead of 1×1 minimum.
- **Aggregated Tool Enhancements** — Added `latest_execution` and `send_message` tool actions for agent execution monitoring and control.
- **Agent Execution Timeline** — Refactored timeline with tool thinking event support and improved event rendering.
- **React/Chat Dual-Path Execution** — Agents support both React reasoning loop and direct chat execution paths with background API.
- **Concise React Prompts** — Optimized agent React prompts and UTF-8 truncation safety.
- **Execution Detail Layout** — Improved execution detail dialog layout.

### Fixed

- **Streaming Tool Calls** — Fixed tool call streaming event handling in chat interface.
- **Sidebar Scroll** — Fixed sidebar scroll behavior and chat layout issues.
- **Scheduler Panic** — Fixed agent scheduler panic on concurrent access.
- **Thinking Model Compatibility** — Memory extraction and compression LLM calls now disable thinking (`thinking_enabled: Some(false)`), preventing token waste on reasoning models (qwen3.x, deepseek-r1).
- **Memory Config Alignment** — Backend `ExtractionConfig` now matches frontend Config UI fields.
- **Memory Extraction Returns Zero** — Fixed extraction returning 0 entries when using thinking-capable models.
- **llama.cpp Multimodal Detection** — Auto-detect vision, tool calling, and context size from `/props` endpoint.
