package server

import (
	"bytes"
	"context"
	"encoding/json"
	"errors"
	"fmt"
	"log"
	"math"
	"net/http"
	"path/filepath"
	"strconv"
	"strings"
	"time"
	"unicode/utf8"

	"github.com/Autumn-27/artex/agent"
	"github.com/Autumn-27/artex/db"
	"github.com/Autumn-27/artex/intercept"
	"github.com/Autumn-27/artex/llmrec"
	"github.com/Autumn-27/artex/sidequestion"
)

const (
	maxConversationRequestBytes  = 64 << 10
	maxConversationAgentKeyRunes = 120
	maxConversationTitleRunes    = 200
)

// 对话端点的中文 HTTP 错误响应，失败时直接展示为 toast。
// agent_key、title、pinned、ids、id、LLM、API Key、token 等字段和技术标识保持原文。
// 包含 %d 的常量由 fmt.Sprintf 填充。默认标题由 convDefaultTitle、convAttachmentTitle
// 集中维护，复测原因与活动错误由 convRetest*、transcriptErrorSummary 统一维护。
const (
	convErrRequestTooLarge = "请求正文过大"
	convErrAgentKeyEmpty   = "agent_key 不能为空"
	convErrAgentKeyTooLong = "agent_key 最多 %d 个字符"
	convErrAgentNotFound   = "找不到 Agent"
	convErrLLMProfile      = "指定的 LLM 配置不存在或未设置 API Key"
	convErrTitleTooLong    = "标题最多 %d 个字符"
	convErrTitleOrPinned   = "至少提供 title 或 pinned 之一"
	convErrTitleEmpty      = "标题不能为空"
	convErrBadConvID       = "对话 id 无效"
	convErrIDsCount        = "ids 数量必须在 1 到 %d 之间"
	convErrMessageEmpty    = "消息不能为空"
	convErrBusy            = "此对话正在处理上一条消息，请稍候"
)

// 对话默认标题。convDefaultTitle 同时作为创建默认值和自动标题标记。
// 首条用户消息到达时，仅标题为空或等于该值才自动替换标题，赋值与比较必须一致。
// convAttachmentTitle 是只发送附件时的首条默认标题。
const (
	convDefaultTitle    = "新对话"
	convAttachmentTitle = "附件消息"
)

// runConversationTurn 封存复测对话时使用的终止原因，存入 finding_retests.error
// 并直接显示于复测面板 item.error。与 db/finding_retests.go 的无结论、重启原因一致。
// failed、stopped、completed 为状态协议标识，由 StatusLabel 映射显示，保持 ASCII。
const (
	convRetestFailedToStart    = "无法启动复测"
	convRetestStatusReadFailed = "无法读取复测状态，请重新启动"
	convRetestStoppedOrClosed  = "复测已停止或服务已关闭"

	// 复核（finding_verifications.error）的对应三条。措辞与复测保持平行，
	// 让面板上「复测失败了」和「复核失败了」读起来是同一件事的两种视角。
	convVerifyFailedToStart    = "无法启动复核"
	convVerifyStatusReadFailed = "无法读取复核状态，请重新启动"
	convVerifyStoppedOrClosed  = "复核已停止或服务已关闭"
)

// isDefaultConversationTitle 判断标题是否为空或为 convDefaultTitle。
// 此时首条用户消息可自动生成标题；创建与比较共用同一常量，避免不一致。
func isDefaultConversationTitle(title string) bool {
	return title == "" || title == convDefaultTitle
}

func decodeConversationRequest(w http.ResponseWriter, r *http.Request, value any) bool {
	r.Body = http.MaxBytesReader(w, r.Body, maxConversationRequestBytes)
	if err := decode(r, value); err != nil {
		var tooLarge *http.MaxBytesError
		if errors.As(err, &tooLarge) {
			writeErr(w, http.StatusRequestEntityTooLarge, convErrRequestTooLarge)
		} else {
			writeErr(w, http.StatusBadRequest, err.Error())
		}
		return false
	}
	return true
}

// ---------- conversations (chat page) ----------
//
// A conversation is a ChatGPT-style thread bound to an agent key, independent of
// the pentest task graph. Turns run on ChatAgent; steps persist to
// conversation_activities and the browser POLLS ?since=cursor for live updates
// (no per-conversation SSE broadcaster needed).

type conversationListItem struct {
	*db.Conversation
	Running bool `json:"running"`
}

func (s *Server) pgListConversations(w http.ResponseWriter, r *http.Request) {
	pg := s.pg(w)
	if pg == nil {
		return
	}
	cs, err := pg.ListConversations()
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	items := make([]conversationListItem, 0, len(cs))
	s.chatMu.Lock()
	for _, c := range cs {
		items = append(items, conversationListItem{Conversation: c, Running: s.chatBusy[s.convBusyKey(c.ID)]})
	}
	s.chatMu.Unlock()
	writeJSON(w, 200, map[string]any{"conversations": items})
}

