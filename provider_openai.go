package core

import (
	"bufio"
	"bytes"
	"encoding/json"
	"errors"
	"fmt"
	"io"
	"net/http"
	"os"
	"strings"
)

// OpenAICompatProvider works with any OpenAI-compatible API:
// Fireworks, OpenAI, Ollama, Together, Groq, etc.
type OpenAICompatProvider struct {
	name       string
	apiKey     string
	url        string
	models     map[ModelTier]string
	inputCost  float64 // per 1M tokens
	cachedCost float64
	outputCost float64
	authHeader string // "Bearer" or empty for no auth (Ollama)
}

func (p *OpenAICompatProvider) Name() string                            { return p.name }
func (p *OpenAICompatProvider) Models() map[ModelTier]string            { return p.models }
func (p *OpenAICompatProvider) CostPer1M() (float64, float64, float64) { return p.inputCost, p.cachedCost, p.outputCost }
func (p *OpenAICompatProvider) SupportsNativeTools() bool {
	// All OpenAI-compatible Chat Completions endpoints accept the
	// `tools` field. Ollama is the lone exception in practice — tool
	// support is gated per-model and most local models don't honor it
	// reliably, so we keep our prompt-level fallback there. Anything
	// else (OpenAI, Fireworks, OpenCode Go, NVIDIA NIM, Together,
	// Groq, …) gets native tool calls.
	return p.name != "ollama"
}

func (p *OpenAICompatProvider) AvailableBuiltinTools() []BuiltinTool {
	if p.name == "openai" {
		return []BuiltinTool{
			{Type: "code_interpreter", Name: "code_interpreter"},
		}
	}
	return nil
}

func (p *OpenAICompatProvider) SetBuiltinTools(tools []string) {
	// OpenAI built-in tools handled via Responses API, not Chat Completions
	// Placeholder for future support
}

func (p *OpenAICompatProvider) WithBuiltins(builtins []string) LLMProvider {
	return p // OpenAI compat providers don't use builtins in Chat Completions
}

// openaiMessage serializes a Message for the OpenAI API.
// When Parts is set, content becomes the array (native format).
type openaiMessage struct {
	Role    string `json:"role"`
	Content any    `json:"content"` // string or []ContentPart
}

// convertAudioURLParts converts audio_url parts to input_audio (OpenAI format).
func convertAudioURLParts(parts []ContentPart) []ContentPart {
	var out []ContentPart
	for _, p := range parts {
		if p.Type == "audio_url" && p.AudioURL != nil {
			if strings.HasPrefix(p.AudioURL.URL, "data:") {
				data, mime := parseDataURI(p.AudioURL.URL)
				format := "wav"
				if strings.Contains(mime, "mp3") || strings.Contains(mime, "mpeg") {
					format = "mp3"
				}
				out = append(out, ContentPart{Type: "input_audio", InputAudio: &InputAudio{Data: data, Format: format}})
			} else {
				// Fetch and convert
				b64, mime, err := fetchMediaAsBase64(p.AudioURL.URL)
				if err != nil {
					logMsg("OPENAI", fmt.Sprintf("audio fetch error: %v", err))
					out = append(out, ContentPart{Type: "text", Text: fmt.Sprintf("[audio fetch failed: %s]", p.AudioURL.URL)})
				} else {
					format := "wav"
					if strings.Contains(mime, "mp3") || strings.Contains(mime, "mpeg") {
						format = "mp3"
					}
					out = append(out, ContentPart{Type: "input_audio", InputAudio: &InputAudio{Data: b64, Format: format}})
				}
			}
		} else {
			out = append(out, p)
		}
	}
	return out
}

// openaiToolCallDelta tracks streaming tool call assembly.
type openaiToolCallDelta struct {
	Index    int    `json:"index"`
	ID       string `json:"id,omitempty"`
	Type     string `json:"type,omitempty"`
	Function *struct {
		Name      string `json:"name,omitempty"`
		Arguments string `json:"arguments,omitempty"`
	} `json:"function,omitempty"`
}

