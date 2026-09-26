// Copyright 2026 The Railgrid Authors.
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//     http://www.apache.org/licenses/LICENSE-2.0

// Package engine runs the agent chat loop on Eino. This milestone implements a
// streaming single-turn completion (system prompt + history + user message);
// the tool-call loop, checkpoints, and sub-agent delegation build on this in
// later milestones. The package is provider-agnostic and SDK-portable.
package engine

import (
	"context"
	"encoding/base64"
	"encoding/json"
	"errors"
	"fmt"
	"io"
	"strings"
	"time"

	einomodel "github.com/cloudwego/eino/components/model"
	"github.com/cloudwego/eino/schema"
	"github.com/eino-contrib/jsonschema"
)

// Role constants for engine messages (aligned with Eino's schema roles).
const (
	RoleSystem    = "system"
	RoleUser      = "user"
	RoleAssistant = "assistant"
	RoleTool      = "tool"
)

// Message is a role-tagged turn in the conversation the engine runs over.
type Message struct {
	Role       string            `json:"role"`
	Content    string            `json:"content,omitempty"`
	ToolCalls  []schema.ToolCall `json:"toolCalls,omitempty"`
	ToolCallID string            `json:"toolCallID,omitempty"`
	Name       string            `json:"name,omitempty"`
	ID         string            `json:"id,omitempty"`
	Sequence   int64             `json:"sequence,omitempty"`
	// Ephemeral marks engine-generated context that has no durable transcript
	// identity, such as a tool-returned image follow-up. It must not become a
	// durable user request or enter a session replacement checkpoint.
	Ephemeral bool `json:"ephemeral,omitempty"`
}

// Param describes one tool parameter (a pragmatic subset of JSON schema).
type Param struct {
	Type     string // "string" | "integer" | "number" | "boolean"
	Desc     string
	Required bool
	Enum     []string
}

// Tool is one callable function exposed to the model. Exactly one of Params or
// JSONSchema describes the arguments: Params for the built-in families,
// JSONSchema (a raw JSON-schema document) for pass-through tools like MCP.
type Tool struct {
	Name       string
	Desc       string
	Params     map[string]Param
	JSONSchema map[string]any
	// Exec runs the tool with the model-provided JSON arguments and returns
	// the text observation fed back to the model. An error is also fed back (as
	// an error observation) rather than aborting the run. Set this for text-only
	// tools; tools that can return images set ExecRich instead.
	Exec func(ctx context.Context, argsJSON string) (string, error)
	// ExecRich, when non-nil, is used in preference to Exec and may return
	// images (e.g. a camera snapshot) alongside text. The engine feeds the text
	// back as the tool observation and the images as a follow-up user message so
	// vision-capable models can actually see them.
	ExecRich func(ctx context.Context, argsJSON string) (Observation, error)
}

// ToolImage is binary image output from a tool (e.g. a UniFi Protect camera
// snapshot), carried back to the model as vision input. Data is the raw,
// un-encoded image bytes; the engine base64-encodes them for the model.
type ToolImage struct {
	MIMEType string // e.g. "image/jpeg"; defaults to image/jpeg when empty
	Data     []byte
}

// Observation is a rich tool result: a text observation plus any images.
type Observation struct {
	Text   string
	Images []ToolImage
}

// maxTurnImages caps how many tool-returned images are fed back to the model in
// a single turn, so a fan-out of snapshot calls can't blow the token budget.
const maxTurnImages = 8

// ToolEvent reports a completed tool invocation to the caller (for SSE/UI +
// audit). ID is the model's tool-call id, correlating with OnToolStart.
type ToolEvent struct {
	ID       string
	Name     string
	Args     string // raw JSON arguments from the model
	Result   string // observation (or error text)
	Err      bool
	Duration time.Duration
}

// AssistantMessage is one model response attempt in a tool-call turn. The
// callback is deliberately emitted only after a successful streamed response
// has been concatenated, because only then is HasToolCalls authoritative. A
// failed stream still emits an attempt with Complete=false so callers can
// account for the model time without classifying partial deltas as a final
// answer. Duration is the active model time for this response; callers that
// need a whole-turn duration can accumulate it with ToolEvent.Duration.
type AssistantMessage struct {
	Content      string
	HasToolCalls bool
	ToolCalls    []schema.ToolCall
	Complete     bool
	Duration     time.Duration
}