func (s *Server) pgCreateConversation(w http.ResponseWriter, r *http.Request) {
	pg := s.pg(w)
	if pg == nil {
		return
	}
	var req struct {
		AgentKey     string `json:"agent_key"`
		Title        string `json:"title"`
		LLMProfileID *int64 `json:"llm_profile_id"`
	}
	if !decodeConversationRequest(w, r, &req) {
		return
	}
	req.AgentKey = strings.TrimSpace(req.AgentKey)
	if req.AgentKey == "" {
		writeErr(w, 400, convErrAgentKeyEmpty)
		return
	}
	if utf8.RuneCountInString(req.AgentKey) > maxConversationAgentKeyRunes {
		writeErr(w, 400, fmt.Sprintf(convErrAgentKeyTooLong, maxConversationAgentKeyRunes))
		return
	}
	a, err := pg.GetAgentByKey(req.AgentKey)
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	if a == nil {
		writeErr(w, 404, convErrAgentNotFound)
		return
	}
	if req.LLMProfileID != nil {
		if _, ok := s.loadProfileConfig(*req.LLMProfileID); !ok {
			writeErr(w, 400, convErrLLMProfile)
			return
		}
	}
	title := strings.TrimSpace(req.Title)
	if title == "" {
		title = convDefaultTitle
	}
	if utf8.RuneCountInString(title) > maxConversationTitleRunes {
		writeErr(w, 400, fmt.Sprintf(convErrTitleTooLong, maxConversationTitleRunes))
		return
	}
	c, err := pg.CreateConversation(req.AgentKey, title, req.LLMProfileID)
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	writeJSON(w, 200, c)
}

func (s *Server) pgUpdateConversation(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	// llm_profile_id 用 RawMessage 而不是 *int64：这里必须区分「没传」和「显式传 null」。
	var req struct {
		LLMProfileID json.RawMessage `json:"llm_profile_id"`
	}
	if !decodeConversationRequest(w, r, &req) {
		return
	}
	setProfile := len(bytes.TrimSpace(req.LLMProfileID)) > 0
	var profileID *int64
	if setProfile && !bytes.Equal(bytes.TrimSpace(req.LLMProfileID), []byte("null")) {
		var id int64
		if err := json.Unmarshal(req.LLMProfileID, &id); err != nil {
			writeErr(w, 400, "llm_profile_id 必须是数字或 null")
			return
		}
		if _, ok := s.loadProfileConfig(id); !ok {
			writeErr(w, 400, convErrLLMProfile)
			return
		}
		profileID = &id
	}

	if setProfile {
		if err := pg.UpdateConversationProfile(c.ID, profileID); err != nil {
			writeErr(w, 500, err.Error())
			return
		}
	}
	writeJSON(w, 200, map[string]any{"ok": true})
}

// convByID resolves the {id} path value to a conversation (404 if absent).
func (s *Server) convByID(w http.ResponseWriter, r *http.Request) (*db.DB, *db.Conversation, bool) {
	pg := s.pg(w)
	if pg == nil {
		return nil, nil, false
	}
	id, ok := pathInt(r, "id")
	if !ok {
		writeErr(w, 400, "bad conversation id")
		return nil, nil, false
	}
	c, err := pg.GetConversation(id)
	if err != nil {
		writeErr(w, 500, err.Error())
		return nil, nil, false
	}
	if c == nil {
		writeErr(w, 404, "conversation not found")
		return nil, nil, false
	}
	return pg, c, true
}

func (s *Server) pgRenameConversation(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	var req struct {
		Title  *string `json:"title"`
		Pinned *bool   `json:"pinned"`
	}
	if !decodeConversationRequest(w, r, &req) {
		return
	}
	if req.Title == nil && req.Pinned == nil {
		writeErr(w, 400, convErrTitleOrPinned)
		return
	}
	if req.Title != nil {
		title := strings.TrimSpace(*req.Title)
		if title == "" {
			writeErr(w, 400, convErrTitleEmpty)
			return
		}
		if utf8.RuneCountInString(title) > maxConversationTitleRunes {
			writeErr(w, 400, fmt.Sprintf(convErrTitleTooLong, maxConversationTitleRunes))
			return
		}
		req.Title = &title
	}
	updated, err := pg.UpdateConversation(c.ID, db.ConversationPatch{Title: req.Title, Pinned: req.Pinned})
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	if updated == nil {
		writeErr(w, 404, "conversation not found")
		return
	}
	writeJSON(w, 200, updated)
}

func (s *Server) pgDeleteConversation(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	s.cancelConversation(c.ID)
	s.cancelSideWhere(func(p sidequestion.Parent) bool { return p.ConversationID == c.ID })
	if err := pg.DeleteConversation(c.ID); err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	writeJSON(w, 200, map[string]any{"deleted": c.ID})
}

const maxConversationDeleteBatch = 100

type conversationDeleteItem struct {
	ID    int64  `json:"id"`
	OK    bool   `json:"ok"`
	Error string `json:"error,omitempty"`
}

func (s *Server) cancelConversation(id int64) {
	busyKey := s.convBusyKey(id)
	s.chatMu.Lock()
	cancel := s.chatCancel[busyKey]
	s.chatMu.Unlock()
	if cancel != nil {
		cancel(agent.AbortChatStoppedByUser)
	}
}

// pgDeleteConversationsBatch deletes up to 100 selected conversations in one
// database statement. Missing ids are reported per item so a stale list does not
// hide what was actually removed.
func (s *Server) pgDeleteConversationsBatch(w http.ResponseWriter, r *http.Request) {
	pg := s.pg(w)
	if pg == nil {
		return
	}
	var request struct {
		IDs []int64 `json:"ids"`
	}
	if !decodeConversationRequest(w, r, &request) {
		return
	}
	ids := make([]int64, 0, len(request.IDs))
	seen := make(map[int64]struct{}, len(request.IDs))
	for _, id := range request.IDs {
		if id <= 0 {
			writeErr(w, http.StatusBadRequest, convErrBadConvID)
			return
		}
		if _, exists := seen[id]; exists {
			continue
		}
		seen[id] = struct{}{}
		ids = append(ids, id)
	}
	if len(ids) == 0 || len(ids) > maxConversationDeleteBatch {
		writeErr(w, http.StatusBadRequest, fmt.Sprintf(convErrIDsCount, maxConversationDeleteBatch))
		return
	}
	for _, id := range ids {
		s.cancelConversation(id)
		s.cancelSideWhere(func(p sidequestion.Parent) bool { return p.ConversationID == id })
	}
	deleted, err := pg.DeleteConversations(ids)
	if err != nil {
		writeErr(w, http.StatusInternalServerError, err.Error())
		return
	}
	deletedSet := make(map[int64]struct{}, len(deleted))
	for _, id := range deleted {
		deletedSet[id] = struct{}{}
	}
	items := make([]conversationDeleteItem, 0, len(ids))
	for _, id := range ids {
		_, ok := deletedSet[id]
		item := conversationDeleteItem{ID: id, OK: ok}
		if !ok {
			item.Error = "conversation not found"
		}
		items = append(items, item)
	}
	writeJSON(w, http.StatusOK, map[string]any{"items": items})
}

