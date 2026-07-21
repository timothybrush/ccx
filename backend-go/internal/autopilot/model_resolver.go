package autopilot

import (
	"fmt"
	"strings"
	"time"

	"github.com/BenedictKing/ccx/internal/config"
	"github.com/BenedictKing/ccx/internal/metrics"
)

// ── CapabilityFloor 能力下界 ──

// CapabilityFloor 描述请求对候选模型的能力要求。
// 上下文、推理、视觉和工具调用是硬约束；质量档是优先目标，
// 仅在没有满足目标质量的模型时允许降档兜底。
type CapabilityFloor struct {
	MinContextTokens int         // 最小上下文窗口（0=不限）
	NeedsReasoning   bool        // 必须支持推理
	NeedsVision      bool        // 必须支持视觉
	NeedsToolCalls   bool        // 必须支持工具调用
	MinQualityTier   QualityTier // 目标质量档（无同档候选时允许降档）
}

// BuildCapabilityFloorFromRequestProfile 从 RequestProfile 推导能力下界。
// 复用 RequestProfile 已有的 QualityNeed/ContextNeed/VisionNeed/ToolUseNeed/ReasoningNeed，
// 零额外计算。
func BuildCapabilityFloorFromRequestProfile(profile *RequestProfile) CapabilityFloor {
	if profile == nil {
		return CapabilityFloor{}
	}
	return CapabilityFloor{
		MinContextTokens: profile.ContextNeed,
		NeedsReasoning:   profile.ReasoningNeed,
		NeedsVision:      profile.VisionNeed,
		NeedsToolCalls:   profile.ToolUseNeed,
		MinQualityTier:   requestQualityTarget(profile),
	}
}

func requestQualityTarget(profile *RequestProfile) QualityTier {
	if profile == nil {
		return ""
	}
	if profile.QualityTarget != "" {
		return profile.QualityTarget
	}
	return ResolveQualityTarget(profile)
}

// ── ModelResolver 模型自动映射器 ──

// ModelResolver 实现设计 doc §5.4 的模型自动映射逻辑。
// 当请求模型在渠道 supportedModels 中不存在时，从 ModelProfileStore 中
// 找到满足 CapabilityFloor 的最佳匹配模型。
//
// 仅对 AutoManaged==true 的渠道生效；手动配置渠道通过 config.RedirectModel
// 直接短路，不经过自动映射。
type ModelResolver struct {
	profileStore *ModelProfileStore
	cfgManager   *config.ConfigManager
}

// NewModelResolver 创建 ModelResolver。
// profileStore 为 nil 时所有自动映射退化为 no-op（fail-open）。
func NewModelResolver(profileStore *ModelProfileStore, cfgManager *config.ConfigManager) *ModelResolver {
	return &ModelResolver{
		profileStore: profileStore,
		cfgManager:   cfgManager,
	}
}

