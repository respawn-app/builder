package runtime

import (
	"context"
	"encoding/json"
	"io"
	"net/http"
	"net/http/httptest"
	"testing"
	"time"

	"builder/server/llm"
	"builder/server/session"
	"builder/server/tools"
	"builder/shared/cachewarn"
	"builder/shared/config"
	"builder/shared/toolspec"
	"builder/shared/transcript"
)

func TestApplyPersistedCacheWarningUsesCacheWarningModeVisibility(t *testing.T) {
	tests := []struct {
		name string
		mode config.CacheWarningMode
		want transcript.EntryVisibility
	}{
		{name: "default", mode: config.CacheWarningModeDefault, want: transcript.EntryVisibilityDetailOnly},
		{name: "verbose", mode: config.CacheWarningModeVerbose, want: transcript.EntryVisibilityAll},
	}
	for _, tt := range tests {
		t.Run(tt.name, func(t *testing.T) {
			eng := &Engine{cfg: Config{CacheWarningMode: tt.mode}, chat: newChatStore()}
			eng.applyPersistedCacheWarning(cachewarn.Warning{Scope: cachewarn.ScopeConversation, Reason: cachewarn.ReasonReuseDropped})
			snapshot := eng.ChatSnapshot()
			if len(snapshot.Entries) != 1 {
				t.Fatalf("expected one cache warning entry, got %d", len(snapshot.Entries))
			}
			if got := snapshot.Entries[0].Visibility; got != tt.want {
				t.Fatalf("cache warning visibility = %q, want %q", got, tt.want)
			}
		})
	}
}

type transportStaticAuth struct{}

func (transportStaticAuth) AuthorizationHeader(context.Context) (string, error) {
	return "Bearer token", nil
}

func TestGenerateWithRetryClient_PersistsExactNonPostfixCacheWarningInDefaultMode(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10, HasCachedInputTokens: true, CachedInputTokens: 7}}, {Usage: llm.Usage{InputTokens: 12, HasCachedInputTokens: true, CachedInputTokens: 0}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeDefault})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if warnings := persistedCacheWarnings(t, store); len(warnings) != 0 {
		t.Fatalf("warning count after baseline success = %d, want 0", len(warnings))
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testPromptCacheRequest("cache-key-1", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("second generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 1 {
		t.Fatalf("warning count = %d, want 1", len(warnings))
	}
	if warnings[0].Reason != cachewarn.ReasonNonPostfix {
		t.Fatalf("warning reason = %q, want %q", warnings[0].Reason, cachewarn.ReasonNonPostfix)
	}
	if warnings[0].LostInputTokens != 7 {
		t.Fatalf("warning lost input tokens = %d, want 7", warnings[0].LostInputTokens)
	}
}

func TestNew_RejectsInvalidCacheWarningMode(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	if _, err := New(store, &fakeClient{}, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningMode("bogus")}); err == nil {
		t.Fatal("expected invalid cache_warning_mode to fail")
	}
}

func TestGenerateWithRetryClient_OffModeSuppressesExactNonPostfixWarning(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeOff})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testPromptCacheRequest("cache-key-1", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("second generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestGenerateWithRetryClient_FailedRequestDoesNotAdvanceLineage(t *testing.T) {
	withGenerateRetryDelays(t, []time.Duration{time.Millisecond, time.Millisecond, time.Millisecond, time.Millisecond, time.Millisecond})

	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeDefault})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	failingClient := failingCacheClient{caps: llm.ProviderCapabilities{ProviderID: "openai", SupportsResponsesAPI: true, SupportsPromptCacheKey: true, IsOpenAIFirstParty: true}}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", &failingClient, testPromptCacheRequest("cache-key-1", "beta"), nil, nil, nil); err == nil {
		t.Fatal("expected failed generate")
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-3", client, testPromptCacheRequest("cache-key-1", "alpha", "omega"), nil, nil, nil); err != nil {
		t.Fatalf("third generate: %v", err)
	}
	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestGenerateWithRetryClient_PersistsVerboseReuseDropWarning(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10, HasCachedInputTokens: true, CachedInputTokens: 4}}, {Usage: llm.Usage{InputTokens: 12, HasCachedInputTokens: true, CachedInputTokens: 0}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testPromptCacheRequest("cache-key-1", "alpha", "omega"), nil, nil, nil); err != nil {
		t.Fatalf("second generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 1 {
		t.Fatalf("warning count = %d, want 1", len(warnings))
	}
	if warnings[0].Reason != cachewarn.ReasonReuseDropped {
		t.Fatalf("warning reason = %q, want %q", warnings[0].Reason, cachewarn.ReasonReuseDropped)
	}
	if warnings[0].LostInputTokens != 4 {
		t.Fatalf("warning lost input tokens = %d, want 4", warnings[0].LostInputTokens)
	}
}