func (s *Server) convBusyKey(id int64) string { return "conv-" + strconv.FormatInt(id, 10) }

// pgConversationMessages returns steps after ?since=cursor plus whether a turn is
// still running (so the client knows to keep polling). Same item shape as the task
// activity stream, so the frontend transcript renderer is reused verbatim.
func (s *Server) pgConversationMessages(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	q := r.URL.Query()
	limit := atoiDefault(q.Get("limit"), 200)
	s.chatMu.Lock()
	running := s.chatBusy[s.convBusyKey(c.ID)]
	s.chatMu.Unlock()

	// Incremental tail: ?since=N returns steps after id N (ASC) — used by the live
	// poll and the post-send fetch. A generous cap so a burst is never dropped.
	if sv := q.Get("since"); sv != "" {
		since, _ := strconv.ParseInt(sv, 10, 64)
		items, cursor, err := pg.ConvActivityList(c.ID, since, max(limit, 1000))
		if err != nil {
			writeErr(w, 500, err.Error())
			return
		}
		writeJSON(w, 200, map[string]any{"items": activityDTOs(items), "cursor": cursor, "running": running, "hasMore": false})
		return
	}

	// History page (reverse pagination): no ?since → the latest page; ?before=N →
	// the page of older steps ending before id N. hasMore lets the client stop
	// loading earlier history once the top of the thread is reached.
	before, _ := strconv.ParseInt(q.Get("before"), 10, 64)
	items, hasMore, err := pg.ConvActivityPage(c.ID, before, limit)
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	cursor := before
	if n := len(items); n > 0 {
		cursor = items[n-1].ID
	}
	writeJSON(w, 200, map[string]any{"items": activityDTOs(items), "cursor": cursor, "running": running, "hasMore": hasMore})
}

// pgConversationMsgDetail lazily returns one step's full detail blob.
func (s *Server) pgConversationMsgDetail(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	seq, ok := pathInt(r, "seq")
	if !ok {
		writeErr(w, 400, "bad seq")
		return
	}
	detail, err := pg.ConvActivityDetail(c.ID, seq)
	if err != nil {
		writeErr(w, 500, err.Error())
		return
	}
	writeJSON(w, 200, map[string]any{"detail": detail})
}

// pgStopConversation aborts the in-flight run for one conversation (manual stop —
// the run/stop button in the chat UI). It cancels only THIS session's agent run;
// the P3 trigger queue is untouched, so the agent's next queued fire still starts.
func (s *Server) pgStopConversation(w http.ResponseWriter, r *http.Request) {
	_, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	busyKey := s.convBusyKey(c.ID)
	s.chatMu.Lock()
	cancel := s.chatCancel[busyKey]
	s.chatMu.Unlock()
	if cancel == nil {
		writeJSON(w, 200, map[string]any{"status": "idle"}) // nothing running
		return
	}
	// 中断检查点（批次 6 / #27）：在取消之前落盘，快照即「停止前的时间线」。
	s.captureConversationCheckpointNow(c, db.CheckpointReasonInterrupt, "用户停止本轮（中断）")
	cancel(agent.AbortChatStoppedByUser)
	writeJSON(w, 200, map[string]any{"status": "stopping"})
}

