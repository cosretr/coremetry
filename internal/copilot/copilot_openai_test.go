package copilot

import (
	"context"
	"io"
	"net/http"
	"net/http/httptest"
	"strings"
	"testing"

	"github.com/cilcenk/coremetry/internal/ai/provider"
)

// v0.8.x — the OpenAI-compatible Explain path didn't handle local reasoning
// models (Qwen3, deepseek-r1, …): they put the answer in reasoning_content
// and/or inline a <think>…</think> block, and the fixed max_tokens=1024 budget
// often filled mid-thought (finish_reason "length", empty content). The empty
// explanation was then swallowed by the frontend's `{text && …}` guard, so the
// user saw neither answer nor error. These tests pin the fix end-to-end on the
// real explain path (white-box, httptest-backed — New/Configure as in
// production, not mocked). Faz 1.2'den beri o yol s.explainOpenAI →
// internal/ai/provider.DoOpenAI; testler UÇTAN UCA kaldı, yani taşıma
// zincirin herhangi bir halkasını düşürseydi burada patlardı.

// newOpenAITestService wires a Service at an httptest server returning the given
// OpenAI-compatible JSON body, using the real constructor + Configure.
func newOpenAITestService(t *testing.T, responseBody string) (*Service, func()) {
	t.Helper()
	srv := httptest.NewServer(http.HandlerFunc(func(w http.ResponseWriter, _ *http.Request) {
		w.Header().Set("Content-Type", "application/json")
		_, _ = w.Write([]byte(responseBody))
	}))
	s := New("openai", "", "test-model")
	s.Configure("openai", "", "test-model", srv.URL, false, true)
	return s, srv.Close
}

// NOT: TestStripThinking Faz 1.2'de bu dosyadan kalktı — fonksiyonun
// kendisi internal/ai/provider'a taşındı ve tablosu orada
// TestStripThinkingAndThinkingContent olarak (ThinkingContent ile
// birlikte, aynı vakalarla) yaşıyor. Buradaki testler artık zinciri
// UÇTAN UCA, gerçek Explain yolundan doğruluyor — asıl değeri de o.