func TestGenerateWithRetryClient_DoesNotWarnAcrossDistinctCacheKeys(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testPromptCacheRequest("cache-key-2", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("second generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestBuildRequest_SkipsPromptCacheKeyForUnsupportedProvider(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5"})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	req, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "hello"}}, true)
	if err != nil {
		t.Fatalf("build request: %v", err)
	}
	if req.PromptCacheKey != "" {
		t.Fatalf("PromptCacheKey = %q, want empty", req.PromptCacheKey)
	}
	if req.PromptCacheScope != "" {
		t.Fatalf("PromptCacheScope = %q, want empty", req.PromptCacheScope)
	}
}

func TestBuildRequest_UsesBasePromptCacheKeyBeforeFirstCompactionWhenProviderSupportsIt(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5"})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	req, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "hello"}}, true)
	if err != nil {
		t.Fatalf("build request: %v", err)
	}
	if got, want := req.SessionID, eng.conversationSessionID(); got != want {
		t.Fatalf("SessionID = %q, want %q", got, want)
	}
	if got, want := req.PromptCacheKey, eng.conversationPromptCacheKey(); got != want {
		t.Fatalf("PromptCacheKey = %q, want %q", got, want)
	}
	if req.PromptCacheScope != cachewarn.ScopeConversation {
		t.Fatalf("PromptCacheScope = %q, want %q", req.PromptCacheScope, cachewarn.ScopeConversation)
	}
}

func TestBuildRequest_RotatesPromptCacheKeyWithRequestSessionIDAfterCompaction(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5"})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	eng.compactionCount = 1
	req, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "hello"}}, true)
	if err != nil {
		t.Fatalf("build request: %v", err)
	}
	if got, want := req.SessionID, eng.conversationSessionID(); got != want {
		t.Fatalf("SessionID = %q, want %q", got, want)
	}
	if got, want := req.PromptCacheKey, eng.conversationPromptCacheKey(); got != want {
		t.Fatalf("PromptCacheKey = %q, want %q", got, want)
	}
}

func TestBuildRequest_RotatesPromptCacheKeyFromPersistedCompactionOnReopen(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	if _, err := store.AppendEvent("legacy-compact", "history_replaced", historyReplacementPayload{
		Engine: "local",
		Mode:   string(compactionModeManual),
		Items:  llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}}),
	}); err != nil {
		t.Fatalf("append history_replaced: %v", err)
	}

	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	client := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true}}
	eng, err := New(reopened, client, tools.NewRegistry(), Config{Model: "gpt-5"})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	req, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "hello"}}, true)
	if err != nil {
		t.Fatalf("build request: %v", err)
	}
	if got, want := req.SessionID, eng.conversationSessionID(); got != want {
		t.Fatalf("SessionID = %q, want %q", got, want)
	}
	if got, want := req.PromptCacheKey, eng.conversationPromptCacheKey(); got != want {
		t.Fatalf("PromptCacheKey = %q, want %q", got, want)
	}
}