// pgSendConversationMessage persists the human turn, then runs the agent in the
// background (steps stream to conversation_activities, polled by the client). One
// in-flight turn per conversation.
func (s *Server) pgSendConversationMessage(w http.ResponseWriter, r *http.Request) {
	pg, c, ok := s.convByID(w, r)
	if !ok {
		return
	}
	var req struct {
		Message     string           `json:"message"`
		Attachments []chatAttachment `json:"attachments,omitempty"` // 方式1 上传的文件(路径相对会话工作目录)
	}
	if err := decode(r, &req); err != nil {
		writeErr(w, 400, err.Error())
		return
	}
	msg := strings.TrimSpace(req.Message)
	if msg == "" && len(req.Attachments) == 0 {
		writeErr(w, 400, convErrMessageEmpty)
		return
	}
	agentMessage, ok := s.prepareChatMentionMessage(w, msg)
	if !ok {
		return
	}
	// Same resolution as the background runner: honour the agent binding / this
	// conversation's chosen profile before falling back to the global config, so a
	// conversation that picked a valid LLM is not rejected just because no global
	// config is active.
	if s.resolveChatAgent(c) == nil {
		writeErr(w, 503, s.chatUnavailableReason())
		return
	}
	// 输入模态闸门(计划 75–96)：与 server.chat 同一条规则——目标配置未声明支持
	// 图片/音频/PDF 附件时在这里显式拒绝，绝不静默丢弃附件，也不把附件硬塞进
	// 纯文本请求。放在持久化用户轮次与 busy 标记之前，被拦下的消息不入档。
	if len(req.Attachments) > 0 {
		name, effective := s.conversationTurnModalities(c)
		if err := checkTurnAttachments(name, effective, req.Attachments); err != nil {
			writeErr(w, 400, err.Error())
			return
		}
	}

	busyKey := s.convBusyKey(c.ID)
	s.chatMu.Lock()
	if s.chatBusy[busyKey] {
		s.chatMu.Unlock()
		writeErr(w, 409, convErrBusy)
		return
	}
	s.chatBusy[busyKey] = true
	s.chatMu.Unlock()

	// persist + float the human turn; auto-title the thread from the first message.
	// Worker is the agent key (not "user") so the transcript stays a single lane
	// (no worker chips) — the kind='user' already right-aligns it as a human bubble.
	// With attachments, Detail carries {text, attachments} JSON so the transcript
	// renders attachment cards; without, Detail is the full text (Summary is truncated,
	// so the transcript lazy-loads Detail to show the message untruncated).
	ua := userActivityWithAttachments(c.AgentKey, msg, req.Attachments)
	ua.Summary = firstLine(msg, 200)
	if ua.Summary == "" && len(req.Attachments) > 0 {
		// 纯附件消息（只贴图/只传文件不写字）。会话时间线与列表都只读 summary，
		// 留空会让这条消息在前端「看起来根本没发出去」。给一条可读的占位摘要。
		ua.Summary = attachmentSummary(req.Attachments)
	}
	if ua.Detail == "" {
		ua.Detail = msg
	}
	userActivityID, err := pg.AppendConvActivity(c.ID, ua)
	if err != nil {
		log.Printf("[conv %d] append user msg failed: %v", c.ID, err)
	}
	if isDefaultConversationTitle(c.Title) {
		title := firstLine(msg, 40)
		if title == "" {
			title = convAttachmentTitle
		}
		_ = pg.RenameConversation(c.ID, title)
	}
	_ = pg.TouchConversation(c.ID)
	// 时间线检查点（批次 6 / #29–#31）：用户消息落库后、回合开始前。回滚到它 =
	// 把这条消息之后的回答/副作用从时间线上隐藏，transcript 截断回本回合之前——
	// 即「重跑这一轮」。
	s.captureConversationCheckpoint(c, db.CheckpointReasonUserMessage, "用户消息："+firstLine(msg, 60), userActivityID)

	// Append the uploaded files' ABSOLUTE paths so the ChatAgent opens them with its
	// Read/Bash tools. baseDir = the agent's per-session CWD (<workDir>/sessions/
	// conv-<id>/), matching chatUpload's landing dir and agent/chat.go's sessionWorkDir
	// — busyKey == convBusyKey(c.ID) == "conv-<id>" == that session id.
	baseDir := filepath.Join(s.m.dir, "sessions", busyKey)
	atts := req.Attachments
	s.runConversationWith(c, func(runCtx context.Context) string {
		// 视觉桥：SDK 的消息模型不含 image 块，图片必须先转写成文本再交给 agent。
		// 转写在 run ctx 内完成，失败会写一条错误活动（可见，不静默）。
		return s.visionMessageForConversation(runCtx, c, atts, baseDir, composeAgentMessage(agentMessage, atts, baseDir))
	}, busyKey, conversationAttribution{}, msg)
	writeJSON(w, 202, map[string]any{"status": "accepted"})
}

// conversationAttribution carries the LLM-ledger attribution (任务 id + 泳道标签)
// for sessions started outside a task run (触发器会话 reporter 等 / retester)。
// llmrec 从 run ctx 读这两个值：task_id 让这些消耗能按任务聚合(成本归因)，
// worker 让 by-worker 聚合能区分 reporter / retester 等泳道，而不是一律 (unknown)。
// 零值(空串)完全保持原有行为，人工聊天与任务内会话不受影响。
type conversationAttribution struct {
	taskID string
	worker string
}

// decorate 把归因挂到会话 run 的 ctx 上；空字段不挂(保持 session 推导/无归因)。
func (a conversationAttribution) decorate(ctx context.Context) context.Context {
	if a.worker != "" {
		ctx = llmrec.WithWorker(ctx, a.worker)
	}
	if a.taskID != "" {
		ctx = llmrec.WithTaskID(ctx, a.taskID)
	}
	return ctx
}

// runConversation runs ONE agent turn on a conversation in a background goroutine
// (each conversation is independent → parallel). Steps stream to
// conversation_activities. Shared by the chat HTTP handler and the P3 scheduler.
// busyKey clears when the run ends (best-effort in-flight marker).
// attr 为任务外会话(复测/触发)提供 LLM 归因；人工聊天传零值。
func (s *Server) runConversation(c *db.Conversation, msg, busyKey string, attr conversationAttribution, userMessage ...string) {
	s.runConversationWith(c, func(context.Context) string { return msg }, busyKey, attr, userMessage...)
}

// runConversationWith 与 runConversation 等价，只是把「最终发给 agent 的消息」
// 推迟到后台 goroutine 里再合成。视觉桥要读图并额外发一次多模态请求（秒级），
// 放在 HTTP 处理路径上会拖慢 202 响应；放到 run ctx 里算，既能并行，也能被
// 「停止本轮」取消。
func (s *Server) runConversationWith(c *db.Conversation, compose func(context.Context) string, busyKey string, attr conversationAttribution, userMessage ...string) {
	ctx, cancel := s.conversationRunContext(c.ID, busyKey)
	ctx = attr.decorate(ctx)
	// Only the human-message handler supplies this field, before adding the
	// attachment manifest. Scheduler/retest prompts must not be labelled as users.
	if len(userMessage) == 1 {
		ctx = intercept.WithReviewContext(ctx, "", intercept.ReviewBackground{Source: intercept.BackgroundUserMessage, Text: userMessage[0]})
	}
	go s.runConversationTurn(ctx, cancel, c, compose(ctx), busyKey)
}