// ResolveModel 将请求模型映射到渠道实际支持的最佳模型。
//
// 返回:
//   - mappedModel: 映射后的模型名（可能与 requestModel 相同）
//   - resolved: true 表示成功映射，false 表示该渠道无满足下界的模型
//   - reason: 决策原因（用于 trace / 日志）
//
// 安全不变量:
//   - 显式 modelMapping（用户手动配置）始终优先，不经过能力下界检查
//   - 禁止链式映射：candidate 源始终是原始 GetModelProfiles 结果
//   - 仅 autoManaged 渠道走自动映射；手动渠道由 config.RedirectModel 短路
//   - 只有 ModelRoutingPolicy 白名单入口允许跨模型替代；其余请求必须精确命中模型 ID
func (r *ModelResolver) ResolveModel(
	requestModel string,
	channelUID string,
	channelKind string,
	metricsKey string,
	floor CapabilityFloor,
) (mappedModel string, resolved bool, reason string) {

	// Step 1: 显式 modelMapping（精确 → 模糊）始终优先。
	// 手动配置视为已知正确，不经过能力下界检查（设计 doc 安全边界）。
	if r.cfgManager != nil {
		upstream := r.findUpstream(channelUID, channelKind)
		if upstream != nil && !upstream.AutoManaged {
			redirected, matched := config.RedirectModelWithMatch(requestModel, upstream)
			if matched && redirected != requestModel {
				return redirected, true, "manual_redirect"
			}
		}
	}

	// Step 2: 无 ModelProfileStore 时自动映射不可用，fail-open。
	if r.profileStore == nil {
		return requestModel, false, "model_profile_store_unavailable"
	}

	// Step 3: 查询候选模型画像。
	candidates := r.profileStore.GetModelProfiles(channelUID, channelKind, metricsKey)
	if len(candidates) == 0 {
		return requestModel, false, "no_model_profiles"
	}
	candidates = r.refreshAutoDiscoveryCapabilities(candidates, channelUID, channelKind)

	// Step 4: 能力过滤——上下文、推理、视觉、工具调用仍是硬约束；
	// 质量档作为首选条件，只有更高质量候选完全不存在时才允许降档，
	// 避免“没有 Opus 等价模型就整条请求不可用”。
	qualityFallback := false
	// CapabilityFloorEnabled=false 时跳过硬过滤（紧急逃生口，所有候选均可参与排序）。
	if r.cfgManager != nil {
		routingCfg := r.cfgManager.GetAutopilotRouting()
		if !routingCfg.ModelMapping.CapabilityFloorEnabled {
			// 仅过滤掉未验证的模型，不做能力下界检查。
			probeEligible := filterProbedModelProfiles(candidates)
			if len(probeEligible) == 0 {
				return requestModel, false, "no_probed_model"
			}
			candidates = probeEligible
		} else {
			candidates, qualityFallback = filterByCapabilityFloorWithQualityFallback(candidates, floor)
		}
	} else {
		candidates, qualityFallback = filterByCapabilityFloorWithQualityFallback(candidates, floor)
	}
	if len(candidates) == 0 {
		return requestModel, false, "no_capable_model"
	}

	// Step 5: 精确模型始终优先；非自适应入口不得跨模型替代。
	if exact, found := findExactModelProfile(candidates, requestModel); found {
		return exact.ModelID, true, modelResolutionReason("found_exact_model_in_profile", qualityFallback)
	}
	if equivalent, found := findEquivalentModelProfile(candidates, requestModel); found {
		return equivalent.ModelID, true, modelResolutionReason("found_equivalent_model_in_profile", qualityFallback)
	}
	intent := ClassifyModelRoutingIntent(channelKind, requestModel)
	if !intent.AllowsSubstitution() {
		return requestModel, false, "exact_model_required"
	}

	// Step 6: 自适应入口在满足下界的候选中按模型质量、实测表现和成本选优。
	best := r.rankEligibleModels(candidates, requestModel, channelUID, channelKind)
	baseReason := fmt.Sprintf("mapped %s->%s (intent:%s, %s)",
		requestModel, best.profile.ModelID, intent, best.reasonSummary())
	return best.profile.ModelID, true, modelResolutionReason(baseReason, qualityFallback)
}

// ResolveModelAnyEndpoint 在渠道的所有 endpoint 中判断 requestModel 是否可由自动映射支持。
// 不限定 metricsKey，适用于调度器候选筛选阶段（此时无具体 API Key）。
// 精确命中已发现模型时直接返回该模型；未命中时从该渠道所有已探测成功模型中选一个
// request-scoped 候选，避免 autoManaged 渠道在进入 EndpointAttemptPolicy 前被 active_model_filter 误剔除。
// 真正发送请求前仍会用带 metricsKey 和完整 CapabilityFloor 的 ResolveModel 再做一次 endpoint 级决策。
func (r *ModelResolver) ResolveModelAnyEndpoint(
	requestModel string,
	channelUID string,
	channelKind string,
) (mappedModel string, found bool, reason string) {
	return r.resolveModelAnyEndpoint(requestModel, channelUID, channelKind, CapabilityFloor{})
}

