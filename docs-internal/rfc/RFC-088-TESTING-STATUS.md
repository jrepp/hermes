# RFC-088 Testing Status

## Overview

This document tracks the testing status for RFC-088: Event-Driven Document Indexer with Pipeline Rulesets.

## Test Coverage Completed ✅

### 1. Publisher Integration Tests (`pkg/indexer/publisher/publisher_test.go`)

**Test Cases:**
- ✅ `TestPublisher_PublishRevisionCreated` - Verifies events are correctly written to outbox
- ✅ `TestPublisher_Idempotency` - Ensures duplicate events are not created
- ✅ `TestPublisher_MultipleEvents` - Tests multiple revisions with different content hashes
- ✅ `TestPublisher_PublishFromDocument` - Tests convenience helper method
- ✅ `TestPublisher_PublishFromDocument_Idempotency` - Verifies idempotency with helper

**Coverage:**
- ✅ Transactional consistency (outbox created in same TX as revision)
- ✅ Idempotent key generation (`{uuid}:{content_hash}`)
- ✅ Payload structure validation
- ✅ Event type handling (created/updated/deleted)

### 2. Relay Service Tests (`pkg/indexer/relay/relay_test.go`)

**Test Cases:**
- ✅ `TestRelay_GetStats` - Tests outbox status statistics
- ✅ `TestOutboxEntry_MarkAsPublished` - Verifies state transitions
- ✅ `TestOutboxEntry_MarkAsFailed` - Tests failure handling
- ✅ `TestOutboxEntry_Retry` - Tests retry logic
- ✅ `TestFindPendingOutboxEntries` - Tests batch fetching
- ✅ `TestFindPendingOutboxEntries_Limit` - Tests batch size limits
- ✅ `TestDeleteOldPublishedEntries` - Tests cleanup logic
- ✅ `TestGetOutboxByIdempotentKey` - Tests idempotency lookups
- ✅ `TestGetFailedOutboxEntries` - Tests failed entry queries

**Coverage:**
- ✅ Outbox entry state machine (pending → published/failed)
- ✅ Batch processing logic
- ✅ Cleanup of old published events
- ✅ Retry mechanism for failed entries
- ✅ Statistics and monitoring queries

**Note:** Full Relay service testing with real Kafka requires Redpanda testcontainer (TODO)

### 3. End-to-End Integration Tests (`tests/integration/indexer/e2e_test.go`)

**Test Cases:**
- ✅ `TestEndToEnd_PublishAndExecute` - Full flow from publish → pipeline execution
- ✅ `TestEndToEnd_RulesetMatching` - Tests ruleset matching logic
- ✅ `TestEndToEnd_PipelineFailure` - Tests error handling in pipelines
- ✅ `TestEndToEnd_Idempotency` - End-to-end idempotency verification

**Coverage:**
- ✅ Publisher → Outbox → Pipeline → Execution tracking
- ✅ Ruleset matching with different conditions
- ✅ Pipeline step execution order
- ✅ Step result recording
- ✅ Failure handling and recording
- ✅ Full idempotency flow

## Test Infrastructure

### In-Memory SQLite Database
All tests use in-memory SQLite for fast, isolated testing:
```go
db, err := gorm.Open(sqlite.Open(":memory:"), &gorm.Config{})
```

### Auto-Migration
Tests auto-migrate required tables:
- `document_revisions`
- `document_revision_outbox`
- `document_revision_pipeline_executions`
- `document_summaries`

### Mock Components
- **MockStep**: Simulates pipeline steps with configurable success/failure
- **MockLLMClient**: Simulates LLM API calls for testing

## Remaining Testing Work 🚧

### 1. Kafka/Redpanda Integration Tests (High Priority) ✅ COMPLETED

**Status:** Implemented successfully - `pkg/indexer/relay/relay_redpanda_test.go`