// runConversationSync runs ONE agent turn on a conversation and BLOCKS until the
// run ends (clearing busyKey). runConversation wraps it in a goroutine for the
// fire-and-forget chat path; the P3 trigger queue calls it directly so it can wait
// for completion before starting the next queued fire for the same agent.
// attr 携带归因(触发器会话标成对应 agent 泳道 + 任务 id)。
func (s *Server) runConversationSync(c *db.Conversation, msg, busyKey string, attr conversationAttribution) {
	ctx, cancel := s.conversationRunContext(c.ID, busyKey)
	ctx = attr.decorate(ctx)
	s.runConversationTurn(ctx, cancel, c, msg, busyKey)
}

// Register cancellation before returning 202, so an immediate stop/delete cannot
// miss a background goroutine which has not started yet.
func (s *Server) conversationRunContext(id int64, busyKey string) (context.Context, context.CancelCauseFunc) {
	// Per-run cancellable context so a manual stop (pgStopConversation) can abort
	// just this session. Registered under chatMu so the stop handler can find it.
	ctx, cancel := context.WithCancelCause(intercept.WithConvID(s.ctx, id))
	s.chatMu.Lock()
	s.chatCancel[busyKey] = cancel
	s.chatMu.Unlock()
	return ctx, cancel
}

// transcriptErrorSummary 生成执行失败时的活动摘要。
// 聊天轮次 label 为空，任务主 Agent 使用“主 Agent”；均以中文括号和错误标签包装。
// 仅翻译外层标签，内部 err 原文完整保留。
// 包装使用中文全角括号与全角冒号，内部提示不额外插入空格，避免混排。
func transcriptErrorSummary(label, errMsg string) string {
	if label != "" {
		label += " "
	}
	return "（" + label + "错误：" + errMsg + "）"
}