// openaiToolDef is the OpenAI tool format for the request.
type openaiToolDef struct {
	Type     string `json:"type"`
	Function struct {
		Name        string         `json:"name"`
		Description string         `json:"description"`
		Parameters  map[string]any `json:"parameters"`
		Strict      bool           `json:"strict,omitempty"`
	} `json:"function"`
}

// openaiToolResultMsg is a tool result message.
type openaiToolResultMsg struct {
	Role       string `json:"role"` // "tool"
	Content    string `json:"content"`
	ToolCallID string `json:"tool_call_id"`
}

func toOpenAIMessages(messages []Message) []any {
	var out []any
	for _, m := range messages {
		// Tool result messages
		if len(m.ToolResults) > 0 {
			for _, tr := range m.ToolResults {
				if tr.Image != nil {
					// Tool result with image (screenshot) — send as multimodal content
					// Use "original" detail for computer use to preserve full resolution
					out = append(out, map[string]any{
						"role":         "tool",
						"tool_call_id": tr.CallID,
						"content": []map[string]any{
							{"type": "text", "text": tr.Content},
							{"type": "image_url", "image_url": map[string]any{
								"url":    "data:image/png;base64," + base64Encode(tr.Image),
								"detail": "original",
							}},
						},
					})
				} else {
					out = append(out, openaiToolResultMsg{
						Role:       "tool",
						Content:    tr.Content,
						ToolCallID: tr.CallID,
					})
				}
			}
			continue
		}

		// Assistant message with tool calls.
		//
		// `content` is ALWAYS included, even as empty string. The
		// OpenAI spec allows omitting it when tool_calls is present,
		// and OpenAI/Fireworks accept that — but Moonshot Kimi K2.6
		// (which OpenCode Go proxies for the kimi-k2.6 slug) rejects
		// the message with HTTP 400 unless `content` is on the wire.
		// Empty string is interop-safe across every backend we've
		// tested (OpenAI, Fireworks, Moonshot, NVIDIA NIM, OpenRouter,
		// Together, Groq); `null` is not (older NIM builds reject it).
		//
		// `reasoning_content` is included when the message carries
		// reasoning captured from the prior turn. Moonshot with
		// thinking enabled requires it on assistant tool_call
		// messages — without it the next request 400s with
		// "thinking is enabled but reasoning_content is missing in
		// assistant tool call message". Other backends ignore the
		// field (it's a known reasoning-model extension).
		if len(m.ToolCalls) > 0 {
			toolCalls := make([]map[string]any, len(m.ToolCalls))
			for i, tc := range m.ToolCalls {
				argsJSON, _ := json.Marshal(tc.Args)
				toolCalls[i] = map[string]any{
					"id":   tc.ID,
					"type": "function",
					"function": map[string]any{
						"name":      tc.Name,
						"arguments": string(argsJSON),
					},
				}
			}
			msg := map[string]any{
				"role":       "assistant",
				"content":    m.Content, // always present; "" when only tool_calls
				"tool_calls": toolCalls,
			}
			if m.Reasoning != "" {
				msg["reasoning_content"] = m.Reasoning
			}
			out = append(out, msg)
			continue
		}

		// Regular message.
		//
		// Skip assistant turns that have nothing to say AND no tool
		// calls AND no parts. Those are dead-air entries (e.g. left
		// behind when an upstream Chat() errored after the message was
		// already appended) and Moonshot rejects them with HTTP 400
		// "Invalid request: the message at position N with role
		// 'assistant' must not be empty" — which then poisons every
		// subsequent iteration. User and system messages are kept even
		// when empty (rare but legitimate signals like "[admin]"
		// directives).
		if m.Role == "assistant" && m.Content == "" && len(m.ToolCalls) == 0 && !m.HasParts() {
			continue
		}
		if m.HasParts() {
			out = append(out, openaiMessage{Role: m.Role, Content: convertAudioURLParts(m.Parts)})
		} else {
			out = append(out, openaiMessage{Role: m.Role, Content: m.Content})
		}
	}
	return out
}

