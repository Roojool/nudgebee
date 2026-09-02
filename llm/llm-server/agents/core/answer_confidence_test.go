package core

import (
	"strings"
	"testing"
	"time"

	"nudgebee/llm/config"
	"nudgebee/llm/security"

	"github.com/stretchr/testify/assert"
	"github.com/stretchr/testify/require"
)

// The grader's JSON is model-produced, so every degenerate shape has to degrade
// to nil rather than to a half-populated grade. A chip that says "high" because
// the level field was garbage is worse than no chip.
func TestParseAnswerConfidence(t *testing.T) {
	tests := []struct {
		name            string
		raw             string
		wantNil         bool
		wantLevel       string
		wantRationale   string
		wantLimitations []string
	}{
		{
			name:    "not json at all",
			raw:     "I think this answer is pretty good actually",
			wantNil: true,
		},
		{
			name:    "empty string",
			raw:     "",
			wantNil: true,
		},
		{
			name:    "valid json but no level",
			raw:     `{"rationale": "because"}`,
			wantNil: true,
		},
		{
			name:    "unrecognised level is dropped, not guessed",
			raw:     `{"level": "very high", "rationale": "r"}`,
			wantNil: true,
		},
		{
			name:    "numeric level is dropped (we do not accept percentages)",
			raw:     `{"level": "85%"}`,
			wantNil: true,
		},
		{
			name:      "level only",
			raw:       `{"level": "high"}`,
			wantLevel: ConfidenceLevelHigh,
		},
		{
			name:      "level is case- and whitespace-insensitive",
			raw:       `{"level": "  MEDIUM  "}`,
			wantLevel: ConfidenceLevelMedium,
		},
		{
			name: "full grade",
			raw: `{"level": "low",
			       "rationale": "Only the kubectl tool ran and it returned empty.",
			       "limitations": ["metrics tool returned empty", "no deploy correlation attempted"]}`,
			wantLevel:       ConfidenceLevelLow,
			wantRationale:   "Only the kubectl tool ran and it returned empty.",
			wantLimitations: []string{"metrics tool returned empty", "no deploy correlation attempted"},
		},
		{
			// Graders routinely wrap JSON in a markdown fence despite the
			// "ONLY this JSON object" instruction; ExtractAndUnmarshalJSON
			// handles it and we pin that here.
			name:      "fenced json",
			raw:       "```json\n{\"level\": \"medium\", \"rationale\": \"one source only\"}\n```",
			wantLevel: ConfidenceLevelMedium, wantRationale: "one source only",
		},
		{
			name:      "prose around the json",
			raw:       `Here is my grade: {"level": "high", "rationale": "two tools agree"} Hope that helps.`,
			wantLevel: ConfidenceLevelHigh, wantRationale: "two tools agree",
		},
		{
			name:            "blank and duplicate limitations are dropped",
			raw:             `{"level": "low", "limitations": ["  ", "same gap", "SAME GAP", "other"]}`,
			wantLevel:       ConfidenceLevelLow,
			wantLimitations: []string{"same gap", "other"},
		},
		{
			name:      "empty limitations array yields nil, not an empty slice",
			raw:       `{"level": "high", "limitations": []}`,
			wantLevel: ConfidenceLevelHigh,
		},
	}

	for _, tt := range tests {
		t.Run(tt.name, func(t *testing.T) {
			got := parseAnswerConfidence(tt.raw)
			if tt.wantNil {
				assert.Nil(t, got)
				return
			}
			require.NotNil(t, got)
			assert.Equal(t, tt.wantLevel, got.Level)
			assert.Equal(t, tt.wantRationale, got.Rationale)
			assert.Equal(t, tt.wantLimitations, got.Limitations)
		})
	}
}

