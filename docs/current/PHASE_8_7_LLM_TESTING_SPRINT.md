# Phase 8.7: LLM Support Testing Sprint

**Date**: December 2, 2025  
**Duration**: 19 days (4 sprints of 4-5 days each)  
**Status**: 📋 **PLANNED**  
**Objective**: Raise LLM support crate coverage from **35.54%** to **80%+** across 6 crates

---

## Executive Summary

**Mission**: Comprehensively test LLM integration quality, streaming reliability, batch performance, and production readiness across all 6 LLM support crates.

**Approach**: 4-week sprint broken into focused sub-sprints per crate group.

**Target Metrics**:
- **Coverage**: 35.54% → 80%+ (44.46 point gain average)
- **Tests**: ~305 new tests across 6 crates
- **Quality**: Fix MockEmbeddingClient determinism bug, validate all LLM paths
- **Performance**: Streaming <500ms, batch <3s for 10 agents

---

## Current State Analysis

### Coverage by Crate

| Crate | Current | Target | Gap | Tests Needed | Priority |
|-------|---------|--------|-----|--------------|----------|
| astraweave-llm | 64.30% | 80% | 15.7% | 47 | P0 |
| astraweave-context | 27.81% | 80% | 52.19% | 53 | P0 |
| astraweave-rag | 21.44% | 80% | 58.56% | 72 | P0 |
| astraweave-persona | 17.67% | 80% | 62.33% | 45 | P1 |
| astraweave-prompts | 12.35% | 80% | 67.65% | 60 | P0 |
| astraweave-embeddings | 69.65% | 80% | 10.35% | 28 | P0 (fix bug) |
| **TOTAL** | **35.54%** | **80%** | **44.46%** | **305** | - |

### Critical Issues

**BLOCKER: MockEmbeddingClient Determinism Bug**
- **Location**: `astraweave-embeddings/src/client.rs:77`
- **Issue**: Uses unseeded `rand::rng()` instead of deterministic RNG
- **Impact**: Tests may be flaky, non-reproducible
- **Fix**: Use `SmallRng::seed_from_u64(hash)` instead of `rand::rng()`

---

## Sprint Structure (4 Weeks)

### Sprint 1 (Week 1): Foundations - Context & RAG Core
**Duration**: 5 days  
**Focus**: Fix determinism bug, core context/RAG functionality  
**Tests**: 63 tests

### Sprint 2 (Week 2): Prompts & LLM Streaming
**Duration**: 4 days  
**Focus**: Template engine, LLM reliability  
**Tests**: 59 tests

### Sprint 3 (Week 3): Persona & Memory Management
**Duration**: 4 days  
**Focus**: LLM-enhanced personas, memory consolidation  
**Tests**: 67 tests

### Sprint 4 (Week 4): Advanced Features & Integration
**Duration**: 6 days  
**Focus**: Complete coverage, integration tests  
**Tests**: 108 tests

---

## Sprint 1: Foundations (Week 1, 5 days)

### Day 1: Fix Determinism Bug (4 hours)

**Critical Fix**: MockEmbeddingClient determinism

**Tasks**:
1. Read `astraweave-embeddings/src/client.rs`
2. Locate line 77: `let mut rng = rand::rng();`
3. Replace with:
   ```rust
   use rand::{rngs::SmallRng, SeedableRng, Rng};
   let mut hasher = DefaultHasher::new();
   text.hash(&mut hasher);
   let seed = hasher.finish();
   let mut seed_bytes = [0u8; 32];
   seed_bytes[..8].copy_from_slice(&seed.to_le_bytes());
   let mut rng = SmallRng::from_seed(seed_bytes);
   ```
4. **Write 4 determinism validation tests**:
   - `test_mock_embedding_determinism_same_text()` - Same text → same embedding
   - `test_mock_embedding_determinism_across_runs()` - Multi-run consistency
   - `test_mock_embedding_different_text()` - Different text → different embedding
   - `test_mock_embedding_cache_hit()` - Cache returns same result

**Validation**: `cargo test -p astraweave-embeddings -- determinism`

**Acceptance Criteria**:
- ✅ 4 tests passing
- ✅ Same text always generates identical embedding vectors
- ✅ Zero flakiness across 10 test runs

---

### Day 2-3: Context Core Tests (2 days, ~8 hours)

