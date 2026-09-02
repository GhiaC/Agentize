package engine

import (
	"context"
	"encoding/json"
	"fmt"
	"strings"
	"sync"
	"time"

	"github.com/ghiac/agentize/debuger"
	"github.com/ghiac/agentize/log"
	"github.com/ghiac/agentize/metrics"
	"github.com/ghiac/agentize/model"
	"github.com/sashabaranov/go-openai"
)

// SessionSchedulerConfig holds configuration for the session scheduler
type SessionSchedulerConfig struct {
	// CheckInterval is how often to check sessions (default: 5 minutes)
	CheckInterval time.Duration

	// FirstSummarizationThreshold is the minimum number of messages for FIRST summarization
	// when session has never been summarized before (default: 5)
	FirstSummarizationThreshold int

	// SubsequentMessageThreshold is the minimum number of messages for subsequent summarizations
	// after session has been summarized at least once (default: 25)
	SubsequentMessageThreshold int

	// SubsequentTimeThreshold is the minimum time that must pass after last summarization
	// before allowing another summarization (default: 1 hour)
	SubsequentTimeThreshold time.Duration

	// LastActivityThreshold is how recent LastActivity should be to consider session active (default: 1 hour)
	LastActivityThreshold time.Duration

	// ImmediateSummarizationThreshold is the message count that triggers immediate summarization
	// regardless of other conditions (default: 50)
	ImmediateSummarizationThreshold int

	// RetainRecentMessages is how many of the most recent messages are kept in the
	// active conversation (Msgs) after summarization, instead of archiving everything.
	// This gives a rolling window of verbatim recent context so the conversation does
	// not suddenly go empty. Older messages are moved to ArchivedMsgs. (default: 10)
	RetainRecentMessages int

	// SummaryModel is the LLM model to use for summarization (default: gpt-4o-mini)
	SummaryModel string

	// SummaryMaxCompletionTokens includes both hidden reasoning and visible
	// output tokens. Reasoning models can otherwise consume the whole budget
	// and return an empty Content field.
	SummaryMaxCompletionTokens int

	// MetadataMaxCompletionTokens is the corresponding budget for short tag and
	// title generations.
	MetadataMaxCompletionTokens int

	// SummaryReasoningEffort is sent to reasoning-capable OpenAI-compatible
	// providers. "minimal" preserves budget for the small structured result.
	SummaryReasoningEffort string

	// DisableLogs if true, SessionScheduler does not emit any logs
	DisableLogs bool

	// SummarizationPrompts holds customizable prompts for summarization
	SummarizationPrompts SummarizationPrompts

	// OnSessionSummarized, when set, is called after a session is successfully
	// summarized, with the session's user and ID. Hosts running the multi-agent
	// Core should wire this to CoreHandler.InvalidateSystemPromptCache(userID) so
	// the Core rebuilds that user's memory in its system prompt immediately rather
	// than waiting for the prompt cache TTL to expire. Must be fast and non-blocking.
	OnSessionSummarized func(userID, sessionID string)
}

// SummarizationPrompts holds customizable prompts for LLM-based summarization
type SummarizationPrompts struct {
	// SummarySystemPrompt is the system prompt for generating summaries
	// If empty, uses default prompt
	SummarySystemPrompt string

	// SummaryUserPromptTemplate is the user prompt template for summaries
	// Use {{.PreviousSummary}} and {{.ConversationText}} as placeholders
	// If empty, uses default template
	SummaryUserPromptTemplate string

	// TagSystemPrompt is the system prompt for generating tags
	TagSystemPrompt string

	// TagUserPromptTemplate is the user prompt template for tags
	// Use {{.ExistingTags}} and {{.ConversationText}} as placeholders
	TagUserPromptTemplate string

	// TitleSystemPrompt is the system prompt for generating titles
	TitleSystemPrompt string
}

// DefaultSessionSchedulerConfig returns default configuration
func DefaultSessionSchedulerConfig() SessionSchedulerConfig {
	return SessionSchedulerConfig{
		CheckInterval:                   5 * time.Minute,
		FirstSummarizationThreshold:     5,             // First summarization after 5 messages
		SubsequentMessageThreshold:      25,            // Subsequent summarizations need 25 messages
		SubsequentTimeThreshold:         1 * time.Hour, // Plus at least 1 hour since last summarization
		LastActivityThreshold:           1 * time.Hour, // Session must be active within last hour
		ImmediateSummarizationThreshold: 50,            // Immediate summarization when messages exceed 50
		RetainRecentMessages:            10,            // Keep the last 10 messages active (rolling window)
		SummaryMaxCompletionTokens:      2048,
		MetadataMaxCompletionTokens:     256,
		SummaryReasoningEffort:          "minimal",
		SummarizationPrompts:            DefaultSummarizationPrompts(),
	}
}

// SummaryOffensiveContentSignal is the exact single word the LLM must return when user messages contain offensive/vulgar content. Used to trigger user ban.
const SummaryOffensiveContentSignal = "OFFENSIVE_CONTENT"

// userStore is implemented by stores that can get/save users (for ban on offensive content). Used via type assertion from session store.
type userStore interface {
	GetOrCreateUser(userID string) (*model.User, error)
	PutUser(user *model.User) error
}

type conversationMetadataStore interface {
	GetConversationBySession(sessionID string) (*model.Conversation, error)
	PutConversation(conversation *model.Conversation) error
}