func (p *OpenAICompatProvider) Chat(messages []Message, model string, tools []NativeTool, onChunk func(string), onThinking func(string), onToolChunk func(string, string, string)) (ChatResponse, error) {
	// Build request
	reqMap := map[string]any{
		"model":    model,
		"messages": toOpenAIMessages(messages),
		"stream":   true,
	}
	// OpenAI supports stream_options for usage in streaming; Fireworks may not
	if p.name == "openai" {
		reqMap["stream_options"] = map[string]any{"include_usage": true}
	}

	// Add tools if provider supports them
	// OpenAI native Computer Use uses the Responses API (computer_call/computer_call_output),
	// which is a different API shape from Chat Completions. For Chat Completions (what we use),
	// computer_use is handled as a regular function tool via SetComputer() — gpt-5.4 works
	// well with custom tool harnesses (Option 2 in their docs).
	// We skip computer_use/browser_session from the tools list for native OpenAI since
	// they're handled by the thinker's computer interceptor.
	if len(tools) > 0 && p.SupportsNativeTools() {
		var defs []openaiToolDef
		for _, t := range tools {
			def := openaiToolDef{Type: "function"}
			def.Function.Name = t.Name
			def.Function.Description = t.Description
			def.Function.Parameters = t.Parameters
			// Note: Strict mode not supported by all providers (Fireworks ignores it)
			defs = append(defs, def)
		}
		reqMap["tools"] = defs
	}

	body, err := json.Marshal(reqMap)
	if err != nil {
		return ChatResponse{}, err
	}

	// Log message count and types for debugging
	if msgs, ok := reqMap["messages"].([]any); ok {
		for i, m := range msgs {
			switch v := m.(type) {
			case map[string]any:
				if v["role"] == "tool" {
					logMsg("OPENAI", fmt.Sprintf("msg[%d] role=tool call_id=%v content_type=%T", i, v["tool_call_id"], v["content"]))
				}
			}
		}
	}

	req, err := http.NewRequest("POST", p.url, bytes.NewReader(body))
	if err != nil {
		return ChatResponse{}, err
	}
	req.Header.Set("Content-Type", "application/json")
	if p.apiKey != "" && p.authHeader != "" {
		req.Header.Set("Authorization", p.authHeader+" "+p.apiKey)
	}

	resp, err := llmHTTPClient.Do(req)
	if err != nil {
		return ChatResponse{}, err
	}

	// Capture provider-side request identifiers so a future stall /
	// hang can be cross-referenced with the provider's own logs without
	// another round-trip. Different vendors use different header names
	// (Fireworks ships x-request-id; some return x-fw-request-id). Log
	// whatever we find.
	reqIDs := extractProviderRequestIDs(resp.Header)
	if len(reqIDs) > 0 {
		logMsg("PROVIDER", fmt.Sprintf("model=%s request_ids=%v", model, reqIDs))
	}

	if resp.StatusCode != http.StatusOK {
		respBody, _ := io.ReadAll(resp.Body)
		resp.Body.Close()
		return ChatResponse{}, fmt.Errorf("API error %d: %s (request_ids=%v)", resp.StatusCode, string(respBody), reqIDs)
	}

	// Wrap the streaming body in an idle-read monitor. Any pause longer
	// than streamIdleTimeout without a single byte arriving is treated
	// as a provider stall — we close the body so the scanner unblocks
	// with an error, and the caller returns ErrStreamIdleTimeout (with
	// request_ids folded in) so the think loop can retry.
	idleBody := newIdleReader(resp.Body, streamIdleTimeout(), func() {
		logMsg("FIREWORKS-STALL", fmt.Sprintf("stream idle for %s on model=%s request_ids=%v — aborting",
			streamIdleTimeout(), model, reqIDs))
	})
	resp.Body = idleBody
	defer resp.Body.Close()

	var full strings.Builder
	// Accumulate reasoning chunks too. We forward each one through
	// onThinking for live UI rendering, but also capture the full
	// transcript so the caller can write it back onto the assistant
	// Message it appends — Moonshot via OpenCode Go requires the
	// `reasoning_content` field on the next-turn assistant tool_call
	// message, otherwise it 400s with "thinking is enabled but
	// reasoning_content is missing".
	var fullReasoning strings.Builder
	var usage TokenUsage
	// Track streamed tool calls by index
	pendingTools := make(map[int]*struct {
		id         string
		name       string
		argsJSON   strings.Builder
		pendingBuf strings.Builder
	})

	scanner := bufio.NewScanner(resp.Body)
	for scanner.Scan() {
		line := scanner.Text()
		if !strings.HasPrefix(line, "data: ") {
			continue
		}
		data := strings.TrimPrefix(line, "data: ")
		if data == "[DONE]" {
			break
		}
		// Debug: dump the raw delta so we can see what fields Fireworks is
		// actually returning (reasoning_content, thinking, etc.). Enable via
		// APTEVA_DUMP_STREAM=1 to avoid log spam in production.
		if os.Getenv("APTEVA_DUMP_STREAM") == "1" {
			logMsg("OPENAI-STREAM", data)
		}

		var event struct {
			Choices []struct {
				Delta struct {
					Content          string                `json:"content"`
					ReasoningContent string                `json:"reasoning_content,omitempty"`
					Reasoning        string                `json:"reasoning,omitempty"`
					ToolCalls        []openaiToolCallDelta `json:"tool_calls,omitempty"`
				} `json:"delta"`
			} `json:"choices"`
			Usage *Usage `json:"usage,omitempty"`
		}
		if err := json.Unmarshal([]byte(data), &event); err != nil {
			continue
		}
		if len(event.Choices) > 0 {
			delta := event.Choices[0].Delta
			// Reasoning chain-of-thought arrives under different field
			// names depending on the gateway:
			//   reasoning_content — Fireworks, DeepSeek, OpenAI o-series
			//   reasoning         — OpenRouter-style proxies (OpenCode Go)
			// Both go through onThinking (not onChunk) so the UI can
			// distinguish reasoning from output, and neither is appended
			// to `full` (the visible answer).
			reasoning := delta.ReasoningContent
			if reasoning == "" {
				reasoning = delta.Reasoning
			}
			if reasoning != "" {
				fullReasoning.WriteString(reasoning)
				if onThinking != nil {
					onThinking(reasoning)
				}
			}
			if delta.Content != "" {
				full.WriteString(delta.Content)
				if onChunk != nil {
					onChunk(delta.Content)
				}
			}
			for _, tc := range delta.ToolCalls {
				pt, ok := pendingTools[tc.Index]
				if !ok {
					pt = &struct {
						id         string
						name       string
						argsJSON   strings.Builder
						pendingBuf strings.Builder // chunks accumulated before tc.ID arrived
					}{}
					pendingTools[tc.Index] = pt
				}
				if tc.ID != "" {
					pt.id = tc.ID
				}
				if tc.Function != nil {
					if tc.Function.Name != "" {
						pt.name = tc.Function.Name
					}
					if tc.Function.Arguments != "" {
						pt.argsJSON.WriteString(tc.Function.Arguments)
						// Only emit chunks once pt.id is known so the call_id
						// on every llm.tool_chunk event matches the eventual
						// tool.call (both use the upstream provider id). Using
						// an index-based fallback split streaming rows in the
						// dashboard because the fallback and the real id were
						// different strings.
						if pt.id == "" {
							pt.pendingBuf.WriteString(tc.Function.Arguments)
						} else if onToolChunk != nil && pt.name != "" {
							if pt.pendingBuf.Len() > 0 {
								onToolChunk(pt.name, pt.id, pt.pendingBuf.String())
								pt.pendingBuf.Reset()
							}
							onToolChunk(pt.name, pt.id, tc.Function.Arguments)
						}
					}
				}
			}
		}
		if event.Usage != nil {
			usage.PromptTokens = event.Usage.PromptTokens
			usage.CompletionTokens = event.Usage.CompletionTokens
			if event.Usage.PromptTokensDetails != nil {
				usage.CachedTokens = event.Usage.PromptTokensDetails.CachedTokens
			}
		}
	}

	// Surface any scanner error (stall, I/O error) with the request IDs
	// attached so the operator can cross-reference with the provider's
	// own logs. Idle-timeout stalls get a dedicated sentinel so callers
	// (and tests) can tell them apart from transport errors.
	if scerr := scanner.Err(); scerr != nil {
		if errors.Is(scerr, ErrStreamIdleTimeout) {
			return ChatResponse{}, fmt.Errorf("%w (model=%s request_ids=%v)", ErrStreamIdleTimeout, model, reqIDs)
		}
		return ChatResponse{}, fmt.Errorf("stream read error: %w (model=%s request_ids=%v)", scerr, model, reqIDs)
	}

	// Assemble completed tool calls
	var toolCalls []NativeToolCall
	for i := 0; i < len(pendingTools); i++ {
		pt, ok := pendingTools[i]
		if !ok {
			continue
		}
		// Flush any chunks buffered before pt.id arrived. By now the stream
		// is done so pt.id is either set (happy path — flush under real id)
		// or never arrived (pathological provider — nothing to emit since
		// the dashboard has no way to match anyway).
		if onToolChunk != nil && pt.id != "" && pt.pendingBuf.Len() > 0 && pt.name != "" {
			onToolChunk(pt.name, pt.id, pt.pendingBuf.String())
			pt.pendingBuf.Reset()
		}
		args := make(map[string]string)
		var raw map[string]any
		if err := json.Unmarshal([]byte(pt.argsJSON.String()), &raw); err == nil {
			for k, v := range raw {
				switch v.(type) {
				case string:
					args[k] = v.(string)
				default:
					// Preserve arrays/objects/numbers as JSON strings
					b, _ := json.Marshal(v)
					args[k] = string(b)
				}
			}
		}
		toolCalls = append(toolCalls, NativeToolCall{
			ID:   pt.id,
			Name: pt.name,
			Args: args,
		})
	}

	return ChatResponse{
		Text:      full.String(),
		Reasoning: fullReasoning.String(),
		ToolCalls: toolCalls,
		Usage:     usage,
	}, nil
}