**Focus**: ConversationHistory & ContextWindow (27 tests)

**ConversationHistory Tests** (15 tests):
1. `test_add_message()` - Add message with role/content/metadata
2. `test_retrieve_message_by_id()` - Retrieve specific message
3. `test_prune_sliding_window()` - Keep last N messages
4. `test_prune_summarization()` - LLM summarizes old messages
5. `test_prune_hybrid()` - Sliding window + summarization
6. `test_token_counting_integration()` - Token limits enforced
7. `test_concurrent_access()` - Thread-safe operations
8. `test_metrics_tracking()` - Message count, token count tracked
9. `test_message_metadata()` - Timestamp, speaker, sentiment
10. `test_clear_history()` - Full reset
11. `test_get_recent_n()` - Retrieve last N messages
12. `test_get_by_role()` - Filter by user/assistant/system
13. `test_get_by_time_range()` - Time-based retrieval
14. `test_prune_by_importance()` - Keep high-importance messages
15. `test_serialization()` - Save/load conversation history

**ContextWindow Tests** (12 tests):
1. `test_add_to_window()` - Add message to context window
2. `test_attention_based_pruning()` - Remove low-attention messages
3. `test_hierarchical_window()` - Short-term + long-term windows
4. `test_multi_agent_context_sharing()` - Shared context between agents
5. `test_window_overflow_handling()` - Graceful token limit enforcement
6. `test_attention_weight_calculation()` - Recency + relevance scoring
7. `test_get_context_for_prompt()` - Format for LLM prompt
8. `test_window_clear()` - Reset context
9. `test_window_size_limits()` - Max token enforcement
10. `test_context_compression()` - Summarize old context
11. `test_context_priority()` - System > user > assistant priority
12. `test_context_serialization()` - Save/load window state

**Acceptance Criteria**:
- ✅ 27 tests passing
- ✅ Conversation history CRUD operations validated
- ✅ Context window token budgets enforced
- ✅ Coverage: astraweave-context ~55%+

---

### Day 4-5: RAG Core Tests (2 days, ~8 hours)

**Focus**: RagPipeline & Retrieval (32 tests)

**RagPipeline Tests** (18 tests):
1. `test_add_memory_with_importance()` - Store memory with score
2. `test_retrieve_by_query()` - Semantic search
3. `test_inject_context_prepend()` - Injection strategy: prepend
4. `test_inject_context_append()` - Injection strategy: append
5. `test_inject_context_insert()` - Injection strategy: insert
6. `test_inject_context_interleave()` - Injection strategy: interleave
7. `test_cache_hit_behavior()` - Cached retrieval
8. `test_cache_miss_behavior()` - Fresh retrieval
9. `test_consolidation_trigger()` - Auto-consolidate at threshold
10. `test_metrics_tracking()` - Query count, hit rate, latency
11. `test_memory_addition_batch()` - Batch insert
12. `test_retrieval_with_filters()` - Category, time, entity filters
13. `test_token_budget_enforcement()` - Limit injected context
14. `test_empty_pipeline()` - No memories → empty retrieval
15. `test_duplicate_memory_handling()` - Deduplication
16. `test_importance_decay()` - Old memories decay over time
17. `test_pipeline_reset()` - Clear all memories
18. `test_pipeline_serialization()` - Save/load RAG state

**Retrieval Tests** (14 tests):
1. `test_semantic_search_accuracy()` - Top-k most similar
2. `test_category_filtering()` - Filter by memory category
3. `test_time_based_filtering()` - Retrieve from time range
4. `test_entity_based_filtering()` - Retrieve mentions of entity
5. `test_diversity_in_results()` - Avoid redundant memories
6. `test_hybrid_search_keyword_semantic()` - Combined search
7. `test_retrieval_empty_query()` - Handle empty queries
8. `test_retrieval_no_matches()` - No results handling
9. `test_retrieval_similarity_threshold()` - Min similarity cutoff
10. `test_retrieval_top_k()` - Return exactly k results
11. `test_retrieval_with_metadata()` - Include timestamps, importance
12. `test_retrieval_performance()` - <10ms for 1000 memories
13. `test_retrieval_concurrent_queries()` - Thread-safe
14. `test_retrieval_cache_invalidation()` - Cache updates on new memory