// DefaultSummarizationPrompts returns default prompts for summarization
func DefaultSummarizationPrompts() SummarizationPrompts {
	return SummarizationPrompts{
		SummarySystemPrompt: `You are an incremental conversation summarizer. The application stores summary memory as an append-only array. Return only NEW important facts from the new conversation; never repeat, rewrite, merge, correct, or delete an existing entry.

CONTENT VIOLATION (check first): If the user's messages contain offensive, vulgar, abusive, or clearly inappropriate language (insults, slurs, explicit content, hate speech, etc.), respond with ONLY this exact word, nothing else: OFFENSIVE_CONTENT. No explanation, no other text.

APPEND-ONLY RULES:
- Treat existing summary entries as immutable history.
- Emit only genuinely new specific information from the NEW conversation.
- If a fact changed, append a new entry describing the change; do not rewrite the old entry.
- Do not emit facts already present in the existing entries.

WHAT COUNTS AS SPECIFIC (include):
- Names of people, places, or entities
- Personal details: age, birthday, preferences, relationships
- Decisions, commitments, goals
- Important numbers/IDs/dates the user defined
- Custom configurations or settings

WHAT TO IGNORE (never add):
- Greetings, pleasantries, small talk, acknowledgments
- Generic Q&A (unit conversions, weather, time), temporary calculations
- Generic how-to and common-knowledge lookups, filler

OUTPUT REQUIREMENTS:
- Return a valid JSON array of compact strings and nothing else.
- Each string is one independently useful new fact.
- Return [] when there is nothing important to append.

Example: existing ["User Ali is 28."] + new "I turned 29 and joined TechCorp" => ["User Ali turned 29.","User Ali joined TechCorp."]`,

		SummaryUserPromptTemplate: `{{if .PreviousSummary}}IMMUTABLE EXISTING SUMMARY ENTRIES (do not repeat or edit):
{{.PreviousSummary}}

NEW conversation to inspect:
{{end}}{{.ConversationText}}

Return only the JSON array of NEW important facts to append:`,

		TagSystemPrompt: `You are a conversation tagger that identifies SPECIFIC topics only.

WHAT TO TAG (specific topics):
- Named entities (people, companies, products)
- Technical projects or systems being worked on
- Personal topics (health, family, work)
- Specific domains the user is interested in

WHAT NOT TO TAG (generic topics):
- "questions", "help", "conversation"
- "math", "calculations", "conversions" (unless it's a recurring theme)
- "greetings", "chat"
- Any generic action words

CRITICAL RULES:
1. Existing tags are immutable; never return them again
2. Return only new tags for genuinely specific new topics
3. The application will append at most enough tags to reach 7 total
4. Be very selective - fewer specific tags are better than many generic ones

Format: lowercase, hyphenated (e.g., "kubernetes", "project-alpha", "user-preferences")
Return only new tags, comma-separated, no quotes or extra text. Return an empty response when none are new.`,

		TagUserPromptTemplate: `{{if .ExistingTags}}EXISTING TAGS (preserve these unless completely irrelevant): {{.ExistingTags}}

{{end}}NEW CONVERSATION CONTENT:
{{.ConversationText}}

		Generate only NEW tags for SPECIFIC topics (ignore generic questions and small talk):`,

		TitleSystemPrompt: `Generate a short title (3-5 words) for this conversation.
Focus on the SPECIFIC topic or person discussed, not generic actions.

Good examples:
- "Ali's Kubernetes Project"
- "TechCorp API Design"
- "User Profile Settings"

Bad examples (too generic):
- "Questions and Answers"
- "Help with Calculations"
- "General Discussion"

Return only the title, no quotes or extra text.`,
	}
}

// SessionScheduler periodically checks and summarizes sessions
type SessionScheduler struct {
	sessionHandler *model.SessionHandler
	llmClient      *openai.Client
	backups        *BackupChain // backup LLM providers (OSS 120B first, then others)
	config         SessionSchedulerConfig
	stopChan       chan struct{}
	running        bool
	mu             sync.Mutex
}

// NewSessionScheduler creates a new session scheduler
func NewSessionScheduler(
	sessionHandler *model.SessionHandler,
	llmClient *openai.Client,
	config SessionSchedulerConfig,
) *SessionScheduler {
	return &SessionScheduler{
		sessionHandler: sessionHandler,
		llmClient:      llmClient,
		config:         config,
		stopChan:       make(chan struct{}),
		running:        false,
	}
}

// SetBackupChain sets the backup LLM chain for the scheduler
// Backups are tried IN ORDER before falling back to the main llmClient
// Recommended: put OSS 120B first for cost efficiency
func (ss *SessionScheduler) SetBackupChain(backups *BackupChain) {
	ss.mu.Lock()
	defer ss.mu.Unlock()
	ss.backups = backups
}

// Start starts the scheduler in a background goroutine
func (ss *SessionScheduler) Start(ctx context.Context) {
	ss.mu.Lock()
	defer ss.mu.Unlock()

	if ss.running {
		if !ss.config.DisableLogs {
			log.Log.Warnf("[SessionScheduler] ⚠️  Scheduler is already running")
		}
		return
	}

	ss.running = true
	ss.stopChan = make(chan struct{}) // Recreate stopChan in case it was closed
	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🚀 Starting session scheduler | CheckInterval: %v | FirstThreshold: %d msgs | SubsequentThreshold: %d msgs + %v",
			ss.config.CheckInterval, ss.config.FirstSummarizationThreshold, ss.config.SubsequentMessageThreshold, ss.config.SubsequentTimeThreshold)
	}

	go ss.run(ctx)
}

// Stop stops the scheduler gracefully
func (ss *SessionScheduler) Stop() {
	ss.mu.Lock()
	defer ss.mu.Unlock()

	if !ss.running {
		return
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🛑 Stopping session scheduler")
	}
	close(ss.stopChan)
	ss.running = false
}

// GetMessageThreshold returns the first summarization threshold from scheduler config
// This is used for backward compatibility
func (ss *SessionScheduler) GetMessageThreshold() int {
	ss.mu.Lock()
	defer ss.mu.Unlock()
	return ss.config.FirstSummarizationThreshold
}

// GetConfig returns the full scheduler configuration
func (ss *SessionScheduler) GetConfig() SessionSchedulerConfig {
	ss.mu.Lock()
	defer ss.mu.Unlock()
	return ss.config
}

// isStopping checks if shutdown has been requested
func (ss *SessionScheduler) isStopping() bool {
	select {
	case <-ss.stopChan:
		return true
	default:
		return false
	}
}

// sleepWithCancel sleeps for the given duration but can be interrupted by stop signal
func (ss *SessionScheduler) sleepWithCancel(d time.Duration) bool {
	select {
	case <-time.After(d):
		return false // completed normally
	case <-ss.stopChan:
		return true // interrupted
	}
}

// chatCompletion tries backup providers first (OSS 120B priority), then falls back to main llmClient
// This optimizes for cost by using cheaper models for summarization tasks
func (ss *SessionScheduler) chatCompletion(ctx context.Context, request openai.ChatCompletionRequest) (openai.ChatCompletionResponse, error) {
	// Try backup chain first (OSS 120B should be first in the chain for priority)
	if ss.backups != nil {
		log.Log.Infof("[SessionScheduler] 🔄 BACKUP CHAIN >> Attempting backup chain for summarization | BackupProviders: %d | RequestModel: %s",
			len(ss.backups.providers), request.Model)
		resp, ok := ss.backups.TryBackup(ctx, request.Messages, nil, "SessionScheduler")
		if ok && len(resp.Choices) > 0 && getMessageContentString(resp.Choices[0].Message) != "" {
			log.Log.Infof("[SessionScheduler] ✅ BACKUP CHAIN >> Success | UsedModel: %s | ResponseTokens: %d",
				resp.Model, resp.Usage.TotalTokens)
			return resp, nil
		}
		if ok {
			log.Log.Warnf("[SessionScheduler] ⚠️ BACKUP CHAIN >> Provider returned no visible output; falling back to main LLM")
		}
		log.Log.Warnf("[SessionScheduler] ⚠️ BACKUP CHAIN >> All backup providers failed, falling back to main LLM: %s", ss.config.SummaryModel)
	} else {
		log.Log.Warnf("[SessionScheduler] ⚠️ BACKUP CHAIN >> No backup chain configured, using main LLM: %s", ss.config.SummaryModel)
	}

	// Fall back to main llmClient
	log.Log.Infof("[SessionScheduler] 🔵 MAIN LLM >> Calling main LLM | Model: %s", ss.config.SummaryModel)
	sumStart := time.Now()
	resp, err := ss.llmClient.CreateChatCompletion(ctx, request)
	cached := 0
	if resp.Usage.PromptTokensDetails != nil {
		cached = resp.Usage.PromptTokensDetails.CachedTokens
	}
	metrics.LLMCall("summary", ss.config.SummaryModel, metrics.Status(err), time.Since(sumStart), resp.Usage.PromptTokens, resp.Usage.CompletionTokens, cached)
	return resp, err
}