func TestLocalCompactionSummary_UsesMainConversationRequestIdentityAndPrompt(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{
		caps:      llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true},
		responses: []llm.Response{{Assistant: llm.Message{Role: llm.RoleAssistant, Content: "summary"}}},
	}
	eng, err := New(store, client, tools.NewRegistry(fakeTool{name: toolspec.ToolExecCommand}), Config{Model: "gpt-5", EnabledTools: []toolspec.ID{toolspec.ToolExecCommand}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	eng.compactionCount = 1
	input := llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleUser, Content: "alpha"}, {Role: llm.RoleAssistant, Content: "beta"}})
	if _, err := eng.localCompactionSummary(context.Background(), input, compactionInstructions("keep API details")); err != nil {
		t.Fatalf("local compaction summary: %v", err)
	}
	if len(client.calls) != 1 {
		t.Fatalf("model calls = %d, want 1", len(client.calls))
	}
	req := client.calls[0]
	locked, err := eng.ensureLocked()
	if err != nil {
		t.Fatalf("ensure locked: %v", err)
	}
	if got, want := req.SessionID, eng.conversationSessionID(); got != want {
		t.Fatalf("SessionID = %q, want %q", got, want)
	}
	if got, want := req.PromptCacheKey, eng.conversationPromptCacheKey(); got != want {
		t.Fatalf("PromptCacheKey = %q, want %q", got, want)
	}
	if got, want := req.PromptCacheScope, cachewarn.ScopeConversation; got != want {
		t.Fatalf("PromptCacheScope = %q, want %q", got, want)
	}
	if got, want := req.SystemPrompt, eng.systemPrompt(locked); got != want {
		t.Fatalf("SystemPrompt mismatch\ngot: %q\nwant: %q", got, want)
	}
	if got, want := req.ReasoningEffort, eng.ThinkingLevel(); got != want {
		t.Fatalf("ReasoningEffort = %q, want %q", got, want)
	}
	if got, want := req.FastMode, eng.FastModeEnabled(); got != want {
		t.Fatalf("FastMode = %v, want %v", got, want)
	}
	if len(req.Tools) != 1 || req.Tools[0].Name != string(toolspec.ToolExecCommand) {
		t.Fatalf("Tools = %+v, want exec_command tool contract", req.Tools)
	}
}

func TestOpenAIResponsesPayload_UsesExpectedCacheKeyShapesAcrossConversationSupervisorAndReopen(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai", SupportsResponsesAPI: true, SupportsPromptCacheKey: true, IsOpenAIFirstParty: true}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	payloadOptions := llm.OpenAIResponsesPayloadOptions{Capabilities: client.caps}

	beforeReq, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "before"}}, true)
	if err != nil {
		t.Fatalf("build before request: %v", err)
	}
	beforePayload := mustDecodeJSONMap(t, mustMarshalOpenAIResponsesPayloadForLineage(t, beforeReq, payloadOptions))
	if got, want := stringValue(beforePayload["prompt_cache_key"]), conversationPromptCacheKey(store.Meta().SessionID, 0); got != want {
		t.Fatalf("before prompt_cache_key = %q, want %q payload=%s", got, want, mustMarshalCanonicalJSONForLineage(t, beforePayload))
	}

	eng.compactionCount = 1
	conversationReq, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "payload-probe"}}, true)
	if err != nil {
		t.Fatalf("build conversation request: %v", err)
	}
	conversationPayload := mustDecodeJSONMap(t, mustMarshalOpenAIResponsesPayloadForLineage(t, conversationReq, payloadOptions))
	if got, want := conversationReq.SessionID, store.Meta().SessionID; got != want {
		t.Fatalf("conversation SessionID = %q, want %q", got, want)
	}
	if got, want := stringValue(conversationPayload["prompt_cache_key"]), conversationPromptCacheKey(store.Meta().SessionID, 1); got != want {
		t.Fatalf("conversation prompt_cache_key = %q, want %q", got, want)
	}

	reviewerReq, err := eng.buildReviewerRequest(context.Background(), client)
	if err != nil {
		t.Fatalf("build reviewer request: %v", err)
	}
	reviewerPayload := mustDecodeJSONMap(t, mustMarshalOpenAIResponsesPayloadForLineage(t, reviewerReq, payloadOptions))
	if got, want := reviewerReq.SessionID, reviewerSessionID(store.Meta().SessionID); got != want {
		t.Fatalf("reviewer SessionID = %q, want %q", got, want)
	}
	if got, want := stringValue(reviewerPayload["prompt_cache_key"]), reviewerPromptCacheKey(store.Meta().SessionID, 1); got != want {
		t.Fatalf("reviewer prompt_cache_key = %q, want %q", got, want)
	}

	if _, err := store.AppendEvent("legacy-compact", "history_replaced", historyReplacementPayload{
		Engine: "local",
		Mode:   string(compactionModeManual),
		Items:  llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}}),
	}); err != nil {
		t.Fatalf("append history_replaced: %v", err)
	}
	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	reopenedEng, err := New(reopened, client, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new reopened engine: %v", err)
	}
	reopenedReq, err := reopenedEng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "payload-probe"}}, true)
	if err != nil {
		t.Fatalf("build reopened request: %v", err)
	}
	reopenedPayload := mustDecodeJSONMap(t, mustMarshalOpenAIResponsesPayloadForLineage(t, reopenedReq, payloadOptions))
	if got, want := reopenedReq.SessionID, reopened.Meta().SessionID; got != want {
		t.Fatalf("reopened SessionID = %q, want %q", got, want)
	}
	if got, want := stringValue(reopenedPayload["prompt_cache_key"]), conversationPromptCacheKey(reopened.Meta().SessionID, reopenedEng.compactionCountSnapshot()); got != want {
		t.Fatalf("reopened prompt_cache_key = %q, want %q", got, want)
	}
	if got, want := stringValue(reopenedPayload["instructions"]), stringValue(conversationPayload["instructions"]); got != want {
		t.Fatalf("reopened instructions = %q, want %q", got, want)
	}
}

