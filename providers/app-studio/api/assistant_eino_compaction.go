/*
Copyright 2026 The Railgrid Authors.

Licensed under the Apache License, Version 2.0 (the "License");
you may not use this file except in compliance with the License.
You may obtain a copy of the License at

    http://www.apache.org/licenses/LICENSE-2.0

Unless required by applicable law or agreed to in writing, software
distributed under the License is distributed on an "AS IS" BASIS,
WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
See the License for the specific language governing permissions and
limitations under the License.
*/

package api

import (
	"context"
	"encoding/json"
	"errors"
	"fmt"
	"os"
	"strconv"
	"strings"
	"sync"
	"time"
	"unicode/utf8"

	"github.com/cloudwego/eino/adk"
	"github.com/cloudwego/eino/adk/middlewares/summarization"
	"github.com/cloudwego/eino/callbacks"
	"github.com/cloudwego/eino/components"
	einomodel "github.com/cloudwego/eino/components/model"
	"github.com/cloudwego/eino/schema"
	"github.com/google/uuid"
)

const (
	projectEinoAssistantModelContextTokensEnv     = "APP_STUDIO_ASSISTANT_MODEL_CONTEXT_TOKENS"
	projectEinoAssistantDefaultModelContextTokens = 128000
	projectEinoAssistantCompactionReservePercent  = 25
	// Context overflow recovery is deliberately bounded.  Each retry removes
	// one oldest conversation segment, while the caller's context remains the
	// authority for cancellation and deadline handling.
	projectEinoAssistantCompactionMaxContextRecoveryAttempts = 3
)

type projectEinoAssistantContextRecoveryModel struct {
	einomodel.BaseChatModel
	maxAttempts int
}

func projectEinoAssistantModelWithContextRecovery(base einomodel.BaseChatModel) einomodel.BaseChatModel {
	if base == nil {
		return nil
	}
	return &projectEinoAssistantContextRecoveryModel{
		BaseChatModel: base,
		maxAttempts:   projectEinoAssistantCompactionMaxContextRecoveryAttempts,
	}
}

