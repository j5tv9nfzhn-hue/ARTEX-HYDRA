package server

import (
	"context"
	"fmt"
	"log"
	"time"

	"github.com/Autumn-27/artex/agent"
	"github.com/Autumn-27/artex/db"
	"github.com/Autumn-27/artex/llmpool"
	"github.com/Autumn-27/artex/llmrec"
	"github.com/Autumn-27/norma/llm"
)

// LLM 轮询(故障转移)的服务端接线。设计见 docs/LLM轮询设计.md：
//   - 全局激活配置这条路径(agent 未绑定、任务未 pin)才轮询;
//   - 绑定/pin 的路径默认独占该配置,失败即失败(可由 llm_pool_bind_fallback 打开兜底);
//   - 链序 = 激活配置 → 其余按 priority DESC,排除 pool_exclude 的;
//   - 熔断状态进程级共享(s.llmHealth),重建 pool 不清空。

// newLLMHealthRegistry builds the process-wide circuit-breaker registry, mirroring
// state into PG so a cooling-off window survives a restart. Writes are async and
// best-effort — the in-memory copy is authoritative.
func newLLMHealthRegistry(pg *db.DB) *llmpool.Registry {
	if pg == nil {
		return llmpool.NewRegistry(nil, nil)
	}
	persist := func(id int64, st llmpool.State) {
		h := db.LLMHealth{ProfileID: id, Fails: st.Fails, Trips: st.Trips, LastError: st.LastError}
		if !st.OpenUntil.IsZero() {
			t := st.OpenUntil
			h.OpenUntil = &t
		}
		go func() {
			if err := pg.SaveLLMHealth(h); err != nil {
				log.Printf("[llmpool] 熔断状态落库失败: %v", err)
			}
		}()
	}
	forget := func(id int64) {
		go func() { _ = pg.ClearLLMHealth(id) }()
	}
	reg := llmpool.NewRegistry(persist, forget)
	// Restore only windows that haven't expired (LoadLLMHealth filters), so a
	// profile that finished cooling while we were down comes back healthy.
	if rows, err := pg.LoadLLMHealth(); err == nil {
		for _, h := range rows {
			st := llmpool.State{Fails: h.Fails, Trips: h.Trips, LastError: h.LastError, LastAt: h.LastAt}
			if h.OpenUntil != nil {
				st.OpenUntil = *h.OpenUntil
			}
			reg.Restore(h.ProfileID, st)
			log.Printf("[llmpool] 恢复熔断状态: 配置 #%d 冷却至 %s", h.ProfileID, st.OpenUntil.Format(time.RFC3339))
		}
	}
	return reg
}

// attachMemberQuotaHook 让「链上某个配置额度用尽」在发生的那一刻就落到当前任务的
// 链游标上，而不是等整条链都失败。
//
// 原来的缺口很具体：A 欠费 402 → 轮询切到 B 成功 → 任务照跑，但 task_llm_profiles
// 里 A 仍然是 ready，下一次运行时任务又会先拿 A 去撞一次（有熔断兜着，每次只浪费
// 一次失败，但一天几十次 × 每次最长 50 秒）。成员级标记把这个洞补上：谁的额度没了
// 就记谁，链游标随之前移。
//
// 任务 id 从 ctx 上取（server/task_llm.go 用 llmrec.WithTaskID 挂的）；chat、侧问、
// 连接测试没有任务游标，自然跳过。
func (s *Server) attachMemberQuotaHook(pool *llmpool.Pool) {
	if pool == nil || s.m == nil || s.m.pg == nil {
		return
	}
	pool.SetFailureHook(func(ctx context.Context, profileID int64, err error) {
		if !isQuotaExhaustedError(err) {
			return
		}
		taskID, perr := parseTaskID(llmrec.TaskIDFrom(ctx))
		if perr != nil {
			return
		}
		reason := err.Error()
		if len(reason) > 300 {
			reason = reason[:300] + "…"
		}
		transition, merr := s.m.pg.MarkTaskLLMProfileQuotaExhausted(taskID, profileID, reason)
		if merr != nil {
			log.Printf("[llmpool] 标记配置 #%d 额度耗尽失败(task %d): %v", profileID, taskID, merr)
			return
		}
		next := "（已在链尾）"
		if transition.NextProfileID != nil {
			next = fmt.Sprintf("→ 下一个配置 #%d", *transition.NextProfileID)
		}
		log.Printf("[llmpool] 配置 #%d 额度耗尽，已从任务 %d 的链上摘除 %s", profileID, taskID, next)
		if pt, gerr := s.m.pg.GetTask(taskID); gerr == nil && pt != nil {
			s.syncTaskLLMState(pt)
		}
	})
}