**Acceptance Criteria**:
- ✅ 32 tests passing
- ✅ RAG pipeline add/retrieve/inject validated
- ✅ Retrieval accuracy and filtering validated
- ✅ Coverage: astraweave-rag ~45%+

---

## Sprint 2: Prompts & LLM Streaming (Week 2, 4 days)

### Day 6-7: Prompts Core Tests (2 days, ~8 hours)

**Focus**: TemplateEngine, PromptTemplate, TemplateContext (37 tests)

**TemplateEngine Tests** (12 tests):
1. `test_register_template()` - Register template by name
2. `test_render_template()` - Render with context
3. `test_render_undefined_template()` - Error handling
4. `test_template_caching()` - Compiled templates cached
5. `test_engine_clear_cache()` - Cache invalidation
6. `test_register_duplicate_template()` - Overwrite behavior
7. `test_render_with_partial()` - Include partials
8. `test_render_with_helpers()` - Custom helper functions
9. `test_engine_list_templates()` - Get all template names
10. `test_engine_hot_reload()` - Reload template from file
11. `test_engine_thread_safety()` - Concurrent rendering
12. `test_engine_error_formatting()` - Clear error messages

**PromptTemplate Tests** (15 tests):
1. `test_template_creation()` - From string
2. `test_variable_extraction()` - Find all {{variable}} placeholders
3. `test_template_validation()` - Balanced braces
4. `test_render_with_single_variable()` - {{name}} → value
5. `test_render_with_multiple_variables()` - {{a}} {{b}} → values
6. `test_nested_variable_support()` - {{user.name}} → nested access
7. `test_render_missing_variable()` - Error or empty string
8. `test_conditional_rendering()` - {{#if condition}}...{{/if}}
9. `test_loop_rendering()` - {{#each items}}...{{/each}}
10. `test_escape_braces()` - \\{{literal}}
11. `test_whitespace_handling()` - Preserve/trim modes
12. `test_comment_stripping()` - {{! comment}} removed
13. `test_template_clone()` - Deep copy
14. `test_template_equality()` - Same content = equal
15. `test_template_debug_output()` - Debug formatting

**TemplateContext Tests** (10 tests):
1. `test_context_creation()` - Empty context
2. `test_set_variable_string()` - Set string value
3. `test_set_variable_number()` - Set i64/f64 value
4. `test_set_variable_bool()` - Set boolean
5. `test_set_variable_array()` - Set Vec<Dynamic>
6. `test_set_variable_object()` - Set HashMap<String, Dynamic>
7. `test_get_variable()` - Retrieve by key
8. `test_nested_variable_access()` - Dot notation (user.name)
9. `test_context_merge()` - Combine two contexts
10. `test_context_serialization()` - Save/load context

**Acceptance Criteria**:
- ✅ 37 tests passing
- ✅ Template rendering with variables validated
- ✅ Context management validated
- ✅ Coverage: astraweave-prompts ~65%+

---

### Day 8-9: LLM Streaming & Batching (2 days, ~8 hours)

**Focus**: OllamaChatClient, streaming_parser (22 tests)

**OllamaChatClient Tests** (12 tests):
1. `test_warmup_success()` - Model loads successfully
2. `test_warmup_failure()` - Handle Ollama not running
3. `test_complete_single()` - Single prompt → response
4. `test_complete_batch()` - 10 prompts → 10 responses
5. `test_complete_streaming_chunks()` - Stream 129 chunks
6. `test_streaming_early_exit_json()` - Stop when JSON complete
7. `test_streaming_timeout()` - Handle slow responses
8. `test_streaming_connection_loss()` - Reconnect on error
9. `test_batch_parallel_execution()` - Concurrent requests
10. `test_batch_sequential_fallback()` - Fallback if parallel fails
11. `test_client_health_check()` - Verify Ollama availability
12. `test_client_model_info()` - Query model capabilities

**streaming_parser Tests** (10 tests):
1. `test_parse_complete_json()` - Valid JSON → plan
2. `test_parse_partial_json()` - Buffer incomplete chunks
3. `test_parse_malformed_json()` - Handle syntax errors
4. `test_parse_code_fence_extraction()` - Extract ```json...```
5. `test_parse_envelope_extraction()` - Extract {"plan": ...}
6. `test_parse_tolerant_mode()` - Fix common errors
7. `test_parse_streaming_buffering()` - Accumulate chunks
8. `test_parse_early_exit_detection()` - Detect JSON completion
9. `test_parse_multiple_json_objects()` - Handle multiple plans
10. `test_parse_performance_1mb()` - <100ms for 1MB response

**Acceptance Criteria**:
- ✅ 22 tests passing
- ✅ Streaming reliability validated (connection loss, timeouts)
- ✅ Batch execution validated (10 agents < 3s)
- ✅ Coverage: astraweave-llm ~75%+

---

## Sprint 3: Persona & Memory (Week 3, 4 days)

### Day 10-11: Persona Tests (2 days, ~8 hours)

**Focus**: LlmPersona, prompt generation, LLM integration (37 tests)

**LlmPersona State Tests** (15 tests):
1. `test_persona_creation()` - Initialize with personality factors
2. `test_update_mood()` - Mood changes (happy, sad, neutral)
3. `test_update_energy()` - Energy levels (high, low)
4. `test_update_confidence()` - Confidence adjustments
5. `test_update_trust_level()` - Trust increases/decreases
6. `test_emotional_state_transitions()` - State machine
7. `test_memory_profile_management()` - Link to CompanionProfile
8. `test_adaptation_data_tracking()` - Learn from interactions
9. `test_personality_factor_influence()` - Factors affect behavior
10. `test_persona_serialization()` - Save/load persona state
11. `test_persona_reset()` - Reset to initial state
12. `test_persona_clone()` - Deep copy
13. `test_persona_equality()` - Same state = equal
14. `test_persona_debug_output()` - Debug formatting
15. `test_persona_metrics()` - Interaction count, average mood

**Prompt Generation Tests** (10 tests):
1. `test_generate_dialogue_prompt()` - Context → dialogue prompt
2. `test_generate_system_prompt()` - Personality → system instructions
3. `test_generate_few_shot_examples()` - Include examples in prompt
4. `test_prompt_includes_mood()` - Mood reflected in prompt
5. `test_prompt_includes_energy()` - Energy reflected in prompt
6. `test_prompt_includes_trust()` - Trust reflected in prompt
7. `test_prompt_token_budgeting()` - Stay within limits
8. `test_prompt_template_integration()` - Use astraweave-prompts
9. `test_prompt_context_aware()` - Recent conversation included
10. `test_prompt_error_handling()` - Handle missing data

**LLM Integration Tests** (12 tests):
1. `test_llm_enhanced_dialogue()` - Generate NPC dialogue
2. `test_llm_personality_influence()` - Friendly vs hostile tone
3. `test_llm_response_style_variation()` - Verbose vs terse
4. `test_llm_emotional_response()` - Mood affects response
5. `test_llm_trust_based_disclosure()` - High trust → more info
6. `test_llm_energy_based_brevity()` - Low energy → short responses
7. `test_llm_fallback_on_error()` - Use default if LLM fails
8. `test_llm_response_caching()` - Cache similar prompts
9. `test_llm_batch_dialogue_generation()` - Multiple NPCs
10. `test_llm_streaming_dialogue()` - Progressive response
11. `test_llm_adaptation_learning()` - Update persona from feedback
12. `test_llm_persona_consistency()` - Same personality across calls

**Acceptance Criteria**:
- ✅ 37 tests passing
- ✅ Persona state management validated
- ✅ LLM-enhanced behavior validated
- ✅ Coverage: astraweave-persona ~70%+

---

### Day 12-13: Memory Management Tests (2 days, ~8 hours)

**Focus**: RAG consolidation, forgetting, injection (30 tests)

**Consolidation Tests** (12 tests):
1. `test_consolidate_by_importance()` - Keep high-importance memories
2. `test_consolidate_by_recency()` - Keep recent memories
3. `test_consolidate_by_similarity()` - Merge similar memories
4. `test_consolidate_batch()` - Process multiple memories
5. `test_consolidate_memory_limit()` - Enforce max count
6. `test_consolidate_triggered_automatically()` - Auto-run at threshold
7. `test_consolidate_manual_trigger()` - Explicit call
8. `test_consolidate_preserve_metadata()` - Keep timestamps, importance
9. `test_consolidate_llm_summarization()` - Use LLM to merge
10. `test_consolidate_deterministic()` - Same input → same output
11. `test_consolidate_performance()` - <500ms for 1000 memories
12. `test_consolidate_empty_pipeline()` - Handle no memories

**Forgetting Tests** (10 tests):
1. `test_forget_by_age()` - Remove memories older than threshold
2. `test_forget_by_low_importance()` - Remove low-value memories
3. `test_forget_forced_at_limit()` - Enforce max age
4. `test_forget_cleanup_scheduling()` - Periodic cleanup
5. `test_forget_time_based_decay()` - Importance decays over time
6. `test_forget_preserve_pinned()` - Never forget pinned memories
7. `test_forget_gradual_decay()` - Smooth decay curve
8. `test_forget_batch_removal()` - Remove multiple at once
9. `test_forget_metrics_tracking()` - Count forgotten memories
10. `test_forget_empty_pipeline()` - Handle no memories

**Injection Tests** (8 tests):
1. `test_inject_token_budget()` - Respect token limits
2. `test_inject_template_based()` - Use prompt template
3. `test_inject_summarization()` - Summarize long context
4. `test_inject_metadata_inclusion()` - Include timestamps, importance
5. `test_inject_prepend_strategy()` - Add at start
6. `test_inject_append_strategy()` - Add at end
7. `test_inject_insert_strategy()` - Add at specific position
8. `test_inject_interleave_strategy()` - Mix with conversation

**Acceptance Criteria**:
- ✅ 30 tests passing
- ✅ Memory consolidation validated
- ✅ Forgetting mechanisms validated
- ✅ Coverage: astraweave-rag ~75%+

---

## Sprint 4: Advanced & Integration (Week 4, 6 days)

### Day 14-15: LLM Advanced Features (2 days, ~8 hours)

**Focus**: phi3_ollama, compression, few_shot, hermes2pro (25 tests)

**phi3_ollama Tests** (8 tests):
1. `test_phi3_model_loading()` - Load Phi-3 model
2. `test_phi3_warmup()` - Warmup call
3. `test_phi3_health_check()` - Verify availability
4. `test_phi3_device_selection_cpu()` - CPU inference
5. `test_phi3_device_selection_gpu()` - GPU inference
6. `test_phi3_device_selection_metal()` - Metal (macOS)
7. `test_phi3_vs_hermes_comparison()` - Compare outputs
8. `test_phi3_performance_benchmark()` - Measure latency

**Compression Tests** (6 tests):
1. `test_compress_prompt()` - Reduce token count
2. `test_compression_ratio()` - Measure compression %
3. `test_compression_quality()` - Preserve meaning
4. `test_compression_token_accuracy()` - Token count correct
5. `test_compression_summarization()` - Use LLM to compress
6. `test_compression_performance()` - <200ms for 1000 tokens

**Few-Shot Tests** (5 tests):
1. `test_few_shot_example_selection()` - Dynamic selection
2. `test_few_shot_role_specific()` - Examples match role
3. `test_few_shot_validation()` - Valid examples only
4. `test_few_shot_token_budgeting()` - Fit in context
5. `test_few_shot_formatting()` - Correct prompt format

**hermes2pro_ollama Tests** (6 tests):
1. `test_hermes_model_loading()` - Load Hermes 2 Pro
2. `test_hermes_warmup()` - Warmup call
3. `test_hermes_health_check()` - Verify availability
4. `test_hermes_json_quality()` - 100% JSON output
5. `test_hermes_tactical_reasoning()` - Plan quality
6. `test_hermes_vs_phi3_comparison()` - Compare models

**Acceptance Criteria**:
- ✅ 25 tests passing
- ✅ Model loading and health checks validated
- ✅ Compression quality validated
- ✅ Coverage: astraweave-llm ~82%+

---

### Day 16: Context Advanced Tests (1.5 days, ~6 hours)

**Focus**: TokenCounter, Summarizer, E2E (26 tests)

**TokenCounter Tests** (8 tests):
1. `test_count_tokens_cl100k_base()` - GPT-4 encoding
2. `test_count_tokens_p50k_base()` - GPT-3 encoding
3. `test_count_tokens_batch()` - Multiple strings
4. `test_count_tokens_empty_string()` - Edge case
5. `test_count_tokens_unicode()` - Unicode handling
6. `test_count_tokens_emojis()` - Emoji handling
7. `test_count_tokens_performance()` - <1ms for 1000 tokens
8. `test_token_encoding_accuracy()` - Match OpenAI API

**Summarizer Tests** (10 tests):
1. `test_summarize_conversation()` - LLM summarizes
2. `test_summarize_single_turn_strategy()` - Keep last turn
3. `test_summarize_multi_turn_strategy()` - Summarize all
4. `test_summarize_token_budget_enforcement()` - Stay within limit
5. `test_summarize_quality_validation()` - Coherent summary
6. `test_summarize_error_handling()` - LLM failure fallback
7. `test_summarize_caching()` - Cache summaries
8. `test_summarize_incremental()` - Update existing summary
9. `test_summarize_metadata_preservation()` - Keep timestamps
10. `test_summarize_performance()` - <2s for 10k tokens

**E2E Flows Tests** (8 tests):
1. `test_e2e_add_retrieve_inject()` - Full pipeline
2. `test_e2e_long_conversation()` - 100+ messages
3. `test_e2e_context_migration()` - Agent to agent
4. `test_e2e_persistence()` - Save/load conversation
5. `test_e2e_concurrent_access()` - Multi-threaded
6. `test_e2e_memory_evolution()` - Old memories decay
7. `test_e2e_token_budget_management()` - Stay within limits
8. `test_e2e_performance_stress()` - 1000 messages

**Acceptance Criteria**:
- ✅ 26 tests passing
- ✅ Token counting validated
- ✅ Summarization quality validated
- ✅ Coverage: astraweave-context ~85%+

---

### Day 17: Embeddings Advanced Tests (1 day, ~4 hours)

**Focus**: VectorStore, EmbeddingClient, Utils (24 tests)

**VectorStore Tests** (10 tests):
1. `test_large_scale_search()` - 10,000 vectors
2. `test_distance_metric_cosine()` - Cosine similarity
3. `test_distance_metric_euclidean()` - Euclidean distance
4. `test_distance_metric_manhattan()` - Manhattan distance
5. `test_distance_metric_dot()` - Dot product
6. `test_capacity_limits()` - Max vector count
7. `test_overflow_handling()` - Auto-prune old vectors
8. `test_concurrent_insertion()` - Thread-safe insert
9. `test_concurrent_search()` - Thread-safe search
10. `test_vectorstore_serialization()` - Save/load

**EmbeddingClient Tests** (8 tests):
1. `test_batch_embedding()` - Multiple texts
2. `test_cache_hit_behavior()` - Return cached
3. `test_cache_miss_behavior()` - Generate new
4. `test_network_failure_handling()` - Retry on error
5. `test_timeout_handling()` - Handle slow responses
6. `test_model_info_validation()` - Correct model metadata
7. `test_embedding_dimension_consistency()` - Same dim
8. `test_client_thread_safety()` - Concurrent calls

**Utils Tests** (6 tests):
1. `test_vector_normalization()` - L2 norm = 1.0
2. `test_cosine_distance_accuracy()` - Validate math
3. `test_euclidean_distance_accuracy()` - Validate math
4. `test_manhattan_distance_accuracy()` - Validate math
5. `test_dot_product_accuracy()` - Validate math
6. `test_distance_edge_cases()` - Zero vectors, identical

**Acceptance Criteria**:
- ✅ 24 tests passing
- ✅ VectorStore performance validated (<10ms search)
- ✅ Distance metrics mathematically correct
- ✅ Coverage: astraweave-embeddings ~85%+

---

### Day 18: Prompts Advanced Tests (1 day, ~4 hours)

**Focus**: Helpers, Library, Optimization (23 tests)

**Helpers Tests** (8 tests):
1. `test_register_helper()` - Add custom helper
2. `test_invoke_helper()` - Call helper in template
3. `test_helper_with_arguments()` - Pass args to helper
4. `test_helper_error_handling()` - Handle helper errors
5. `test_builtin_helpers()` - `uppercase`, `lowercase`, `length`
6. `test_helper_override()` - Replace existing helper
7. `test_helper_thread_safety()` - Concurrent calls
8. `test_helper_debug_output()` - Debug formatting

**Library Tests** (8 tests):
1. `test_load_library_from_directory()` - Load all .hbs files
2. `test_library_hot_reload()` - Reload on file change
3. `test_library_versioning()` - Track template versions
4. `test_library_list_templates()` - Get all names
5. `test_library_get_template()` - Retrieve by name
6. `test_library_delete_template()` - Remove template
7. `test_library_template_metadata()` - Author, description
8. `test_library_file_watcher()` - Monitor directory

**Optimization Tests** (7 tests):
1. `test_optimize_template_compilation()` - Cache AST
2. `test_optimize_variable_lookup()` - Fast context access
3. `test_ab_testing_variants()` - Multiple templates
4. `test_ab_testing_metrics()` - Track performance
5. `test_performance_regression_detection()` - Alert on slowdown
6. `test_template_precompilation()` - Compile ahead of time
7. `test_optimization_benchmarks()` - <1ms render

**Acceptance Criteria**:
- ✅ 23 tests passing
- ✅ Helper system validated
- ✅ Library management validated
- ✅ Coverage: astraweave-prompts ~85%+

---

### Day 19: Integration Tests (0.5 days, ~4 hours)

**Focus**: Cross-crate integration (10 tests)

**Integration Tests** (10 tests):
1. `test_full_llm_pipeline()` - Prompt → LLM → parse → plan
2. `test_context_to_rag_integration()` - Context feeds RAG
3. `test_rag_to_persona_integration()` - Memories inform persona
4. `test_persona_to_prompts_integration()` - Persona → prompt template
5. `test_embeddings_to_rag_integration()` - Embeddings → vector search
6. `test_llm_streaming_to_context()` - Stream → conversation history
7. `test_batch_llm_with_personas()` - Multiple agents with personas
8. `test_rag_retrieval_in_prompt()` - Inject memories into prompt
9. `test_end_to_end_npc_dialogue()` - Full NPC conversation
10. `test_determinism_across_modules()` - Consistent seeding

**Acceptance Criteria**:
- ✅ 10 tests passing
- ✅ Cross-crate integration validated
- ✅ End-to-end LLM flows working

---

## Success Metrics

**Coverage Targets** (by crate):
- astraweave-llm: 64.30% → 82%+ (~18 points)
- astraweave-context: 27.81% → 85%+ (~57 points)
- astraweave-rag: 21.44% → 77%+ (~56 points)
- astraweave-persona: 17.67% → 72%+ (~54 points)
- astraweave-prompts: 12.35% → 85%+ (~73 points)
- astraweave-embeddings: 69.65% → 85%+ (~15 points)

**Overall**: 35.54% → 80%+ (44.46 point gain)

**Test Count**: ~305 new tests across 6 crates

**Quality Gates**:
- ✅ Zero test failures (all 305+ pass)
- ✅ MockEmbeddingClient determinism fixed
- ✅ Zero compilation warnings in test code
- ✅ Performance: Streaming <500ms, batch <3s

**Deliverables**:
1. Fixed `astraweave-embeddings/src/client.rs` (determinism bug)
2. 27 test files created across 6 crates
3. `PHASE_8_7_LLM_TESTING_COMPLETE.md` - Completion report
4. Updated `MASTER_COVERAGE_REPORT.md` v1.32+

---

## Risks & Mitigations

**Risk 1**: LLM tests require external Ollama service  
**Mitigation**: Use `#[ignore]` for external tests, mock-based tests run in CI

**Risk 2**: Streaming tests may be flaky (network issues)  
**Mitigation**: Mock streaming responses, add retries

**Risk 3**: Coverage may not reach 80% due to private methods  
**Mitigation**: Prioritize public API, integration tests validate private indirectly

**Risk 4**: Time estimate may be optimistic (305 tests in 19 days)  
**Mitigation**: Focus on high-value tests first, defer edge cases if needed

---

## Next Steps After Sprint

1. **LLM Quality Benchmarking**: Measure plan quality, tactical soundness
2. **Production Readiness**: Stress testing (100+ concurrent agents)
3. **Integration with Gameplay**: Wire LLM NPCs into Veilweaver demo
4. **Documentation**: LLM integration guide, best practices

---

**Sprint Owner**: Verdent AI  
**Estimated Effort**: 19 days (4 sprints × ~5 days each)  
**Dependencies**: MockEmbeddingClient fix (Day 1 blocker)  
**Blockers**: None identified