**Test Cases Implemented:**
- ✅ `TestRelay_PublishToRedpanda` - Tests relay publishing to real Redpanda instance
- ✅ `TestRelay_MultipleBatches` - Tests processing multiple batches with real Kafka
- ✅ `TestRelay_FailureHandling` - Tests error handling when Kafka is unavailable
- ✅ `TestRelay_RetryFailed` - Tests retrying failed entries with real Redpanda
- ✅ `TestRelay_CleanupOldEntries_WithRedpanda` - Tests cleanup with real broker

**Key Features:**
- Uses testcontainers to start real Redpanda instance
- Creates Kafka topics programmatically via admin API
- Verifies messages are published correctly with proper partitioning
- Tests consumer reading from Redpanda and validating message content
- Full end-to-end flow: outbox → relay → Redpanda → consumer

**Dependencies Added:**
- ✅ `github.com/testcontainers/testcontainers-go@v0.40.0`
- ✅ `github.com/testcontainers/testcontainers-go/modules/redpanda@v0.40.0`

**Fixed Issues:**
- Added `serializer:json` tag to DocumentRevisionOutbox.Payload for SQLite compatibility
- All existing relay tests now pass with proper JSON serialization

### 2. Consumer Kafka Integration Tests (High Priority) ✅ COMPLETED

**Status:** Implemented successfully - `pkg/indexer/consumer/consumer_redpanda_test.go`