// run runs the scheduler loop
func (ss *SessionScheduler) run(ctx context.Context) {
	// Check for early shutdown before initial check
	if ss.isStopping() || ctx.Err() != nil {
		if !ss.config.DisableLogs {
			log.Log.Infof("[SessionScheduler] ✅ Scheduler stopped before initial check")
		}
		return
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🔍 Starting initial session check (checking all sessions immediately)...")
	}
	ss.checkAndSummarizeSessions(ctx)

	// Check for shutdown after initial check
	if ss.isStopping() || ctx.Err() != nil {
		if !ss.config.DisableLogs {
			log.Log.Infof("[SessionScheduler] ✅ Scheduler stopped after initial check")
		}
		return
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] ✅ Initial session check completed, starting periodic checks...")
	}

	ticker := time.NewTicker(ss.config.CheckInterval)
	defer ticker.Stop()

	for {
		select {
		case <-ticker.C:
			ss.checkAndSummarizeSessions(ctx)
		case <-ss.stopChan:
			if !ss.config.DisableLogs {
				log.Log.Infof("[SessionScheduler] ✅ Scheduler stopped")
			}
			return
		case <-ctx.Done():
			if !ss.config.DisableLogs {
				log.Log.Infof("[SessionScheduler] ✅ Scheduler stopped (context cancelled)")
			}
			return
		}
	}
}

// checkAndSummarizeSessions checks all sessions and summarizes eligible ones
func (ss *SessionScheduler) checkAndSummarizeSessions(ctx context.Context) {
	// Check for early shutdown
	if ss.isStopping() || ctx.Err() != nil {
		return
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🔍 Checking sessions for summarization...")
	}

	runStart := time.Now()
	metrics.SchedulerRunning(true)
	defer metrics.SchedulerRunning(false)

	// Get all sessions from store
	sessionStore := ss.sessionHandler.GetStore()
	debugStore, ok := sessionStore.(debuger.DebugStore)
	if !ok {
		if !ss.config.DisableLogs {
			log.Log.Errorf("[SessionScheduler] ❌ Store does not implement DebugStore interface")
		}
		metrics.SchedulerRun("error", time.Since(runStart), 0, 0)
		return
	}

	sessionsByUser, err := debugStore.GetAllSessions()
	if err != nil {
		if !ss.config.DisableLogs {
			log.Log.Errorf("[SessionScheduler] ❌ Failed to get all sessions: %v", err)
		}
		metrics.SchedulerRun("error", time.Since(runStart), 0, 0)
		return
	}

	totalSessions := 0
	eligibleSessions := 0
	summarizedSessions := 0
	sessionsWithMessages := 0
	sessionsWithoutMessages := 0
	alreadySummarizedSessions := 0
	sessionsNotEligible := 0
	totalUsers := len(sessionsByUser)
	totalMessages := 0
	stoppedEarly := false

	now := time.Now()

	// Iterate through all sessions
sessionLoop:
	for userID, sessions := range sessionsByUser {
		totalSessions += len(sessions)
		for _, session := range sessions {
			// Check for shutdown before processing each session
			if ss.isStopping() || ctx.Err() != nil {
				if !ss.config.DisableLogs {
					log.Log.Infof("[SessionScheduler] 🛑 Shutdown requested, stopping session check early")
				}
				stoppedEarly = true
				break sessionLoop
			}

			msgCount := len(session.Msgs)
			totalMessages += msgCount

			// Track sessions with/without messages
			if msgCount > 0 {
				sessionsWithMessages++
			} else {
				sessionsWithoutMessages++
			}

			// Track already summarized sessions
			if !session.SummarizedAt.IsZero() {
				alreadySummarizedSessions++
			}

			isEligible := ss.isEligibleForSummarization(session, now)
			if !isEligible && msgCount > 0 {
				sessionsNotEligible++
				// Log why session is not eligible (only for sessions with messages)
				reasons := []string{}
				if msgCount == 0 {
					reasons = append(reasons, "no messages")
				}

				// Check thresholds based on whether session was summarized before
				if session.SummarizedAt.IsZero() || (!session.SummaryInitialized && len(session.Summary) == 0) {
					// First summarization check
					if msgCount < ss.config.FirstSummarizationThreshold {
						reasons = append(reasons, fmt.Sprintf("only %d messages (need %d for first summarization)", msgCount, ss.config.FirstSummarizationThreshold))
					}
				} else {
					// Subsequent summarization check
					if msgCount < ss.config.SubsequentMessageThreshold {
						reasons = append(reasons, fmt.Sprintf("only %d messages (need %d for subsequent summarization)", msgCount, ss.config.SubsequentMessageThreshold))
					}
					summarizedAge := now.Sub(session.SummarizedAt)
					if summarizedAge < ss.config.SubsequentTimeThreshold {
						reasons = append(reasons, fmt.Sprintf("summarized %v ago (need %v)", summarizedAge, ss.config.SubsequentTimeThreshold))
					}
					if !session.UpdatedAt.IsZero() {
						lastActivityAge := now.Sub(session.UpdatedAt)
						if lastActivityAge > ss.config.LastActivityThreshold {
							reasons = append(reasons, fmt.Sprintf("last activity %v ago (need within %v)", lastActivityAge, ss.config.LastActivityThreshold))
						}
					}
				}
				if len(reasons) > 0 && !ss.config.DisableLogs {
					log.Log.Debugf("[SessionScheduler] ⏭️  Session %s not eligible: %s | Messages: %d", session.SessionID, strings.Join(reasons, ", "), msgCount)
				}
			}
			if isEligible {
				eligibleSessions++
				if !ss.config.DisableLogs {
					log.Log.Infof("[SessionScheduler] 🎯 Session eligible for summarization | SessionID: %s | UserID: %s | Messages: %d", session.SessionID, userID, msgCount)
				}
				sumStart := time.Now()
				sumErr := ss.summarizeSession(ctx, session)
				metrics.SchedulerSummary(metrics.Status(sumErr), time.Since(sumStart))
				if err := sumErr; err != nil {
					// Check if error is due to context cancellation
					if ctx.Err() != nil {
						if !ss.config.DisableLogs {
							log.Log.Infof("[SessionScheduler] 🛑 Summarization cancelled due to shutdown")
						}
						stoppedEarly = true
						break sessionLoop
					}
					if !ss.config.DisableLogs {
						log.Log.Errorf("[SessionScheduler] ❌ Failed to summarize session %s: %v", session.SessionID, err)
					}
				} else {
					summarizedSessions++
					if !ss.config.DisableLogs {
						log.Log.Infof("[SessionScheduler] ✅ Summarized session %s (UserID: %s)", session.SessionID, userID)
					}
				}

				// Sleep with cancellation support
				if !ss.config.DisableLogs {
					log.Log.Infof("[SessionScheduler] ⏸️  Sleeping 10 seconds before next summarization...")
				}
				if ss.sleepWithCancel(10 * time.Second) {
					if !ss.config.DisableLogs {
						log.Log.Infof("[SessionScheduler] 🛑 Sleep interrupted by shutdown")
					}
					stoppedEarly = true
					break sessionLoop
				}
			}
		}
	}

	if !ss.config.DisableLogs {
		status := "completed"
		if stoppedEarly {
			status = "interrupted by shutdown"
		}
		log.Log.Infof("[SessionScheduler] 📊 Summary check %s | Total: %d | Users: %d | Messages: %d | WithMsgs: %d | NoMsgs: %d | AlreadySummarized: %d | NotEligible: %d | Eligible: %d | Summarized: %d | FirstThreshold: %d msgs | SubsequentThreshold: %d msgs + %v time",
			status, totalSessions, totalUsers, totalMessages, sessionsWithMessages, sessionsWithoutMessages, alreadySummarizedSessions, sessionsNotEligible, eligibleSessions, summarizedSessions,
			ss.config.FirstSummarizationThreshold, ss.config.SubsequentMessageThreshold, ss.config.SubsequentTimeThreshold)
	}

	runStatus := "ok"
	if stoppedEarly {
		runStatus = "interrupted"
	}
	metrics.SchedulerRun(runStatus, time.Since(runStart), totalSessions, summarizedSessions)
}