// --- Factory functions ---

func NewFireworksProvider(apiKey string) LLMProvider {
	return &OpenAICompatProvider{
		name:       "fireworks",
		apiKey:     apiKey,
		url:        "https://api.fireworks.ai/inference/v1/chat/completions",
		authHeader: "Bearer",
		models: map[ModelTier]string{
			ModelLarge:  "accounts/fireworks/models/kimi-k2p6",
			ModelMedium: "accounts/fireworks/models/kimi-k2p6",
			ModelSmall:  "accounts/fireworks/models/kimi-k2p6",
		},
		inputCost:  0.60,
		cachedCost: 0.10,
		outputCost: 3.00,
	}
}

// NewOpenCodeGoProvider — flat-rate subscription gateway from
// opencode.ai/go that fronts the same Kimi K2.6 we use via Fireworks
// plus Qwen / GLM / MiMo variants under one OpenAI-compatible endpoint.
//
// Per-token costs are placeholders (0/0/0) because OpenCode Go bills
// per subscription, not per call — the server's model_fetch.go pricing
// table reports the same so the dashboard's per-call $ figure stays
// blank rather than misleadingly nonzero.
//
// Defaults: kimi-k2.6 across all three tiers. With a flat-rate plan
// the per-iteration cost incentive that justified Qwen on small/medium
// for token-priced providers doesn't apply, so we let the agent run
// the strongest model end-to-end. Users who want to stretch the
// monthly cap with cheaper tiers can override per-instance in the
// dashboard provider settings.
func NewOpenCodeGoProvider(apiKey string) LLMProvider {
	return &OpenAICompatProvider{
		name:       "opencode-go",
		apiKey:     apiKey,
		url:        "https://opencode.ai/zen/go/v1/chat/completions",
		authHeader: "Bearer",
		models: map[ModelTier]string{
			ModelLarge:  "kimi-k2.6",
			ModelMedium: "kimi-k2.6",
			ModelSmall:  "kimi-k2.6",
		},
		inputCost:  0,
		cachedCost: 0,
		outputCost: 0,
	}
}

