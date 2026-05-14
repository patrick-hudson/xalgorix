// Package llm provides the LLM API client for Xalgorix.
package llm

import (
	"bufio"
	"bytes"
	"context"
	"encoding/json"
	"fmt"
	"io"
	"log"
	"net/http"
	"strings"
	"sync"
	"sync/atomic"
	"time"

	"github.com/xalgord/xalgorix/v4/internal/config"
)

// Message represents a chat message.
type Message struct {
	Role    string `json:"role"`
	Content string `json:"content"`
}

// StreamChunk is a piece of streaming response.
type StreamChunk struct {
	Content string
	Done    bool
	Err     error
}

// Client is the LLM API client.
type Client struct {
	cfg        *config.Config
	httpClient *http.Client
	apiModel   string
	provider   string // "openai", "anthropic", "google", "gemini", "deepseek", etc.
	mu         sync.Mutex
	totalIn    int
	totalOut   int
	// ctx is read concurrently by chatWithRetry / ChatStream and written by
	// SetContext. Use atomic.Value to avoid a race; loadCtx() is the only
	// reader, storeCtx() is the only writer.
	ctx atomic.Value // context.Context
}

// TokenUsage holds cumulative token counts.
type TokenUsage struct {
	PromptTokens     int `json:"prompt_tokens"`
	CompletionTokens int `json:"completion_tokens"`
	TotalTokens      int `json:"total_tokens"`
}

// GetTokens returns cumulative token usage.
func (c *Client) GetTokens() (promptTokens, completionTokens, totalTokens int) {
	c.mu.Lock()
	defer c.mu.Unlock()
	return c.totalIn, c.totalOut, c.totalIn + c.totalOut
}

// maxTokens returns the configured per-turn assistant token cap, falling
// back to a conservative 8192 default when XALGORIX_LLM_MAX_TOKENS is unset
// or zero. Used by the OpenAI-compat and Anthropic request builders so the
// upstream gateway never falls back to its own (often tiny) default.
func (c *Client) maxTokens() int {
	if c.cfg != nil && c.cfg.LLMMaxTokens > 0 {
		return c.cfg.LLMMaxTokens
	}
	return 8192
}

// NewClient creates a new LLM client.
func NewClient(cfg *config.Config) *Client {
	apiModel := cfg.ResolveModel()
	provider := ""
	if idx := strings.Index(apiModel, "/"); idx >= 0 {
		provider = strings.ToLower(apiModel[:idx])
	}
	c := &Client{
		cfg:        cfg,
		httpClient: &http.Client{Timeout: 10 * time.Minute},
		apiModel:   apiModel,
		provider:   provider,
	}
	c.ctx.Store(ctxHolder{ctx: context.Background()})
	return c
}

// ctxHolder wraps context.Context so atomic.Value sees a concrete type even
// when callers pass a nil context.Context interface.
type ctxHolder struct{ ctx context.Context }

// SetContext sets the context for HTTP requests, enabling cancellation.
// Safe for concurrent use.
func (c *Client) SetContext(ctx context.Context) {
	if ctx == nil {
		ctx = context.Background()
	}
	c.ctx.Store(ctxHolder{ctx: ctx})
}

// loadCtx returns the current request context, falling back to Background
// if SetContext has never been called.
func (c *Client) loadCtx() context.Context {
	if v := c.ctx.Load(); v != nil {
		if h, ok := v.(ctxHolder); ok && h.ctx != nil {
			return h.ctx
		}
	}
	return context.Background()
}

// chatRequest is the OpenAI-compatible chat completion request.
type chatRequest struct {
	Model         string         `json:"model"`
	Messages      []Message      `json:"messages"`
	Stream        bool           `json:"stream"`
	StreamOptions *streamOptions `json:"stream_options,omitempty"`
	Temperature   float64        `json:"temperature,omitempty"`
	MaxTokens     int            `json:"max_tokens,omitempty"`
}

// streamOptions opts into usage stats for OpenAI-compatible streaming
// responses (OpenAI, Groq, DeepSeek, MiniMax, etc.). Without this the
// final `usage` field is omitted from the SSE stream.
type streamOptions struct {
	IncludeUsage bool `json:"include_usage"`
}

// chatChoice represents a response choice.
type chatChoice struct {
	Delta        struct{ Content string } `json:"delta"`
	Message      struct{ Content string } `json:"message"`
	FinishReason string                   `json:"finish_reason,omitempty"`
}