// ResolveModelAnyEndpointWithFloor 在渠道所有 endpoint 中查找满足完整能力下界的映射。
// 该方法只读且不修改配置，可供 dry-run 诊断和 scheduler 首次候选过滤复用。
func (r *ModelResolver) ResolveModelAnyEndpointWithFloor(
	requestModel string,
	channelUID string,
	channelKind string,
	floor CapabilityFloor,
) (mappedModel string, found bool, reason string) {
	return r.resolveModelAnyEndpoint(requestModel, channelUID, channelKind, floor)
}

func (r *ModelResolver) resolveModelAnyEndpoint(
	requestModel string,
	channelUID string,
	channelKind string,
	floor CapabilityFloor,
) (mappedModel string, found bool, reason string) {
	if r.profileStore == nil {
		return requestModel, false, "model_profile_store_unavailable"
	}

	candidates := make([]ModelProfile, 0)
	all := r.profileStore.ListActiveByChannel(channelUID)
	for _, p := range all {
		if p.ChannelKind != channelKind {
			continue
		}
		if !p.ProbeSuccess {
			continue
		}
		candidates = append(candidates, p)
	}
	if len(candidates) == 0 {
		return requestModel, false, "no_probed_model_profiles"
	}
	candidates = r.refreshAutoDiscoveryCapabilities(candidates, channelUID, channelKind)

	qualityFallback := false
	if r.cfgManager != nil {
		routingCfg := r.cfgManager.GetAutopilotRouting()
		if routingCfg.ModelMapping.CapabilityFloorEnabled {
			candidates, qualityFallback = filterByCapabilityFloorWithQualityFallback(candidates, floor)
		}
	} else {
		candidates, qualityFallback = filterByCapabilityFloorWithQualityFallback(candidates, floor)
	}
	if len(candidates) == 0 {
		return requestModel, false, "no_capable_model"
	}
	if exact, found := findExactModelProfile(candidates, requestModel); found {
		return exact.ModelID, true, modelResolutionReason("found_exact_model_in_profile", qualityFallback)
	}
	if equivalent, found := findEquivalentModelProfile(candidates, requestModel); found {
		return equivalent.ModelID, true, modelResolutionReason("found_equivalent_model_in_profile", qualityFallback)
	}
	intent := ClassifyModelRoutingIntent(channelKind, requestModel)
	if !intent.AllowsSubstitution() {
		return requestModel, false, "exact_model_required"
	}

	best := r.rankEligibleModels(candidates, requestModel, channelUID, channelKind)
	baseReason := fmt.Sprintf("mapped_any_endpoint %s->%s (intent:%s, %s)",
		requestModel, best.profile.ModelID, intent, best.reasonSummary())
	return best.profile.ModelID, true, modelResolutionReason(baseReason, qualityFallback)
}

// ── 过滤与排序 ──

// filterByCapabilityFloor 只保留满足所有能力下界约束的模型。
// 与 capability_floor.go 的 CapabilityFloorReasons 逻辑一致，
// 但作用于 ModelProfile（而非 CandidateCapabilities），并额外检查 QualityTier。
func filterByCapabilityFloor(profiles []ModelProfile, floor CapabilityFloor) []ModelProfile {
	return filterByCapabilityFloorInternal(profiles, floor, true)
}

// filterByCapabilityFloorWithoutQuality 保留所有真实能力约束，仅跳过质量档约束。
// 用于“高档候选不存在时”的用户体验兜底；不会放行上下文或工具能力不足的模型。
func filterByCapabilityFloorWithoutQuality(profiles []ModelProfile, floor CapabilityFloor) []ModelProfile {
	return filterByCapabilityFloorInternal(profiles, floor, false)
}