func TestOpenAITransport_UsesExpectedSessionHeadersAndPromptCacheKeysAcrossConversationSupervisorAndReopen(t *testing.T) {
	type capturedRequest struct {
		path      string
		sessionID string
		payload   map[string]any
	}
	var capturedRequests []capturedRequest
	server := httptest.NewServer(http.HandlerFunc(func(w http.ResponseWriter, r *http.Request) {
		body, err := io.ReadAll(r.Body)
		if err != nil {
			t.Fatalf("read request body: %v", err)
		}
		var payload map[string]any
		if err := json.Unmarshal(body, &payload); err != nil {
			t.Fatalf("decode request payload: %v", err)
		}
		captured := capturedRequest{
			path:      r.URL.Path,
			sessionID: r.Header.Get("session_id"),
			payload:   payload,
		}
		capturedRequests = append(capturedRequests, captured)
		w.Header().Set("Content-Type", "application/json")
		_, _ = w.Write([]byte(`{"id":"resp_1","output":[{"type":"message","role":"assistant","status":"completed","content":[{"type":"output_text","text":"ok","annotations":[]}]}],"usage":{"input_tokens":1,"output_tokens":1,"total_tokens":2}}`))
	}))
	defer server.Close()

	transport := llm.NewHTTPTransport(transportStaticAuth{})
	transport.BaseURL = server.URL + "/v1"
	transport.Client = server.Client()
	openAIClient := llm.NewOpenAIClient(transport)

	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	engineClient := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai", SupportsResponsesAPI: true, SupportsPromptCacheKey: true, IsOpenAIFirstParty: true}}
	eng, err := New(store, engineClient, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	send := func(req llm.Request) capturedRequest {
		t.Helper()
		before := len(capturedRequests)
		if _, err := openAIClient.Generate(context.Background(), req); err != nil {
			t.Fatalf("transport generate: %v", err)
		}
		if len(capturedRequests) != before+1 {
			t.Fatalf("captured requests = %d, want %d", len(capturedRequests), before+1)
		}
		return capturedRequests[len(capturedRequests)-1]
	}

	mainBeforeReq, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "before"}}, true)
	if err != nil {
		t.Fatalf("build main before request: %v", err)
	}
	mainBefore := send(mainBeforeReq)
	if got, want := mainBefore.path, "/v1/responses"; got != want {
		t.Fatalf("main before path = %q, want %q", got, want)
	}
	if got, want := mainBefore.sessionID, store.Meta().SessionID; got != want {
		t.Fatalf("main before session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(mainBefore.payload["prompt_cache_key"]), store.Meta().SessionID; got != want {
		t.Fatalf("main before prompt_cache_key = %q, want %q", got, want)
	}

	reviewerBeforeReq, err := eng.buildReviewerRequest(context.Background(), engineClient)
	if err != nil {
		t.Fatalf("build reviewer before request: %v", err)
	}
	reviewerBefore := send(reviewerBeforeReq)
	if got, want := reviewerBefore.sessionID, reviewerSessionID(store.Meta().SessionID); got != want {
		t.Fatalf("reviewer before session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(reviewerBefore.payload["prompt_cache_key"]), reviewerPromptCacheKey(store.Meta().SessionID, 0); got != want {
		t.Fatalf("reviewer before prompt_cache_key = %q, want %q", got, want)
	}

	eng.compactionCount = 1
	mainAfterReq, err := eng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "after"}}, true)
	if err != nil {
		t.Fatalf("build main after request: %v", err)
	}
	mainAfter := send(mainAfterReq)
	if got, want := mainAfter.sessionID, store.Meta().SessionID; got != want {
		t.Fatalf("main after session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(mainAfter.payload["prompt_cache_key"]), conversationPromptCacheKey(store.Meta().SessionID, 1); got != want {
		t.Fatalf("main after prompt_cache_key = %q, want %q", got, want)
	}

	reviewerAfterReq, err := eng.buildReviewerRequest(context.Background(), engineClient)
	if err != nil {
		t.Fatalf("build reviewer after request: %v", err)
	}
	reviewerAfter := send(reviewerAfterReq)
	if got, want := reviewerAfter.sessionID, reviewerSessionID(store.Meta().SessionID); got != want {
		t.Fatalf("reviewer after session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(reviewerAfter.payload["prompt_cache_key"]), reviewerPromptCacheKey(store.Meta().SessionID, 1); got != want {
		t.Fatalf("reviewer after prompt_cache_key = %q, want %q", got, want)
	}

	if _, err := store.AppendEvent("legacy-compact", "history_replaced", historyReplacementPayload{
		Engine: "local",
		Mode:   string(compactionModeManual),
		Items:  llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}}),
	}); err != nil {
		t.Fatalf("append history_replaced: %v", err)
	}
	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	reopenedEng, err := New(reopened, engineClient, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new reopened engine: %v", err)
	}
	reopenedMainReq, err := reopenedEng.buildRequestWithExtraItems(context.Background(), []llm.ResponseItem{{Type: llm.ResponseItemTypeMessage, Role: llm.RoleUser, Content: "reopened"}}, true)
	if err != nil {
		t.Fatalf("build reopened main request: %v", err)
	}
	reopenedMain := send(reopenedMainReq)
	if got, want := reopenedMain.sessionID, reopened.Meta().SessionID; got != want {
		t.Fatalf("reopened main session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(reopenedMain.payload["prompt_cache_key"]), conversationPromptCacheKey(reopened.Meta().SessionID, reopenedEng.compactionCountSnapshot()); got != want {
		t.Fatalf("reopened main prompt_cache_key = %q, want %q", got, want)
	}

	reopenedReviewerReq, err := reopenedEng.buildReviewerRequest(context.Background(), engineClient)
	if err != nil {
		t.Fatalf("build reopened reviewer request: %v", err)
	}
	reopenedReviewer := send(reopenedReviewerReq)
	if got, want := reopenedReviewer.sessionID, reviewerSessionID(reopened.Meta().SessionID); got != want {
		t.Fatalf("reopened reviewer session_id header = %q, want %q", got, want)
	}
	if got, want := stringValue(reopenedReviewer.payload["prompt_cache_key"]), reviewerPromptCacheKey(reopened.Meta().SessionID, reopenedEng.compactionCountSnapshot()); got != want {
		t.Fatalf("reopened reviewer prompt_cache_key = %q, want %q", got, want)
	}
}