func (s *Server) runConversationTurn(ctx context.Context, cancel context.CancelCauseFunc, c *db.Conversation, msg, busyKey string) {
	// 对话链路此前没有任何实时帧：前端只能等活动落库后轮询，
	// 所以推理总是“推理结束后一次性全量出现”（Memo 03）。
	// 这里挂与任务侧完全相同的 liveEmitter：worker 固定 "chat"，
	// 键用会话 busy 键 conv-<id>（db.Conversation 没有 task 关联，不能用 task.ID）。
	ctx = agent.WithLiveDelta(ctx, newLiveEmitter(s.liveBroadcaster(), busyKey, "chat", 0))
	defer func() {
		cancel(agent.AbortChatTurnFinished)
		s.chatMu.Lock()
		delete(s.chatBusy, busyKey)
		delete(s.chatCancel, busyKey)
		s.chatMu.Unlock()
		// busyKey 也是 waitTaskQuiescent 读取的条件，清除后唤醒等待者。
		s.engine.notifyDrain()
	}()
	// Only the first turn executes a historical retest. Follow-up conversation
	// turns may explain the sealed result; the result tool refuses to overwrite it.
	finishStatus, finishReason := "failed", convRetestFailedToStart
	// 应用内通知：AI 回复回合结束。runConversationTurn 是聊天、复测、触发器
	// 三类会话共用的唯一收敛点，挂在这里既不会漏（所有入口都经过）也不会重
	// （一个回合只 defer 一次）。finishStatus 在返回前已定型，defer 读到的就是
	// 最终结果。
	defer func() {
		if c != nil {
			emitChatMilestone(c.ID, c.Title, finishStatus, finishReason)
		}
	}()
	// 时间线检查点（批次 6 / #29–#35）：回合结束点。回滚到它 = 丢弃此后的一切
	// （可见时间线与 LLM 上下文同步回退）。注册在清理 defer 之后 → 先于清理执行，
	// 此时本回合全部活动行（含错误行）都已落库。
	defer func() {
		s.captureConversationCheckpointNow(c, db.CheckpointReasonTurnComplete,
			"回合结束："+convFinishLabel(finishStatus))
	}()
	if c.AgentKey == db.VerifierAgentKey {
		// 复核会话的封存与复测同构，只是结论落到 findings.validation。差别在于
		// 「读不到记录」时不按会话 id 兜底：验证记录的 finding_id 是唯一真相，
		// 而 FailPendingVerificationForConversation 正是按会话补齐这条路。
		v, err := s.m.pg.FindingVerificationForConversation(context.Background(), c.ID)
		if err != nil {
			log.Printf("[conv %d] load verification: %v", c.ID, err)
			if err := s.m.pg.FailPendingVerificationForConversation(c.ID, convVerifyStatusReadFailed); err != nil {
				log.Printf("[conv %d] seal verification: %v", c.ID, err)
			}
			return
		}
		if v != nil && v.Status == "pending" {
			defer func() {
				if ctx.Err() != nil {
					finishStatus, finishReason = "stopped", convVerifyStoppedOrClosed
				}
				// 第六阶段：结论由引擎从最终回复解析并落库（模型已无写结论工具）。
				s.captureVerificationVerdict(c.ID)
				s.finishVerification(v.ID, finishStatus, finishReason)
			}()
			if ctx.Err() != nil {
				return
			}
			started, err := s.m.pg.StartFindingVerification(ctx, v.ID)
			if err != nil {
				finishReason = err.Error()
				return
			}
			if !started {
				return
			}
		}
	}
	if c.AgentKey == db.FindingRetestAgentKey {
		// Read without the run cancellation so an immediate stop still seals pending.
		r, err := s.m.pg.FindingRetestForConversation(context.Background(), c.ID)
		if err != nil {
			// The sealing defer below needs r.ID, which we do not have here. Seal by
			// conversation instead, otherwise the row stays 'pending' forever.
			log.Printf("[conv %d] load retest: %v", c.ID, err)
			if err := s.m.pg.FailPendingRetestForConversation(c.ID, convRetestStatusReadFailed); err != nil {
				log.Printf("[conv %d] seal retest: %v", c.ID, err)
			}
			return
		}
		if r != nil && r.Status == "pending" {
			defer func() {
				if ctx.Err() != nil {
					finishStatus, finishReason = "stopped", convRetestStoppedOrClosed
				}
				// 第六阶段：同上，复测结论由引擎解析落库。
				s.captureRetestVerdict(c.ID)
				s.finishRetest(r.ID, finishStatus, finishReason)
			}()
			if ctx.Err() != nil {
				return
			}
			started, err := s.m.pg.StartFindingRetest(ctx, r.ID)
			if err != nil {
				finishReason = err.Error()
				return
			}
			if !started {
				return
			}
		}
	}
	if ctx.Err() != nil {
		return
	}
	// precedence: the conversation agent's own binding → this conversation's pin → global.
	ca := s.resolveChatAgent(c)
	if ca == nil {
		finishReason = s.chatUnavailableReason()
		return
	}
	pg := s.m.pg
	maxTurns := s.agentMaxTurns(c.AgentKey)
	maxDuration := time.Duration(s.agentRunSeconds(c.AgentKey)) * time.Second
	webSearch := false
	if a, err := pg.GetAgentByKey(c.AgentKey); err == nil && a != nil {
		webSearch = a.WebSearch
	}
	// 会话级 Token 预算（控制台聊天与 Harness 共用这条路径）。
	// 默认值来自系统设置，用户不配置也有刹车；mode=warn 只显示不拦截。
	budgetLimit := int64(s.m.DefaultConvTokenBudget())
	// 与任务级预算的边界：带 task 归因的 run（触发器 / 复测 / reporter）由
	// server/engine.go checkTokenBudget 负责。这里不再挂第二道闸——否则同一笔消耗
	// 会被两个口径不同的预算各判一次，出问题时没人说得清是谁停的。
	if llmrec.TaskIDFrom(ctx) != "" {
		budgetLimit = 0
	}
	var budgetBase int64
	if n, err := pg.ConvTokenTotal(c.ID); err == nil {
		budgetBase = n
	}
	ledger := agent.NewConvLedger(c.ID, budgetLimit, s.m.ConvBudgetMode(), budgetBase)
	ledger.SetStop(func() { cancel(agent.AbortChatBudgetExhausted) })
	ctx = agent.WithConvLedger(ctx, ledger)
	// 预降级：本轮开始前已接近上限（tight）→ 先关掉最贵的能力，把预算留给收尾。
	webSearchOff := false
	if ledger.Tier() == "tight" {
		// 降级必须可见：关掉联网搜索这件事会写一条系统记录，不做静默能力削除。
		webSearchOff = webSearch
		webSearch = false
	}
	sessionID := s.convBusyKey(c.ID) // "conv-<id>" transcript session
	emit := func(rec db.Activity) {
		if _, err := pg.AppendConvActivity(c.ID, rec); err != nil {
			log.Printf("[conv %d] append activity failed: %v", c.ID, err)
		}
	}
	if webSearchOff {
		emit(db.Activity{Worker: "system", Kind: "text",
			Summary: "会话预算已用到 85% 以上：本轮关闭联网搜索，优先把已有证据收尾（不是故障，可在系统配置调整预算）"})
	}
	// On a manual stop ctx is cancelled; Chat already emits a clean "已手动停止"
	// step, so skip the raw-error entry — only surface genuine failures.
	if _, err := ca.Chat(ctx, c.AgentKey, sessionID, msg, maxTurns, maxDuration, webSearch, emit); err != nil {
		finishReason = err.Error()
		// 预算越线是「预期内的停止」，不是故障：写结构化终止记录而不是原始错误。
		if ledger.Exhausted() {
			finishStatus, finishReason = "stopped", "budget_exhausted"
			s.emitConvBudgetStop(pg, c.ID, ledger.Used(), budgetLimit)
		} else if ctx.Err() == nil {
			_, _ = pg.AppendConvActivity(c.ID, db.Activity{Worker: c.AgentKey, Kind: "text", IsError: true,
				Summary: transcriptErrorSummary("", err.Error()), Detail: err.Error()})
		}
	} else {
		finishStatus, finishReason = "completed", ""
	}
	_ = pg.TouchConversation(c.ID)
}

// triggerBehavior is an agent's cached P3 trigger post-processing策略 (see the
// agents table trigger_* columns). Read once per fire in StartTriggeredRun so the
// pump never touches the DB while holding queueMu.
type triggerBehavior struct {
	runMode     string // serial | parallel
	mergeMode   string // by_task | all | none (serial 用;parallel 忽略,每条各自一个会话)
	maxParallel int    // parallel 用的每 agent 并发上限;<=0=不限
}

// readTriggerBehavior loads an agent's策略, falling back to safe defaults
// (serial / all / 5) on any error or unknown enum value.
func (s *Server) readTriggerBehavior(agentKey string) triggerBehavior {
	b := triggerBehavior{runMode: "serial", mergeMode: "all", maxParallel: 5}
	if s.m.pg == nil {
		return b
	}
	a, err := s.m.pg.GetAgentByKey(agentKey)
	if err != nil || a == nil {
		return b
	}
	if a.TriggerRunMode == "parallel" {
		b.runMode = "parallel"
	}
	switch a.TriggerMergeMode {
	case "by_task", "all", "none":
		b.mergeMode = a.TriggerMergeMode
	}
	b.maxParallel = a.TriggerMaxParallel
	return b
}