// ContextCompactionFunc replaces an over-budget model history. The estimate
// includes the bound tool schemas as well as all messages. The returned history
// must fit within estimate.BudgetTokens and retain the latest user message.
type ContextCompactionFunc func(ctx context.Context, history []Message, estimate ContextEstimate) ([]Message, error)

// Callbacks stream run progress to the caller. All fields are optional.
type Callbacks struct {
	// OnDelta receives assistant content deltas as they stream.
	OnDelta func(string)
	// OnAssistantMessage fires once a streamed model response attempt finishes.
	// Complete is false when streaming failed, in which case Content may be
	// incomplete and must not be treated as a final answer. Successful callbacks
	// run before the response's tool calls are executed, when any, and before the
	// loop asks the model for its next response.
	OnAssistantMessage func(AssistantMessage)
	// OnToolStart fires when a tool call begins executing.
	OnToolStart func(id, name, args string)
	// OnTool fires when a tool call completes (or fails).
	OnTool func(ToolEvent)
	// OnCheckpoint offers a resumable snapshot of the loop, every
	// TurnConfig.CheckpointEvery iterations, at a point where no tool call is
	// half-executed. The caller persists it so a crash or restart mid-run can
	// continue from here instead of losing the work. Pending is always empty in
	// these snapshots: resuming re-asks the model rather than re-running tools,
	// which costs one model call and keeps resume free of any assumption that
	// tools are safe to repeat.
	OnCheckpoint func(Checkpoint)
	// CheckAbort is consulted before every model round and before every tool
	// call — the two points where no call is half-executed. A non-nil error
	// ends the turn with that error, which is how a cancellation that did not
	// arrive through ctx (a durable cancel flag written by another replica)
	// stops a run cleanly instead of after the whole loop.
	CheckAbort func(ctx context.Context) error
}

func (c Callbacks) abort(ctx context.Context) error {
	if c.CheckAbort == nil {
		return nil
	}
	return c.CheckAbort(ctx)
}

func (c Callbacks) assistantMessage(message AssistantMessage) {
	if c.OnAssistantMessage != nil {
		c.OnAssistantMessage(message)
	}
}

func (c Callbacks) toolStart(id, name, args string) {
	if c.OnToolStart != nil {
		c.OnToolStart(id, name, args)
	}
}

func (c Callbacks) tool(ev ToolEvent) {
	if c.OnTool != nil {
		c.OnTool(ev)
	}
}

func (c Callbacks) checkpoint(ck Checkpoint) {
	if c.OnCheckpoint != nil {
		c.OnCheckpoint(ck)
	}
}

// TurnConfig bounds one turn. Zero values mean "provider default", so a caller
// can pass just the fields it cares about.
type TurnConfig struct {
	// MaxIters caps tool-call rounds. <=0 becomes 1.
	MaxIters int
	// ContextBudgetTokens caps the estimated size of the wire conversation,
	// including bound tool schemas. 0 disables budget enforcement. When the
	// estimate exceeds this budget, ContextCompactor must return a fitting
	// structured replacement history or the turn fails with ContextBudgetError.
	ContextBudgetTokens int
	// ContextCompactor is called before each model request when the estimated
	// input exceeds ContextBudgetTokens. Without it, over-budget requests fail
	// instead of silently deleting tool-result prefixes.
	ContextCompactor ContextCompactionFunc
	// CheckpointEvery is how many iterations pass between OnCheckpoint offers.
	// 0 disables periodic checkpointing.
	CheckpointEvery int
}

// Usage reports token consumption for a completed turn, when the provider
// returns it.
type Usage struct {
	InputTokens  int64
	OutputTokens int64
}

// Result is the outcome of a streaming turn. When Interrupt is non-nil the
// turn did not complete: a gated tool call paused the run, and Interrupt
// carries the checkpoint to resume from once the user decides.
type Result struct {
	// Content retains the historical concatenated turn result, including model
	// commentary and the tool-limit notice when a turn is truncated.
	Content string
	// FinalContent is the presentation answer for the latest model boundary. It
	// is the latest model response on success, or the standalone tool-limit
	// notice when the loop exhausts its allowance without a final response.
	// Interrupts and errors leave it empty.
	FinalContent string
	Usage        Usage
	Interrupt    *Interrupt
}