**Test Cases Implemented:**
- ✅ `TestConsumer_ConsumeFromRedpanda` - Tests full consumer flow with pipeline execution
- ✅ `TestConsumer_RulesetMatching` - Tests conditional ruleset matching (e.g., RFC documents only)
- ✅ `TestConsumer_NoMatchingRuleset` - Tests that no pipeline executes when no ruleset matches
- ✅ `TestConsumer_Idempotency` - Tests duplicate event handling (doesn't reprocess)

**Key Features:**
- Uses testcontainers to start real Redpanda instance
- Full end-to-end flow: Redpanda → Consumer → Ruleset Matcher → Pipeline Executor
- Validates pipeline execution tracking in database
- Tests ruleset condition matching (equals, contains, etc.)
- Mock pipeline steps for verification
- Unique consumer groups per test to avoid conflicts
- `ConsumeFromStart` option for testing (reads all messages from beginning)

**Fixed Issues:**
- Added `serializer:json` tags to `DocumentRevisionPipelineExecution` model fields
- Made `consumer.Stop()` idempotent to prevent double-close panics
- Fixed `Rulesets` type usage and `GroupMetadata()` handling
- All consumer tests now pass with proper JSON serialization

**Validated Full Architecture:**
```
Outbox → Relay → Redpanda → Consumer → Matcher → Executor → [Steps]
  ✅      ✅        ✅         ✅         ✅         ✅        ✅
```

### 3. LLM Client Tests (Medium Priority) ✅ COMPLETED (OpenAI)

**Status:** OpenAI client implemented and tested - `pkg/llm/openai.go` & `pkg/llm/openai_test.go`

**Test Cases Implemented:**
- ✅ `TestOpenAIClient_GenerateSummary` - Tests full summary generation flow with mock HTTP server
- ✅ `TestOpenAIClient_GenerateSummary_APIError` - Tests API error handling (rate limits, etc.)
- ✅ `TestOpenAIClient_GenerateSummary_Timeout` - Tests timeout handling
- ✅ `TestOpenAIClient_GenerateSummary_EmptyResponse` - Tests empty response handling
- ✅ `TestOpenAIClient_ParseSummaryResponse` - Tests structured response parsing (4 sub-tests)
- ✅ `TestNewOpenAIClient_Validation` - Tests client configuration validation (3 sub-tests)
- ✅ `TestOpenAIClient_ContentTruncation` - Tests large content truncation

**Key Features:**
- Full OpenAI Chat Completions API integration
- Structured prompt system with system/user messages
- Response parsing: Executive Summary, Key Points, Topics, Tags
- HTTP mock server for testing (no real API calls needed)
- Comprehensive error handling (rate limits, timeouts, API errors)
- Content truncation for large documents (40k chars max)
- Configurable temperature and token limits

**Fixed Issues:**
- Parser bug: Section headers using `strings.Contains` would match keywords in content
- Solution: Changed to `strings.HasPrefix` for precise header detection

**Test Results:** 7 tests, 11 sub-tests - ALL PASSING ✅

### 4. Ollama LLM Client Tests (Medium Priority) ✅ COMPLETED

**Status:** Ollama client implemented and tested - `pkg/llm/ollama.go` & `pkg/llm/ollama_test.go`

**Test Cases Implemented:**
- ✅ `TestOllamaClient_GenerateSummary` - Tests full summary generation with mock Ollama server
- ✅ `TestOllamaClient_GenerateSummary_APIError` - Tests API error handling
- ✅ `TestOllamaClient_GenerateSummary_Timeout` - Tests timeout handling
- ✅ `TestOllamaClient_GenerateSummary_EmptyResponse` - Tests empty response handling
- ✅ `TestOllamaClient_ParseSummaryResponse` - Tests structured response parsing (4 sub-tests)
- ✅ `TestNewOllamaClient_Validation` - Tests client configuration (3 sub-tests)
- ✅ `TestOllamaClient_ContentTruncation` - Tests large content truncation
- ✅ `TestOllamaClient_DifferentModels` - Tests with different Ollama models (llama2, mistral, codellama, phi)

**Key Features:**
- Local LLM integration via Ollama API
- Chat-based API similar to OpenAI for consistency
- Support for multiple models (llama2, mistral, codellama, phi, etc.)
- Same structured parsing as OpenAI client
- No token counting (Ollama doesn't provide this)
- Longer default timeout (300s) for local generation
- Default endpoint: http://localhost:11434

**Test Results:** 8 tests, 15 sub-tests - ALL PASSING ✅

### 5. AWS Bedrock LLM Client Tests (Medium Priority) ✅ COMPLETED

**Status:** Bedrock client implemented and tested - `pkg/llm/bedrock.go` & `pkg/llm/bedrock_test.go`

**Test Cases Implemented:**
- ✅ `TestBedrockClient_GenerateSummary` - Tests full summary generation with mock Bedrock API
- ✅ `TestBedrockClient_GenerateSummary_DefaultModel` - Tests default Claude 3.7 Sonnet model
- ✅ `TestBedrockClient_GenerateSummary_EmptyResponse` - Tests empty response handling
- ✅ `TestBedrockClient_GenerateSummary_NoOutput` - Tests missing output handling
- ✅ `TestBedrockClient_ParseSummaryResponse` - Tests structured response parsing (4 sub-tests)
- ✅ `TestBedrockClient_ContentTruncation` - Tests large content truncation
- ✅ `TestBedrockClient_BuildPrompt_DifferentStyles` - Tests prompt style variations (4 sub-tests)
- ✅ `TestBedrockClient_SystemPrompt` - Tests system prompt generation
- ✅ `TestBedrockClient_DifferentModels` - Tests multiple Claude models (Claude 3.7, 3.5, 3 Opus)

**Key Features:**
- AWS Bedrock Converse API integration
- Default model: Claude 3.7 Sonnet (us.anthropic.claude-3-7-sonnet-20250219-v1:0)
- Support for all Claude 3 models via Bedrock
- Same structured parsing as OpenAI/Ollama
- AWS SDK v2 with proper credential handling
- Region-based configuration (default: us-east-1)

**Test Results:** 9 tests, 13 sub-tests - ALL PASSING ✅

**Combined LLM Stack:** OpenAI (cloud), Ollama (local), and Bedrock (AWS) clients with 89.5% combined coverage ✅

### 6. Ruleset Matcher Tests (High Priority) ✅ COMPLETED

**Status:** Comprehensive unit tests implemented - `pkg/indexer/ruleset/ruleset_test.go`

**Test Cases Implemented:**
- ✅ `TestMatcher_Match_NoConditions` - Tests matching all documents with empty conditions
- ✅ `TestMatcher_Match_MultipleRulesets` - Tests multiple ruleset matching
- ✅ `TestMatcher_Match_NoMatches` - Tests no ruleset matches
- ✅ `TestRuleset_Matches_ExactMatch` - Tests exact field matching
- ✅ `TestRuleset_Matches_PartialMatch_ShouldFail` - Tests AND logic between conditions
- ✅ `TestRuleset_Matches_WithMetadata` - Tests metadata field matching
- ✅ `TestRuleset_CompareEquals_InOperator` - Tests IN operator (comma-separated values)
- ✅ `TestRuleset_CompareContains` - Tests case-insensitive substring matching
- ✅ `TestRuleset_CompareGreaterThan` - Tests numeric > comparisons (7 sub-tests)
- ✅ `TestRuleset_CompareLessThan` - Tests numeric < comparisons (7 sub-tests)
- ✅ `TestRuleset_GetValue_RevisionFields` - Tests revision field extraction (7 sub-tests)
- ✅ `TestRuleset_GetValue_MetadataFields` - Tests metadata field extraction (4 sub-tests)
- ✅ `TestRuleset_GetValue_StripsOperatorSuffixes` - Tests operator suffix stripping (3 sub-tests)
- ✅ `TestRuleset_CompareEquals_NilValue` - Tests nil value handling
- ✅ `TestRuleset_CompareGreaterThan_NilValue` - Tests nil value handling for >
- ✅ `TestRuleset_CompareLessThan_NilValue` - Tests nil value handling for <
- ✅ `TestRuleset_CompareContains_NilValue` - Tests nil value handling for contains
- ✅ `TestRuleset_ToNumber_DifferentTypes` - Tests type conversion (7 sub-tests)
- ✅ `TestRuleset_GetStepConfig` - Tests step configuration extraction
- ✅ `TestRuleset_GetStepConfig_NoConfig` - Tests missing config handling
- ✅ `TestRuleset_GetStepConfig_InvalidType` - Tests invalid config type
- ✅ `TestRuleset_Validate_Success` - Tests valid ruleset validation
- ✅ `TestRuleset_Validate_MissingName` - Tests missing name error
- ✅ `TestRuleset_Validate_MissingPipeline` - Tests missing pipeline error
- ✅ `TestRuleset_Validate_InvalidStep` - Tests invalid step name error
- ✅ `TestRuleset_Validate_AllValidSteps` - Tests all valid step names
- ✅ `TestRulesets_ValidateAll_Success` - Tests collection validation
- ✅ `TestRulesets_ValidateAll_EmptyRulesets` - Tests empty collection error
- ✅ `TestRulesets_ValidateAll_OneInvalid` - Tests validation fails on one invalid
- ✅ `TestRuleset_ComplexConditions` - Tests complex multi-condition matching
- ✅ `TestRuleset_CaseInsensitiveContains` - Tests case-insensitive contains (5 sub-tests)
- ✅ `TestRuleset_MultipleMatchers_Priority` - Tests ruleset ordering

**Key Features Tested:**
- Condition operators: equals, IN (comma-separated), gt, lt, contains
- Field sources: revision fields, metadata fields
- Type conversion: int, int64, float64, string
- Validation: ruleset names, pipeline steps, conditions
- Edge cases: nil values, empty conditions, invalid types
- Complex conditions: multiple conditions with AND logic
- Case-insensitive string matching

**Test Results:** 29 tests, 50+ sub-tests - ALL PASSING with 97.8% coverage ✅

### 7. Pipeline Executor Tests (High Priority) ✅ COMPLETED

**Status:** Comprehensive unit tests implemented - `pkg/indexer/pipeline/executor_test.go`

**Test Cases Implemented:**
- ✅ `TestNewExecutor_Success` - Tests executor creation with steps
- ✅ `TestNewExecutor_MissingDB` - Tests validation of required DB parameter
- ✅ `TestNewExecutor_NoLogger` - Tests default logger creation
- ✅ `TestExecutor_Execute_Success` - Tests successful pipeline execution
- ✅ `TestExecutor_Execute_StepFailure_NonRetryable` - Tests fail-fast on non-retryable errors
- ✅ `TestExecutor_Execute_StepFailure_Retryable` - Tests continue-on-error for retryable failures
- ✅ `TestExecutor_Execute_UnknownStep` - Tests error handling for unknown steps
- ✅ `TestExecutor_Execute_WithStepConfig` - Tests step-specific configuration passing
- ✅ `TestExecutor_ExecuteMultiple_Success` - Tests multiple ruleset execution
- ✅ `TestExecutor_ExecuteMultiple_WithErrors` - Tests error aggregation across rulesets
- ✅ `TestExecutor_RegisterStep` - Tests dynamic step registration
- ✅ `TestExecutor_UnregisterStep` - Tests step removal
- ✅ `TestExecutor_GetRegisteredSteps` - Tests step discovery
- ✅ `TestStepContext_GetConfigString` - Tests string configuration helpers
- ✅ `TestStepContext_GetConfigInt` - Tests integer configuration helpers
- ✅ `TestStepContext_GetConfigBool` - Tests boolean configuration helpers
- ✅ `TestStepContext_GetConfigMap` - Tests map configuration helpers
- ✅ `TestStepContext_Elapsed` - Tests execution timing
- ✅ `TestExecutor_Execute_RecordsStepDuration` - Tests duration tracking

**Key Features Tested:**
- Executor initialization and validation
- Step execution orchestration
- Error handling strategies (fail-fast vs continue)
- Retryable vs non-retryable error distinction
- Pipeline execution tracking in database
- Step result recording with durations
- Multiple ruleset execution
- Dynamic step registration/unregistration
- Configuration passing to steps
- StepContext helper utilities

**Bug Fixed:**
- SQLite JSON serialization issue with `db.Model().Updates()` for map fields
- Changed all model update methods to use `db.Save()` for proper JSON serialization
- Affects: `Start()`, `RecordStepResult()`, `MarkAsCompleted()`, `MarkAsFailed()`, `MarkAsPartial()`, `Retry()`

**Test Results:** 18 tests - ALL PASSING with ~90% coverage ✅

### 3. Search Index Step Tests (Medium Priority)

**Status:** Basic implementation - needs real Meilisearch testing

**What to Test:**
```go
func TestSearchIndexStep_WithMeilisearch(t *testing.T) {
    // Start Meilisearch testcontainer
    // Create search provider
    // Execute search index step
    // Verify document indexed in Meilisearch
}
```

### 4. Content Fetching Tests (High Priority) ✅ COMPLETED

**Status:** Implemented and tested - `pkg/indexer/pipeline/steps/llm_summary_test.go`

**Test Cases Implemented:**
- ✅ `TestLLMSummaryStep_FetchDocumentContent_Success` - Tests successful content fetching
- ✅ `TestLLMSummaryStep_FetchDocumentContent_ProviderError` - Tests provider error handling
- ✅ `TestLLMSummaryStep_FetchDocumentContent_NoProvider` - Tests missing provider handling
- ✅ `TestLLMSummaryStep_CleanContent` - Tests content cleaning (4 sub-tests)
- ✅ `TestLLMSummaryStep_Execute_WithContentFetching` - Tests full execution with content fetching
- ✅ `TestLLMSummaryStep_Execute_ContentTooShort` - Tests short content skip logic
- ✅ `TestLLMSummaryStep_Execute_IdempotentSummary` - Tests idempotent summary generation
- ✅ `TestLLMSummaryStep_Execute_FetchContentError` - Tests content fetch error propagation
- ✅ `TestMockWorkspaceProvider_DefaultContent` - Tests mock provider default behavior
- ✅ `TestMockWorkspaceProvider_SpecificContent` - Tests mock provider with specific content

**Key Features Implemented:**
- Workspace provider integration via `WorkspaceContentProvider` interface
- Content fetching from workspace providers (Google Drive, local, etc.)
- Content cleaning and normalization for LLM processing
- Error handling for provider failures
- Mock workspace provider for testing
- Integration with LLM summary step

**Implementation:**
- Added `WorkspaceContentProvider` interface to `llm_summary.go`
- Implemented `fetchDocumentContent()` method
- Added `cleanContent()` method for content normalization
- Created `MockWorkspaceProvider` for testing
- Updated `NewLLMSummaryStep()` constructor to accept workspace provider

**Test Results:** 10 tests, 14 sub-tests - ALL PASSING ✅

### 5. Performance/Load Tests (Low Priority)

**What to Test:**
- Relay throughput (events/sec)
- Consumer processing rate
- Database performance with large outbox
- Pipeline execution time

## Running Tests

### Unit Tests (Fast)
```bash
# Publisher tests
go test ./pkg/indexer/publisher/... -v

# Relay tests
go test ./pkg/indexer/relay/... -v

# E2E tests
go test ./tests/integration/indexer/... -v
```

### Integration Tests (Requires Docker)
```bash
# Start test infrastructure
cd testing
docker compose up -d postgres redpanda meilisearch

# Run tests with real services
go test ./tests/integration/... -tags=integration -v
```

### All Tests
```bash
make test
```

## Test Metrics

| Component | Tests | Coverage | Status |
|-----------|-------|----------|--------|
| Publisher | 5 | ~90% | ✅ Good |
| Relay | 14 | ~85% | ✅ Good (with Redpanda integration) |
| Consumer | 5 (4 Redpanda + 1 E2E) | ~80% | ✅ Good (with Redpanda integration) |
| LLM Client (OpenAI) | 7 (11 sub-tests) | ~90% | ✅ Excellent |
| LLM Client (Ollama) | 8 (15 sub-tests) | ~90% | ✅ Excellent |
| LLM Client (Bedrock) | 9 (13 sub-tests) | ~90% | ✅ Excellent |
| Ruleset Matcher | 29 (50+ sub-tests) | 97.8% | ✅ Excellent |
| Pipeline Executor | 18 | ~90% | ✅ Excellent |
| Pipeline Steps (LLM Summary) | 10 (14 sub-tests) | ~85% | ✅ Excellent |
| Pipeline Steps (Search Index) | 0 | ~0% | ⚠️  Basic implementation only |
| **Overall** | **106** | **~86%** | ✅ **Excellent Progress** |

## Success Criteria

### Phase 1: Basic Testing ✅ (Current)
- [x] Publisher integration tests
- [x] Relay unit tests
- [x] Basic E2E test
- [x] Idempotency verification

### Phase 2: Integration Testing ✅ (Completed)
- [x] Redpanda testcontainer integration
- [x] Relay → Redpanda publishing tests
- [x] Consumer → Redpanda consumption tests
- [x] Full relay → Redpanda → consumer flow test
- [ ] Meilisearch integration test (Future)
- [ ] Content fetching tests (Future)

### Phase 3: Production Readiness (Future)
- [ ] Load tests (1000+ events/sec)
- [ ] Chaos testing (network failures, DB unavailable)
- [ ] Performance benchmarks
- [ ] Monitoring/observability tests

## Next Actions

1. ~~**Implement Redpanda testcontainer tests**~~ ✅ COMPLETED
   - ~~Install testcontainers-go~~ ✅
   - ~~Create `TestRelay_WithRedpanda`~~ ✅
   - ~~Test relay publishing to Redpanda~~ ✅
   - ~~Test error handling and retries~~ ✅

2. ~~**Implement Consumer Redpanda tests**~~ ✅ COMPLETED
   - ~~Create `TestConsumer_WithRedpanda`~~ ✅
   - ~~Test full publish → consume flow~~ ✅
   - ~~Verify pipeline execution from Kafka events~~ ✅

3. ~~**Implement OpenAI LLM client**~~ ✅ COMPLETED
   - ~~OpenAI Chat Completions API integration~~ ✅
   - ~~Comprehensive test suite with mock HTTP server~~ ✅
   - ~~Error handling (rate limits, timeouts, API errors)~~ ✅

4. ~~**Add Ollama LLM client**~~ ✅ COMPLETED
   - ~~Ollama client for local testing~~ ✅
   - ~~Integration tests with mock Ollama server~~ ✅
   - ~~Support for multiple models (llama2, mistral, codellama, phi)~~ ✅

5. ~~**Add AWS Bedrock LLM client**~~ ✅ COMPLETED
   - ~~Bedrock Converse API integration~~ ✅
   - ~~Default Claude 3.7 Sonnet model~~ ✅
   - ~~Support for all Claude 3 models~~ ✅
   - ~~Mock-based testing~~ ✅

6. ~~**Add unit tests for ruleset matcher**~~ ✅ COMPLETED
   - ~~Test condition matching (equals, IN, gt/lt, contains)~~ ✅
   - ~~Test edge cases (empty conditions, invalid values)~~ ✅
   - ~~29 tests with 97.8% coverage~~ ✅

7. ~~**Add unit tests for pipeline executor**~~ ✅ COMPLETED
   - ~~Test step registration and unregistration~~ ✅
   - ~~Test error handling (retryable vs non-retryable)~~ ✅
   - ~~Test retry logic and fail-fast behavior~~ ✅
   - ~~Test configuration passing to steps~~ ✅
   - ~~Test StepContext helper methods~~ ✅
   - ~~18 tests with ~90% coverage~~ ✅

8. ~~**Implement content fetching**~~ ✅ COMPLETED
   - ~~Add workspace provider integration~~ ✅
   - ~~Implement content fetching in LLM summary step~~ ✅
   - ~~Add content cleaning and normalization~~ ✅
   - ~~Test with mock workspace provider~~ ✅
   - ~~10 tests with ~85% coverage~~ ✅

9. **Implement search index step**
   - Add search provider integration
   - Test with mock Meilisearch
   - Test document indexing

## Test Commands Reference

```bash
# Run all tests
go test ./... -v

# Run specific package tests
go test ./pkg/indexer/publisher/... -v

# Run with coverage
go test ./... -cover -coverprofile=coverage.out
go tool cover -html=coverage.out

# Run integration tests only
go test ./tests/integration/... -tags=integration -v

# Run with race detector
go test ./... -race

# Run benchmarks
go test ./... -bench=. -benchmem
```

---

**Status**: Phase 1 Complete ✅ | Phase 2 Complete ✅ | Phase 3 In Progress 🚀
**Last Updated**: 2025-11-15
**Next Milestone**: Search Index Step Implementation
**Recent Completions**:
- ✅ Content fetching implementation with workspace provider integration (10 tests, ~85% coverage)
- ✅ Content cleaning and normalization for LLM processing
- ✅ Pipeline Executor comprehensive unit tests (18 tests, ~90% coverage)
- ✅ Fixed SQLite JSON serialization bug in model update methods
- ✅ AWS Bedrock LLM client with Claude 3.7 Sonnet (9 tests, 13 sub-tests)
- ✅ Ruleset Matcher comprehensive unit tests (29 tests, 97.8% coverage)
- ✅ Triple LLM Stack: OpenAI (cloud) + Ollama (local) + Bedrock (AWS)
**Total Test Count**: 106 tests | 86% overall coverage | 🎉 Excellent progress!