// ChatMeta carries the per-response metadata the agent needs to
// distinguish a truncated completion ("the model ran out of tokens
// mid-tool-call") from a clean stop. StopReason normalizes the two
// provider conventions:
//   - OpenAI / OpenAI-compatible (incl. bedrock-access-gateway): "length"
//     when truncated by max_tokens; "stop" / "" otherwise.
//   - Anthropic native: "max_tokens" when truncated; "end_turn" otherwise.
//   - Gemini: "MAX_TOKENS" when truncated; passed through verbatim.
//
// Callers should treat StopReason ∈ {"length", "max_tokens", "MAX_TOKENS"}
// as "truncated".
type ChatMeta struct {
	StopReason   string
	OutputTokens int
}

// IsTruncated reports whether the LLM was cut off by the max_tokens limit.
func (m ChatMeta) IsTruncated() bool {
	switch m.StopReason {
	case "length", "max_tokens", "MAX_TOKENS":
		return true
	}
	return false
}

// chatResponse is the OpenAI-compatible response.
type chatResponse struct {
	Choices []chatChoice `json:"choices"`
	Usage   *TokenUsage  `json:"usage,omitempty"`
}

// ── Google Gemini types ──────────────────────────────────────────────────────

type geminiPart struct {
	Text string `json:"text"`
}

type geminiContent struct {
	Role  string       `json:"role,omitempty"`
	Parts []geminiPart `json:"parts"`
}

type geminiRequest struct {
	Contents          []geminiContent `json:"contents,omitempty"`
	SystemInstruction *geminiContent  `json:"system_instruction,omitempty"`
}

type geminiCandidate struct {
	Content struct {
		Parts []geminiPart `json:"parts"`
	} `json:"content"`
	FinishReason string `json:"finishReason,omitempty"`
}

type geminiResponse struct {
	Candidates []geminiCandidate `json:"candidates"`
}

// geminiStreamResponse is the same structure but used for SSE streaming responses.
type geminiStreamResponse = geminiResponse

// ── Anthropic types ──────────────────────────────────────────────────────────

type anthropicRequest struct {
	Model     string    `json:"model"`
	Messages  []Message `json:"messages"`
	System    string    `json:"system,omitempty"`
	MaxTokens int       `json:"max_tokens"`
	Stream    bool      `json:"stream"`
}

type anthropicContentBlock struct {
	Type string `json:"type"`
	Text string `json:"text,omitempty"`
}

type anthropicMessage struct {
	ID         string                  `json:"id"`
	Type       string                  `json:"type"`
	Role       string                  `json:"role"`
	Content    []anthropicContentBlock `json:"content"`
	Model      string                  `json:"model"`
	StopReason string                  `json:"stop_reason,omitempty"`
	Usage      struct {
		InputTokens  int `json:"input_tokens"`
		OutputTokens int `json:"output_tokens"`
	} `json:"usage"`
}

type anthropicResponse struct {
	Type    string           `json:"type"`
	Message anthropicMessage `json:"message,omitempty"`
	Delta   struct {
		Text string `json:"text"`
	} `json:"delta,omitempty"`
	Index int `json:"index,omitempty"`
}