// Engine runs turns against a chat model. It holds no per-request state, so a
// single Engine is safe for concurrent use.
type Engine struct{}

// New returns an Engine.
func New() *Engine { return &Engine{} }

// StreamTurn runs one assistant turn (no tools) and streams content deltas.
func (e *Engine) StreamTurn(ctx context.Context, model einomodel.BaseChatModel, msgs []Message, onDelta func(string)) (Result, error) {
	return e.StreamTurnWithTools(ctx, model, msgs, nil, TurnConfig{MaxIters: 1}, Callbacks{OnDelta: onDelta})
}

// StreamTurnWithTools runs an assistant turn with a tool-call loop: the model
// may call tools, observations are fed back, and the loop continues until the
// model answers without tool calls or maxIters is reached. A tool returning an
// *InterruptError pauses the loop and yields a Result with an Interrupt
// checkpoint instead of finishing the turn.
func (e *Engine) StreamTurnWithTools(
	ctx context.Context,
	model einomodel.BaseChatModel,
	msgs []Message,
	tools []Tool,
	cfg TurnConfig,
	cb Callbacks,
) (Result, error) {
	active, byName, err := e.bindTools(model, tools)
	if err != nil {
		return Result{}, err
	}
	schemaTokens, err := estimateToolSchemaTokens(tools)
	if err != nil {
		return Result{}, fmt.Errorf("engine: estimating tool schemas: %w", err)
	}
	in, identities := toEinoWithIdentities(msgs)
	if len(in) == 0 {
		return Result{}, errors.New("engine: no messages to send")
	}
	task := latestUserMessage(msgs)
	var content strings.Builder
	var usage Usage
	return e.loop(ctx, active, byName, in, identities, schemaTokens, task, cfg.normalized(), 0, &content, &usage, nil, nil, cb)
}

// normalized applies the defaults so the loop can read cfg without guarding.
func (c TurnConfig) normalized() TurnConfig {
	if c.MaxIters <= 0 {
		c.MaxIters = 1
	}
	return c
}

// ResumeTurnWithTools continues a checkpointed turn after the user decided on
// the gated tool call. approve=true executes the pending call (the caller's
// wrapper must grant it — the engine just re-runs it); approve=false injects a
// denial observation so the model can react, then the loop continues normally.
func (e *Engine) ResumeTurnWithTools(
	ctx context.Context,
	model einomodel.BaseChatModel,
	ck Checkpoint,
	tools []Tool,
	cfg TurnConfig,
	approve bool,
	denyNote string,
	cb Callbacks,
) (Result, error) {
	active, byName, err := e.bindTools(model, tools)
	if err != nil {
		return Result{}, err
	}
	schemaTokens, err := estimateToolSchemaTokens(tools)
	if err != nil {
		return Result{}, fmt.Errorf("engine: estimating tool schemas: %w", err)
	}
	in, identities := restoreMessagesWithIdentities(ck.Messages)
	if len(in) == 0 {
		return Result{}, errors.New("engine: checkpoint has no messages")
	}
	checkpointHistory := make([]Message, 0, len(ck.Messages))
	for _, message := range ck.Messages {
		checkpointHistory = append(checkpointHistory, Message{
			Role: message.Role, Content: message.Content, ToolCallID: message.ToolCallID,
			Name: checkpointMessageName(message), ToolCalls: checkpointToolCalls(message.ToolCalls),
			ID: message.ID, Sequence: message.Sequence, Ephemeral: message.Ephemeral,
		})
	}
	task := latestUserMessage(checkpointHistory)
	cfg = cfg.normalized()
	// A resume must be able to take at least one more step, even when the
	// checkpoint already sits at the configured limit.
	if cfg.MaxIters <= ck.Iter {
		cfg.MaxIters = ck.Iter + 1
	}
	var content strings.Builder
	content.WriteString(ck.Content)
	usage := ck.Usage
	pending := ck.Pending
	dec := &decision{approve: approve, note: denyNote}
	return e.loop(ctx, active, byName, in, identities, schemaTokens, task, cfg, ck.Iter, &content, &usage, pending, dec, cb)
}

// decision is the user's verdict on the FIRST pending call of a resumed turn.
type decision struct {
	approve bool
	note    string
	used    bool
}