// filterByCapabilityFloorWithQualityFallback 先按完整能力目标筛选；若仅质量档
// 导致无候选，则保留所有真实能力硬约束并允许质量降档。
func filterByCapabilityFloorWithQualityFallback(profiles []ModelProfile, floor CapabilityFloor) ([]ModelProfile, bool) {
	eligible := filterByCapabilityFloor(profiles, floor)
	if len(eligible) > 0 || floor.MinQualityTier == "" {
		return eligible, false
	}
	fallback := filterByCapabilityFloorWithoutQuality(profiles, floor)
	return fallback, len(fallback) > 0
}

func filterProbedModelProfiles(profiles []ModelProfile) []ModelProfile {
	eligible := make([]ModelProfile, 0, len(profiles))
	for _, profile := range profiles {
		if profile.ProbeSuccess {
			eligible = append(eligible, profile)
		}
	}
	return eligible
}

func filterByCapabilityFloorInternal(profiles []ModelProfile, floor CapabilityFloor, enforceQuality bool) []ModelProfile {
	var eligible []ModelProfile
	for _, p := range profiles {
		// 未验证通过的模型不参与自动映射
		if !p.ProbeSuccess {
			continue
		}
		if p.ContextTokens < floor.MinContextTokens {
			continue
		}
		if floor.NeedsReasoning && !p.SupportsReasoning {
			continue
		}
		if floor.NeedsVision && !p.SupportsVision {
			continue
		}
		if floor.NeedsToolCalls && !p.SupportsToolCalls {
			continue
		}
		if enforceQuality && qualityTierRank(p.QualityTier) < qualityTierRank(floor.MinQualityTier) {
			continue
		}
		eligible = append(eligible, p)
	}
	return eligible
}

// modelResolutionReason 标记发生了质量降档，但不改变现有调用方的映射结果。
func modelResolutionReason(reason string, qualityFallback bool) string {
	if !qualityFallback {
		return reason
	}
	return "quality_fallback: " + reason
}

// rankedModelCandidate 保存模型选优所需的软证据。
// 上下文窗口不在这里评分；它只在 CapabilityFloor 阶段作为硬下限使用。
type rankedModelCandidate struct {
	profile               ModelProfile
	qualityRank           int
	measuredQualityScore  float64
	latencyKnown          bool
	latencyMs             int64
	costKnown             bool
	normalizedCostUSD     float64
	sameFamily            bool
	normalizedCandidateID string
}

func (candidate rankedModelCandidate) reasonSummary() string {
	measuredQuality := "unknown"
	if candidate.profile.ProviderQualityConfidence >= 0.5 {
		measuredQuality = fmt.Sprintf("%.3f", candidate.measuredQualityScore)
	}
	latency := "unknown"
	if candidate.latencyKnown {
		latency = fmt.Sprintf("%dms", candidate.latencyMs)
	}
	cost := "unknown"
	if candidate.costKnown {
		cost = fmt.Sprintf("%.6f", candidate.normalizedCostUSD)
	}
	return fmt.Sprintf("family:%s, quality:%s, measured_quality:%s, latency:%s, normalized_cost_usd:%s",
		candidate.profile.ModelFamily, candidate.profile.QualityTier, measuredQuality, latency, cost)
}