func TestReviewerSuggestions_SkipsPromptCacheKeyForUnsupportedProvider(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	engineClient := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai", SupportsResponsesAPI: true, SupportsPromptCacheKey: true, IsOpenAIFirstParty: true}}
	reviewerClient := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true}, responses: []llm.Response{{Assistant: llm.Message{Role: llm.RoleAssistant, Content: `{"suggestions":[]}`}}}}
	eng, err := New(store, engineClient, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	if _, err := eng.runReviewerSuggestions(context.Background(), "step-1", reviewerClient); err != nil {
		t.Fatalf("run reviewer suggestions: %v", err)
	}
	if len(reviewerClient.calls) != 1 {
		t.Fatalf("reviewer client calls = %d, want 1", len(reviewerClient.calls))
	}
	if got, want := reviewerClient.calls[0].SessionID, reviewerSessionID(store.Meta().SessionID); got != want {
		t.Fatalf("reviewer SessionID = %q, want %q", got, want)
	}
	if reviewerClient.calls[0].PromptCacheKey != "" {
		t.Fatalf("reviewer PromptCacheKey = %q, want empty", reviewerClient.calls[0].PromptCacheKey)
	}
	if reviewerClient.calls[0].PromptCacheScope != "" {
		t.Fatalf("reviewer PromptCacheScope = %q, want empty", reviewerClient.calls[0].PromptCacheScope)
	}
}