// bindTools prepares the (optionally tool-bound) model and the tool index.
func (e *Engine) bindTools(model einomodel.BaseChatModel, tools []Tool) (einomodel.BaseChatModel, map[string]Tool, error) {
	if model == nil {
		return nil, nil, errors.New("engine: nil chat model")
	}
	byName := map[string]Tool{}
	if len(tools) == 0 {
		return model, byName, nil
	}
	tcm, ok := model.(einomodel.ToolCallingChatModel)
	if !ok {
		return nil, nil, errors.New("engine: model does not support tool calling")
	}
	infos, err := toToolInfos(tools)
	if err != nil {
		return nil, nil, fmt.Errorf("engine: building tool schemas: %w", err)
	}
	bound, err := tcm.WithTools(infos)
	if err != nil {
		return nil, nil, fmt.Errorf("engine: binding tools: %w", err)
	}
	for _, t := range tools {
		byName[t.Name] = t
	}
	return bound, byName, nil
}

// loop is the shared tool-call loop for fresh and resumed turns. When pending
// is non-empty the first pass skips the model stream and executes the pending
// calls (a resume); dec applies to the first of them.
func (e *Engine) loop(
	ctx context.Context,
	active einomodel.BaseChatModel,
	byName map[string]Tool,
	in []*schema.Message,
	identities map[*schema.Message]historyIdentity,
	toolSchemaTokens int,
	task *Message,
	cfg TurnConfig,
	startIter int,
	content *strings.Builder,
	usage *Usage,
	pending []PendingCall,
	dec *decision,
	cb Callbacks,
) (Result, error) {
	for iter := startIter; iter < cfg.MaxIters; iter++ {
		if len(pending) == 0 {
			if err := cb.abort(ctx); err != nil {
				return Result{}, err
			}
			var compacted bool
			var compactErr error
			in, identities, compacted, compactErr = compactBeforeRequest(ctx, in, identities, toolSchemaTokens, task, cfg)
			if compactErr != nil {
				return Result{}, compactErr
			}
			// Offer a resumable snapshot: no tool call is in flight here, so the
			// checkpoint is coherent and resuming just re-asks the model. A compacted
			// replacement is checkpointed immediately even when the periodic cadence
			// would not otherwise fire, so recovery never restores stale history.
			if cb.OnCheckpoint != nil && (compacted || (cfg.CheckpointEvery > 0 && iter > startIter && (iter-startIter)%cfg.CheckpointEvery == 0)) {
				cb.checkpoint(Checkpoint{
					Messages: checkpointMessagesWithIdentities(in, identities),
					Content:  content.String(),
					Usage:    *usage,
					Iter:     iter,
				})
			}
			started := time.Now()
			full, err := e.streamOnce(ctx, active, in, content, usage, cb.OnDelta)
			if err != nil {
				cb.assistantMessage(AssistantMessage{Duration: time.Since(started)})
				return Result{}, err
			}
			cb.assistantMessage(AssistantMessage{
				Content: full.Content, HasToolCalls: len(full.ToolCalls) > 0, ToolCalls: cloneToolCalls(full.ToolCalls),
				Complete: true, Duration: time.Since(started),
			})
			if len(full.ToolCalls) == 0 {
				return Result{Content: content.String(), FinalContent: full.Content, Usage: *usage}, nil
			}
			// Feed the assistant's tool-call message back, then execute each
			// call and append its observation.
			in = append(in, full)
			pending = pendingFromToolCalls(full.ToolCalls)
		}

		// Images returned by tools are collected and appended once, after all
		// tool messages: the OpenAI wire format requires each tool_call to be
		// answered by a contiguous tool message, and image content must ride on
		// a user message, so the images become a single follow-up user turn.
		var turnImages []ToolImage
		for len(pending) > 0 {
			pc := pending[0]

			// A resumed denial: answer the gated call with a denial observation
			// instead of executing it.
			if dec != nil && !dec.used && !dec.approve {
				dec.used = true
				result := "the user denied this tool call"
				if dec.note != "" {
					result += ": " + dec.note
				}
				cb.tool(ToolEvent{ID: pc.ID, Name: pc.Name, Args: pc.Args, Result: result, Err: false})
				in = append(in, schema.ToolMessage(result, pc.ID, schema.WithToolName(pc.Name)))
				pending = pending[1:]
				continue
			}
			if dec != nil && !dec.used {
				dec.used = true // approved: execute normally (the wrapper grants it)
			}

			if err := cb.abort(ctx); err != nil {
				return Result{}, err
			}
			started := time.Now()
			cb.toolStart(pc.ID, pc.Name, pc.Args)
			result, images, execErr := execute(ctx, byName, pc)
			if ie := asInterrupt(execErr); ie != nil {
				// Pause: checkpoint the conversation with the un-executed calls
				// (this one first) so the run resumes exactly here.
				return Result{
					Content: content.String(), Usage: *usage,
					Interrupt: &Interrupt{
						Tool: ie.Tool, Args: ie.Args, RequestID: ie.RequestID,
						Checkpoint: Checkpoint{
							Messages: checkpointMessagesWithIdentities(in, identities),
							Pending:  pending,
							Content:  content.String(),
							Usage:    *usage,
							Iter:     iter,
						},
					},
				}, nil
			}
			failed := false
			if execErr != nil {
				result, failed = "error: "+execErr.Error(), true
			}
			turnImages = append(turnImages, images...)
			cb.tool(ToolEvent{ID: pc.ID, Name: pc.Name, Args: pc.Args, Result: result, Err: failed, Duration: time.Since(started)})
			in = append(in, schema.ToolMessage(result, pc.ID, schema.WithToolName(pc.Name)))
			pending = pending[1:]
		}
		// A durable result write may have failed in OnTool, including on the
		// final allowed tool round. Check before reporting a successful limit
		// stop or issuing another model request.
		if err := cb.abort(ctx); err != nil {
			return Result{Usage: *usage}, err
		}
		if msg := imageUserMessage(turnImages); msg != nil {
			in = append(in, msg)
			identities[msg] = historyIdentity{ephemeral: true}
		}
	}

	// Ran out of iterations mid-loop: surface what we have plus a marker so
	// the transcript is honest about the truncation.
	const toolCallLimitNotice = "[stopped: reached the tool-call limit for one turn]"
	content.WriteString("\n\n" + toolCallLimitNotice)
	return Result{Content: content.String(), FinalContent: toolCallLimitNotice, Usage: *usage}, nil
}