// isEligibleForSummarization checks if a session is eligible for summarization
// Three different thresholds apply:
// 1. Immediate summarization: if messages >= ImmediateSummarizationThreshold (default: 50), summarize immediately
// 2. First summarization (never summarized): only needs FirstSummarizationThreshold messages
// 3. Subsequent summarizations: needs SubsequentMessageThreshold messages AND SubsequentTimeThreshold time since last summarization
func (ss *SessionScheduler) isEligibleForSummarization(session *model.Session, now time.Time) bool {
	// Check if session has messages
	if len(session.Msgs) == 0 {
		// Legacy rows could archive everything and still persist an empty provider
		// response as "summarized". Recover them once from archived user messages.
		return !session.SummaryInitialized && len(session.Summary) == 0 && len(session.ArchivedMsgs) > 0
	}

	msgCount := len(session.Msgs)

	// IMMEDIATE CASE: If messages exceed ImmediateSummarizationThreshold, summarize immediately
	// This overrides all other conditions to prevent context window overflow
	immediateThreshold := ss.config.ImmediateSummarizationThreshold
	if immediateThreshold <= 0 {
		immediateThreshold = 50 // fallback default
	}
	if msgCount >= immediateThreshold {
		if !ss.config.DisableLogs {
			log.Log.Infof("[SessionScheduler] ⚡ Immediate summarization triggered for session (messages: %d >= threshold: %d)",
				msgCount, immediateThreshold)
		}
		return true
	}

	// CASE 1: First summarization (session never summarized before)
	if session.SummarizedAt.IsZero() || (!session.SummaryInitialized && len(session.Summary) == 0) {
		// Only need FirstSummarizationThreshold messages (default: 5)
		return msgCount >= ss.config.FirstSummarizationThreshold
	}

	// CASE 2: Subsequent summarization (session has been summarized before)
	// Need BOTH conditions:
	// - At least SubsequentMessageThreshold messages (default: 25)
	// - At least SubsequentTimeThreshold time since last summarization (default: 1 hour)

	// Check message threshold
	if msgCount < ss.config.SubsequentMessageThreshold {
		return false
	}

	// Check time threshold since last summarization
	timeSinceLastSummarization := now.Sub(session.SummarizedAt)
	if timeSinceLastSummarization < ss.config.SubsequentTimeThreshold {
		return false
	}

	// Check if LastActivity is recent (session is being used)
	if session.UpdatedAt.IsZero() {
		return false
	}
	lastActivityRecent := now.Sub(session.UpdatedAt) <= ss.config.LastActivityThreshold
	if !lastActivityRecent {
		return false
	}

	return true
}

// splitRollingWindow splits messages into the older ones to archive and the most
// recent `retain` to keep active. When len(msgs) <= retain nothing is archived and
// all messages are kept (the session is never emptied below the window size).
//
// The cut is moved backwards when needed to avoid splitting a tool-call / tool-result
// pair: if the first message of toKeep has role "tool" its paired assistant message
// (which holds the ToolCalls) would be in toArchive, and any subsequent LLM call
// would fail with "No tool call found for function call output with call_id X".
func splitRollingWindow(msgs []openai.ChatCompletionMessage, retain int) (toArchive, toKeep []openai.ChatCompletionMessage) {
	if retain < 0 {
		retain = 0
	}
	if len(msgs) <= retain {
		return nil, msgs
	}
	cut := len(msgs) - retain

	// Walk the cut backwards until toKeep no longer starts with a tool-result message.
	// Guard cut < len(msgs): when retain=0 cut equals len(msgs) and toKeep is empty.
	for cut > 0 && cut < len(msgs) && msgs[cut].Role == openai.ChatMessageRoleTool {
		cut--
	}
	if cut == 0 {
		return nil, msgs
	}
	return msgs[:cut], msgs[cut:]
}