// resolveEndpoint returns the full chat completions URL and clean model name.
// Handles provider prefixes like "minimax/", "openai/", "anthropic/", etc.
// Auto-appends /v1/chat/completions if the base doesn't already contain /v1.
// Also supports custom providers - just set XALGORIX_API_BASE to your endpoint.
func (c *Client) resolveEndpoint() (string, string) {
	apiBase := c.cfg.APIBase
	model := c.apiModel

	// Extract provider prefix if present (e.g., "openai/gpt-5.4" -> provider="openai", model="gpt-5.4")
	provider := ""
	if idx := strings.Index(model, "/"); idx >= 0 {
		provider = strings.ToLower(model[:idx])
		model = model[idx+1:]
	}

	// Provider prefix in model name is the source of truth for API base.
	// However, if a non-empty API base was explicitly set (e.g., from web UI), use it.
	providerBases := map[string]string{
		"openai":    "https://api.openai.com/v1",
		"anthropic": "https://api.anthropic.com",
		"minimax":   "https://api.minimax.io/v1",
		"deepseek":  "https://api.deepseek.com/v1",
		"groq":      "https://api.groq.com/openai/v1",
		"ollama":    "http://localhost:11434/v1",
		// Google's chat endpoint is /v1beta/models/MODEL:generateContent — we
		// store the bare host here and append the version segment below.
		"google": "https://generativelanguage.googleapis.com",
		"gemini": "https://generativelanguage.googleapis.com",
	}

	if apiBase == "" {
		// No explicit API base set — use provider default
		if knownBase, ok := providerBases[provider]; ok {
			apiBase = knownBase
		} else {
			// Unknown/no provider — default to OpenAI
			apiBase = "https://api.openai.com/v1"
		}
	}

	apiBase = strings.TrimRight(apiBase, "/")

	// Build the URL based on provider
	url := apiBase
	if provider == "anthropic" || strings.Contains(strings.ToLower(apiBase), "anthropic") {
		// Anthropic uses /v1/messages
		if !strings.HasSuffix(strings.ToLower(url), "/messages") {
			if !strings.HasSuffix(apiBase, "/v1") && !strings.Contains(apiBase, "/v1/") {
				url += "/v1"
			}
			url += "/messages"
		}
	} else if isGeminiProvider(provider) || isGeminiAPIBase(apiBase) {
		// Google Gemini uses /v1beta/models/MODEL:generateContent.
		// Strip any trailing /v1 so we don't end up with /v1beta concatenated
		// onto a version segment the user supplied.
		url = strings.TrimSuffix(url, "/v1")
		url += "/v1beta/models/" + model + ":generateContent"
	} else {
		if !strings.HasSuffix(strings.ToLower(url), "/chat/completions") {
			if !strings.HasSuffix(apiBase, "/v1") && !strings.Contains(apiBase, "/v1/") {
				url += "/v1"
			}
			url += "/chat/completions"
		}
	}

	return url, model
}

func isGeminiProvider(provider string) bool {
	provider = strings.ToLower(provider)
	return provider == "google" || provider == "gemini"
}

func isGeminiAPIBase(value string) bool {
	value = strings.ToLower(value)
	return strings.Contains(value, "generativelanguage.googleapis.com") ||
		strings.Contains(value, "generativelanguage")
}

func (c *Client) usesGeminiAPI(endpoint string) bool {
	return isGeminiProvider(c.provider) ||
		isGeminiAPIBase(c.cfg.APIBase) ||
		isGeminiAPIBase(endpoint)
}

func isAnthropicAPIBase(value string) bool {
	return strings.Contains(strings.ToLower(value), "anthropic")
}

func (c *Client) usesAnthropicAPI(endpoint string) bool {
	return c.provider == "anthropic" ||
		isAnthropicAPIBase(c.cfg.APIBase) ||
		isAnthropicAPIBase(endpoint)
}

func apiErrorHasStatus(errStr string, status int) bool {
	errStr = strings.ToLower(errStr)
	statusText := fmt.Sprintf("%d", status)
	return strings.Contains(errStr, "api returned "+statusText) ||
		strings.Contains(errStr, "http "+statusText)
}

func isContextWindowError(errStr string) bool {
	errStr = strings.ToLower(errStr)
	// Body-wording match. Historically required HTTP 400 too, but Bedrock-via-
	// gateway sometimes remaps the status to 422/500 while keeping a clear
	// "input is too long" body — relying on the body alone catches more
	// providers without false positives. Each fragment below maps to a known
	// upstream error message:
	//   - context window / maximum context length: OpenAI, Azure OpenAI
	//   - too many tokens / token limit:           OpenAI, MiniMax
	//   - invalid params:                          DeepSeek
	//   - input is too long / prompt is too long:  AWS Bedrock (Anthropic / Nova)
	//   - validationexception:                     AWS Bedrock generic
	//   - tokens exceed:                           Anthropic native, some clones
	fragments := []string{
		"context window",
		"maximum context length",
		"too many tokens",
		"token limit",
		"invalid params",
		"input is too long",
		"prompt is too long",
		"validationexception",
		"tokens exceed",
	}
	for _, f := range fragments {
		if strings.Contains(errStr, f) {
			return true
		}
	}
	return false
}

func isRateLimitError(errStr string) bool {
	errStr = strings.ToLower(errStr)
	return apiErrorHasStatus(errStr, http.StatusTooManyRequests) ||
		strings.Contains(errStr, "too many requests") ||
		strings.Contains(errStr, "rate limited") ||
		strings.Contains(errStr, "rate limit") ||
		strings.Contains(errStr, "rate_limit") ||
		strings.Contains(errStr, "ratelimit") ||
		strings.Contains(errStr, "resource_exhausted")
}