func NewOpenAIProvider(apiKey string) LLMProvider {
	return &OpenAICompatProvider{
		name:       "openai",
		apiKey:     apiKey,
		url:        "https://api.openai.com/v1/chat/completions",
		authHeader: "Bearer",
		models: map[ModelTier]string{
			ModelLarge:  "gpt-4.1",
			ModelMedium: "gpt-4.1-mini",
			ModelSmall:  "gpt-4.1-nano",
		},
		inputCost:  2.50,
		cachedCost: 1.25,
		outputCost: 10.00,
	}
}

// NewNvidiaProvider wires up NVIDIA's NIM hosted catalog. They expose an
// OpenAI-compatible Chat Completions endpoint at integrate.api.nvidia.com,
// so we reuse OpenAICompatProvider verbatim — just the base URL and default
// model slugs are NVIDIA-specific. Pricing is left at zero by default because
// NIM billing is account-scoped rather than per-token-listed, so cost
// projections in the dashboard stats bar will stay at $0 unless the user
// manually overrides these costs via config.
func NewNvidiaProvider(apiKey string) LLMProvider {
	return &OpenAICompatProvider{
		name:       "nvidia",
		apiKey:     apiKey,
		url:        "https://integrate.api.nvidia.com/v1/chat/completions",
		authHeader: "Bearer",
		models: map[ModelTier]string{
			// Defaults picked from NVIDIA's public NIM catalog. Users will
			// typically override via Config.Providers[].Models on the
			// dashboard settings page.
			ModelLarge:  "nvidia/llama-3.1-nemotron-70b-instruct",
			ModelMedium: "meta/llama-3.1-70b-instruct",
			ModelSmall:  "meta/llama-3.1-8b-instruct",
		},
		// NIM pricing is account-plan dependent — leave the per-token cost
		// at 0 so calculateCostForProvider() returns 0 instead of a
		// misleading number. Users wanting real cost tracking can edit
		// the struct directly from a fork or set costs via a future
		// config field.
		inputCost:  0,
		cachedCost: 0,
		outputCost: 0,
	}
}