// StartTriggeredRun enqueues a P3 trigger fire for agentKey and pumps the queue. The
// agent's策略 decides concurrency + merge: serial → run one at a time (optionally
// merging by task / all / none); parallel → run each fire in its own concurrent
// conversation up to trigger_max_parallel. Distinct agents always run concurrently.
func (s *Server) StartTriggeredRun(agentKey, title, message string, taskID int64, mergeable bool, taskDesc, taskGoal string) {
	if s.m.pg == nil || s.chatAgentRef() == nil {
		return
	}
	cfg := s.readTriggerBehavior(agentKey) // DB read BEFORE the lock (never under queueMu)
	s.queueMu.Lock()
	s.triggerCfg[agentKey] = cfg
	s.triggerQ[agentKey] = append(s.triggerQ[agentKey], triggeredRun{agentKey: agentKey, title: title, message: message, taskID: taskID, taskDesc: taskDesc, taskGoal: taskGoal, mergeable: mergeable})
	s.pumpLocked(agentKey)
	s.queueMu.Unlock()
}

// pumpLocked launches queued fires for one agent up to its concurrency limit, then
// returns. Serial → limit 1; parallel → limit = maxParallel (<=0 → unlimited). Each
// launched run re-pumps on completion (runAndPump) to fill the freed slot. Caller
// holds queueMu.
func (s *Server) pumpLocked(agentKey string) {
	if s.ctx.Err() != nil {
		return
	}
	cfg := s.triggerCfg[agentKey]
	limit := 1
	if cfg.runMode == "parallel" {
		if cfg.maxParallel <= 0 {
			limit = math.MaxInt
		} else {
			limit = cfg.maxParallel
		}
	}
	for s.triggerActive[agentKey] < limit && len(s.triggerQ[agentKey]) > 0 {
		item := s.nextTriggerRun(agentKey, cfg)
		s.triggerActive[agentKey]++
		go s.runAndPump(agentKey, item)
	}
}

// runAndPump runs one fire to completion, then decrements the active counter and
// re-pumps to fill the freed slot (cleaning up the agent's maps when fully idle).
func (s *Server) runAndPump(agentKey string, item triggeredRun) {
	s.runTriggeredRun(item)
	s.queueMu.Lock()
	s.triggerActive[agentKey]--
	if s.triggerActive[agentKey] <= 0 && len(s.triggerQ[agentKey]) == 0 {
		delete(s.triggerActive, agentKey)
		delete(s.triggerQ, agentKey)
		delete(s.triggerCfg, agentKey)
	} else {
		s.pumpLocked(agentKey)
	}
	s.queueMu.Unlock()
}

// nextTriggerRun pops the next run from the agent's queue per the merge mode:
//
//	parallel / none → one head item, no merge
//	by_task         → head + all queued same-task mergeable fires merged into one
//	all             → the ENTIRE queue merged into one run (regardless of task/type)
//
// Caller holds queueMu.
func (s *Server) nextTriggerRun(agentKey string, cfg triggerBehavior) triggeredRun {
	q := s.triggerQ[agentKey]
	if cfg.runMode == "parallel" || cfg.mergeMode == "none" {
		s.triggerQ[agentKey] = q[1:]
		return q[0]
	}
	if cfg.mergeMode == "all" {
		s.triggerQ[agentKey] = q[:0:0]
		return mergeAllRuns(q)
	}
	// by_task: head + same-task mergeable fires.
	head := q[0]
	if !head.mergeable || head.taskID == 0 {
		s.triggerQ[agentKey] = q[1:]
		return head
	}
	group := []triggeredRun{head}
	rest := q[:0:0] // keep non-matching items in order
	for _, it := range q[1:] {
		if it.mergeable && it.taskID == head.taskID {
			group = append(group, it)
		} else {
			rest = append(rest, it)
		}
	}
	s.triggerQ[agentKey] = rest
	return mergeTriggeredRuns(group)
}

// P3 触发消息合成（taskContextHeader、finalTriggerMessage、mergeTriggeredRuns、
// mergeAllRuns）保留中文 framing。消息既进入 runTriggeredRun → ca.Chat 的 user 输入，
// 也作为 kind=user 的 AppendConvActivity 显示，不能改动模型与转录的共享格式。
// 保留【任务 …】、【本会话合并了…请一并处理】、── 触发 N ── 与合并标题。
// trigger_merge_test.go 固定【任务 #、── 触发、共 N 个任务、【本会话合并了、（目标：。
// taskContextHeader 每个任务只生成一次描述与目标，避免同任务重复事件使长目标乘倍膨胀。
// interval、none 触发的 taskID==0 时返回空字符串，描述、目标会截断以限制单个块大小。
func taskContextHeader(taskID int64, desc, goal string) string {
	if desc == "" && goal == "" {
		// No task context to show (interval/none fire, or a merged run that already
		// embedded its per-task headers and cleared these fields).
		return ""
	}
	if goal != "" {
		return fmt.Sprintf("【任务 #%d %s（目标：%s）】", taskID, trunc(desc, 200), trunc(goal, 500))
	}
	return fmt.Sprintf("【任务 #%d %s】", taskID, trunc(desc, 200))
}

// finalTriggerMessage renders the message actually sent to the agent for a single
// (non-merged) fire: the task-context header (written once) followed by the event
// body. Merged runs embed their per-task headers inline and clear taskDesc/taskGoal,
// so this returns their message unchanged.
func finalTriggerMessage(item triggeredRun) string {
	if h := taskContextHeader(item.taskID, item.taskDesc, item.taskGoal); h != "" {
		return h + "\n" + item.message
	}
	return item.message
}