func isNonRetryableLLMError(errStr string) bool {
	errStr = strings.ToLower(errStr)
	if apiErrorHasStatus(errStr, http.StatusBadRequest) ||
		apiErrorHasStatus(errStr, http.StatusUnauthorized) ||
		apiErrorHasStatus(errStr, http.StatusForbidden) ||
		apiErrorHasStatus(errStr, http.StatusNotFound) {
		return true
	}
	return strings.Contains(errStr, "unauthenticated") ||
		strings.Contains(errStr, "access_token_type_unsupported") ||
		strings.Contains(errStr, "invalid authentication credentials") ||
		strings.Contains(errStr, "permission_denied") ||
		strings.Contains(errStr, "model not found") ||
		strings.Contains(errStr, "not found")
}

// Chat sends a non-streaming chat request and returns the full response.
// Most callers want this — it discards the per-response metadata. Use
// ChatWithMeta when you need to differentiate a truncated completion from
// a clean stop (see the agent loop, which uses this to detect tool calls
// that the model was cut off mid-emission).
func (c *Client) Chat(messages []Message) (string, error) {
	content, _, err := c.ChatWithMeta(messages)
	return content, err
}

// ChatWithMeta is Chat plus the per-response metadata the agent needs
// (StopReason etc.). Same retry / non-retryable semantics as Chat.
func (c *Client) ChatWithMeta(messages []Message) (string, ChatMeta, error) {
	return c.chatWithRetryMeta(messages)
}

func (c *Client) chatWithRetryMeta(messages []Message) (string, ChatMeta, error) {
	maxRetries := c.cfg.LLMMaxRetries
	if maxRetries < 3 {
		maxRetries = 3
	}
	var lastErr error

	for attempt := range maxRetries {
		if attempt > 0 {
			// Smart backoff based on error type
			backoff := time.Duration(attempt*3) * time.Second
			if lastErr != nil {
				errStr := lastErr.Error()
				if isRateLimitError(errStr) {
					backoff = 30 * time.Second // rate limit: wait longer
				} else if strings.Contains(errStr, "connection") || strings.Contains(errStr, "timeout") || strings.Contains(errStr, "EOF") {
					backoff = time.Duration(attempt*10) * time.Second // network: longer backoff
				} else if strings.Contains(errStr, "500") || strings.Contains(errStr, "502") || strings.Contains(errStr, "503") {
					backoff = time.Duration(attempt*5) * time.Second // server error
				}
			}
			if backoff > 60*time.Second {
				backoff = 60 * time.Second
			}
			log.Printf("[llm] Retry %d/%d after %s (last error: %v)", attempt+1, maxRetries, backoff, lastErr)
			time.Sleep(backoff)
		}

		// Check if context is cancelled before retrying
		if ctx := c.loadCtx(); ctx.Err() != nil {
			return "", ChatMeta{}, fmt.Errorf("LLM request cancelled: %w", ctx.Err())
		}

		result, meta, err := c.doChatWithMeta(messages)
		if err == nil {
			return result, meta, nil
		}
		lastErr = err

		// Non-retryable errors: context window overflow, malformed request, etc.
		// These will never succeed on retry — return immediately so the caller
		// can handle them (e.g. by pruning messages).
		errStr := err.Error()
		if isContextWindowError(errStr) {
			log.Printf("[llm] Non-retryable error (context overflow), returning immediately: %v", err)
			return "", ChatMeta{}, fmt.Errorf("context window overflow: %w", err)
		}

		if isNonRetryableLLMError(errStr) {
			log.Printf("[llm] Non-retryable LLM error, returning immediately: %v", err)
			return "", ChatMeta{}, fmt.Errorf("LLM request failed: %w", err)
		}

		// Track if last error was a rate limit for the post-loop wrapper
		if isRateLimitError(errStr) {
			lastErr = fmt.Errorf("rate limited: %w", err)
			continue
		}
	}

	// Preserve rate-limit marker if the final error was rate-limited
	if lastErr != nil && strings.Contains(lastErr.Error(), "rate limited:") {
		return "", ChatMeta{}, fmt.Errorf("rate limited: LLM request failed after %d retries: %w", maxRetries, lastErr)
	}
	return "", ChatMeta{}, fmt.Errorf("LLM request failed after %d retries: %w", maxRetries, lastErr)
}