// A grader that emits 40 gaps must not bloat the message metadata jsonb or the
// tooltip — the list is a glance surface, not an audit log.
func TestParseAnswerConfidence_CapsLimitations(t *testing.T) {
	items := make([]string, 0, 40)
	for i := range 40 {
		items = append(items, `"gap number `+string(rune('a'+i%26))+string(rune('a'+i/26))+`"`)
	}
	raw := `{"level": "low", "limitations": [` + strings.Join(items, ",") + `]}`

	got := parseAnswerConfidence(raw)
	require.NotNil(t, got)
	assert.Len(t, got.Limitations, maxConfidenceLimitations)
}

// Free-text fields are length-bounded so a runaway generation cannot blow up the
// metadata column. Truncation must not split a multi-byte rune.
func TestParseAnswerConfidence_TruncatesLongText(t *testing.T) {
	long := strings.Repeat("é", maxConfidenceTextLength) // 2 bytes per rune
	got := parseAnswerConfidence(`{"level": "low", "rationale": "` + long + `"}`)
	require.NotNil(t, got)
	assert.LessOrEqual(t, len(got.Rationale), maxConfidenceTextLength)
	assert.True(t, strings.HasPrefix(long, got.Rationale), "truncation must not split a rune")
}

// The manifest is the grader's only view of what actually ran, so its shape is
// load-bearing: distinct-tool count drives the "2+ independent sources" rule,
// and an empty manifest must read as "nothing was gathered" rather than as an
// absent section the grader can ignore.
func TestFormatExecutionManifest(t *testing.T) {
	t.Run("empty manifest is explicit, not blank", func(t *testing.T) {
		out := formatExecutionManifest(nil)
		assert.Contains(t, out, "no tools were executed")
	})

	t.Run("renders each outcome with status and call count", func(t *testing.T) {
		out := formatExecutionManifest([]ToolCallOutcome{
			{ToolName: "kubectl", Status: "success", Count: 3},
			{ToolName: "metrics", Status: "empty_result", Count: 1},
		})
		assert.Contains(t, out, "- kubectl: success (3 calls)")
		assert.Contains(t, out, "- metrics: empty_result (1 call)")
		assert.Contains(t, out, "Distinct tools used: 2")
	})

	t.Run("same tool under two statuses counts as ONE source", func(t *testing.T) {
		// The rubric's corroboration rule is about distinct sources; a tool that
		// partly succeeded and partly failed is still one source. Counting rows
		// here instead of names would silently inflate every grade.
		out := formatExecutionManifest([]ToolCallOutcome{
			{ToolName: "kubectl", Status: "success", Count: 2},
			{ToolName: "kubectl", Status: "fail", Count: 1},
		})
		assert.Contains(t, out, "Distinct tools used: 1")
	})

	t.Run("caps very long manifests", func(t *testing.T) {
		outcomes := make([]ToolCallOutcome, 0, 100)
		for i := range 100 {
			outcomes = append(outcomes, ToolCallOutcome{ToolName: "tool" + string(rune('a'+i%26)), Status: "success", Count: 1})
		}
		out := formatExecutionManifest(outcomes)
		assert.LessOrEqual(t, strings.Count(out, "\n- "), maxConfidenceManifestRows)
	})
}

// The gate decides whether we spend an LLM call at all. It must never fire on a
// plain retrieval turn, and must never fire without the identifiers the grader
// and the metadata write both need.
func TestShouldScoreAnswerConfidence(t *testing.T) {
	base := func() NBAgentRequest {
		return NBAgentRequest{MessageId: "msg-1", Query: "why is the checkout pod crashing?"}
	}

	t.Run("investigation query qualifies", func(t *testing.T) {
		assert.True(t, shouldScoreAnswerConfidence(base(), "root cause found"))
	})

	t.Run("plain retrieval does not", func(t *testing.T) {
		r := base()
		r.Query = "list all pods in the prod namespace"
		assert.False(t, shouldScoreAnswerConfidence(r, "here are your pods"))
	})

	t.Run("investigation source qualifies regardless of wording", func(t *testing.T) {
		r := base()
		r.Query = "list all pods in the prod namespace"
		r.ConversationSource = ConversationSourceInvestigation
		assert.True(t, shouldScoreAnswerConfidence(r, "here are your pods"))
	})

	t.Run("classifies on the top-level question, not a sub-agent brief", func(t *testing.T) {
		// OriginalQuery holds the user's verbatim ask; Query may have been
		// rewritten. Grading the rewrite would misclassify.
		r := base()
		r.OriginalQuery = "why did the deployment fail?"
		r.Query = "get pod list"
		assert.True(t, shouldScoreAnswerConfidence(r, "answer"))
	})

	t.Run("empty answer does not qualify", func(t *testing.T) {
		assert.False(t, shouldScoreAnswerConfidence(base(), "   "))
	})

	t.Run("missing message id does not qualify", func(t *testing.T) {
		r := base()
		r.MessageId = ""
		assert.False(t, shouldScoreAnswerConfidence(r, "answer"))
	})

	t.Run("empty question does not qualify", func(t *testing.T) {
		r := base()
		r.Query = ""
		assert.False(t, shouldScoreAnswerConfidence(r, "answer"))
	})
}