// summarizeSession summarizes a session and moves older messages to ArchivedMsgs,
// keeping the most recent RetainRecentMessages active (rolling window).
func (ss *SessionScheduler) summarizeSession(ctx context.Context, session *model.Session) error {
	// Lock the session to prevent race conditions with AddMessage
	ss.sessionHandler.LockSession(session.SessionID)
	defer ss.sessionHandler.UnlockSession(session.SessionID)

	// Re-fetch the session to get latest state after acquiring lock
	sessionStore := ss.sessionHandler.GetStore()
	freshSession, err := sessionStore.Get(session.SessionID)
	if err != nil {
		return fmt.Errorf("failed to get fresh session: %w", err)
	}
	session = freshSession

	msgCount := len(session.Msgs)
	// When Msgs is empty but summarization is needed (e.g. SummarizedAt set but Summary empty), use ArchivedMsgs
	useArchivedForSummary := false
	if msgCount == 0 {
		if len(session.ArchivedMsgs) == 0 {
			if !ss.config.DisableLogs {
				log.Log.Infof("[SessionScheduler] ⏭️  Session %s has no messages and no archived messages, skipping", session.SessionID)
			}
			return nil
		}
		// Should re-summarize using archived messages (e.g. incomplete: SummarizedAt set but Summary empty)
		useArchivedForSummary = true
		msgCount = len(session.ArchivedMsgs) // for log stats
		if !ss.config.DisableLogs {
			log.Log.Infof("[SessionScheduler] 📝 Session %s has no current Msgs, using %d archived messages for summarization", session.SessionID, msgCount)
		}
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 📝 Summarizing session %s | Messages: %d | PreviousSummary: %s | ExistingTags: %v",
			session.SessionID, msgCount, truncateStringForLog(session.Summary.Text(), 50), session.Tags)
	}

	// Ensure user_id is in context
	ctx = model.WithUserID(ctx, session.UserID)

	// Determine summarization type
	summarizationType := "first"
	if !session.SummarizedAt.IsZero() && !session.SummaryInitialized && len(session.Summary) == 0 {
		summarizationType = "recovery"
	} else if !session.SummarizedAt.IsZero() {
		if msgCount >= ss.config.ImmediateSummarizationThreshold {
			summarizationType = "immediate"
		} else {
			summarizationType = "subsequent"
		}
	}

	// Create summarization log with all context before summarization
	summLog := model.NewSummarizationLog(session)
	summLog.SessionTitle = session.Title
	summLog.PreviousSummary = session.Summary.Text()
	summLog.PreviousTags = strings.Join(session.Tags, ", ")
	summLog.MessagesBeforeCount = msgCount
	summLog.ArchivedMessagesCount = len(session.ArchivedMsgs)
	summLog.RequestedModel = ss.config.SummaryModel
	summLog.SummarizationType = summarizationType

	// Get debug store for logging
	debugStore, hasDebugStore := sessionStore.(debuger.DebugStore)

	// Format conversation for summarization (use current Msgs or ArchivedMsgs when Msgs empty)
	var conversationText string
	if useArchivedForSummary {
		conversationText = formatMessagesForSummary(session.ArchivedMsgs)
	} else {
		conversationText = formatMessagesForSummary(session.Msgs)
	}

	// Track what we generate
	var generatedSummary, generatedTags, generatedTitle string

	// Generate only the delta and append it to immutable prior entries.
	previousSummary := session.Summary.Clone()
	previousTitle := session.Title
	previousTags := append([]string(nil), session.Tags...)
	previousSummaryPrompt := ""
	if len(previousSummary) > 0 {
		previousSummaryJSON, _ := json.Marshal(previousSummary)
		previousSummaryPrompt = string(previousSummaryJSON)
	}
	rawSummary, summaryResp, promptSent, err := ss.generateImprovedSummaryWithResponse(ctx, session.SessionID, session.UserID, previousSummaryPrompt, conversationText)
	summLog.PromptSent = promptSent // Store prompt for debug/DB (even on failure)
	if summaryResp != nil {
		summLog.PromptTokens = summaryResp.Usage.PromptTokens
		summLog.CompletionTokens = summaryResp.Usage.CompletionTokens
		summLog.TotalTokens = summaryResp.Usage.TotalTokens
		if summaryResp.Model != "" {
			summLog.ModelUsed = summaryResp.Model
		}
	}
	if err != nil {
		if !ss.config.DisableLogs {
			log.Log.Warnf("[SessionScheduler] ⚠️  Failed to generate summary for session %s: %v", session.SessionID, err)
		}
		LogLLMError("Scheduler", ss.config.SummaryModel, err)
		summLog.ErrorMessage = fmt.Sprintf("summary generation failed: %v", err)
		summLog.MarkCompleted("failed")
		if hasDebugStore {
			_ = debugStore.PutSummarizationLog(summLog)
		}
		metrics.SummarizationResult(summarizationType, "failed", msgCount, 0, 0, len(previousSummary.Text()), 0, 0, 0)
		// Do not set SummarizedAt or move messages when summary generation failed
		return fmt.Errorf("failed to generate summary: %w", err)
	}

	// Offensive content: LLM returned the signal word → ban user and do not save summary
	if strings.TrimSpace(rawSummary) == SummaryOffensiveContentSignal {
		if us, ok := sessionStore.(userStore); ok {
			user, err := us.GetOrCreateUser(session.UserID)
			if err == nil {
				user.Ban(0, "You have been restricted due to use of inappropriate language.")
				metrics.Ban("offensive")
				if putErr := us.PutUser(user); putErr == nil && !ss.config.DisableLogs {
					log.Log.Infof("[SessionScheduler] 🚫 User banned (offensive content) | UserID: %s", session.UserID)
				}
			}
		}
		metrics.SummarizationResult(summarizationType, "offensive", msgCount, 0, 0, len(previousSummary.Text()), 0, 0, 0)
		// Do not save OFFENSIVE_CONTENT as summary; do not set SummarizedAt or move messages
		return nil
	}

	newEntries, err := parseSummaryEntries(rawSummary)
	if err != nil {
		summLog.ErrorMessage = fmt.Sprintf("invalid summary response: %v", err)
		summLog.ResponseReceived = rawSummary
		summLog.MarkCompleted("failed")
		if hasDebugStore {
			_ = debugStore.PutSummarizationLog(summLog)
		}
		metrics.SummarizationResult(summarizationType, "failed", msgCount, 0, 0, len(previousSummary.Text()), 0, 0, 0)
		return fmt.Errorf("invalid summary response: %w", err)
	}
	session.Summary = model.AppendSummaryEntries(previousSummary, newEntries...)
	previousSummaryInitialized := session.SummaryInitialized
	session.SummaryInitialized = true
	generatedSummary = strings.Join(newEntries, "\n")

	// Generate and merge tags
	existingTags := session.Tags
	mergedTags, err := ss.generateAndMergeTags(ctx, existingTags, conversationText)
	if err != nil {
		if !ss.config.DisableLogs {
			log.Log.Warnf("[SessionScheduler] ⚠️  Failed to generate tags for session %s: %v", session.SessionID, err)
		}
	} else {
		session.Tags = mergedTags
		if len(mergedTags) > len(existingTags) {
			generatedTags = strings.Join(mergedTags[len(existingTags):], ", ")
		}
	}

	// Refresh the title on every cycle from accumulated memory plus the new
	// window. Conversation rows are synchronized after the session is durable.
	titleContext := strings.TrimSpace(conversationText + "\nAccumulated summary:\n" + session.Summary.Text())
	title, err := ss.generateTitle(ctx, titleContext)
	if err != nil {
		if !ss.config.DisableLogs {
			log.Log.Warnf("[SessionScheduler] ⚠️  Failed to generate title for session %s: %v", session.SessionID, err)
		}
	} else if title = strings.TrimSpace(title); title != "" {
		session.Title = title
		generatedTitle = title
	}

	// Update log with generated content
	summLog.GeneratedSummary = generatedSummary
	summLog.GeneratedTags = generatedTags
	summLog.GeneratedTitle = generatedTitle
	summLog.ResponseReceived = rawSummary
	if summLog.ModelUsed == "" {
		summLog.ModelUsed = ss.config.SummaryModel
	}

	// Rolling window: keep the most recent RetainRecentMessages in the active
	// conversation and archive only the older ones, so the session never goes
	// suddenly empty. When we summarized from ArchivedMsgs (Msgs empty), nothing moves.
	originalMsgs := make([]openai.ChatCompletionMessage, len(session.Msgs))
	copy(originalMsgs, session.Msgs)

	retain := ss.config.RetainRecentMessages
	if retain < 0 {
		retain = 0
	}

	archivedMsgsBackup := append([]openai.ChatCompletionMessage(nil), session.ArchivedMsgs...)
	previousSummarizedAt := session.SummarizedAt

	toArchive, toKeep := splitRollingWindow(originalMsgs, retain)
	movedCount := len(toArchive)
	// System messages are mutable runtime context, not conversation history.
	// Keep current ones active and purge historical snapshots accumulated by old
	// versions. This also repairs existing sessions on their next summary cycle.
	toArchive, keptSystem := withoutSystemMessages(toArchive)
	session.ArchivedMsgs, _ = withoutSystemMessages(session.ArchivedMsgs)
	toKeep = append(keptSystem, toKeep...)
	movedCount = len(toArchive)
	if movedCount > 0 || len(archivedMsgsBackup) != len(session.ArchivedMsgs) {
		session.ArchivedMsgs = append(session.ArchivedMsgs, toArchive...)
		kept := make([]openai.ChatCompletionMessage, len(toKeep))
		copy(kept, toKeep)
		session.Msgs = kept
	}
	retainedCount := len(session.Msgs)

	session.SummarizedAt = time.Now()
	session.UpdatedAt = time.Now()

	// Update log with after-state before save
	summLog.MessagesAfterCount = len(session.Msgs)
	summLog.ArchivedMessagesCount = len(session.ArchivedMsgs)

	// Save session - if this fails, rollback all in-memory changes
	if err := sessionStore.Put(session); err != nil {
		session.Msgs = originalMsgs
		session.ArchivedMsgs = archivedMsgsBackup
		session.Summary = previousSummary
		session.SummaryInitialized = previousSummaryInitialized
		session.Title = previousTitle
		session.Tags = previousTags
		session.SummarizedAt = previousSummarizedAt
		summLog.MarkCompleted("failed")
		summLog.ErrorMessage = fmt.Sprintf("failed to save session: %v", err)
		if hasDebugStore {
			_ = debugStore.PutSummarizationLog(summLog)
		}
		metrics.SummarizationResult(summarizationType, "failed", msgCount, 0, 0, len(previousSummary.Text()), 0, summLog.PromptTokens, summLog.CompletionTokens)
		return fmt.Errorf("failed to save session: %w", err)
	}
	if generatedTitle != "" {
		if err := syncConversationTitle(sessionStore, session.SessionID, generatedTitle, session.UpdatedAt); err != nil {
			if !ss.config.DisableLogs {
				log.Log.Warnf("[SessionScheduler] ⚠️  Session title saved but conversation title sync failed | SessionID: %s | Error: %v", session.SessionID, err)
			}
		}
	}

	// Mark log as successful and save
	summLog.MarkCompleted("success")
	if hasDebugStore {
		_ = debugStore.PutSummarizationLog(summLog)
	}

	metrics.SummarizationResult(summarizationType, "ok", msgCount, movedCount, retainedCount,
		len(previousSummary.Text()), len(session.Summary.Text()), summLog.PromptTokens, summLog.CompletionTokens)

	// Record how stale the previous summary was when we refreshed it. Skipped on
	// the first-ever summarization, where there is no previous summary to age.
	if !previousSummarizedAt.IsZero() {
		metrics.SummaryAge(time.Since(previousSummarizedAt))
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] ✅ Session %s summarized | Type: %s | Moved: %d msgs | Retained: %d | Archived: %d | Summary: %s | Tags: %v | Duration: %dms",
			session.SessionID, summarizationType, movedCount, retainedCount, len(session.ArchivedMsgs),
			truncateStringForLog(session.Summary.Text(), 50), session.Tags, summLog.DurationMs)
	}

	// Notify the host (e.g. so the Core drops this user's cached system prompt and
	// rebuilds their memory on the next message). Best-effort; must not block.
	if ss.config.OnSessionSummarized != nil {
		ss.config.OnSessionSummarized(session.UserID, session.SessionID)
	}

	return nil
}