// rankEligibleModels 在已经满足能力下界的候选中选择最佳模型。
//
// 排序优先级（高→低）：
//  1. 模型质量档越高越优先；质量目标是准入下限，不再惩罚高于目标的模型
//  2. 带置信度折算的供应商实测质量越高越优先
//  3. 已测延迟优先于未知延迟，同为已测时延迟越低越优先
//  4. 已知公开成本优先于未知成本，同为已知时成本越低越优先
//  5. 同模型族作为兼容性兜底，最后按 model ID 保证确定性
func (r *ModelResolver) rankEligibleModels(
	eligible []ModelProfile,
	requestModel string,
	channelUID string,
	channelKind string,
) rankedModelCandidate {
	reqFamily := InferModelFamily(requestModel, "")
	upstream, global := r.modelRankingCapabilityContext(channelUID, channelKind)

	ranked := make([]rankedModelCandidate, 0, len(eligible))
	for _, profile := range eligible {
		costUSD, costKnown := normalizedModelCostUSD(profile.ModelID, upstream, global)
		ranked = append(ranked, rankedModelCandidate{
			profile:               profile,
			qualityRank:           qualityTierRank(profile.QualityTier),
			measuredQualityScore:  measuredProviderQualityScore(profile),
			latencyKnown:          profile.ProbeLatencyMs > 0,
			latencyMs:             profile.ProbeLatencyMs,
			costKnown:             costKnown,
			normalizedCostUSD:     costUSD,
			sameFamily:            profile.ModelFamily == reqFamily,
			normalizedCandidateID: strings.ToLower(profile.ModelID),
		})
	}

	best := ranked[0]
	for i := 1; i < len(ranked); i++ {
		if betterRankedModel(ranked[i], best) {
			best = ranked[i]
		}
	}
	return best
}

func betterRankedModel(candidate, current rankedModelCandidate) bool {
	if candidate.qualityRank != current.qualityRank {
		return candidate.qualityRank > current.qualityRank
	}
	if candidate.measuredQualityScore != current.measuredQualityScore {
		return candidate.measuredQualityScore > current.measuredQualityScore
	}
	if candidate.latencyKnown != current.latencyKnown {
		return candidate.latencyKnown
	}
	if candidate.latencyKnown && candidate.latencyMs != current.latencyMs {
		return candidate.latencyMs < current.latencyMs
	}
	if candidate.costKnown != current.costKnown {
		return candidate.costKnown
	}
	if candidate.costKnown && candidate.normalizedCostUSD != current.normalizedCostUSD {
		return candidate.normalizedCostUSD < current.normalizedCostUSD
	}
	if candidate.sameFamily != current.sameFamily {
		return candidate.sameFamily
	}
	return candidate.normalizedCandidateID < current.normalizedCandidateID
}

// measuredProviderQualityScore 将供应商实测质量按置信度向 0.5 中性值收缩。
// 无可信观测时保持中性，避免零值被误判为最差质量。
func measuredProviderQualityScore(profile ModelProfile) float64 {
	confidence := clampUnit(profile.ProviderQualityConfidence)
	if confidence < 0.5 {
		return 0.5
	}
	quality := clampUnit(profile.ProviderQualityScore)
	return 0.5 + (quality-0.5)*confidence
}

// normalizedModelCostUSD 使用统一的 100 万输入 + 100 万输出作为公开价格比较基准。
// 实际渠道折扣由 endpoint 调度继续处理；这里只用于同一 endpoint 内的模型选优。
func normalizedModelCostUSD(
	modelID string,
	upstream *config.UpstreamConfig,
	global map[string]config.UpstreamModelCapability,
) (float64, bool) {
	resolved := config.ResolveUpstreamCapability(modelID, upstream, global)
	if !resolved.Known || !hasKnownModelPricing(resolved.Capability.Pricing) {
		return 0, false
	}
	cost := metrics.CalculateTokenCostUSDWithPricing(
		resolved.Capability.Pricing,
		1_000_000,
		1_000_000,
		0,
		0,
	)
	return cost, true
}

func hasKnownModelPricing(pricing *config.ModelPricing) bool {
	if pricing == nil {
		return false
	}
	if pricing.InputCacheHitPrice != nil || pricing.InputCacheMissPrice != nil || pricing.OutputPrice != nil {
		return true
	}
	for _, tier := range pricing.Tiers {
		if tier.InputCacheHitPrice != nil || tier.InputCacheMissPrice != nil || tier.OutputPrice != nil {
			return true
		}
	}
	return false
}