// The tenant gate decides whether a completed investigation turn spends an LLM
// call at all, so each precedence rule is pinned. Fail-closed is the through
// line: every uncertain path must resolve to false rather than silently billing
// a tenant that never opted in.
func TestAnswerConfidenceEnabledForTenant(t *testing.T) {
	const tenant = "11111111-1111-1111-1111-111111111111"

	restore := func(orig func(string, string) (bool, error)) func() {
		return func() { answerConfidenceFeatureCheck = orig }
	}
	origCheck := answerConfidenceFeatureCheck

	t.Run("enabled when the tenant has the flag", func(t *testing.T) {
		defer restore(origCheck)()
		answerConfidenceFeatureCheck = func(feature, tenantId string) (bool, error) {
			assert.Equal(t, FeatureAnswerConfidence, feature)
			assert.Equal(t, tenant, tenantId)
			return true, nil
		}
		assert.True(t, AnswerConfidenceEnabledForTenant(nil, tenant))
	})

	t.Run("disabled when the tenant has no flag row", func(t *testing.T) {
		defer restore(origCheck)()
		answerConfidenceFeatureCheck = func(string, string) (bool, error) { return false, nil }
		assert.False(t, AnswerConfidenceEnabledForTenant(nil, tenant))
	})

	t.Run("fails closed when the metastore is unreachable", func(t *testing.T) {
		// A DB error must not be read as "enabled" — that would bill every
		// tenant for a feature none of them opted into.
		defer restore(origCheck)()
		answerConfidenceFeatureCheck = func(string, string) (bool, error) {
			return false, assert.AnError
		}
		assert.False(t, AnswerConfidenceEnabledForTenant(nil, tenant))
	})

	t.Run("empty tenant is disabled without touching the database", func(t *testing.T) {
		defer restore(origCheck)()
		answerConfidenceFeatureCheck = func(string, string) (bool, error) {
			t.Fatal("an empty tenant must short-circuit before the flag is read")
			return true, nil
		}
		assert.False(t, AnswerConfidenceEnabledForTenant(nil, ""))
	})
}

// The tests below cover the async path itself rather than its helpers: which
// turns reach the grader, what it is handed, and how long it may take. They
// swap package-level seams and config, so they must not run in parallel.

// recordedGrade captures one grader invocation, including the deadline the
// task body was given.
type recordedGrade struct {
	messageID   string
	question    string
	answer      string
	remaining   time.Duration
	hasDeadline bool
	alreadyDone bool
}

// stubGraderAndFlag swaps the grader + tenant-flag seams for the test and
// returns the channel each invocation is reported on. Buffered so a duplicate
// invocation is recorded (and therefore detectable) rather than deadlocking.
func stubGraderAndFlag(t *testing.T, tenantEnabled bool) <-chan recordedGrade {
	t.Helper()
	origGrader, origFlag := scoreAnswerConfidenceFn, answerConfidenceFeatureCheck
	t.Cleanup(func() {
		scoreAnswerConfidenceFn, answerConfidenceFeatureCheck = origGrader, origFlag
	})

	answerConfidenceFeatureCheck = func(string, string) (bool, error) { return tenantEnabled, nil }

	calls := make(chan recordedGrade, 8)
	scoreAnswerConfidenceFn = func(ctx *security.RequestContext, _, _, _, messageId, question, answer string) error {
		deadline, ok := ctx.GetContext().Deadline()
		done := false
		select {
		case <-ctx.GetContext().Done():
			done = true
		default:
		}
		calls <- recordedGrade{
			messageID:   messageId,
			question:    question,
			answer:      answer,
			remaining:   time.Until(deadline),
			hasDeadline: ok,
			alreadyDone: done,
		}
		return nil
	}
	return calls
}