// generateImprovedSummaryWithResponse generates an improved summary and returns the full response and the prompt sent (for logging).
func (ss *SessionScheduler) generateImprovedSummaryWithResponse(ctx context.Context, sessionID string, userID string, previousSummary string, conversationText string) (string, *openai.ChatCompletionResponse, string, error) {
	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🔍 generateImprovedSummaryWithResponse called | SessionID: %s | PreviousSummary: %s",
			sessionID, truncateStringForLog(previousSummary, 50))
	}

	// Use configured prompts
	systemPrompt := ss.config.SummarizationPrompts.SummarySystemPrompt
	if systemPrompt == "" {
		systemPrompt = DefaultSummarizationPrompts().SummarySystemPrompt
	}

	// Build user prompt from template
	userPromptTemplate := ss.config.SummarizationPrompts.SummaryUserPromptTemplate
	if userPromptTemplate == "" {
		userPromptTemplate = DefaultSummarizationPrompts().SummaryUserPromptTemplate
	}

	userPrompt := userPromptTemplate
	if previousSummary != "" {
		userPrompt = strings.Replace(userPrompt, "{{if .PreviousSummary}}", "", 1)
		userPrompt = strings.Replace(userPrompt, "{{end}}", "", 1)
		userPrompt = strings.Replace(userPrompt, "{{.PreviousSummary}}", previousSummary, 1)
	} else {
		// Remove the conditional block if no previous summary
		startIdx := strings.Index(userPrompt, "{{if .PreviousSummary}}")
		endIdx := strings.Index(userPrompt, "{{end}}")
		if startIdx != -1 && endIdx != -1 {
			userPrompt = userPrompt[:startIdx] + userPrompt[endIdx+7:]
		}
	}
	userPrompt = strings.Replace(userPrompt, "{{.ConversationText}}", conversationText, 1)

	// Build prompt string for DB/debug (same format as sent to LLM)
	promptSent := formatPromptForLog(systemPrompt, userPrompt)

	maxCompletionTokens := ss.config.SummaryMaxCompletionTokens
	if maxCompletionTokens <= 0 {
		maxCompletionTokens = 2048
	}
	reasoningEffort := strings.TrimSpace(ss.config.SummaryReasoningEffort)
	if reasoningEffort == "" {
		reasoningEffort = "minimal"
	}
	request := openai.ChatCompletionRequest{
		Model: ss.config.SummaryModel,
		Messages: []openai.ChatCompletionMessage{
			{Role: openai.ChatMessageRoleSystem, Content: systemPrompt},
			{Role: openai.ChatMessageRoleUser, Content: userPrompt},
		},
		MaxCompletionTokens: maxCompletionTokens,
		ReasoningEffort:     reasoningEffort,
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 🔵 LLM >> Model: %s | Messages: %d (improved summary)", ss.config.SummaryModel, len(request.Messages))
	}

	resp, err := ss.chatCompletion(ctx, request)
	if err != nil {
		return "", nil, promptSent, err
	}

	if len(resp.Choices) == 0 {
		return "", nil, promptSent, fmt.Errorf("no response from LLM")
	}

	summary := getSummaryMessageContent(resp.Choices[0].Message)
	if summary == "" {
		// A reasoning model can consume the full completion budget without
		// producing visible output. Retry once with a larger budget; fail closed
		// if the second response is still empty.
		retryRequest := request
		retryRequest.MaxCompletionTokens = max(maxCompletionTokens*2, 4096)
		retryResp, retryErr := ss.chatCompletion(ctx, retryRequest)
		if retryErr != nil {
			return "", &resp, promptSent, fmt.Errorf("empty visible summary response; retry failed: %w", retryErr)
		}
		retryResp.Usage.PromptTokens += resp.Usage.PromptTokens
		retryResp.Usage.CompletionTokens += resp.Usage.CompletionTokens
		retryResp.Usage.TotalTokens += resp.Usage.TotalTokens
		resp = retryResp
		if len(resp.Choices) == 0 {
			return "", &resp, promptSent, fmt.Errorf("empty visible summary response after retry: no choices")
		}
		summary = getSummaryMessageContent(resp.Choices[0].Message)
		if summary == "" {
			return "", &resp, promptSent, fmt.Errorf("empty visible summary response after retry (finish_reason=%s, completion_tokens=%d)", resp.Choices[0].FinishReason, resp.Usage.CompletionTokens)
		}
	}

	if !ss.config.DisableLogs {
		log.Log.Infof("[SessionScheduler] 📊 TOKEN USAGE >> total=%d (improved summary)", resp.Usage.TotalTokens)
	}

	return summary, &resp, promptSent, nil
}