func TestReviewerSuggestions_UsesReviewerClientPromptCacheCapability(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	engineClient := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true}}
	reviewerClient := &fakeClient{
		caps:      llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true},
		responses: []llm.Response{{Assistant: llm.Message{Role: llm.RoleAssistant, Content: `{"suggestions":[]}`}}},
	}
	eng, err := New(store, engineClient, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	eng.compactionCount = 1
	if _, err := eng.runReviewerSuggestions(context.Background(), "step-1", reviewerClient); err != nil {
		t.Fatalf("run reviewer suggestions: %v", err)
	}
	if len(reviewerClient.calls) != 1 {
		t.Fatalf("reviewer client calls = %d, want 1", len(reviewerClient.calls))
	}
	if got, want := reviewerClient.calls[0].SessionID, reviewerSessionID(store.Meta().SessionID); got != want {
		t.Fatalf("reviewer SessionID = %q, want %q", got, want)
	}
	if got, want := reviewerClient.calls[0].PromptCacheKey, reviewerPromptCacheKey(store.Meta().SessionID, eng.compactionCountSnapshot()); got != want {
		t.Fatalf("reviewer PromptCacheKey = %q, want %q", got, want)
	}
	if reviewerClient.calls[0].PromptCacheScope != cachewarn.ScopeReviewer {
		t.Fatalf("reviewer PromptCacheScope = %q, want %q", reviewerClient.calls[0].PromptCacheScope, cachewarn.ScopeReviewer)
	}
}

func TestReviewerSuggestions_PromptCacheKeyStaysOnReviewerSessionAfterConversationCompaction(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	if _, err := store.AppendEvent("legacy-compact", "history_replaced", historyReplacementPayload{
		Engine: "local",
		Mode:   string(compactionModeManual),
		Items:  llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}}),
	}); err != nil {
		t.Fatalf("append history_replaced: %v", err)
	}

	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	engineClient := &fakeClient{caps: llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true}}
	reviewerClient := &fakeClient{
		caps:      llm.ProviderCapabilities{ProviderID: "openai-compatible", SupportsResponsesAPI: true, SupportsPromptCacheKey: true},
		responses: []llm.Response{{Assistant: llm.Message{Role: llm.RoleAssistant, Content: `{"suggestions":[]}`}}},
	}
	eng, err := New(reopened, engineClient, tools.NewRegistry(), Config{Model: "gpt-5", Reviewer: ReviewerConfig{Model: "gpt-5"}})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	if _, err := eng.runReviewerSuggestions(context.Background(), "step-1", reviewerClient); err != nil {
		t.Fatalf("run reviewer suggestions: %v", err)
	}
	if len(reviewerClient.calls) != 1 {
		t.Fatalf("reviewer client calls = %d, want 1", len(reviewerClient.calls))
	}
	if got, want := reviewerClient.calls[0].SessionID, reviewerSessionID(reopened.Meta().SessionID); got != want {
		t.Fatalf("reviewer SessionID = %q, want %q", got, want)
	}
	if got, want := reviewerClient.calls[0].PromptCacheKey, reviewerPromptCacheKey(reopened.Meta().SessionID, eng.compactionCountSnapshot()); got != want {
		t.Fatalf("reviewer PromptCacheKey = %q, want %q", got, want)
	}
}