// execute runs one tool call, preferring the rich executor. The returned error
// may be an *InterruptError (approval gate) — callers check before treating it
// as a failure observation.
func execute(ctx context.Context, byName map[string]Tool, pc PendingCall) (string, []ToolImage, error) {
	tool, ok := byName[pc.Name]
	if !ok {
		return "", nil, fmt.Errorf("unknown tool %q", pc.Name)
	}
	switch {
	case tool.ExecRich != nil:
		obs, err := tool.ExecRich(ctx, pc.Args)
		if err != nil {
			return "", nil, err
		}
		result := obs.Text
		if result == "" && len(obs.Images) > 0 {
			result = fmt.Sprintf("[returned %d image(s); shown below]", len(obs.Images))
		}
		return result, obs.Images, nil
	case tool.Exec != nil:
		out, err := tool.Exec(ctx, pc.Args)
		return out, nil, err
	default:
		return "", nil, fmt.Errorf("tool %q has no executor", pc.Name)
	}
}

// streamOnce streams a single model response, forwarding content deltas and
// accumulating usage, and returns the concatenated full message (which may
// carry tool calls).
func (e *Engine) streamOnce(ctx context.Context, model einomodel.BaseChatModel, in []*schema.Message, content *strings.Builder, usage *Usage, onDelta func(string)) (*schema.Message, error) {
	stream, err := model.Stream(ctx, in)
	if err != nil {
		return nil, fmt.Errorf("engine: start stream: %w", err)
	}
	defer stream.Close()

	var chunks []*schema.Message
	for {
		chunk, err := stream.Recv()
		if errors.Is(err, io.EOF) {
			break
		}
		if err != nil {
			return nil, fmt.Errorf("engine: stream recv: %w", err)
		}
		if chunk == nil {
			continue
		}
		chunks = append(chunks, chunk)
		if chunk.Content != "" {
			content.WriteString(chunk.Content)
			if onDelta != nil {
				onDelta(chunk.Content)
			}
		}
		if u := chunk.ResponseMeta; u != nil && u.Usage != nil {
			// Providers report cumulative usage on the final chunk of each
			// response; add per response, not per chunk.
			usage.InputTokens += int64(u.Usage.PromptTokens)
			usage.OutputTokens += int64(u.Usage.CompletionTokens)
		}
	}
	if len(chunks) == 0 {
		return nil, errors.New("engine: model returned an empty stream")
	}
	full, err := schema.ConcatMessages(chunks)
	if err != nil {
		return nil, fmt.Errorf("engine: concatenating stream: %w", err)
	}
	return full, nil
}