// poolMember builds one chain member from a profile, reusing the per-profile
// provider cache so every agent pointing at the same profile shares one provider
// (hence one rate limiter). Returns nil when the profile can't be built.
func (s *Server) poolMember(p *db.LLMProfile, rank int) *llmpool.Member {
	prov, cfg, ok := s.providerForProfile(p.ID)
	if !ok {
		return nil
	}
	return &llmpool.Member{
		ID: p.ID, Name: p.Name, Model: p.Model, Format: p.Format,
		Priority: p.Priority, Active: p.IsDefault, Rank: rank,
		WindowTokens: cfg.CompactionWindow(), Prov: prov,
	}
}

// poolChain reads the failover chain from the DB. headID/headProv/headCfg describe
// the member that must lead the chain — the globally active profile on the normal
// path, or an explicitly bound one when bound-profile fallback is on. The head is
// passed in (rather than resolved through the cache) so applyLLM's already-built
// provider is reused instead of duplicated.
//
// poolChain preserves the operator-controlled pool behavior. Automatic recovery
// uses the same ordered candidates but is entered only after the primary response
// fails; it does not rotate a healthy primary into a different model.
func (s *Server) poolChain(headID int64, headProv llm.Provider, headCfg agent.Config) *llmpool.Pool {
	return s.buildPoolChain(headID, headProv, headCfg, s.m != nil && s.m.LLMPoolEnabled(), true)
}

func (s *Server) recoveryChain(headID int64, headProv llm.Provider, headCfg agent.Config) *llmpool.Pool {
	return s.buildPoolChain(headID, headProv, headCfg, true, false)
}

func (s *Server) buildPoolChain(headID int64, headProv llm.Provider, headCfg agent.Config, enabled, trackTaskQuota bool) *llmpool.Pool {
	if s.m == nil || s.m.pg == nil || !enabled {
		return nil
	}
	profs, err := s.m.pg.PoolProfiles()
	if err != nil {
		log.Printf("[llmpool] 读取轮询链失败: %v", err)
		return nil
	}
	var head *db.LLMProfile
	for _, p := range profs {
		if p.ID == headID {
			head = p
			break
		}
	}
	if head == nil { // head excluded from the chain (bound + pool_exclude) — still leads
		if p, err := s.m.pg.ProfileByID(headID); err == nil && p != nil {
			head = p
		} else {
			return nil
		}
	}
	members := []*llmpool.Member{{
		ID: head.ID, Name: head.Name, Model: head.Model, Format: head.Format,
		Priority: head.Priority, Active: head.IsDefault, Rank: llmpool.RankActive,
		WindowTokens: headCfg.CompactionWindow(), Prov: headProv,
	}}
	for _, p := range profs {
		if p.ID == headID {
			continue
		}
		// The globally active profile outranks the others when it isn't the head
		// (bound-fallback chains), so it stays the first fallback tried.
		rank := p.Priority
		if p.IsDefault {
			rank = llmpool.RankActive - 1
		}
		if m := s.poolMember(p, rank); m != nil {
			members = append(members, m)
		}
	}
	if len(members) < 2 {
		return nil // nothing to fail over to
	}
	pool := llmpool.New(members, s.llmHealth)
	if trackTaskQuota {
		s.attachMemberQuotaHook(pool)
	}
	return pool
}

// poolForActive keeps the selected profile as the primary and attaches an
// automatic failure-only recovery chain when another eligible profile exists.
func (s *Server) poolForActive(activeID int64, prov llm.Provider, cfg agent.Config) llm.Provider {
	pool := s.poolChain(activeID, prov, cfg)
	if pool == nil {
		pool = s.recoveryChain(activeID, prov, cfg)
	}
	if pool == nil {
		return prov
	}
	names := make([]string, 0, len(pool.Members()))
	for _, m := range pool.Members() {
		names = append(names, m.Name+"/"+m.Model)
	}
	log.Printf("[llmpool] LLM 故障恢复链已接线，链路(%d): %v", len(names), names)
	return pool
}

// poolForBinding keeps a bound profile primary. The optional configured pool may
// add its normal chain; otherwise a failure-only recovery chain is attached
// automatically so response repair does not depend on a per-agent setting.
func (s *Server) poolForBinding(id int64, prov llm.Provider, cfg agent.Config) llm.Provider {
	if s.m != nil && s.m.LLMPoolEnabled() && s.m.LLMPoolBindFallback() {
		if pool := s.poolChain(id, prov, cfg); pool != nil {
			return pool
		}
	}
	if pool := s.recoveryChain(id, prov, cfg); pool != nil {
		return pool
	}
	return prov
}