func TestGenerateWithRetryClient_KeepsReviewerLineageIndependent(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 12}}, {Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("conversation first generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testReviewerPromptCacheRequest("cache-key-1/supervisor", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("reviewer first generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-3", client, testPromptCacheRequest("cache-key-1", "alpha", "omega"), nil, nil, nil); err != nil {
		t.Fatalf("conversation postfix generate: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-4", client, testReviewerPromptCacheRequest("cache-key-1/supervisor", "gamma"), nil, nil, nil); err != nil {
		t.Fatalf("reviewer non-postfix generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 1 {
		t.Fatalf("warning count = %d, want 1", len(warnings))
	}
	if warnings[0].Reason != cachewarn.ReasonNonPostfix {
		t.Fatalf("warning reason = %q, want %q", warnings[0].Reason, cachewarn.ReasonNonPostfix)
	}
	if warnings[0].Scope != cachewarn.ScopeReviewer {
		t.Fatalf("warning scope = %q, want %q", warnings[0].Scope, cachewarn.ScopeReviewer)
	}
}

func TestGenerateWithRetryClient_CompactionRotatesConversationCacheKeyWithoutWarning(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}, {Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeDefault})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if err := eng.replaceHistory("step-compact", "local", compactionModeManual, llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}})); err != nil {
		t.Fatalf("replace history: %v", err)
	}
	if len(persistedCacheWarnings(t, store)) != 0 {
		t.Fatal("expected compaction to avoid warnings before the next rotated-key request")
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-2", client, testPromptCacheRequest("cache-key-1/compact-1", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("second generate: %v", err)
	}

	warnings := persistedCacheWarnings(t, store)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestGenerateWithRetryClient_RestoreIgnoresRequestObservationWithoutResponse(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	if _, err := store.AppendEvent("legacy-request", sessionEventCacheRequestObserved, persistedCacheRequestObserved{
		DigestVersion: requestCacheDigestVersion,
		CacheKey:      "cache-key-1",
		Scope:         cachewarn.ScopeConversation,
		ChunkCount:    1,
		TerminalHash:  "failed-only-hash",
	}); err != nil {
		t.Fatalf("append request event: %v", err)
	}
	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(reopened, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeDefault})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}
	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha", "omega"), nil, nil, nil); err != nil {
		t.Fatalf("generate after reopen: %v", err)
	}
	warnings := persistedCacheWarnings(t, reopened)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

type failingCacheClient struct {
	caps llm.ProviderCapabilities
}

func (f *failingCacheClient) Generate(context.Context, llm.Request) (llm.Response, error) {
	return llm.Response{}, context.DeadlineExceeded
}

func (f *failingCacheClient) ProviderCapabilities(context.Context) (llm.ProviderCapabilities, error) {
	return f.caps, nil
}

func TestGenerateWithRetryClient_RestorePreservesRotatedCompactionKeyWithoutWarning(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 10}}}}
	eng, err := New(store, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "alpha"), nil, nil, nil); err != nil {
		t.Fatalf("first generate: %v", err)
	}
	if err := eng.replaceHistory("step-compact", "local", compactionModeManual, llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}})); err != nil {
		t.Fatalf("replace history: %v", err)
	}
	if err := eng.Close(); err != nil {
		t.Fatalf("close engine: %v", err)
	}

	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	reopenedClient := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 12}}}}
	reopenedEng, err := New(reopened, reopenedClient, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new reopened engine: %v", err)
	}

	if _, err := reopenedEng.generateWithRetryClient(context.Background(), "step-2", reopenedClient, testPromptCacheRequest("cache-key-1/compact-1", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("generate after reopen: %v", err)
	}

	warnings := persistedCacheWarnings(t, reopened)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestGenerateWithRetryClient_RestoreSkipsDigestVersionMismatch(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	legacyRequest := persistedCacheRequestObserved{
		DigestVersion: 999,
		CacheKey:      "cache-key-1",
		Scope:         cachewarn.ScopeConversation,
		ChunkCount:    1,
		TerminalHash:  "legacy-hash",
	}
	legacyResponse := persistedCacheResponseObserved{
		DigestVersion:        999,
		CacheKey:             "cache-key-1",
		Scope:                cachewarn.ScopeConversation,
		ChunkCount:           1,
		TerminalHash:         "legacy-hash",
		HasCachedInputTokens: true,
		CachedInputTokens:    42,
	}
	if _, err := store.AppendEvent("legacy-request", sessionEventCacheRequestObserved, legacyRequest); err != nil {
		t.Fatalf("append legacy request: %v", err)
	}
	if _, err := store.AppendEvent("legacy-response", sessionEventCacheResponseObserved, legacyResponse); err != nil {
		t.Fatalf("append legacy response: %v", err)
	}

	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(reopened, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeDefault})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest("cache-key-1", "beta"), nil, nil, nil); err != nil {
		t.Fatalf("generate after reopen: %v", err)
	}

	warnings := persistedCacheWarnings(t, reopened)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func TestGenerateWithRetryClient_DoesNotInventCompactionCauseWithoutPriorLineageOnReopen(t *testing.T) {
	dir := t.TempDir()
	store, err := session.Create(dir, "ws", dir)
	if err != nil {
		t.Fatalf("create store: %v", err)
	}
	if _, err := store.AppendEvent("legacy-compact", "history_replaced", historyReplacementPayload{
		Engine: "local",
		Mode:   string(compactionModeManual),
		Items:  llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleAssistant, MessageType: llm.MessageTypeCompactionSummary, Content: "summary"}}),
	}); err != nil {
		t.Fatalf("append history_replaced: %v", err)
	}

	reopened, err := session.Open(store.Dir())
	if err != nil {
		t.Fatalf("reopen store: %v", err)
	}
	client := &fakeClient{responses: []llm.Response{{Usage: llm.Usage{InputTokens: 12}}}}
	eng, err := New(reopened, client, tools.NewRegistry(), Config{Model: "gpt-5", CacheWarningMode: config.CacheWarningModeVerbose})
	if err != nil {
		t.Fatalf("new engine: %v", err)
	}

	if _, err := eng.generateWithRetryClient(context.Background(), "step-1", client, testPromptCacheRequest(reopened.Meta().SessionID, "beta"), nil, nil, nil); err != nil {
		t.Fatalf("generate after reopen: %v", err)
	}

	warnings := persistedCacheWarnings(t, reopened)
	if len(warnings) != 0 {
		t.Fatalf("warning count = %d, want 0", len(warnings))
	}
}