// ChatStream sends a streaming chat request and returns a channel of chunks.
func (c *Client) ChatStream(messages []Message) <-chan StreamChunk {
	ch := make(chan StreamChunk, 64)

	go func() {
		defer close(ch)

		endpoint, model := c.resolveEndpoint()
		isGoogle := c.usesGeminiAPI(endpoint)
		isAnthropic := c.usesAnthropicAPI(endpoint)

		var body []byte
		if isGoogle {
			endpoint = strings.TrimSuffix(endpoint, "generateContent") + "streamGenerateContent?alt=sse"
			var systemParts []geminiPart
			contents := make([]geminiContent, 0, len(messages))
			for _, m := range messages {
				if m.Role == "system" {
					systemParts = append(systemParts, geminiPart{Text: m.Content})
				} else {
					role := m.Role
					if role == "assistant" {
						role = "model"
					}
					contents = append(contents, geminiContent{Role: role, Parts: []geminiPart{{Text: m.Content}}})
				}
			}
			gemReq := geminiRequest{Contents: contents}
			if len(systemParts) > 0 {
				gemReq.SystemInstruction = &geminiContent{Role: "user", Parts: systemParts}
			}
			body, _ = json.Marshal(gemReq)
		} else if isAnthropic {
			var systemPrompt string
			anthropicMsgs := make([]Message, 0, len(messages))
			for _, m := range messages {
				if m.Role == "system" {
					systemPrompt = m.Content
				} else {
					anthropicMsgs = append(anthropicMsgs, m)
				}
			}
			maxTokens := 8192
			anReq := anthropicRequest{
				Model:     model,
				Messages:  anthropicMsgs,
				System:    systemPrompt,
				MaxTokens: maxTokens,
				Stream:    true,
			}
			body, _ = json.Marshal(anReq)
		} else {
			reqBody := chatRequest{
				Model:         model,
				Messages:      messages,
				Stream:        true,
				StreamOptions: &streamOptions{IncludeUsage: true},
				MaxTokens:     c.maxTokens(),
			}
			body, _ = json.Marshal(reqBody)
		}

		reqCtx := c.loadCtx()
		req, err := http.NewRequestWithContext(reqCtx, http.MethodPost, endpoint, bytes.NewReader(body))
		if err != nil {
			ch <- StreamChunk{Err: err}
			return
		}

		req.Header.Set("Content-Type", "application/json")
		if isGoogle {
			if c.cfg.APIKey != "" {
				req.Header.Set("x-goog-api-key", c.cfg.APIKey)
			}
		} else if isAnthropic && c.cfg.APIKey != "" {
			req.Header.Set("x-api-key", c.cfg.APIKey)
			req.Header.Set("anthropic-version", "2023-06-01")
		} else if c.cfg.APIKey != "" {
			req.Header.Set("Authorization", "Bearer "+c.cfg.APIKey)
		}

		resp, err := c.httpClient.Do(req)
		if err != nil {
			ch <- StreamChunk{Err: fmt.Errorf("request failed: %w", err)}
			return
		}
		defer resp.Body.Close()

		if resp.StatusCode != http.StatusOK {
			respBody, readErr := io.ReadAll(resp.Body)
			if readErr != nil {
				ch <- StreamChunk{Err: fmt.Errorf("API returned %d (failed to read body: %v)", resp.StatusCode, readErr)}
				return
			}
			ch <- StreamChunk{Err: fmt.Errorf("API returned %d: %s", resp.StatusCode, string(respBody))}
			return
		}

		scanner := bufio.NewScanner(resp.Body)
		buf := make([]byte, 0, 64*1024)
		scanner.Buffer(buf, 1024*1024)

		if isAnthropic {
			// Anthropic SSE: each line is "event: TYPE" followed by "data: JSON"
			var currentEvent string
			var anResp anthropicResponse
			for scanner.Scan() {
				line := scanner.Text()
				line = strings.TrimSpace(line)
				if line == "" {
					continue
				}
				if ev, ok := strings.CutPrefix(line, "event: "); ok {
					currentEvent = ev
					continue
				}
				data, ok := strings.CutPrefix(line, "data: ")
				if !ok {
					continue
				}
				data = strings.TrimSpace(data)

				if err := json.Unmarshal([]byte(data), &anResp); err != nil {
					continue
				}

				switch currentEvent {
				case "message_start":
					c.mu.Lock()
					c.totalIn += anResp.Message.Usage.InputTokens
					c.totalOut += anResp.Message.Usage.OutputTokens
					c.mu.Unlock()
				case "content_block_delta":
					if anResp.Delta.Text != "" {
						ch <- StreamChunk{Content: anResp.Delta.Text}
					}
				case "message_delta":
					// Final usage update if present
				case "message_stop":
					ch <- StreamChunk{Done: true}
					return
				}
			}
			ch <- StreamChunk{Done: true}
			return
		}

		// OpenAI/Google streaming: "data: JSON" lines
		for scanner.Scan() {
			line := scanner.Text()
			if !strings.HasPrefix(line, "data: ") {
				continue
			}

			data := strings.TrimPrefix(line, "data: ")
			if data == "[DONE]" {
				ch <- StreamChunk{Done: true}
				return
			}

			if isGoogle {
				var gemResp geminiStreamResponse
				if err := json.Unmarshal([]byte(data), &gemResp); err != nil {
					continue
				}
				if len(gemResp.Candidates) > 0 && len(gemResp.Candidates[0].Content.Parts) > 0 {
					content := gemResp.Candidates[0].Content.Parts[0].Text
					if content != "" {
						ch <- StreamChunk{Content: content}
					}
				}
			} else {
				var sseResp chatResponse
				if err := json.Unmarshal([]byte(data), &sseResp); err != nil {
					continue
				}
				if sseResp.Usage != nil {
					c.mu.Lock()
					c.totalIn += sseResp.Usage.PromptTokens
					c.totalOut += sseResp.Usage.CompletionTokens
					c.mu.Unlock()
				}
				if len(sseResp.Choices) > 0 {
					content := sseResp.Choices[0].Delta.Content
					if content != "" {
						ch <- StreamChunk{Content: content}
					}
				}
			}
		}

		ch <- StreamChunk{Done: true}
	}()

	return ch
}