// agentBindingResolution is the role's explicit binding snapshot: the head
// profile (agents.llm_profile_id) with its built provider/config, plus the
// ordered fallback tail saved in agent_llm_fallbacks.
type agentBindingResolution struct {
	headID      int64
	headProv    llm.Provider
	headCfg     agent.Config
	fallbackIDs []int64
}

// resolveAgentBinding reads the role's binding + fallback tail. ok=false when the
// role has no binding or the bound profile can't build — callers then fall through
// to the task chain, exactly like before this feature existed.
func (s *Server) resolveAgentBinding(role string) (agentBindingResolution, bool) {
	if s.m == nil || s.m.pg == nil || role == "" {
		return agentBindingResolution{}, false
	}
	a, err := s.m.pg.GetAgentByKey(role)
	if err != nil || a == nil || a.LLMProfileID == nil {
		return agentBindingResolution{}, false
	}
	prov, cfg, ok := s.providerForProfile(*a.LLMProfileID)
	if !ok {
		return agentBindingResolution{}, false
	}
	fallbacks, err := s.m.pg.AgentLLMFallbacks(role)
	if err != nil {
		// 读备用链失败按「没有备用链」处理:绑定本身仍可用,不让辅助表的问题把
		// 既有绑定路径拖垮(仅记日志)。
		log.Printf("[llmpool] 读取角色 %s 的备用链失败: %v", role, err)
		fallbacks = nil
	}
	return agentBindingResolution{headID: *a.LLMProfileID, headProv: prov, headCfg: cfg, fallbackIDs: fallbacks}, true
}

// roleHealth returns the private in-memory breaker registry for one agent role,
// creating it on first use. persist/forget are nil on purpose: role chains must
// not write into the shared llm_health table (that table drives the global pool
// status page) and must not share state with other roles or the global chain —
// 角色级故障隔离(计划 #151–152)。
func (s *Server) roleHealth(role string) *llmpool.Registry {
	s.roleHealthMu.Lock()
	defer s.roleHealthMu.Unlock()
	if reg := s.roleHealthByRole[role]; reg != nil {
		return reg
	}
	reg := llmpool.NewRegistry(nil, nil)
	// 熔断阈值来自全局策略;注册表按角色懒创建,创建时读一次 DB 拷入,之后由
	// applyRetryPolicy 在策略保存时推新值(不在热路径上做 DB 读取)。
	pol := s.retryPolicy()
	reg.SetPolicy(pol.Breaker.Attempts, pol.Breaker.Interval())
	if s.roleHealthByRole == nil {
		s.roleHealthByRole = map[string]*llmpool.Registry{}
	}
	s.roleHealthByRole[role] = reg
	return reg
}

// roleFallbackPool builds the role's explicit chain: head = the bound profile,
// tail = the saved fallback entries in position order. Returns nil when there
// are no usable members beyond the head; the caller then attaches its general
// automatic recovery chain if one is available.
//
// Explicit role fallbacks keep their saved order; eligible global profiles are
// appended as an automatic safety tail. Equal-priority automatic candidates may
// rotate, while the head remains first. Each role uses its own breaker registry.
func (s *Server) roleFallbackPool(role string, r agentBindingResolution) *llmpool.Pool {
	if len(r.fallbackIDs) == 0 || s.m == nil || s.m.pg == nil {
		return nil
	}
	head, err := s.m.pg.ProfileByID(r.headID)
	if err != nil || head == nil {
		return nil
	}
	members := []*llmpool.Member{{
		ID: head.ID, Name: head.Name, Model: head.Model, Format: head.Format,
		Priority: head.Priority, Active: head.IsDefault, Rank: llmpool.RankActive,
		WindowTokens: r.headCfg.CompactionWindow(), Prov: r.headProv,
	}}
	used := map[int64]bool{r.headID: true}
	for i, id := range r.fallbackIDs {
		if used[id] {
			continue
		}
		used[id] = true
		p, err := s.m.pg.ProfileByID(id)
		if err != nil || p == nil {
			continue // 配置不存在(删除与查询竞态)→ 跳过,不是硬错误
		}
		if m := s.poolMember(p, llmpool.RankActive-1-i); m != nil {
			members = append(members, m)
		}
	}
	// Add eligible global profiles after the explicitly ordered role fallbacks.
	if profs, err := s.m.pg.PoolProfiles(); err == nil {
		for _, p := range profs {
			if p == nil || used[p.ID] {
				continue
			}
			used[p.ID] = true
			rank := p.Priority
			if p.IsDefault {
				rank = llmpool.RankActive - 1 - len(r.fallbackIDs)
			}
			if m := s.poolMember(p, rank); m != nil {
				members = append(members, m)
			}
		}
	} else {
		log.Printf("[llmpool] 读取角色 %s 的自动恢复候选失败: %v", role, err)
	}
	if len(members) < 2 {
		return nil // 没有角色链备选；调用方仍会尝试通用自动恢复链
	}
	pool := llmpool.New(members, s.roleHealth(role))
	s.attachMemberQuotaHook(pool)
	return pool
}