// formatPromptForLog formats system and user prompt for storage in SummarizationLog.PromptSent
func formatPromptForLog(systemPrompt, userPrompt string) string {
	return "=== System ===\n" + systemPrompt + "\n\n=== User ===\n" + userPrompt
}

// generateAndMergeTags generates new tags and merges with existing ones
func (ss *SessionScheduler) generateAndMergeTags(ctx context.Context, existingTags []string, conversationText string) ([]string, error) {
	// Use configured prompts
	systemPrompt := ss.config.SummarizationPrompts.TagSystemPrompt
	if systemPrompt == "" {
		systemPrompt = DefaultSummarizationPrompts().TagSystemPrompt
	}

	userPromptTemplate := ss.config.SummarizationPrompts.TagUserPromptTemplate
	if userPromptTemplate == "" {
		userPromptTemplate = DefaultSummarizationPrompts().TagUserPromptTemplate
	}

	userPrompt := userPromptTemplate
	if len(existingTags) > 0 {
		userPrompt = strings.Replace(userPrompt, "{{if .ExistingTags}}", "", 1)
		userPrompt = strings.Replace(userPrompt, "{{end}}", "", 1)
		userPrompt = strings.Replace(userPrompt, "{{.ExistingTags}}", strings.Join(existingTags, ", "), 1)
	} else {
		startIdx := strings.Index(userPrompt, "{{if .ExistingTags}}")
		endIdx := strings.Index(userPrompt, "{{end}}")
		if startIdx != -1 && endIdx != -1 {
			userPrompt = userPrompt[:startIdx] + userPrompt[endIdx+7:]
		}
	}
	userPrompt = strings.Replace(userPrompt, "{{.ConversationText}}", conversationText, 1)

	metadataMaxTokens := ss.config.MetadataMaxCompletionTokens
	if metadataMaxTokens <= 0 {
		metadataMaxTokens = 256
	}
	request := openai.ChatCompletionRequest{
		Model: ss.config.SummaryModel,
		Messages: []openai.ChatCompletionMessage{
			{Role: openai.ChatMessageRoleSystem, Content: systemPrompt},
			{Role: openai.ChatMessageRoleUser, Content: userPrompt},
		},
		MaxCompletionTokens: metadataMaxTokens,
		ReasoningEffort:     ss.summaryReasoningEffort(),
	}

	resp, err := ss.chatCompletion(ctx, request)
	if err != nil {
		return nil, err
	}

	if len(resp.Choices) == 0 {
		return nil, fmt.Errorf("no response from LLM")
	}

	// Existing tags are immutable. Parse only the delta, then append in order.
	tagsStr := getMessageContentString(resp.Choices[0].Message)
	if tagsStr == "" {
		retryRequest := request
		retryRequest.MaxCompletionTokens = max(metadataMaxTokens*2, 512)
		resp, err = ss.chatCompletion(ctx, retryRequest)
		if err != nil {
			return nil, fmt.Errorf("empty visible tag response; retry failed: %w", err)
		}
		if len(resp.Choices) == 0 || getMessageContentString(resp.Choices[0].Message) == "" {
			return nil, fmt.Errorf("empty visible tag response after retry")
		}
		tagsStr = getMessageContentString(resp.Choices[0].Message)
	}
	tagsStr = strings.Trim(tagsStr, "\"'")
	rawTags := strings.Split(tagsStr, ",")

	additions := make([]string, 0, len(rawTags))
	for _, tag := range rawTags {
		tag = strings.TrimSpace(strings.ToLower(tag))
		if tag != "" {
			additions = append(additions, tag)
		}
	}
	return model.AppendTags(existingTags, additions, 7), nil
}