func (m *projectEinoAssistantContextRecoveryModel) Generate(
	ctx context.Context,
	input []*schema.Message,
	opts ...einomodel.Option,
) (*schema.Message, error) {
	current := append([]*schema.Message(nil), input...)
	for attempt := 0; ; attempt++ {
		if err := ctx.Err(); err != nil {
			return nil, err
		}
		response, err := m.BaseChatModel.Generate(ctx, current, opts...)
		if err == nil || !projectEinoAssistantContextWindowExceeded(err) {
			return response, err
		}
		if attempt >= m.maxAttempts {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		trimmed, ok := projectEinoAssistantEvictOldestModelHistory(current, false)
		if !ok {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		current = trimmed
	}
}

func (m *projectEinoAssistantContextRecoveryModel) Stream(
	ctx context.Context,
	input []*schema.Message,
	opts ...einomodel.Option,
) (*schema.StreamReader[*schema.Message], error) {
	current := append([]*schema.Message(nil), input...)
	for attempt := 0; ; attempt++ {
		if err := ctx.Err(); err != nil {
			return nil, err
		}
		reader, err := m.BaseChatModel.Stream(ctx, current, opts...)
		if err == nil || !projectEinoAssistantContextWindowExceeded(err) {
			return reader, err
		}
		if attempt >= m.maxAttempts {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		trimmed, ok := projectEinoAssistantEvictOldestModelHistory(current, false)
		if !ok {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		current = trimmed
	}
}

func projectEinoAssistantCompactionContextTokens() int {
	raw := strings.TrimSpace(os.Getenv(projectEinoAssistantModelContextTokensEnv))
	if raw == "" {
		return projectEinoAssistantDefaultModelContextTokens
	}
	value, err := strconv.Atoi(raw)
	if err != nil || value <= 0 {
		return projectEinoAssistantDefaultModelContextTokens
	}
	return value
}

// The checkpoint prompt and summary preamble below are adapted from OpenAI
// Codex commit 003ec63bba93cf994246799f795a6a4f6d67743a, specifically
// codex-rs/prompts/templates/compact/{prompt,summary_prefix}.md. Copyright
// OpenAI; used under the Apache License, Version 2.0.
const projectEinoAssistantCompactionPrompt = `You are performing a CONTEXT CHECKPOINT COMPACTION. Create a handoff summary for another LLM that will resume the task.

Include:
- Current progress and key decisions made
- Important context, constraints, or user preferences
- What remains to be done (clear next steps)
- Any critical data, examples, or references needed to continue

Be concise, structured, and focused on helping the next LLM seamlessly continue the work.`

const projectEinoAssistantCompactionSummaryPrefix = "Another language model started to solve this problem and produced a summary of its thinking process. You also have access to the state of the tools that were used by that language model. Use this to build on the work that has already been done and avoid duplicating work. Here is the summary produced by the other language model, use the information in this summary to assist with your own analysis:"

// Image tokenization depends on dimensions and provider policy, neither of
// which belongs in the durable attachment receipt. Reserve a conservative
// fixed budget per retained image so metadata-only placeholders still exert
// context pressure and trigger compaction before the provider rejects a long
// multimodal history.
const projectEinoAssistantHistoricalImageTokenEstimate = 4096

func projectEinoAssistantCompactionMiddleware(
	ctx context.Context,
	chatModel einomodel.BaseChatModel,
	server *Server,
	req projectAssistantRunRequest,
	runState *projectEinoAssistantRunState,
) (adk.ChatModelAgentMiddleware, error) {
	var latestCheckpoint *projectAssistantConversationCompactionCheckpoint
	if server != nil {
		if server.store == nil {
			return nil, fmt.Errorf("assistant conversation checkpoint store is not configured")
		}
		projection, err := loadProjectAssistantConversationProjection(ctx, server.store, req.MessageScope, req.ThreadID)
		if err != nil {
			return nil, fmt.Errorf("load assistant conversation compaction checkpoint: %w", err)
		}
		latestCheckpoint = projection.compactionCheckpoint
	}
	runtime := newProjectEinoAssistantCompactionRuntime(req.auditRecorder, latestCheckpoint)
	base, err := summarization.New(ctx, &summarization.Config{
		Model: &projectEinoAssistantCompactionIsolatedModel{
			BaseChatModel:    chatModel,
			forbidToolChoice: projectEinoAssistantCompactionSupportsForbiddenToolChoice(req.LLM),
		},
		ModelOptions: projectMaxTokensOptions(req.LLM.Model, 4096),
		Retry:        projectEinoAssistantCompactionRetryConfig(req),
		TokenCounter: projectEinoAssistantCompactionTokenCounter,
		Trigger: &summarization.TriggerCondition{
			// Codex rolls context from active model-window pressure rather than an
			// independent message-count ceiling.
			ContextTokens: projectEinoAssistantCompactionContextTokens(),
		},
		UserInstruction: projectEinoAssistantCompactionPrompt,
		// Codex local compaction sends the exact model-visible history followed by
		// one synthesized user checkpoint prompt. Do not inject Eino's generic
		// summarizer system instruction.
		GenModelInput: func(
			modelCtx context.Context,
			systemInstruction *schema.Message,
			userInstruction *schema.Message,
			original []*schema.Message,
		) ([]*schema.Message, error) {
			if err := projectEinoAssistantValidateHistoricalAttachmentMessages(original); err != nil {
				return nil, err
			}
			conversationTail := int64(0)
			if server != nil && server.store != nil {
				projection, err := loadProjectAssistantConversationProjection(modelCtx, server.store, req.MessageScope, req.ThreadID)
				if err != nil {
					return nil, fmt.Errorf("load assistant conversation tail before compaction: %w", err)
				}
				conversationTail = projection.lastSequence
			}
			if err := runtime.begin(modelCtx, projectEinoAssistantMessagesTokenEstimate(original), conversationTail); err != nil {
				return nil, err
			}
			return projectEinoAssistantCompactionModelInput(modelCtx, systemInstruction, userInstruction, original)
		},
		Finalize: func(finalizeCtx context.Context, original []*schema.Message, summary *schema.Message) ([]*schema.Message, error) {
			if err := projectEinoAssistantValidateHistoricalAttachmentMessages(original); err != nil {
				return nil, runtime.fail(finalizeCtx, err)
			}
			toolContinuation := projectEinoAssistantLastNonSystemMessageIsTool(original)
			ignoredToolCallCount := 0
			if summary != nil {
				ignoredToolCallCount = len(summary.ToolCalls)
			}
			canonicalContext, err := projectEinoAssistantCanonicalCompactionContext(finalizeCtx, req, runState)
			if err != nil {
				return nil, runtime.fail(finalizeCtx, err)
			}
			finalized, err := projectEinoAssistantFinalizeCompaction(
				canonicalContext,
				original,
				summary,
				runtime.toolSchemaTokens(),
			)
			if err != nil {
				return nil, runtime.fail(finalizeCtx, err)
			}
			// Codex compaction rebuilds older history as text-only context. Keep
			// image receipts only when they belong to the active incoming turn that
			// triggered this pre-model compaction; all older images leave context
			// with their compacted message payloads.
			finalized = projectEinoAssistantRetainCurrentCompactionImages(finalized, runState)

			summaryText := projectEinoAssistantSummaryText(summary)
			attempt, ok := runtime.activeAttempt()
			if !ok {
				err := fmt.Errorf("compaction attempt metadata is missing")
				return nil, runtime.fail(finalizeCtx, err)
			}
			checkpoint := projectAssistantConversationCompactionCheckpoint{
				Version:                         projectAssistantConversationCheckpointV1,
				ThreadID:                        req.ThreadID,
				ReplacementHistory:              projectEinoMessagesToChat(finalized),
				Summary:                         summaryText,
				TriggerID:                       attempt.triggerID,
				WindowNumber:                    attempt.windowNumber,
				FirstWindowID:                   attempt.firstWindowID,
				PreviousWindowID:                attempt.previousWindowID,
				WindowID:                        attempt.windowID,
				PriorHistoryTokenEstimate:       attempt.priorTokenEstimate,
				ReplacementHistoryTokenEstimate: projectEinoAssistantMessagesTokenEstimate(finalized),
				CompactedThroughSequence:        attempt.compactedThroughSequence,
			}
			if server != nil && server.store != nil {
				if err := appendProjectAssistantConversationCompactionCheckpoint(
					finalizeCtx,
					server.store,
					req.MessageScope,
					projectAssistantRunID(req),
					attempt.id,
					checkpoint,
				); err != nil {
					return nil, runtime.fail(finalizeCtx, fmt.Errorf("persist assistant conversation compaction: %w", err))
				}
			}
			if err := runState.RolloutBudget().RearmAfterCompaction(finalizeCtx); err != nil {
				return nil, runtime.fail(finalizeCtx, fmt.Errorf("rearm rollout budget after compaction: %w", err))
			}
			if toolContinuation {
				runState.DeferSteeringOnceAfterCompaction()
			}
			if err := runtime.complete(finalizeCtx, checkpoint, ignoredToolCallCount); err != nil {
				return nil, err
			}
			// The replacement history no longer contains the prior live context.
			// Clear the lifecycle baseline so the next model boundary performs a
			// full canonical-context reinjection, matching Codex's compaction
			// reference-context reset.
			runState.InvalidateModelContext()
			return finalized, nil
		},
	})
	if err != nil {
		return nil, err
	}
	return &projectEinoAssistantCompactionMiddlewareRuntime{
		ChatModelAgentMiddleware: base,
		runtime:                  runtime,
	}, nil
}

func projectEinoAssistantRetainCurrentCompactionImages(
	messages []*schema.Message,
	runState *projectEinoAssistantRunState,
) []*schema.Message {
	current := make(map[string]struct{})
	if runState != nil {
		for _, receipt := range projectAssistantImageAttachmentReceipts(runState.ContentParts()) {
			current[receipt.ID] = struct{}{}
		}
	}
	out := make([]*schema.Message, 0, len(messages))
	for _, message := range messages {
		if !projectEinoAssistantHistoricalAttachmentMessage(message) {
			out = append(out, message)
			continue
		}
		receipts, err := projectAssistantAttachmentReceiptsFromEinoMessageChecked(message)
		if err != nil {
			continue
		}
		for _, receipt := range receipts {
			// Text receipts are metadata-only mentions and remain selectable
			// after compaction. Images are retained only for the current incoming
			// turn; filtering per receipt is important when an older checkpoint
			// grouped old and current images in one placeholder.
			if projectAssistantAttachmentIsImage(receipt) {
				if _, exists := current[receipt.ID]; !exists {
					continue
				}
			}
			out = append(out, projectAssistantAttachmentPlaceholderMessage(receipt))
		}
	}
	return out
}

func projectEinoAssistantCompactionTokenCounter(
	_ context.Context,
	input *summarization.TokenCounterInput,
) (int, error) {
	if input == nil {
		return 0, nil
	}
	if err := projectEinoAssistantValidateHistoricalAttachmentMessages(input.Messages); err != nil {
		return 0, err
	}
	baseTokens := 0
	incrementStart := 0
	for index := len(input.Messages) - 1; index >= 0; index-- {
		message := input.Messages[index]
		if message == nil || message.Role != schema.Assistant || message.ResponseMeta == nil || message.ResponseMeta.Usage == nil || message.ResponseMeta.Usage.TotalTokens <= 0 {
			continue
		}
		baseTokens = message.ResponseMeta.Usage.TotalTokens
		incrementStart = index + 1
		break
	}
	increment := projectEinoAssistantMessagesTokenEstimate(input.Messages[incrementStart:]) +
		projectEinoAssistantToolSchemasTokenEstimate(input.Tools)
	return baseTokens + increment, nil
}

// Summary sampling is an internal checkpoint operation, not an ordinary agent
// response item. Replace the inherited agent callback set so a failed
// compaction cannot mutate mirrored model history or main-call audit entries.
type projectEinoAssistantCompactionIsolatedModel struct {
	einomodel.BaseChatModel
	forbidToolChoice bool
}

func (m *projectEinoAssistantCompactionIsolatedModel) Generate(
	ctx context.Context,
	input []*schema.Message,
	opts ...einomodel.Option,
) (*schema.Message, error) {
	ctx = callbacks.InitCallbacks(ctx, &callbacks.RunInfo{
		Name:      "app-studio-compaction",
		Type:      "AppStudioCompaction",
		Component: components.ComponentOfChatModel,
	})
	// Codex local compaction exposes no executable tools. Make that boundary
	// explicit for OpenAI-compatible providers: exact history still contains
	// earlier tool calls, and DeepSeek may otherwise continue that pattern even
	// when no tool schemas were supplied by the summarization middleware. Append
	// these options last so inherited or future callers cannot re-enable tools.
	opts = append(opts,
		einomodel.WithTools(nil),
		einomodel.WithDeferredTools(nil),
		einomodel.WithToolSearchTool(nil),
	)
	// The explicit tool_choice prohibition exists for DeepSeek models only:
	// their thinking variants may continue earlier tool-call patterns from the
	// exact history even without tool schemas. Spec-compliant OpenAI endpoints
	// reject tool_choice when no tools are specified, and DeepSeek V4's direct
	// thinking-mode API rejects the field outright, so both omit it. Empty tool
	// sets remain mandatory in every case.
	if m.forbidToolChoice {
		opts = append(opts, einomodel.WithToolChoice(schema.ToolChoiceForbidden))
	}
	currentInput := append([]*schema.Message(nil), input...)
	for attempt := 0; ; attempt++ {
		if err := ctx.Err(); err != nil {
			return nil, err
		}
		response, err := m.BaseChatModel.Generate(ctx, currentInput, opts...)
		if err == nil || !projectEinoAssistantContextWindowExceeded(err) {
			return response, err
		}
		if attempt >= projectEinoAssistantCompactionMaxContextRecoveryAttempts {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		trimmed, ok := projectEinoAssistantEvictOldestCompactionHistory(currentInput)
		if !ok {
			return nil, &projectEinoAssistantContextWindowExceededError{Cause: err}
		}
		currentInput = trimmed
	}
}

// projectEinoAssistantEvictOldestCompactionHistory drops one oldest eligible
// conversation segment while preserving system instructions and the final
// compaction checkpoint prompt.  Tool-call messages are removed together with
// their contiguous tool results so a retry cannot send an orphaned tool
// result to an OpenAI-compatible endpoint.
func projectEinoAssistantEvictOldestCompactionHistory(input []*schema.Message) ([]*schema.Message, bool) {
	return projectEinoAssistantEvictOldestModelHistory(input, true)
}

func projectEinoAssistantEvictOldestModelHistory(input []*schema.Message, preserveCompactionPrompt bool) ([]*schema.Message, bool) {
	if len(input) == 0 {
		return input, false
	}
	start := 0
	for start < len(input) && input[start] != nil && input[start].Role == schema.System {
		start++
	}
	endExclusive := len(input)
	if preserveCompactionPrompt && endExclusive > start {
		last := input[endExclusive-1]
		if last != nil && last.Role == schema.User && last.Content == projectEinoAssistantCompactionPrompt && len(last.ToolCalls) == 0 {
			endExclusive--
		}
	}
	if start >= endExclusive {
		return input, false
	}
	// Ordinary model recovery must retain the newest request/tool continuation.
	// It is a bounded request projection, not a replacement compaction, so the
	// durable history and compaction checkpoint authority remain unchanged.
	latestNonSystem := endExclusive - 1
	if !preserveCompactionPrompt {
		for latestNonSystem >= start {
			message := input[latestNonSystem]
			if message != nil && message.Role != schema.System {
				break
			}
			latestNonSystem--
		}
		if latestNonSystem <= start {
			return input, false
		}
	}

	removeEnd := start + 1
	first := input[start]
	if first != nil && first.Role == schema.Assistant && len(first.ToolCalls) > 0 {
		for removeEnd < endExclusive {
			message := input[removeEnd]
			if message == nil || message.Role != schema.Tool {
				break
			}
			removeEnd++
		}
	}
	if !preserveCompactionPrompt && removeEnd > latestNonSystem {
		return input, false
	}
	trimmed := make([]*schema.Message, 0, len(input)-(removeEnd-start))
	trimmed = append(trimmed, input[:start]...)
	trimmed = append(trimmed, input[removeEnd:]...)
	return trimmed, true
}

// projectEinoAssistantCompactionSupportsForbiddenToolChoice reports whether
// the compaction request should carry an explicit tool_choice "none". The
// OpenAI chat completion spec only allows tool_choice when tools are
// specified, and the compaction request deliberately exposes none, so the
// explicit field is reserved for the DeepSeek models the prohibition was
// written for. DeepSeek V4's direct thinking-mode API rejects the field
// entirely; proxied V4 endpoints such as OpenCode Zen accept it.
func projectEinoAssistantCompactionSupportsForbiddenToolChoice(settings projectLLMSettings) bool {
	model := strings.ToLower(strings.TrimSpace(settings.Model))
	if idx := strings.LastIndex(model, "/"); idx >= 0 {
		model = model[idx+1:]
	}
	if !strings.HasPrefix(model, "deepseek") {
		return false
	}
	if !strings.HasPrefix(model, "deepseek-v4") {
		return true
	}
	baseURL := strings.ToLower(strings.TrimSpace(settings.BaseURL))
	return !strings.Contains(baseURL, "api.deepseek.com")
}

type projectEinoAssistantCompactionMiddlewareRuntime struct {
	adk.ChatModelAgentMiddleware
	runtime *projectEinoAssistantCompactionRuntime
}

func (m *projectEinoAssistantCompactionMiddlewareRuntime) BeforeModelRewriteState(
	ctx context.Context,
	state *adk.ChatModelAgentState,
	modelContext *adk.ModelContext,
) (context.Context, *adk.ChatModelAgentState, error) {
	if m != nil && m.runtime != nil && state != nil {
		m.runtime.setToolSchemaTokens(projectEinoAssistantToolSchemasTokenEstimate(state.ToolInfos))
	}
	nextCtx, nextState, err := m.ChatModelAgentMiddleware.BeforeModelRewriteState(ctx, state, modelContext)
	if err != nil && m != nil && m.runtime != nil {
		return nextCtx, nextState, m.runtime.fail(ctx, err)
	}
	return nextCtx, nextState, err
}

type projectEinoAssistantCompactionAttempt struct {
	id                       string
	triggerID                string
	windowNumber             uint64
	firstWindowID            string
	previousWindowID         string
	windowID                 string
	priorTokenEstimate       int
	compactedThroughSequence int64
}

type projectEinoAssistantCompactionRuntime struct {
	mu                      sync.Mutex
	auditRecorder           *projectAssistantRunAuditRecorder
	active                  *projectEinoAssistantCompactionAttempt
	windowNumber            uint64
	firstWindowID           string
	currentWindowID         string
	toolSchemaTokenEstimate int
}

func newProjectEinoAssistantCompactionRuntime(
	auditRecorder *projectAssistantRunAuditRecorder,
	checkpoint *projectAssistantConversationCompactionCheckpoint,
) *projectEinoAssistantCompactionRuntime {
	firstWindowID := "window-" + uuid.NewString()
	runtime := &projectEinoAssistantCompactionRuntime{
		auditRecorder:   auditRecorder,
		firstWindowID:   firstWindowID,
		currentWindowID: firstWindowID,
	}
	if checkpoint != nil {
		runtime.windowNumber = checkpoint.WindowNumber
		runtime.firstWindowID = checkpoint.FirstWindowID
		runtime.currentWindowID = checkpoint.WindowID
	}
	return runtime
}

func (r *projectEinoAssistantCompactionRuntime) begin(ctx context.Context, priorTokenEstimate int, conversationTail ...int64) error {
	if r == nil {
		return fmt.Errorf("compaction runtime is not configured")
	}
	r.mu.Lock()
	r.windowNumber++
	id := "compaction-" + uuid.NewString()
	attempt := &projectEinoAssistantCompactionAttempt{
		id:                 id,
		triggerID:          id,
		windowNumber:       r.windowNumber,
		firstWindowID:      r.firstWindowID,
		previousWindowID:   r.currentWindowID,
		windowID:           "window-" + uuid.NewString(),
		priorTokenEstimate: priorTokenEstimate,
	}
	if len(conversationTail) > 0 {
		attempt.compactedThroughSequence = max(conversationTail[0], 0)
	}
	r.active = attempt
	r.mu.Unlock()
	if r.auditRecorder == nil {
		return nil
	}
	return r.auditRecorder.recordCompaction(ctx, projectAssistantAuditCompaction{
		ID:                 attempt.id,
		Trigger:            "context_threshold",
		Status:             "started",
		WindowNumber:       attempt.windowNumber,
		PreviousWindowID:   attempt.previousWindowID,
		WindowID:           attempt.windowID,
		PriorTokenEstimate: attempt.priorTokenEstimate,
	})
}

func (r *projectEinoAssistantCompactionRuntime) activeAttempt() (projectEinoAssistantCompactionAttempt, bool) {
	if r == nil {
		return projectEinoAssistantCompactionAttempt{}, false
	}
	r.mu.Lock()
	defer r.mu.Unlock()
	if r.active == nil {
		return projectEinoAssistantCompactionAttempt{}, false
	}
	return *r.active, true
}

func (r *projectEinoAssistantCompactionRuntime) complete(
	ctx context.Context,
	checkpoint projectAssistantConversationCompactionCheckpoint,
	ignoredToolCallCount int,
) error {
	attempt, ok := r.activeAttempt()
	if !ok {
		return fmt.Errorf("compaction attempt metadata is missing")
	}
	if r.auditRecorder != nil {
		if err := r.auditRecorder.recordCompaction(ctx, projectAssistantAuditCompaction{
			ID:                       attempt.id,
			Trigger:                  "context_threshold",
			Status:                   "completed",
			WindowNumber:             checkpoint.WindowNumber,
			PreviousWindowID:         checkpoint.PreviousWindowID,
			WindowID:                 checkpoint.WindowID,
			PriorTokenEstimate:       checkpoint.PriorHistoryTokenEstimate,
			ReplacementTokenEstimate: checkpoint.ReplacementHistoryTokenEstimate,
			IgnoredToolCallCount:     max(ignoredToolCallCount, 0),
		}); err != nil {
			return err
		}
	}
	r.mu.Lock()
	r.currentWindowID = attempt.windowID
	r.active = nil
	r.mu.Unlock()
	return nil
}

func (r *projectEinoAssistantCompactionRuntime) fail(ctx context.Context, cause error) error {
	if r == nil || cause == nil {
		return cause
	}
	attempt, ok := r.activeAttempt()
	if !ok {
		return cause
	}
	if r.auditRecorder != nil {
		auditErr := r.auditRecorder.recordCompaction(ctx, projectAssistantAuditCompaction{
			ID:                 attempt.id,
			Trigger:            "context_threshold",
			Status:             "failed",
			WindowNumber:       attempt.windowNumber,
			PreviousWindowID:   attempt.previousWindowID,
			WindowID:           attempt.windowID,
			PriorTokenEstimate: attempt.priorTokenEstimate,
			Error:              projectEinoAssistantSafeErrorText(cause),
		})
		cause = errors.Join(cause, auditErr)
	}
	r.mu.Lock()
	r.active = nil
	r.mu.Unlock()
	return cause
}

func (r *projectEinoAssistantCompactionRuntime) setToolSchemaTokens(tokens int) {
	if r == nil {
		return
	}
	r.mu.Lock()
	r.toolSchemaTokenEstimate = max(tokens, 0)
	r.mu.Unlock()
}

func (r *projectEinoAssistantCompactionRuntime) toolSchemaTokens() int {
	if r == nil {
		return 0
	}
	r.mu.Lock()
	defer r.mu.Unlock()
	return r.toolSchemaTokenEstimate
}

func projectEinoAssistantCompactionModelInput(
	_ context.Context,
	_ *schema.Message,
	_ *schema.Message,
	original []*schema.Message,
) ([]*schema.Message, error) {
	input := make([]*schema.Message, 0, len(original)+1)
	input = append(input, original...)
	input = append(input, schema.UserMessage(projectEinoAssistantCompactionPrompt))
	return input, nil
}

func projectEinoAssistantCanonicalCompactionContext(
	ctx context.Context,
	req projectAssistantRunRequest,
	runState *projectEinoAssistantRunState,
) ([]*schema.Message, error) {
	if req.Project == nil {
		return nil, fmt.Errorf("project is required for compaction context")
	}
	currentReq := req
	// Persisted Kubernetes Projects always carry a resourceVersion. Synthetic
	// unit-test Projects do not have a server object to refresh.
	if req.Client != nil && strings.TrimSpace(req.Project.ResourceVersion) != "" {
		refreshed, err := refreshProjectAssistantWorkflowRunContext(ctx, projectAssistantWorkflowRunContext{
			Client:     req.Client,
			Project:    req.Project,
			Repository: req.Repository,
		})
		if err != nil {
			return nil, fmt.Errorf("refresh project compaction context: %w", err)
		}
		currentReq.Project = refreshed.Project
		currentReq.Repository = refreshed.Repository
	}

	contextMessages := []chatMessage{
		{Role: "system", Content: projectEinoAssistantDeepInstructionForRun(runState)},
		{Role: "system", Content: projectSystemPromptForMode(
			currentReq.Project,
			currentReq.Repository,
			currentReq.CollaborationMode,
			projectAssistantInitialBuildActive(currentReq, runState),
		)},
	}
	if snapshot, ok := projectEinoAssistantSessionContextMessage(ctx, currentReq, runState); ok {
		contextMessages = append(contextMessages, snapshot)
	}
	if runState != nil {
		if prompt := runState.ToolPrompt(); prompt != "" {
			contextMessages = append(contextMessages, chatMessage{Role: "system", Content: prompt})
		}
		if prompt := runState.SkillPrompt(); prompt != "" {
			contextMessages = append(contextMessages, chatMessage{Role: "system", Content: prompt})
		}
	}
	messages, err := projectChatMessagesToEino(contextMessages)
	if err != nil {
		return nil, fmt.Errorf("build project compaction context: %w", err)
	}
	return messages, nil
}

func projectEinoAssistantCompactionRetryConfig(req projectAssistantRunRequest) *summarization.RetryConfig {
	maxRetries := projectEinoAssistantModelMaxRetries(req.LLM)
	baseBackoff := req.LLM.RetryBackoff
	if baseBackoff <= 0 {
		baseBackoff = 200 * time.Millisecond
	}
	return &summarization.RetryConfig{
		MaxRetries: &maxRetries,
		ShouldRetry: func(ctx context.Context, response *schema.Message, err error) bool {
			if ctx.Err() != nil || err == nil || projectEinoAssistantCompactionHasOutput(response) {
				return false
			}
			if !projectEinoAssistantShouldRetryModelError(err) {
				return false
			}
			// Eino invokes ShouldRetry once per failed response, before applying
			// BackoffFunc for the corresponding one-based retry attempt.
			return true
		},
		BackoffFunc: func(_ context.Context, attempt int, _ *schema.Message, _ error) time.Duration {
			if attempt < 1 {
				attempt = 1
			}
			projectEinoAssistantPublishRetryAttempt(req.StreamCallbacks, attempt, maxRetries)
			delay := baseBackoff * time.Duration(1<<min(attempt-1, 6))
			return min(delay, 10*time.Second)
		},
	}
}

func projectEinoAssistantCompactionHasOutput(message *schema.Message) bool {
	if message == nil {
		return false
	}
	if strings.TrimSpace(message.Content) != "" || len(message.ToolCalls) > 0 {
		return true
	}
	for _, part := range message.AssistantGenMultiContent {
		if part.Type == schema.ChatMessagePartTypeText && strings.TrimSpace(part.Text) != "" {
			return true
		}
	}
	return false
}

func projectEinoAssistantFinalizeCompaction(
	canonicalContext, original []*schema.Message,
	summary *schema.Message,
	toolSchemaTokens int,
) ([]*schema.Message, error) {
	if summary == nil || summary.Role != schema.Assistant {
		return nil, fmt.Errorf("compaction model returned an invalid assistant response")
	}
	// Codex records every completed compaction response item but extracts only
	// assistant text for the replacement history. Tool calls from this internal
	// request are inert: they are never dispatched, never copied into the
	// checkpoint, and never allowed to fail the outer agent turn. A tool-only
	// response intentionally produces a prefix-only summary checkpoint.
	summaryText := projectEinoAssistantSummaryText(summary)

	userTokenBudget := projectEinoAssistantCompactionUserTokenBudget(canonicalContext, summaryText, toolSchemaTokens)
	userMessages := projectEinoAssistantRecentUserMessages(original, userTokenBudget)
	// The checkpoint retains only the compacted conversational payload. Project
	// metadata, workspace snapshot, and tool guidance are regenerated at each
	// outer model boundary; persisting them here would make a later resume use
	// stale authority and capability context.
	compacted := make([]*schema.Message, 0, len(userMessages)+1)
	compacted = append(compacted, userMessages...)
	compacted = append(compacted, schema.UserMessage(projectEinoAssistantCompactionSummaryContent(summaryText)))
	return compacted, nil
}

func projectEinoAssistantCompactionUserTokenBudget(
	canonicalContext []*schema.Message,
	summary string,
	toolSchemaTokens int,
) int {
	contextTokens := projectEinoAssistantCompactionContextTokens()
	reserve := contextTokens * projectEinoAssistantCompactionReservePercent / 100
	overhead := projectEinoAssistantMessagesTokenEstimate(canonicalContext) +
		max(toolSchemaTokens, 0) +
		projectEinoAssistantApproxTokenCount(projectEinoAssistantCompactionSummaryContent(summary))
	return max(contextTokens-reserve-overhead, 0)
}

func projectEinoAssistantRecentUserMessages(messages []*schema.Message, maxTokens int) []*schema.Message {
	if maxTokens <= 0 {
		return nil
	}
	remaining := maxTokens
	selectedGroups := make([][]*schema.Message, 0)
	pendingAttachments := make([]*schema.Message, 0)
	for index := len(messages) - 1; index >= 0 && remaining > 0; index-- {
		message := messages[index]
		if projectEinoAssistantHistoricalAttachmentMessage(message) {
			// Placeholders are owned by the immediately preceding user message.
			// Hold them until that message is selected so compaction cannot retain
			// a receipt after dropping its originating conversation item.
			pendingAttachments = append(pendingAttachments, message)
			continue
		}
		if message == nil || message.Role != schema.User {
			pendingAttachments = nil
			continue
		}
		content := strings.TrimSpace(message.Content)
		if content == "" ||
			strings.HasPrefix(content, projectEinoAssistantCompactionSummaryPrefix) ||
			projectEinoAssistantSyntheticWorkspaceMutationEvidence(message) {
			pendingAttachments = nil
			continue
		}
		attachmentTokens := 0
		for _, attachment := range pendingAttachments {
			receipts, err := projectAssistantAttachmentReceiptsFromEinoMessageChecked(attachment)
			if err != nil {
				pendingAttachments = nil
				break
			}
			for _, receipt := range receipts {
				if projectAssistantAttachmentIsImage(receipt) {
					attachmentTokens += projectEinoAssistantHistoricalImageTokenEstimate
				}
			}
		}
		keepAttachments := attachmentTokens < remaining
		if keepAttachments {
			remaining -= attachmentTokens
		} else {
			pendingAttachments = nil
		}
		tokens := projectEinoAssistantApproxTokenCount(content)
		retained := message
		if tokens > remaining {
			retained = schema.UserMessage(projectEinoAssistantTruncateToTokens(content, remaining))
			remaining = 0
		} else {
			remaining -= tokens
		}
		group := []*schema.Message{retained}
		for attachmentIndex := len(pendingAttachments) - 1; attachmentIndex >= 0; attachmentIndex-- {
			group = append(group, pendingAttachments[attachmentIndex])
		}
		pendingAttachments = nil
		selectedGroups = append(selectedGroups, group)
	}
	selected := make([]*schema.Message, 0)
	for groupIndex := len(selectedGroups) - 1; groupIndex >= 0; groupIndex-- {
		selected = append(selected, selectedGroups[groupIndex]...)
	}
	return selected
}

func projectEinoAssistantMessagesTokenEstimate(messages []*schema.Message) int {
	if len(messages) == 0 {
		return 0
	}
	raw, err := json.Marshal(projectEinoMessagesToChat(messages))
	if err != nil {
		return 0
	}
	total := projectEinoAssistantApproxTokenCount(string(raw))
	for _, message := range messages {
		if projectEinoAssistantHistoricalAttachmentMessage(message) {
			receipts, receiptErr := projectAssistantAttachmentReceiptsFromEinoMessageChecked(message)
			if receiptErr == nil {
				for _, receipt := range receipts {
					if projectAssistantAttachmentIsImage(receipt) {
						total += projectEinoAssistantHistoricalImageTokenEstimate
					}
				}
			}
			continue
		}
		if message == nil {
			continue
		}
		for _, part := range message.UserInputMultiContent {
			if part.Type == schema.ChatMessagePartTypeImageURL && part.Image != nil {
				total += projectEinoAssistantHistoricalImageTokenEstimate
			}
		}
	}
	return total
}

func projectEinoAssistantToolSchemasTokenEstimate(toolInfos []*schema.ToolInfo) int {
	if len(toolInfos) == 0 {
		return 0
	}
	total := 0
	for _, info := range toolInfos {
		if info == nil {
			continue
		}
		copyInfo := *info
		copyInfo.Extra = nil
		raw, err := json.Marshal(&copyInfo)
		if err != nil {
			continue
		}
		total += projectEinoAssistantApproxTokenCount(string(raw))
	}
	return total
}

func projectEinoAssistantApproxTokenCount(text string) int {
	runes := utf8.RuneCountInString(text)
	if runes == 0 {
		return 0
	}
	return (runes + 3) / 4
}

func projectEinoAssistantTruncateToTokens(text string, maxTokens int) string {
	if maxTokens <= 0 {
		return ""
	}
	maxRunes := maxTokens * 4
	runes := []rune(text)
	if len(runes) <= maxRunes {
		return text
	}
	const marker = "\n[... user message truncated during compaction ...]"
	markerRunes := []rune(marker)
	if len(markerRunes) >= maxRunes {
		return string(markerRunes[:maxRunes])
	}
	return string(runes[:maxRunes-len(markerRunes)]) + marker
}

func projectEinoAssistantCompactionSummaryContent(summary string) string {
	return projectEinoAssistantCompactionSummaryPrefix + "\n" + strings.TrimSpace(summary)
}

func projectEinoAssistantLastNonSystemMessageIsTool(messages []*schema.Message) bool {
	for index := len(messages) - 1; index >= 0; index-- {
		message := messages[index]
		if message == nil || message.Role == schema.System {
			continue
		}
		if projectEinoAssistantSyntheticWorkspaceMutationEvidence(message) {
			continue
		}
		return message.Role == schema.Tool
	}
	return false
}

func projectEinoAssistantSummaryText(msg *schema.Message) string {
	if msg == nil || msg.Role != schema.Assistant {
		return ""
	}
	var parts []string
	for _, part := range msg.AssistantGenMultiContent {
		if part.Type == schema.ChatMessagePartTypeText && strings.TrimSpace(part.Text) != "" {
			parts = append(parts, strings.TrimSpace(part.Text))
		}
	}
	if len(parts) > 0 {
		return strings.Join(parts, "\n")
	}
	return strings.TrimSpace(msg.Content)
}