func TestExplainOpenAIReasoningContentFallback(t *testing.T) {
	// content empty, answer lives in reasoning_content.
	body := `{"choices":[{"message":{"content":"","reasoning_content":"answer from reasoning field"},"finish_reason":"stop"}],"usage":{"prompt_tokens":5,"completion_tokens":7}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, pt, ct, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err != nil {
		t.Fatalf("unexpected error: %v", err)
	}
	// ⚠ v0.10.66 — content HİÇ gelmediğinde dönen metin modelin ÇALIŞMA
	// NOTUDUR ve artık İŞARETLİ çıkıyor (provider.MarkSalvagedThinking).
	// v0.10.37 yalnız <think> dalını işaretliyordu; fark tamamen
	// TAŞIYICIDAN geliyordu. Sözleşme: gövde korunur, işaret eklenir.
	if !strings.Contains(out, "answer from reasoning field") {
		t.Fatalf("out = %q; want the reasoning_content fallback", out)
	}
	if pt != 5 || ct != 7 {
		t.Fatalf("usage = (%d,%d); want (5,7)", pt, ct)
	}
}

func TestExplainOpenAIStripsThinkBlock(t *testing.T) {
	// content = "<think>…</think>answer" → just the answer.
	body := `{"choices":[{"message":{"content":"<think>pondering the trace</think>real answer"},"finish_reason":"stop"}],"usage":{"prompt_tokens":3,"completion_tokens":4}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, _, _, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err != nil {
		t.Fatalf("unexpected error: %v", err)
	}
	if out != "real answer" {
		t.Fatalf("out = %q; want \"real answer\" (think block stripped)", out)
	}
}

func TestExplainOpenAILengthBudgetError(t *testing.T) {
	// content empty + finish_reason "length" → explanatory budget error.
	body := `{"choices":[{"message":{"content":""},"finish_reason":"length"}],"usage":{"prompt_tokens":9,"completion_tokens":4096}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, _, _, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err == nil {
		t.Fatalf("expected an error for empty content + finish_reason length; got out=%q", out)
	}
	msg := strings.ToLower(err.Error())
	if !strings.Contains(msg, "budget") && !strings.Contains(msg, "max_tokens") {
		t.Fatalf("error %q should mention the token budget / max_tokens", err.Error())
	}
}

func TestExplainOpenAINormalContent(t *testing.T) {
	// plain content returned verbatim, usage parsed.
	body := `{"choices":[{"message":{"content":"plain answer"},"finish_reason":"stop"}],"usage":{"prompt_tokens":11,"completion_tokens":22}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, pt, ct, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err != nil {
		t.Fatalf("unexpected error: %v", err)
	}
	if out != "plain answer" {
		t.Fatalf("out = %q; want \"plain answer\"", out)
	}
	if pt != 11 || ct != 22 {
		t.Fatalf("usage = (%d,%d); want (11,22)", pt, ct)
	}
}

// v0.8.x — operator-reported: a local reasoning model returned "model returned
// empty content" 500s on both chat + explain-trace. Cause: the model emitted
// ONLY a <think> block (no post-</think> answer) or used the `reasoning` field.
// These pin the salvage so the answer is recovered instead of failing.
func TestExplainOpenAISalvagesThinkOnlyContent(t *testing.T) {
	// content = "<think>…the answer…</think>" with NOTHING after the close tag.
	body := `{"choices":[{"message":{"content":"<think>The checkout span is slow due to an Oracle row lock.</think>"},"finish_reason":"stop"}],"usage":{"prompt_tokens":3,"completion_tokens":4}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, _, _, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err != nil {
		t.Fatalf("unexpected error: %v", err)
	}
	// v0.10.37 — kurtarma AYNEN çalışıyor (testin niyeti) ama artık
	// İŞARETLİ: kurtarılan düşünce nihai cevaptan ayırt edilebilmeli.
	const wantBody = "The checkout span is slow due to an Oracle row lock."
	if !strings.Contains(out, wantBody) {
		t.Fatalf("out = %q; kurtarılan reasoning metni bekleniyordu", out)
	}
	if !provider.IsSalvagedThinking(out) {
		t.Fatalf("kurtarılan düşünce İŞARETSİZ — operatör nihai cevap sanar: %q", out)
	}
}

func TestExplainOpenAIReasoningFieldFallback(t *testing.T) {
	// content empty, answer in the `reasoning` field (not reasoning_content).
	body := `{"choices":[{"message":{"content":"","reasoning":"answer from the reasoning field"},"finish_reason":"stop"}],"usage":{"prompt_tokens":5,"completion_tokens":7}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, _, _, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err != nil {
		t.Fatalf("unexpected error: %v", err)
	}
	// v0.10.66 — kardeş testle aynı gerekçe: content hiç gelmedi, dönen
	// metin çalışma notu ve işaretli çıkıyor.
	if !strings.Contains(out, "answer from the reasoning field") {
		t.Fatalf("out = %q; want the reasoning-field fallback", out)
	}
}

func TestExplainOpenAITrulyEmptyStillErrors(t *testing.T) {
	// genuinely nothing anywhere → still a clear error (with the diagnostic hint).
	body := `{"choices":[{"message":{"content":""},"finish_reason":"stop"}],"usage":{"prompt_tokens":1,"completion_tokens":0}}`
	s, done := newOpenAITestService(t, body)
	defer done()
	out, _, _, err := s.explainOpenAI(context.Background(), "sys", "user")
	if err == nil {
		t.Fatalf("expected an error for genuinely empty content; got out=%q", out)
	}
	if !strings.Contains(strings.ToLower(err.Error()), "empty content") {
		t.Fatalf("error %q should mention empty content", err.Error())
	}
}

// v0.8.373 — operator-reported: chat tool-calling against Gemini's
// OpenAI-compat endpoint failed on the SECOND turn with 400
// "Function call is missing a thought_signature in functionCall
// parts". The parser kept only id/name/arguments, so provider extras
// (extra_content → thought_signature) were dropped and the replayed
// assistant tool_call no longer matched what the model emitted. The
// fix captures each tool_call's raw JSON and replays it verbatim.
func TestChatOpenAIToolCallRawPreserved(t *testing.T) {
	const geminiStyle = `{"choices":[{"message":{"content":"",` +
		`"tool_calls":[{"id":"call_1","type":"function",` +
		`"function":{"name":"list_problems","arguments":"{\"status\":\"open\"}"},` +
		`"extra_content":{"google":{"thought_signature":"SIG-XYZ"}}}]}}],` +
		`"usage":{"prompt_tokens":10,"completion_tokens":5}}`

	// Turn 1: parse — the raw object must be captured alongside the
	// trimmed executor view.
	var sentBodies []string
	srv := httptest.NewServer(http.HandlerFunc(func(w http.ResponseWriter, r *http.Request) {
		b := new(strings.Builder)
		_, _ = io.Copy(b, r.Body)
		sentBodies = append(sentBodies, b.String())
		w.Header().Set("Content-Type", "application/json")
		_, _ = w.Write([]byte(geminiStyle))
	}))
	defer srv.Close()
	s := New("openai", "", "test-model")
	s.Configure("openai", "", "test-model", srv.URL, false, true)

	turn, err := s.chatOpenAIWithTools(context.Background(), "sys",
		[]ChatMessage{{Role: "user", Text: "Show me errors in the last hour"}}, nil)
	if err != nil {
		t.Fatalf("turn 1: %v", err)
	}
	if len(turn.ToolCalls) != 1 || turn.ToolCalls[0].Name != "list_problems" ||
		turn.ToolCalls[0].ID != "call_1" || string(turn.ToolCalls[0].Input) != `{"status":"open"}` {
		t.Fatalf("executor view broken: %+v", turn.ToolCalls)
	}
	if !strings.Contains(string(turn.ToolCalls[0].Raw), "SIG-XYZ") {
		t.Fatalf("raw tool_call lost the provider extras: %s", turn.ToolCalls[0].Raw)
	}

	// Turn 2: replay — the request body must carry the tool_call
	// verbatim, thought_signature included.
	msgs := []ChatMessage{
		{Role: "user", Text: "Show me errors in the last hour"},
		{Role: "assistant", ToolCalls: turn.ToolCalls},
		{Role: "user", ToolResults: []ToolResult{{CallID: "call_1", Name: "list_problems", Content: `{"problems":[]}`}}},
	}
	if _, err := s.chatOpenAIWithTools(context.Background(), "sys", msgs, nil); err != nil {
		t.Fatalf("turn 2: %v", err)
	}
	replay := sentBodies[len(sentBodies)-1]
	if !strings.Contains(replay, "thought_signature") || !strings.Contains(replay, "SIG-XYZ") {
		t.Fatalf("replayed body dropped thought_signature:\n%s", replay)
	}
	if !strings.Contains(replay, `"tool_call_id":"call_1"`) {
		t.Fatalf("tool result lost its call id:\n%s", replay)
	}

	// Legacy fallback: a ToolCall without Raw still reconstructs the
	// OpenAI shape instead of sending nothing.
	legacy := []ChatMessage{
		{Role: "user", Text: "q"},
		{Role: "assistant", ToolCalls: []ToolCall{{ID: "c9", Name: "list_problems", Input: []byte(`{}`)}}},
		{Role: "user", ToolResults: []ToolResult{{CallID: "c9", Name: "list_problems", Content: `{}`}}},
	}
	if _, err := s.chatOpenAIWithTools(context.Background(), "sys", legacy, nil); err != nil {
		t.Fatalf("legacy turn: %v", err)
	}
	if last := sentBodies[len(sentBodies)-1]; !strings.Contains(last, `"name":"list_problems"`) || !strings.Contains(last, `"id":"c9"`) {
		t.Fatalf("legacy reconstruction broken:\n%s", last)
	}
}

// v0.8.384 — operator's air-gapped local LLM (vLLM 0.24 behind a
// KServe-style gateway): (1) the gateway authenticates on a bare
// `api-key` header, not Authorization: Bearer; (2) the model returns
// content:null with the whole answer in the `reasoning` field. Chat
// used to come back empty on both counts.
func TestChatOpenAIVLLMReasoningAndAPIKeyHeader(t *testing.T) {
	const vllmStyle = `{"choices":[{"message":{"role":"assistant","content":null,` +
		`"reasoning":"Merhaba! Size nasıl yardımcı olabilirim?"},"finish_reason":"stop"}],` +
		`"usage":{"prompt_tokens":14,"completion_tokens":10}}`

	var gotAuth, gotAPIKey string
	srv := httptest.NewServer(http.HandlerFunc(func(w http.ResponseWriter, r *http.Request) {
		gotAuth = r.Header.Get("Authorization")
		gotAPIKey = r.Header.Get("api-key")
		w.Header().Set("Content-Type", "application/json")
		_, _ = w.Write([]byte(vllmStyle))
	}))
	defer srv.Close()
	s := New("openai", "sekret", "qwen-local")
	s.Configure("openai", "sekret", "qwen-local", srv.URL, false, true)

	turn, err := s.chatOpenAIWithTools(context.Background(), "sys",
		[]ChatMessage{{Role: "user", Text: "Merhaba"}}, nil)
	if err != nil {
		t.Fatalf("chat: %v", err)
	}
	// Kurtarılan düşünce kanalı işaretli döner (salvage.go v0.10.66 —
	// explain yoluyla aynı kural; araç döngüsü de artık işaretliyor).
	if turn.Text != provider.SalvagedThinkingPrefix+"Merhaba! Size nasıl yardımcı olabilirim?" {
		t.Fatalf("reasoning fallback missed: %q", turn.Text)
	}
	if gotAuth != "Bearer sekret" || gotAPIKey != "sekret" {
		t.Fatalf("headers: Authorization=%q api-key=%q — both must carry the key", gotAuth, gotAPIKey)
	}

	// A tool-call turn with empty content must NOT get reasoning text
	// glued on (empty content is legitimate there).
	const toolStyle = `{"choices":[{"message":{"content":null,"reasoning":"thinking...",` +
		`"tool_calls":[{"id":"c1","type":"function","function":{"name":"list_problems","arguments":"{}"}}]}}],` +
		`"usage":{"prompt_tokens":1,"completion_tokens":1}}`
	srv2 := httptest.NewServer(http.HandlerFunc(func(w http.ResponseWriter, _ *http.Request) {
		w.Header().Set("Content-Type", "application/json")
		_, _ = w.Write([]byte(toolStyle))
	}))
	defer srv2.Close()
	s2 := New("openai", "", "m")
	s2.Configure("openai", "", "m", srv2.URL, false, true)
	turn2, err := s2.chatOpenAIWithTools(context.Background(), "sys",
		[]ChatMessage{{Role: "user", Text: "q"}}, nil)
	if err != nil {
		t.Fatalf("tool turn: %v", err)
	}
	if turn2.Text != "" || len(turn2.ToolCalls) != 1 {
		t.Fatalf("tool turn contaminated: text=%q calls=%d", turn2.Text, len(turn2.ToolCalls))
	}
}