func parseSummaryEntries(raw string) ([]string, error) {
	raw = strings.TrimSpace(raw)
	if raw == "" {
		return nil, fmt.Errorf("empty LLM response")
	}
	var entries []string
	if err := json.Unmarshal([]byte(raw), &entries); err != nil {
		return nil, fmt.Errorf("expected JSON string array: %w", err)
	}
	return []string(model.AppendSummaryEntries(nil, entries...)), nil
}

func (ss *SessionScheduler) summaryReasoningEffort() string {
	effort := strings.TrimSpace(ss.config.SummaryReasoningEffort)
	if effort == "" {
		return "minimal"
	}
	return effort
}

func withoutSystemMessages(messages []openai.ChatCompletionMessage) (nonSystem, system []openai.ChatCompletionMessage) {
	for _, message := range messages {
		if message.Role == openai.ChatMessageRoleSystem {
			system = append(system, message)
			continue
		}
		nonSystem = append(nonSystem, message)
	}
	return nonSystem, system
}

func syncConversationTitle(store model.SessionStore, sessionID, title string, updatedAt time.Time) error {
	conversations, ok := store.(conversationMetadataStore)
	if !ok {
		return nil
	}
	conversation, err := conversations.GetConversationBySession(sessionID)
	if err != nil || conversation == nil {
		return err
	}
	conversation.Title = title
	conversation.UpdatedAt = updatedAt
	return conversations.PutConversation(conversation)
}

// generateTitle generates a title for the session
func (ss *SessionScheduler) generateTitle(ctx context.Context, conversationText string) (string, error) {
	systemPrompt := ss.config.SummarizationPrompts.TitleSystemPrompt
	if systemPrompt == "" {
		systemPrompt = DefaultSummarizationPrompts().TitleSystemPrompt
	}

	conversationText = truncateRunesForSummary(conversationText, 300)

	metadataMaxTokens := ss.config.MetadataMaxCompletionTokens
	if metadataMaxTokens <= 0 {
		metadataMaxTokens = 256
	}
	request := openai.ChatCompletionRequest{
		Model: ss.config.SummaryModel,
		Messages: []openai.ChatCompletionMessage{
			{Role: openai.ChatMessageRoleSystem, Content: systemPrompt},
			{Role: openai.ChatMessageRoleUser, Content: "Generate a title for this conversation:\n\n" + conversationText},
		},
		MaxCompletionTokens: metadataMaxTokens,
		ReasoningEffort:     ss.summaryReasoningEffort(),
	}

	resp, err := ss.chatCompletion(ctx, request)
	if err != nil {
		return "", err
	}

	if len(resp.Choices) == 0 {
		return "", fmt.Errorf("no response from LLM")
	}
	title := getMessageContentString(resp.Choices[0].Message)
	if title == "" {
		retryRequest := request
		retryRequest.MaxCompletionTokens = max(metadataMaxTokens*2, 512)
		resp, err = ss.chatCompletion(ctx, retryRequest)
		if err != nil {
			return "", fmt.Errorf("empty visible title response; retry failed: %w", err)
		}
		if len(resp.Choices) == 0 {
			return "", fmt.Errorf("empty visible title response after retry: no choices")
		}
		title = getMessageContentString(resp.Choices[0].Message)
		if title == "" {
			return "", fmt.Errorf("empty visible title response after retry")
		}
	}
	return title, nil
}

// getMessageContentString returns the text content of a chat message as a trimmed string.
// Use this when reading summary/tags/title from LLM responses so parsing can be extended
// if the SDK or provider uses content parts (e.g. array) instead of a plain string.
func getMessageContentString(msg openai.ChatCompletionMessage) string {
	if content := strings.TrimSpace(msg.Content); content != "" {
		return content
	}
	parts := make([]string, 0, len(msg.MultiContent))
	for _, part := range msg.MultiContent {
		if text := strings.TrimSpace(part.Text); text != "" {
			parts = append(parts, text)
		}
	}
	return strings.TrimSpace(strings.Join(parts, "\n"))
}

// getSummaryMessageContent accepts reasoning_content only when it is itself a
// complete strict payload. Arbitrary chain-of-thought is never persisted.
func getSummaryMessageContent(msg openai.ChatCompletionMessage) string {
	if content := getMessageContentString(msg); content != "" {
		return content
	}
	candidate := strings.TrimSpace(msg.ReasoningContent)
	if candidate == SummaryOffensiveContentSignal {
		return candidate
	}
	var entries []string
	if candidate != "" && json.Unmarshal([]byte(candidate), &entries) == nil {
		return candidate
	}
	return ""
}

// formatMessagesForSummary converts messages to a readable format for summarization
func formatMessagesForSummary(msgs []openai.ChatCompletionMessage) string {
	var result string
	for _, msg := range msgs {
		// Only include user messages for summarization
		if msg.Role != openai.ChatMessageRoleUser {
			continue
		}
		// Skip tool-related messages
		if msg.ToolCallID != "" || len(msg.ToolCalls) > 0 {
			continue
		}

		content := getMessageContentString(msg)
		if content == "" {
			continue
		}

		content = truncateRunesForSummary(content, 300)

		result += fmt.Sprintf("%s: %s\n", msg.Role, content)
	}
	return result
}

// min returns the minimum of two integers
func min(a, b int) int {
	if a < b {
		return a
	}
	return b
}

// truncateStringForLog truncates a string to a maximum length for logging
func truncateStringForLog(s string, maxLen int) string {
	return truncateRunesForSummary(s, maxLen)
}

func truncateRunesForSummary(s string, maxLen int) string {
	runes := []rune(s)
	if maxLen <= 0 || len(runes) <= maxLen {
		return s
	}
	return string(runes[:maxLen]) + "..."
}

// OpenAIClientWrapper wraps openai.Client to implement model.LLMClient interface
type OpenAIClientWrapper struct {
	Client *openai.Client
}

// CreateChatCompletion implements model.LLMClient interface
func (w *OpenAIClientWrapper) CreateChatCompletion(ctx context.Context, request openai.ChatCompletionRequest) (openai.ChatCompletionResponse, error) {
	return w.Client.CreateChatCompletion(ctx, request)
}