// doChat performs a single non-streaming API call. Thin wrapper around
// doChatWithMeta that discards the response metadata. Kept on the type
// for backwards compatibility with internal tests that exercise the
// single-shot path.
func (c *Client) doChat(messages []Message) (string, error) {
	content, _, err := c.doChatWithMeta(messages)
	return content, err
}

// doChatWithMeta performs a single non-streaming API call and returns the
// response together with the metadata (StopReason etc.) the caller needs
// to detect truncation.
func (c *Client) doChatWithMeta(messages []Message) (string, ChatMeta, error) {
	endpoint, model := c.resolveEndpoint()
	log.Printf("[llm] Request → URL=%s model=%s apiModel=%s cfgLLM=%s cfgAPIBase=%s", endpoint, model, c.apiModel, c.cfg.LLM, c.cfg.APIBase)

	isGoogle := c.usesGeminiAPI(endpoint)
	isAnthropic := c.usesAnthropicAPI(endpoint)

	var body []byte
	var err error
	if isGoogle {
		// Google Gemini: extract system messages, convert roles
		var systemParts []geminiPart
		contents := make([]geminiContent, 0, len(messages))
		for _, m := range messages {
			if m.Role == "system" {
				systemParts = append(systemParts, geminiPart{Text: m.Content})
			} else {
				role := m.Role
				if role == "assistant" {
					role = "model"
				}
				contents = append(contents, geminiContent{Role: role, Parts: []geminiPart{{Text: m.Content}}})
			}
		}
		gemReq := geminiRequest{Contents: contents}
		if len(systemParts) > 0 {
			gemReq.SystemInstruction = &geminiContent{Role: "user", Parts: systemParts}
		}
		body, err = json.Marshal(gemReq)
		if err != nil {
			return "", ChatMeta{}, fmt.Errorf("failed to marshal Gemini request: %w", err)
		}
	} else if isAnthropic {
		// Anthropic: system as top-level field, max_tokens required
		var systemPrompt string
		anthropicMsgs := make([]Message, 0, len(messages))
		for _, m := range messages {
			if m.Role == "system" {
				systemPrompt = m.Content
			} else {
				anthropicMsgs = append(anthropicMsgs, m)
			}
		}
		// Default max_tokens; Anthropic requires this field
		maxTokens := 8192
		anReq := anthropicRequest{
			Model:     model,
			Messages:  anthropicMsgs,
			System:    systemPrompt,
			MaxTokens: maxTokens,
			Stream:    false,
		}
		body, err = json.Marshal(anReq)
		if err != nil {
			return "", ChatMeta{}, fmt.Errorf("failed to marshal Anthropic request: %w", err)
		}
	} else {
		// Mirror the Anthropic native path: explicitly set max_tokens so we
		// don't depend on the upstream gateway's default. Bedrock's OpenAI-
		// compat shim defaults to a value low enough that Claude extended
		// thinking can consume the entire budget on long prompts and return
		// content="" — surfaced to the agent as the "(x/12) empty response"
		// warning. cfg.LLMMaxTokens is overridable via XALGORIX_LLM_MAX_TOKENS.
		reqBody := chatRequest{
			Model:     model,
			Messages:  messages,
			Stream:    false,
			MaxTokens: c.maxTokens(),
		}
		body, err = json.Marshal(reqBody)
		if err != nil {
			return "", ChatMeta{}, fmt.Errorf("failed to marshal request: %w", err)
		}
	}

	reqCtx := c.loadCtx()
	req, err := http.NewRequestWithContext(reqCtx, http.MethodPost, endpoint, bytes.NewReader(body))
	if err != nil {
		return "", ChatMeta{}, err
	}

	req.Header.Set("Content-Type", "application/json")
	if isGoogle {
		if c.cfg.APIKey != "" {
			req.Header.Set("x-goog-api-key", c.cfg.APIKey)
		}
	} else if isAnthropic && c.cfg.APIKey != "" {
		req.Header.Set("x-api-key", c.cfg.APIKey)
		req.Header.Set("anthropic-version", "2023-06-01")
	} else if c.cfg.APIKey != "" {
		req.Header.Set("Authorization", "Bearer "+c.cfg.APIKey)
	}

	resp, err := c.httpClient.Do(req)
	if err != nil {
		return "", ChatMeta{}, fmt.Errorf("request failed: %w", err)
	}
	defer resp.Body.Close()

	respBody, err := io.ReadAll(resp.Body)
	if err != nil {
		return "", ChatMeta{}, fmt.Errorf("failed to read response body: %w", err)
	}
	if resp.StatusCode != http.StatusOK {
		return "", ChatMeta{}, fmt.Errorf("API returned %d: %s", resp.StatusCode, string(respBody))
	}

	if isGoogle {
		var gemResp geminiResponse
		if err := json.Unmarshal(respBody, &gemResp); err != nil {
			return "", ChatMeta{}, fmt.Errorf("failed to parse Gemini response: %w", err)
		}
		if len(gemResp.Candidates) == 0 || len(gemResp.Candidates[0].Content.Parts) == 0 {
			return "", ChatMeta{}, fmt.Errorf("no content in Gemini response")
		}
		meta := ChatMeta{StopReason: gemResp.Candidates[0].FinishReason}
		return gemResp.Candidates[0].Content.Parts[0].Text, meta, nil
	}

	if isAnthropic {
		var anResp anthropicResponse
		if err := json.Unmarshal(respBody, &anResp); err != nil {
			return "", ChatMeta{}, fmt.Errorf("failed to parse Anthropic response: %w", err)
		}
		// Track token usage
		c.mu.Lock()
		c.totalIn += anResp.Message.Usage.InputTokens
		c.totalOut += anResp.Message.Usage.OutputTokens
		c.mu.Unlock()
		meta := ChatMeta{
			StopReason:   anResp.Message.StopReason,
			OutputTokens: anResp.Message.Usage.OutputTokens,
		}
		// Extract text from content blocks
		for _, block := range anResp.Message.Content {
			if block.Type == "text" && block.Text != "" {
				return block.Text, meta, nil
			}
		}
		return "", meta, fmt.Errorf("no text content in Anthropic response")
	}

	var chatResp chatResponse
	if err := json.Unmarshal(respBody, &chatResp); err != nil {
		return "", ChatMeta{}, fmt.Errorf("failed to parse response: %w", err)
	}
	if len(chatResp.Choices) == 0 {
		return "", ChatMeta{}, fmt.Errorf("no choices in response")
	}
	if chatResp.Usage != nil {
		c.mu.Lock()
		c.totalIn += chatResp.Usage.PromptTokens
		c.totalOut += chatResp.Usage.CompletionTokens
		c.mu.Unlock()
	}
	meta := ChatMeta{StopReason: chatResp.Choices[0].FinishReason}
	if chatResp.Usage != nil {
		meta.OutputTokens = chatResp.Usage.CompletionTokens
	}
	return chatResp.Choices[0].Message.Content, meta, nil
}