// toToolInfos converts engine tools to Eino tool schemas. Built-in families
// use the lightweight ParameterInfo map; pass-through tools (MCP) carry a raw
// JSON schema document.
func toToolInfos(tools []Tool) ([]*schema.ToolInfo, error) {
	out := make([]*schema.ToolInfo, 0, len(tools))
	for _, t := range tools {
		info := &schema.ToolInfo{Name: t.Name, Desc: t.Desc}
		switch {
		case t.JSONSchema != nil:
			raw, err := json.Marshal(t.JSONSchema)
			if err != nil {
				return nil, fmt.Errorf("tool %s: marshal schema: %w", t.Name, err)
			}
			js := &jsonschema.Schema{}
			if err := json.Unmarshal(raw, js); err != nil {
				return nil, fmt.Errorf("tool %s: parse schema: %w", t.Name, err)
			}
			info.ParamsOneOf = schema.NewParamsOneOfByJSONSchema(js)
		default:
			params := map[string]*schema.ParameterInfo{}
			for name, p := range t.Params {
				params[name] = &schema.ParameterInfo{
					Type:     einoDataType(p.Type),
					Desc:     p.Desc,
					Required: p.Required,
					Enum:     p.Enum,
				}
			}
			info.ParamsOneOf = schema.NewParamsOneOfByParams(params)
		}
		out = append(out, info)
	}
	return out, nil
}

func einoDataType(t string) schema.DataType {
	switch t {
	case "integer":
		return schema.Integer
	case "number":
		return schema.Number
	case "boolean":
		return schema.Boolean
	case "array":
		return schema.Array
	case "object":
		return schema.Object
	default:
		return schema.String
	}
}

// imageUserMessage builds a synthetic user turn carrying tool-returned images
// as vision input, or nil when there are none. Images beyond maxTurnImages are
// dropped with a note so the truncation is honest rather than silent.
func imageUserMessage(imgs []ToolImage) *schema.Message {
	if len(imgs) == 0 {
		return nil
	}
	note := "Images returned by the preceding tool call(s):"
	if len(imgs) > maxTurnImages {
		note += fmt.Sprintf(" (showing the first %d of %d)", maxTurnImages, len(imgs))
		imgs = imgs[:maxTurnImages]
	}
	parts := []schema.MessageInputPart{{Type: schema.ChatMessagePartTypeText, Text: note}}
	for _, img := range imgs {
		if len(img.Data) == 0 {
			continue
		}
		b64 := base64.StdEncoding.EncodeToString(img.Data)
		mime := img.MIMEType
		if mime == "" {
			mime = "image/jpeg"
		}
		parts = append(parts, schema.MessageInputPart{
			Type: schema.ChatMessagePartTypeImageURL,
			Image: &schema.MessageInputImage{
				MessagePartCommon: schema.MessagePartCommon{Base64Data: &b64, MIMEType: mime},
				Detail:            schema.ImageURLDetailAuto,
			},
		})
	}
	if len(parts) == 1 { // text note only: every image was empty
		return nil
	}
	return &schema.Message{Role: schema.User, UserInputMultiContent: parts}
}

func toEinoWithIdentities(msgs []Message) ([]*schema.Message, map[*schema.Message]historyIdentity) {
	out := make([]*schema.Message, 0, len(msgs))
	for _, m := range msgs {
		role := schema.RoleType(m.Role)
		switch m.Role {
		case RoleSystem, RoleUser, RoleAssistant, RoleTool:
		default:
			// Unknown roles are treated as user content so nothing is dropped
			// silently.
			role = schema.User
		}
		message := &schema.Message{
			Role: role, Content: m.Content, Name: m.Name,
			ToolCalls: cloneToolCalls(m.ToolCalls), ToolCallID: m.ToolCallID,
		}
		if role == schema.Tool {
			message.ToolName = m.Name
		}
		out = append(out, message)
	}
	return out, identitiesFromMessages(msgs, out)
}