// eligibleConfidenceRequest is an investigation turn that has already been
// through a followup: OriginalQuery holds the real question, Query holds the
// user's answer to the confirmation prompt.
func eligibleConfidenceRequest() NBAgentRequest {
	return NBAgentRequest{
		MessageId:      "msg-under-test",
		AccountId:      "acct-under-test",
		ConversationId: "conv-under-test",
		OriginalQuery:  "why is the checkout pod crashing?",
		Query:          "yes",
	}
}

func tenantRequestContext() *security.RequestContext {
	return security.NewRequestContextForTenantAccountAdmin(
		"22222222-2222-2222-2222-222222222222", "user-under-test", []string{"acct-under-test"})
}

// The grading task contains an LLM round-trip, so its deadline must come from
// the confidence knob and never from AsyncOperationTimeoutSeconds — the
// worker-pool admission budget, which is 5s by default and is shared by every
// other async caller. Reverting the task body to
// context.WithTimeout(..., AsyncOperationTimeoutSeconds ...) fails this test.
//
// Deterministic: it reads the deadline the grader was actually handed and
// compares it against the configured value, with no sleeping.
func TestScoreAnswerConfidenceAsync_TaskDeadlineComesFromConfidenceKnob(t *testing.T) {
	origAdmission := config.Config.AsyncOperationTimeoutSeconds
	origTask := config.Config.AnswerConfidenceTaskTimeoutSeconds
	t.Cleanup(func() {
		config.Config.AsyncOperationTimeoutSeconds = origAdmission
		config.Config.AnswerConfidenceTaskTimeoutSeconds = origTask
	})

	// Distinctive, mutually unrelated values: the observed deadline can only
	// match one of them, so which knob is in force is unambiguous.
	cases := []struct{ admission, task int }{
		{admission: 1, task: 137},
		{admission: 1, task: 43},
		{admission: 90, task: 137}, // admission moved, deadline must not follow
	}

	for _, tc := range cases {
		config.Config.AsyncOperationTimeoutSeconds = tc.admission
		config.Config.AnswerConfidenceTaskTimeoutSeconds = tc.task
		calls := stubGraderAndFlag(t, true)

		ScoreAnswerConfidenceAsync(tenantRequestContext(), eligibleConfidenceRequest(), "root cause found")

		select {
		case got := <-calls:
			require.True(t, got.hasDeadline, "the task body must stay bounded")
			require.False(t, got.alreadyDone, "the task must not start already cancelled")
			// Tight on purpose: only goroutine scheduling separates creating the
			// deadline from reading it, so anything approaching a second means
			// the deadline is not the one we think it is.
			assert.InDelta(t, float64(tc.task), got.remaining.Seconds(), 1,
				"deadline must track AnswerConfidenceTaskTimeoutSeconds (%ds)", tc.task)
			assert.Greater(t, got.remaining.Seconds(), float64(tc.admission),
				"deadline must not be the admission budget (%ds)", tc.admission)
		case <-time.After(10 * time.Second):
			t.Fatalf("grader was never invoked (admission=%ds task=%ds)", tc.admission, tc.task)
		}
	}
}