// modelRankingCapabilityContext 返回模型选优使用的能力与价格上下文。
// 自动解析候选已经是 endpoint 的实际模型名，因此清空 ModelMapping，避免价格查询形成链式重定向。
func (r *ModelResolver) modelRankingCapabilityContext(
	channelUID string,
	channelKind string,
) (*config.UpstreamConfig, map[string]config.UpstreamModelCapability) {
	if r.cfgManager == nil {
		return nil, nil
	}
	cfg := r.cfgManager.GetConfig()
	upstream := r.findUpstream(channelUID, channelKind)
	if upstream == nil {
		return nil, cfg.UpstreamModelCapabilities
	}
	upstreamCopy := *upstream
	upstreamCopy.ModelMapping = nil
	return &upstreamCopy, cfg.UpstreamModelCapabilities
}

func absInt(value int) int {
	if value < 0 {
		return -value
	}
	return value
}

// refreshAutoDiscoveryCapabilities 兼容由旧版本写入的自动发现画像。
// 旧实现误用了下游 AgentModelProfile，可能把 GLM-5.2 等上游模型写成错误窗口和能力；
// 运行时以当前上游能力注册表重新派生，后续自动发现会把同样结果持久化。
func (r *ModelResolver) refreshAutoDiscoveryCapabilities(
	candidates []ModelProfile,
	channelUID string,
	channelKind string,
) []ModelProfile {
	if len(candidates) == 0 {
		return candidates
	}

	var upstream *config.UpstreamConfig
	var global map[string]config.UpstreamModelCapability
	if r.cfgManager != nil {
		cfg := r.cfgManager.GetConfig()
		global = cfg.UpstreamModelCapabilities
		upstream = r.findUpstream(channelUID, channelKind)
	}

	refreshed := append([]ModelProfile(nil), candidates...)
	for i := range refreshed {
		profile := &refreshed[i]
		if profile.Source != "auto_discovery" {
			continue
		}
		oldFamily := profile.ModelFamily
		oldQuality := profile.QualityTier
		oldContext := profile.ContextTokens
		oldVision := profile.SupportsVision
		oldTools := profile.SupportsToolCalls
		oldReasoning := profile.SupportsReasoning
		profile.ModelFamily = InferModelFamily(profile.ModelID, "")
		profile.QualityTier = ModelProfileQualityTierFromFamily(profile.ModelFamily, profile.ModelID)
		if resolved := config.ResolveUpstreamCapability(profile.ModelID, upstream, global); resolved.Known {
			applyUpstreamModelCapability(profile, resolved.Capability)
		}
		if oldFamily != profile.ModelFamily || oldQuality != profile.QualityTier ||
			oldContext != profile.ContextTokens || oldVision != profile.SupportsVision ||
			oldTools != profile.SupportsToolCalls || oldReasoning != profile.SupportsReasoning {
			profile.UpdatedAt = time.Now()
			_ = r.profileStore.Upsert(profile)
		}
	}
	return refreshed
}

// ── 辅助 ──

// findUpstream 根据 channelUID 和 channelKind 从 ConfigManager 查找对应的 UpstreamConfig。
// 遍历所有渠道类型列表，匹配 ChannelUID。
// 返回 nil 表示未找到（渠道已删除或 UID 不匹配）。
func (r *ModelResolver) findUpstream(channelUID, channelKind string) *config.UpstreamConfig {
	if r.cfgManager == nil || channelUID == "" {
		return nil
	}
	cfg := r.cfgManager.GetConfig()

	type upstreamList struct {
		channels []config.UpstreamConfig
		kind     string
	}
	lists := []upstreamList{
		{cfg.Upstream, "messages"},
		{cfg.ResponsesUpstream, "responses"},
		{cfg.GeminiUpstream, "gemini"},
		{cfg.ChatUpstream, "chat"},
		{cfg.ImagesUpstream, "images"},
		{cfg.VectorsUpstream, "vectors"},
	}

	for _, ul := range lists {
		if ul.kind != channelKind {
			continue
		}
		for i := range ul.channels {
			if ul.channels[i].ChannelUID == channelUID {
				return &ul.channels[i]
			}
		}
	}
	return nil
}