// NewVeniceProvider — privacy-focused inference gateway at venice.ai.
// OpenAI-compatible /chat/completions endpoint, large rotating catalog
// (Llama, Qwen, GLM, Mistral, plus Claude/Grok/Gemini reseller variants).
// Pricing varies per model and is set per-account in their dashboard, so
// per-token costs are left at zero here — the model picker / picker
// dropdown is the source of truth for what's available right now.
func NewVeniceProvider(apiKey string) LLMProvider {
	return &OpenAICompatProvider{
		name:       "venice",
		apiKey:     apiKey,
		url:        "https://api.venice.ai/api/v1/chat/completions",
		authHeader: "Bearer",
		models: map[ModelTier]string{
			ModelLarge:  "qwen3-coder-480b-a35b-instruct",
			ModelMedium: "qwen3-6-27b",
			ModelSmall:  "mistral-small-3-2-24b-instruct",
		},
		inputCost:  0,
		cachedCost: 0,
		outputCost: 0,
	}
}

func NewOllamaProvider(host string) LLMProvider {
	url := strings.TrimRight(host, "/") + "/v1/chat/completions"
	return &OpenAICompatProvider{
		name:       "ollama",
		apiKey:     "",
		url:        url,
		authHeader: "",
		models: map[ModelTier]string{
			ModelLarge:  "llama3.1",
			ModelMedium: "llama3.1",
			ModelSmall:  "llama3.1",
		},
		inputCost:  0,
		cachedCost: 0,
		outputCost: 0,
	}
}