// LLMPoolMemberStatus is one chain entry as shown in the UI.
type LLMPoolMemberStatus struct {
	ProfileID string `json:"profile_id"`
	Name      string `json:"name"`
	Model     string `json:"model"`
	Format    string `json:"format"`
	// 供应商归属：界面在轮询链上显示「供应商 / 模型」两层，好区分
	// 「换个模型」和「换一家」——两者在故障转移里是不同程度的动作。
	ProviderID   string `json:"provider_id,omitempty"`
	ProviderName string `json:"provider_name,omitempty"`
	Priority     int    `json:"priority"`
	Active       bool   `json:"active"`   // is the globally-activated profile
	Excluded     bool   `json:"excluded"` // pool_exclude — not a failover target
	// Health: state is "ok" | "degraded" (failing but not tripped) | "tripped".
	State        string `json:"state"`
	Fails        int    `json:"fails"`
	Trips        int    `json:"trips"`
	CooldownSecs int    `json:"cooldown_secs"` // remaining cooling-off seconds; 0 = none
	LastError    string `json:"last_error,omitempty"`
	LastAt       string `json:"last_at,omitempty"`
}

// llmPoolStatus reports the whole picture for the LLM page: whether failover is
// on, the resolved chain order, and each profile's breaker state. Excluded
// profiles are listed too (flagged), so the user can see why one isn't in line.
func (s *Server) llmPoolStatus() map[string]any {
	out := map[string]any{
		"enabled":            false,
		"bind_fallback":      false,
		"automatic_recovery": true,
		"chain":              []LLMPoolMemberStatus{},
	}
	if s.m == nil || s.m.pg == nil {
		return out
	}
	out["enabled"] = s.m.LLMPoolEnabled()
	out["bind_fallback"] = s.m.LLMPoolBindFallback()

	all, err := s.m.pg.ListProfiles()
	if err != nil {
		return out
	}
	health := s.llmHealth.Snapshot()
	now := time.Now()
	// Chain order: active first, then priority DESC / id ASC — the same ordering
	// PoolProfiles applies, recomputed here so excluded ones can be shown in place.
	chain := make([]LLMPoolMemberStatus, 0, len(all))
	for _, p := range all {
		st := health[p.ID]
		m := LLMPoolMemberStatus{
			ProfileID: i64s(p.ID), Name: p.Name, Model: p.Model, Format: p.Format,
			ProviderID: i64s(p.ProviderID), ProviderName: p.ProviderName,
			Priority: p.Priority, Active: p.IsDefault, Excluded: p.PoolExclude,
			State: "ok", Fails: st.Fails, Trips: st.Trips,
			LastError: st.LastError,
		}
		if st.Open() {
			m.State = "tripped"
			m.CooldownSecs = int(st.OpenUntil.Sub(now).Seconds()) + 1
		} else if st.Fails > 0 {
			m.State = "degraded"
		}
		if !st.LastAt.IsZero() {
			m.LastAt = st.LastAt.Format(time.RFC3339)
		}
		chain = append(chain, m)
	}
	sortPoolStatus(chain)
	out["chain"] = chain
	return out
}

// sortPoolStatus orders the status rows exactly like the live chain: active first,
// then priority DESC, then id ASC (the incoming slice is already id-ordered, so a
// stable insertion sort on the first two keys is enough).
func sortPoolStatus(in []LLMPoolMemberStatus) {
	for i := 1; i < len(in); i++ {
		for j := i; j > 0 && poolLess(in[j], in[j-1]); j-- {
			in[j], in[j-1] = in[j-1], in[j]
		}
	}
}

func poolLess(a, b LLMPoolMemberStatus) bool {
	if a.Active != b.Active {
		return a.Active
	}
	return a.Priority > b.Priority
}
