/*
Copyright 2026 The Faros Authors.

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
	"errors"
	"fmt"
	"net/http"
	"net/url"
	"strings"

	"cloud.google.com/go/auth/credentials"
	claudemodel "github.com/cloudwego/eino-ext/components/model/claude"
	geminimodel "github.com/cloudwego/eino-ext/components/model/gemini"
	openaimodel "github.com/cloudwego/eino-ext/components/model/openai"
	einomodel "github.com/cloudwego/eino/components/model"
	"github.com/cloudwego/eino/schema"
	"google.golang.org/genai"
)

const defaultProjectLLMGoogleCloudLocation = "global"

const (
	// projectAssistantDefaultContextWindowTokens is the conservative context
	// window assumed for models App Studio does not recognise. Erring low means
	// the harness compacts a little earlier than strictly necessary, which is
	// safe; erring high risks provider context-overflow errors.
	projectAssistantDefaultContextWindowTokens = 128000
	// projectAssistantSummaryContextTokenFraction is the fraction of the model
	// context window at which conversation summarisation is triggered, leaving
	// headroom for the system prompt, tool schemas, and the model's own reply.
	projectAssistantSummaryContextTokenFraction = 0.6
	// projectAssistantSummaryContextTokenFloor keeps the trigger from collapsing
	// to a tiny value on models that report (or are mapped to) small windows.
	projectAssistantSummaryContextTokenFloor = 24000
	// projectAssistantSummaryContextTokenCap bounds how much raw conversation the
	// harness is willing to hold before summarising even on very large windows,
	// so a single turn does not send an unbounded prompt.
	projectAssistantSummaryContextTokenCap = 300000
)

// projectModelContextWindowTokens returns a conservative estimate of the input
// context window for the configured model, keyed by model family. It exists so
// the summarisation trigger scales with the model instead of a fixed 24k
// ceiling that discarded most of a modern window.
func projectModelContextWindowTokens(model string) int {
	m := strings.ToLower(strings.TrimSpace(model))
	if idx := strings.LastIndex(m, "/"); idx >= 0 {
		m = m[idx+1:]
	}
	switch {
	case m == "":
		return projectAssistantDefaultContextWindowTokens
	case strings.HasPrefix(m, "claude"):
		return 200000
	case strings.HasPrefix(m, "gpt-5"), strings.HasPrefix(m, "gpt5"):
		return 400000
	case strings.HasPrefix(m, "gpt-4.1"):
		return 1000000
	case strings.HasPrefix(m, "gpt-4o"), strings.HasPrefix(m, "gpt-4-turbo"):
		return 128000
	case strings.HasPrefix(m, "o1"), strings.HasPrefix(m, "o3"), strings.HasPrefix(m, "o4"):
		return 200000
	case strings.HasPrefix(m, "gemini-2"), strings.HasPrefix(m, "gemini-1.5"), strings.HasPrefix(m, "gemini-exp"):
		return 1000000
	case strings.HasPrefix(m, "gemini"):
		return 128000
	default:
		return projectAssistantDefaultContextWindowTokens
	}
}

// projectAssistantSummaryContextTokens returns the token count at which the
// conversation summarisation middleware should fire for the configured model.
func projectAssistantSummaryContextTokens(model string) int {
	window := projectModelContextWindowTokens(model)
	trigger := int(float64(window) * projectAssistantSummaryContextTokenFraction)
	if trigger < projectAssistantSummaryContextTokenFloor {
		trigger = projectAssistantSummaryContextTokenFloor
	}
	if trigger > projectAssistantSummaryContextTokenCap {
		trigger = projectAssistantSummaryContextTokenCap
	}
	return trigger
}

func newProjectEinoAssistantModelFactory(server *Server) projectEinoAssistantModelFactory {
	return func(ctx context.Context, req projectAssistantRunRequest, _ *projectEinoAssistantRunState) (einomodel.BaseChatModel, error) {
		if server == nil {
			return nil, errors.New("server is not configured")
		}
		model, err := newProjectEinoChatModel(ctx, req.LLM)
		if err != nil {
			return nil, err
		}
		return projectEinoWithRetries(model), nil
	}
}

func newProjectEinoChatModel(ctx context.Context, settings projectLLMSettings) (einomodel.BaseChatModel, error) {
	if err := normalizeProjectLLMSettings(&settings); err != nil {
		return nil, err
	}
	if strings.TrimSpace(settings.APIKey) == "" {
		return nil, errProjectLLMNotConfigured
	}
	switch strings.TrimSpace(settings.Provider) {
	case projectLLMProviderGoogle:
		return newProjectEinoGeminiChatModel(ctx, settings)
	case projectLLMProviderAnthropic:
		return newProjectEinoClaudeChatModel(ctx, settings)
	default:
		return newProjectEinoOpenAIChatModel(ctx, settings)
	}
}

// projectLLMProviderUsesAnthropicCaching reports whether the configured provider
// is Anthropic, whose prompt caching requires explicit cache breakpoints on the
// stable prompt prefix (system prompt + tool schemas). OpenAI and Gemini cache
// large prefixes automatically, so no per-message annotation is needed there.
func projectLLMProviderUsesAnthropicCaching(provider string) bool {
	return strings.EqualFold(strings.TrimSpace(provider), projectLLMProviderAnthropic)
}

func newProjectEinoClaudeChatModel(ctx context.Context, settings projectLLMSettings) (einomodel.BaseChatModel, error) {
	config := &claudemodel.Config{
		APIKey:     strings.TrimSpace(settings.APIKey),
		Model:      strings.TrimSpace(settings.Model),
		MaxTokens:  projectLLMAnthropicMaxTokens,
		HTTPClient: &http.Client{},
	}
	// Honour a custom Anthropic-compatible endpoint (proxy/gateway) when the
	// tenant configured one; the default Anthropic base URL is used otherwise.
	if base := strings.TrimRight(strings.TrimSpace(settings.BaseURL), "/"); base != "" && !isGenericOpenAIBaseURL(base) {
		config.BaseURL = &base
	}
	temperature := float32(0.2)
	config.Temperature = &temperature
	model, err := claudemodel.NewChatModel(ctx, config)
	if err != nil {
		return nil, fmt.Errorf("create native Eino Claude chat model: %w", err)
	}
	return model, nil
}

// projectAssistantApplyPromptCacheBreakpoints annotates the leading system
// messages with an Anthropic cache breakpoint so the stable prompt prefix (the
// large system prompt and reconstructed evidence block) is served from cache on
// subsequent turns. It is a no-op for non-Anthropic providers, whose SDKs
// ignore the message extra.
func projectAssistantApplyPromptCacheBreakpoints(provider string, messages []*schema.Message) {
	if !projectLLMProviderUsesAnthropicCaching(provider) || len(messages) == 0 {
		return
	}
	// Place the breakpoint on the FIRST system message, which is the stable
	// guardrail preamble. Anthropic caches the prefix up to and including the
	// breakpoint, so only content that is identical across turns is cached —
	// the per-turn project/profile/evidence system messages that follow are
	// intentionally left outside the cached prefix.
	for _, msg := range messages {
		if msg == nil {
			continue
		}
		if msg.Role == schema.System {
			claudemodel.SetMessageCacheControl(msg, nil)
			return
		}
		return
	}
}

func newProjectEinoOpenAIChatModel(ctx context.Context, settings projectLLMSettings) (einomodel.BaseChatModel, error) {
	config := &openaimodel.ChatModelConfig{
		APIKey:     strings.TrimSpace(settings.APIKey),
		BaseURL:    strings.TrimRight(strings.TrimSpace(settings.BaseURL), "/"),
		Model:      strings.TrimSpace(settings.Model),
		HTTPClient: &http.Client{},
	}
	// GPT-5 and the o-series reasoning models reject any temperature other than
	// the fixed default of 1, so only request a custom temperature when the
	// configured model supports it.
	if projectModelSupportsTemperature(settings.Model) {
		temperature := float32(0.2)
		config.Temperature = &temperature
	}
	model, err := openaimodel.NewChatModel(ctx, config)
	if err != nil {
		return nil, fmt.Errorf("create native Eino OpenAI chat model: %w", err)
	}
	return model, nil
}

// projectModelSupportsTemperature reports whether the given model accepts a
// custom sampling temperature. OpenAI's GPT-5 family and the o-series reasoning
// models (o1/o3/o4) fix temperature, top_p, and the penalties, and return an
// error if a non-default value is sent.
func projectModelSupportsTemperature(model string) bool {
	m := strings.ToLower(strings.TrimSpace(model))
	if m == "" {
		return true
	}
	// Drop any provider prefix such as "openai/".
	if idx := strings.LastIndex(m, "/"); idx >= 0 {
		m = m[idx+1:]
	}
	switch {
	case strings.HasPrefix(m, "gpt-5"), strings.HasPrefix(m, "gpt5"):
		return false
	case strings.HasPrefix(m, "o1"), strings.HasPrefix(m, "o3"), strings.HasPrefix(m, "o4"):
		return false
	}
	return true
}

// projectTemperatureOptions returns the per-call temperature option for the
// given model, or nil when the model does not accept a custom temperature.
func projectTemperatureOptions(model string, temperature float32) []einomodel.Option {
	if !projectModelSupportsTemperature(model) {
		return nil
	}
	return []einomodel.Option{einomodel.WithTemperature(temperature)}
}

func newProjectEinoGeminiChatModel(ctx context.Context, settings projectLLMSettings) (einomodel.BaseChatModel, error) {
	clientConfig, err := projectEinoGeminiClientConfig(settings)
	if err != nil {
		return nil, err
	}
	client, err := genai.NewClient(ctx, clientConfig)
	if err != nil {
		return nil, fmt.Errorf("create Google GenAI client: %w", err)
	}
	temperature := float32(0.2)
	model, err := geminimodel.NewChatModel(ctx, &geminimodel.Config{
		Client:      client,
		Model:       strings.TrimSpace(settings.Model),
		Temperature: &temperature,
	})
	if err != nil {
		return nil, fmt.Errorf("create native Eino Gemini chat model: %w", err)
	}
	return model, nil
}

func projectEinoGeminiClientConfig(settings projectLLMSettings) (*genai.ClientConfig, error) {
	apiKey := strings.TrimSpace(settings.APIKey)
	credential, usesServiceAccount, err := googleServiceAccountCredentialFromJSON(apiKey)
	if err != nil {
		return nil, err
	}
	httpOptions := projectEinoGeminiHTTPOptions(settings.BaseURL)
	if !usesServiceAccount {
		return &genai.ClientConfig{
			APIKey:      apiKey,
			Backend:     genai.BackendGeminiAPI,
			HTTPOptions: httpOptions,
		}, nil
	}
	authCredentials, err := credentials.DetectDefault(&credentials.DetectOptions{
		Scopes:          []string{projectLLMGoogleCloudScope},
		CredentialsJSON: []byte(apiKey),
	})
	if err != nil {
		return nil, fmt.Errorf("loading Google service-account JSON credential: %w", err)
	}
	return &genai.ClientConfig{
		Backend:     genai.BackendVertexAI,
		Project:     strings.TrimSpace(credential.ProjectID),
		Location:    projectEinoGoogleCloudLocation(settings.BaseURL),
		Credentials: authCredentials,
		HTTPOptions: httpOptions,
	}, nil
}

func projectEinoGeminiHTTPOptions(baseURL string) genai.HTTPOptions {
	nativeBaseURL := projectEinoGeminiNativeBaseURL(baseURL)
	if nativeBaseURL == "" {
		return genai.HTTPOptions{}
	}
	return genai.HTTPOptions{BaseURL: nativeBaseURL}
}

func projectEinoGeminiNativeBaseURL(baseURL string) string {
	baseURL = strings.TrimRight(strings.TrimSpace(baseURL), "/")
	if baseURL == "" {
		return ""
	}
	u, err := url.Parse(baseURL)
	if err != nil || u.Scheme == "" || u.Host == "" {
		return baseURL
	}
	host := strings.ToLower(u.Host)
	if host == "generativelanguage.googleapis.com" || strings.HasSuffix(host, ".generativelanguage.googleapis.com") {
		return u.Scheme + "://" + u.Host
	}
	if strings.Contains(host, "aiplatform.googleapis.com") {
		return u.Scheme + "://" + u.Host
	}
	return baseURL
}

func projectEinoGoogleCloudLocation(baseURL string) string {
	baseURL = strings.TrimSpace(baseURL)
	if baseURL != "" {
		if u, err := url.Parse(baseURL); err == nil {
			parts := strings.Split(strings.Trim(u.Path, "/"), "/")
			for i, part := range parts {
				if part == "locations" && i+1 < len(parts) && strings.TrimSpace(parts[i+1]) != "" {
					return strings.TrimSpace(parts[i+1])
				}
			}
			host := strings.ToLower(u.Host)
			if suffix := "-aiplatform.googleapis.com"; strings.HasSuffix(host, suffix) {
				location := strings.TrimSuffix(host, suffix)
				if strings.TrimSpace(location) != "" {
					return strings.TrimSpace(location)
				}
			}
		}
	}
	return defaultProjectLLMGoogleCloudLocation
}

func projectEinoMessagesToChat(messages []*schema.Message) []chatMessage {
	out := make([]chatMessage, 0, len(messages))
	for _, msg := range messages {
		if msg == nil {
			continue
		}
		out = append(out, chatMessage{
			Role:       string(msg.Role),
			Content:    msg.Content,
			Name:       msg.Name,
			ToolCallID: msg.ToolCallID,
			ToolCalls:  projectEinoToolCallsToChat(msg.ToolCalls),
		})
		if len(out) > 0 && msg.Role == schema.Tool && out[len(out)-1].Name == "" {
			out[len(out)-1].Name = msg.ToolName
		}
	}
	return out
}

func projectChatMessagesToEino(messages []chatMessage) ([]*schema.Message, error) {
	out := make([]*schema.Message, 0, len(messages))
	for _, msg := range messages {
		switch schema.RoleType(msg.Role) {
		case schema.System:
			out = append(out, schema.SystemMessage(msg.Content))
		case schema.User:
			out = append(out, schema.UserMessage(msg.Content))
		case schema.Assistant:
			out = append(out, schema.AssistantMessage(msg.Content, projectChatToolCallsToEino(msg.ToolCalls)))
		case schema.Tool:
			out = append(out, schema.ToolMessage(msg.Content, msg.ToolCallID, schema.WithToolName(msg.Name)))
		default:
			return nil, fmt.Errorf("unsupported assistant message role %q", msg.Role)
		}
	}
	return out, nil
}

func projectChatToolCallsToEino(toolCalls []chatToolCall) []schema.ToolCall {
	if len(toolCalls) == 0 {
		return nil
	}
	out := make([]schema.ToolCall, 0, len(toolCalls))
	for i, tc := range toolCalls {
		index := i
		extra := map[string]any(nil)
		if len(tc.ExtraContent) > 0 {
			extra = map[string]any{}
			for key, value := range tc.ExtraContent {
				extra[key] = value
			}
		}
		out = append(out, schema.ToolCall{
			Index: &index,
			ID:    tc.ID,
			Type:  projectEinoToolCallType(tc.Type),
			Function: schema.FunctionCall{
				Name:      tc.Function.Name,
				Arguments: tc.Function.Arguments,
			},
			Extra: extra,
		})
	}
	return out
}

func projectEinoToolCallsToChat(toolCalls []schema.ToolCall) []chatToolCall {
	if len(toolCalls) == 0 {
		return nil
	}
	out := make([]chatToolCall, 0, len(toolCalls))
	for _, tc := range toolCalls {
		extra := map[string]any(nil)
		if len(tc.Extra) > 0 {
			extra = map[string]any{}
			for key, value := range tc.Extra {
				extra[key] = value
			}
		}
		out = append(out, chatToolCall{
			ID:           tc.ID,
			Type:         projectEinoToolCallType(tc.Type),
			ExtraContent: extra,
			Function: chatToolCallFunction{
				Name:      tc.Function.Name,
				Arguments: tc.Function.Arguments,
			},
		})
	}
	return out
}

func projectEinoToolCallType(toolType string) string {
	toolType = strings.TrimSpace(toolType)
	if toolType == "" {
		return "function"
	}
	return toolType
}