func testPromptCacheRequest(cacheKey string, messages ...string) llm.Request {
	items := make([]llm.ResponseItem, 0, len(messages))
	for _, message := range messages {
		items = append(items, llm.ItemsFromMessages([]llm.Message{{Role: llm.RoleUser, Content: message}})...)
	}
	return llm.Request{
		Model:            "gpt-5",
		SystemPrompt:     "system",
		PromptCacheKey:   cacheKey,
		PromptCacheScope: cachewarn.ScopeConversation,
		Items:            items,
	}
}

func testReviewerPromptCacheRequest(cacheKey string, messages ...string) llm.Request {
	request := testPromptCacheRequest(cacheKey, messages...)
	request.PromptCacheScope = cachewarn.ScopeReviewer
	return request
}

func mustMarshalOpenAIResponsesPayloadForLineage(t *testing.T, request llm.Request, options llm.OpenAIResponsesPayloadOptions) []byte {
	t.Helper()
	data, err := llm.MarshalOpenAIResponsesRequestJSON(request, options)
	if err != nil {
		t.Fatalf("marshal openai responses payload: %v", err)
	}
	return data
}

func mustDecodeJSONMap(t *testing.T, data []byte) map[string]any {
	t.Helper()
	var decoded map[string]any
	if err := json.Unmarshal(data, &decoded); err != nil {
		t.Fatalf("decode json map: %v", err)
	}
	return decoded
}

func mustMarshalCanonicalJSONForLineage(t *testing.T, value any) []byte {
	t.Helper()
	data, err := json.Marshal(value)
	if err != nil {
		t.Fatalf("marshal canonical json: %v", err)
	}
	return data
}

func stringValue(value any) string {
	if text, ok := value.(string); ok {
		return text
	}
	return ""
}

func persistedCacheWarnings(t *testing.T, store *session.Store) []cachewarn.Warning {
	t.Helper()
	events, err := store.ReadEvents()
	if err != nil {
		t.Fatalf("read events: %v", err)
	}
	warnings := make([]cachewarn.Warning, 0, len(events))
	for _, evt := range events {
		if evt.Kind != sessionEventCacheWarning {
			continue
		}
		var warning cachewarn.Warning
		if err := json.Unmarshal(evt.Payload, &warning); err != nil {
			t.Fatalf("decode warning: %v", err)
		}
		warnings = append(warnings, warning)
	}
	return warnings
}