// An unset or nonsensical knob must fall back to the documented default rather
// than produce a zero/immediately-expired deadline.
func TestScoreAnswerConfidenceAsync_TaskDeadlineFallsBackToDefault(t *testing.T) {
	origTask := config.Config.AnswerConfidenceTaskTimeoutSeconds
	t.Cleanup(func() { config.Config.AnswerConfidenceTaskTimeoutSeconds = origTask })

	for _, unset := range []int{0, -1} {
		config.Config.AnswerConfidenceTaskTimeoutSeconds = unset
		calls := stubGraderAndFlag(t, true)

		ScoreAnswerConfidenceAsync(tenantRequestContext(), eligibleConfidenceRequest(), "root cause found")

		select {
		case got := <-calls:
			require.True(t, got.hasDeadline)
			require.False(t, got.alreadyDone, "a <=0 knob must not yield an expired context")
			assert.InDelta(t, float64(answerConfidenceDefaultTaskTimeoutSeconds), got.remaining.Seconds(), 1)
		case <-time.After(10 * time.Second):
			t.Fatalf("grader was never invoked for knob value %d", unset)
		}
	}
}

// The grader must be handed the user's real question. On a followup resume
// request.Query is the confirmation answer, so grading on it would both
// misclassify the turn and ask the model to grade an answer against "yes".
func TestScoreAnswerConfidenceAsync_GradesOriginalQuestionNotFollowupAnswer(t *testing.T) {
	calls := stubGraderAndFlag(t, true)
	req := eligibleConfidenceRequest()

	ScoreAnswerConfidenceAsync(tenantRequestContext(), req, "root cause found")

	select {
	case got := <-calls:
		assert.Equal(t, req.OriginalQuery, got.question)
		assert.NotEqual(t, req.Query, got.question, `must not grade against the followup answer ("yes")`)
		assert.Equal(t, req.MessageId, got.messageID, "the grade must land on the generation message")
		assert.Equal(t, "root cause found", got.answer)
	case <-time.After(10 * time.Second):
		t.Fatal("grader was never invoked")
	}

	// Exactly once — a second submission would double-bill the tenant and
	// race two writers onto the same metadata key.
	select {
	case extra := <-calls:
		t.Fatalf("grader invoked more than once (second call on %s)", extra.messageID)
	case <-time.After(750 * time.Millisecond):
	}
}

// Ineligible turns must never reach the grader: each of these would otherwise
// spend an LLM call on something with nothing to grade.
func TestScoreAnswerConfidenceAsync_SkipsIneligibleTurns(t *testing.T) {
	cases := []struct {
		name          string
		tenantEnabled bool
		ctx           *security.RequestContext
		mutate        func(*NBAgentRequest)
		answer        string
	}{
		{
			name:          "tenant has not enabled the feature",
			tenantEnabled: false,
			ctx:           tenantRequestContext(),
			answer:        "root cause found",
		},
		{
			name:          "plain retrieval, not an investigation",
			tenantEnabled: true,
			ctx:           tenantRequestContext(),
			mutate:        func(r *NBAgentRequest) { r.OriginalQuery = "list all pods in the prod namespace" },
			answer:        "here are your pods",
		},
		{
			name:          "empty answer has nothing to grade",
			tenantEnabled: true,
			ctx:           tenantRequestContext(),
			answer:        "   ",
		},
		{
			name:          "missing message id leaves nowhere to write the grade",
			tenantEnabled: true,
			ctx:           tenantRequestContext(),
			mutate:        func(r *NBAgentRequest) { r.MessageId = "" },
			answer:        "root cause found",
		},
		{
			name:          "background flow carries no tenant",
			tenantEnabled: true,
			ctx:           security.NewRequestContextForSuperAdmin(), // empty tenant id
			answer:        "root cause found",
		},
	}

	for _, tc := range cases {
		t.Run(tc.name, func(t *testing.T) {
			calls := stubGraderAndFlag(t, tc.tenantEnabled)
			req := eligibleConfidenceRequest()
			if tc.mutate != nil {
				tc.mutate(&req)
			}

			ScoreAnswerConfidenceAsync(tc.ctx, req, tc.answer)

			select {
			case got := <-calls:
				t.Fatalf("grader ran for an ineligible turn (question %q)", got.question)
			case <-time.After(750 * time.Millisecond):
			}
		})
	}
}