// mergeTriggeredRuns folds several same-task event fires into one run: the shared
// task-context header written ONCE, then each fire's event body, so the agent handles
// the task's burst in a single conversation without repeating the (possibly long)
// task description/goal per event.
func mergeTriggeredRuns(items []triggeredRun) triggeredRun {
	if len(items) == 1 {
		return items[0]
	}
	first := items[0]
	var b strings.Builder
	fmt.Fprintf(&b, "【本会话合并了任务 #%d 的 %d 条触发事件，请一并处理】\n", first.taskID, len(items))
	if h := taskContextHeader(first.taskID, first.taskDesc, first.taskGoal); h != "" {
		fmt.Fprintf(&b, "%s\n", h) // same task → task context appears once
	}
	for i, it := range items {
		fmt.Fprintf(&b, "\n── 触发 %d ──\n%s\n", i+1, it.message)
	}
	return triggeredRun{
		agentKey:  first.agentKey,
		title:     fmt.Sprintf("合并触发 task#%d（%d 条）", first.taskID, len(items)),
		message:   b.String(),
		taskID:    first.taskID,
		mergeable: true,
		// taskDesc/taskGoal left empty: header already embedded above.
	}
}

// mergeAllRuns folds the ENTIRE queued burst into one run (merge_mode='all'),
// regardless of type. Events are grouped by task (tasks in first-appearance order,
// events in their original order within a task), so each task's context header — and
// its possibly long description/goal — is written exactly ONCE even when fires from
// different tasks interleave in the queue. Cross-task chronology is not preserved
// (event bodies carry no timestamps, so per-task grouping reads better for the agent).
func mergeAllRuns(items []triggeredRun) triggeredRun {
	if len(items) == 1 {
		return items[0]
	}
	first := items[0]
	order := []int64{}
	groups := map[int64][]triggeredRun{}
	for _, it := range items {
		if _, seen := groups[it.taskID]; !seen {
			order = append(order, it.taskID)
		}
		groups[it.taskID] = append(groups[it.taskID], it)
	}
	var b strings.Builder
	fmt.Fprintf(&b, "【本会话合并了队列中的 %d 条触发事件（共 %d 个任务），请一并处理】\n", len(items), len(order))
	seq := 0
	for _, tid := range order {
		g := groups[tid]
		if h := taskContextHeader(tid, g[0].taskDesc, g[0].taskGoal); h != "" {
			fmt.Fprintf(&b, "\n%s\n", h) // same task → context appears once, even if interleaved
		}
		for _, it := range g {
			seq++
			fmt.Fprintf(&b, "\n── 触发 %d（task#%d）──\n%s\n", seq, tid, it.message)
		}
	}
	// 归因:账本里的 task_id 必须唯一指向一个任务,跨任务合并(且含无任务的
	// interval 触发)时任意选一个都会把消耗记错账,故只在全体同任务时保留。
	mergedTaskID := int64(0)
	if len(order) == 1 && order[0] > 0 {
		mergedTaskID = order[0]
	}
	return triggeredRun{
		agentKey:  first.agentKey,
		title:     fmt.Sprintf("合并触发（全部 %d 条）", len(items)),
		message:   b.String(),
		taskID:    mergedTaskID,
		mergeable: true,
		// taskDesc/taskGoal left empty: per-task headers already embedded above.
	}
}

// runTriggeredRun creates the conversation for one queued fire, records the human
// turn, and runs it synchronously (blocks until the run ends). recover keeps a
// panic from killing the drain loop and wedging the agent's queue.
func (s *Server) runTriggeredRun(item triggeredRun) {
	defer func() {
		if r := recover(); r != nil {
			log.Printf("[trigger] run for %s panicked: %v", item.agentKey, r)
		}
	}()
	pg := s.m.pg
	c, err := pg.CreateConversation(item.agentKey, firstLine(item.title, 60), nil)
	if err != nil {
		log.Printf("[trigger] create conversation for %s failed: %v", item.agentKey, err)
		return
	}
	msg := finalTriggerMessage(item) // prepend the task-context header for single (non-merged) fires
	if _, err := pg.AppendConvActivity(c.ID, db.Activity{Worker: item.agentKey, Kind: "user", Summary: firstLine(msg, 200), Detail: msg}); err != nil {
		log.Printf("[trigger] append msg failed: %v", err)
	}
	busyKey := s.convBusyKey(c.ID)
	s.chatMu.Lock()
	s.chatBusy[busyKey] = true
	s.chatMu.Unlock()
	// 归因补齐:触发器会话(如 reporter)此前在用量台账里 task_id/worker 双缺，
	// 成本无法归因。这里把触发事件里的 task id(interval 触发为 0=无任务)与本
	// agent 的泳道一起显式传播进 llmrec；跨任务合并触发的 taskID 已在
	// mergeAllRuns 里归零,避免把消耗记到某一个任务头上。
	taskID := ""
	if item.taskID > 0 {
		taskID = strconv.FormatInt(item.taskID, 10)
	}
	s.runConversationSync(c, msg, busyKey, conversationAttribution{taskID: taskID, worker: item.agentKey})
}

// firstLine returns a single-line, length-capped preview (shared with summaries).
func firstLine(s string, max int) string {
	s = strings.TrimSpace(s)
	if i := strings.IndexAny(s, "\r\n"); i >= 0 {
		s = s[:i]
	}
	if len([]rune(s)) > max {
		s = string([]rune(s)[:max]) + "…"
	}
	return s
}
