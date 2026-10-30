package kb

import (
	"context"
	"encoding/json"
	"fmt"
	"log"
	"sort"
	"strconv"

	"github.com/ontoagents/ontoagents/backend/internal/store"
)

// ---- GraphRAG 子模块（M14 D-KB4 建制；D-O15/REQ-110 起自研实现）----
//
// graphrag 模式的 KB 在向量索引（chunks/embedding，与 rag 共用）之外，把 chunk 抽取为自存 KG
// （store 表 kg_entity / kg_relationship / kg_claim）。抽取器由 api 层注入（internal/kg：
// REQ-98 LLM 能力代理主路径 + 规则抽取回退），kb 包不依赖 chat（chat → kb 已有依赖，反向会成环）。
// 检索（教学口径「前期够教学」）：向量命中 chunk → 提及实体 → KG 一跳扩展 → 实体描述 + claims 拼上下文。
// 任何失败统一降级（M14 ⑥ 语义保留）：抽取 degraded 不阻断导入，检索回退纯向量。

// KGExtractFunc KG 抽取注入签名（docID 为空 = KB 级重建）。
type KGExtractFunc func(ctx context.Context, kbID, docID string, chunks []*store.KnowledgeChunk) *store.GraphragInfo

// SetKGExtractor api 层装配（Service 构造后立即调用；不装配则 graphrag 抽取退化为 degraded，rag 模式不受影响）。
func (s *Service) SetKGExtractor(fn KGExtractFunc) { s.kgExtract = fn }

// GraphragIngest graphrag 模式文档索引成功后抽取 KG 并自存（M14 ② 槽位不变，实现切自研）。
// 永不返回 error：失败封装为 degraded 结果（非阻断，导入主流程已成功）。
// docID 推断：单文档池（Import/Reindex）取 chunks[0].DocID；跨文档池（KB 级重建）置空 = 全量替换。
func (s *Service) GraphragIngest(ctx context.Context, kbID string, chunks []*store.KnowledgeChunk) *store.GraphragInfo {
	if s.kgExtract == nil {
		return &store.GraphragInfo{Degraded: true, Error: "KG 抽取器未装配（内部装配错误）"}
	}
	docID := ""
	if len(chunks) > 0 {
		same := true
		for _, c := range chunks {
			if c.DocID != chunks[0].DocID {
				same = false
				break
			}
		}
		if same {
			docID = chunks[0].DocID
		}
	}
	info := s.kgExtract(ctx, kbID, docID, chunks)
	if info.OK { // 审计留痕（REQ-101 消费/审计页素材）：抽取方式与规模本身即一条决策
		_, err := s.Store.InsertDecision(&store.OntoDecision{
			SubjectKind: "kg",
			SubjectID:   kbID,
			Title:       "KG 抽取（method=" + info.Method + "）",
			Rationale:   "graphrag 模式文档索引联动：chunks=" + strconv.Itoa(info.Chunks) + "，实体=" + strconv.Itoa(info.Entities) + "，关系=" + strconv.Itoa(info.Relationships),
			MetaJSON: fmt.Sprintf(`{"method":%q,"chunks":%d,"entities":%d,"relationships":%d}`,
				info.Method, info.Chunks, info.Entities, info.Relationships),
		})
		if err != nil {
			log.Printf("[kb] warn: 记录 KG 决策失败 (kb=%s): %v", kbID, err)
		}
		// KB-4②③/M287：抽取成功后刷新实体向量（实体「名称+描述」embedding 落 kg_entity_vec，
		// 指纹未变跳过）。失败/未配置 embedding 连接降级不阻断（导入主链路已成功；检索侧
		// 实体向量臂对无缓存库如实跳过——沿抽取 degraded 非阻断同族语义）。
		if _, _, verr := s.RefreshEntityVectors(ctx, kbID); verr != nil {
			log.Printf("[kb] warn: 实体向量刷新降级 (kb=%s): %v（检索侧实体向量臂将跳过）", kbID, verr)
		}
	}
	return info
}

// errKGEmpty KG 无覆盖（未抽取或实体未命中该问题）→ 回退向量检索的内部信号。
var errKGEmpty = fmt.Errorf("KG 无命中")

// ---- M16 阶段一（REQ-128）：实体聚焦 / 跳数可配 / 关系类型过滤 / 检索明细 ----

// GraphragOpts 增强检索参数。
type GraphragOpts struct {
	Entity     string   `json:"entity,omitempty"`         // 实体聚焦：以该实体为种子跳过向量命中（空 = 原三步管线）
	Hops       int      `json:"hops,omitempty"`           // 关系扩展跳数：1（默认）~3（KB-4① 递归 CTE）
	RelTypes   []string `json:"relation_types,omitempty"` // 关系类型过滤（空 = 不过滤）
	MaxResults int      `json:"max_results,omitempty"`
	// Rank 命中排序口径（KB-4③/M287 只增参数，A/B 对照教学价值点）：
	//   "" | "ppr"（默认）= Personalized PageRank 图感知排序（种子=向量命中/聚焦实体带权）；
	//   "hops" = 原常数口径（seed 1.0/邻居 0.6/claim 0.8）保留作对照与回归护栏。
	Rank string `json:"rank,omitempty"`
}

// KGClaimDetail 带 chunk 溯源的 claim 明细（定位原文 doc#seq；B1 起附出处摘录与句级高亮区间）。
type KGClaimDetail struct {
	Subject  string  `json:"subject"`
	Text     string  `json:"text"`
	ChunkID  string  `json:"chunk_id,omitempty"`
	DocID    string  `json:"doc_id,omitempty"`
	ChunkSeq int     `json:"chunk_seq,omitempty"`
	Score    float64 `json:"score"`
	// B1 引用溯源：出处摘录（≤240 rune 窗，claim 命中处居中）与命中区间（相对摘录 rune 偏移）。
	// 空 = 出处 chunk 缺失或 claim 未原样命中（诚实降级，不臆造区间）。
	ChunkExcerpt string `json:"chunk_excerpt,omitempty"`
	SpanStart    int    `json:"span_start,omitempty"`
	SpanEnd      int    `json:"span_end,omitempty"`
}

// GraphragDetail 增强检索结果：hits 之外携带命中路径上的实体/关系/claims 明细
// （retrieval 事件与图谱页聚焦检索共用）。
type GraphragDetail struct {
	Hits          []RetrievalHit          `json:"hits"`
	Entities      []*store.KGEntity       `json:"entities"`
	Relationships []*store.KGRelationship `json:"relationships"`
	Claims        []KGClaimDetail         `json:"claims"`
}

// GraphragQueryDetail 增强版三步管线：
//   - Entity 聚焦：种子实体直接指定（跳过向量命中），claims 分数仍沿用出处 chunk 命中分；
//   - Hops：关系扩展跳数 1~3（KB-4① 递归 CTE；类型过滤路径为逐跳遍历）；
//   - RelTypes：关系类型白名单过滤（空 = 全部）；
//   - 返回值附命中路径上的实体/关系/claims 明细（溯源：claim.chunk_id → doc/seq）。
func (s *Service) GraphragQueryDetail(ctx context.Context, k *store.KnowledgeBase, query string, opts GraphragOpts) (*GraphragDetail, error) {
	maxResults := opts.MaxResults
	if maxResults <= 0 {
		maxResults = k.TopK
	}
	if maxResults <= 0 {
		maxResults = 4
	}
	hops := opts.Hops
	if hops < 1 {
		hops = 1
	}
	if hops > 3 {
		hops = 3 // KB-4①：递归 CTE 放开 1~3 跳（原「非 2 钳 1」退役，12 号 v0.9 原设计兑现）
	}
	filterRel := func(rels []*store.KGRelationship) []*store.KGRelationship {
		if len(opts.RelTypes) == 0 {
			return rels
		}
		allow := map[string]bool{}
		for _, t := range opts.RelTypes {
			allow[t] = true
		}
		out := make([]*store.KGRelationship, 0, len(rels))
		for _, r := range rels {
			if allow[r.Type] {
				out = append(out, r)
			}
		}
		return out
	}

	var (
		subjects     []string
		seedWeights  map[string]float64 // KB-4②③：种子实体权重（chunk 路径与实体向量臂融合，PPR personalization）
		scoreByChunk map[string]float64
		err          error
	)
	if opts.Entity != "" {
		// 实体聚焦：校验实体存在后直接作种子
		ents, eerr := s.Store.KGEntitiesByNames(k.ID, []string{opts.Entity})
		if eerr != nil {
			return nil, eerr
		}
		if ents[opts.Entity] == nil {
			return nil, errKGEmpty
		}
		subjects = []string{opts.Entity}
		seedWeights = map[string]float64{opts.Entity: 1.0}
		scoreByChunk = map[string]float64{}
	} else {
		if query == "" {
			return nil, fmt.Errorf("query 为空且未指定聚焦实体")
		}
		// ① 向量命中（与 rag 共用通道；score 沿用向量相似度）
		vec, verr := s.embedder().EmbedOne(ctx, query)
		if verr != nil {
			return nil, verr
		}
		seeds, serr := s.Vector.Search(ctx, k.ID, vec, maxResults, 0)
		if serr != nil {
			return nil, serr
		}
		if len(seeds) == 0 {
			return &GraphragDetail{Hits: []RetrievalHit{}, Entities: []*store.KGEntity{}, Relationships: []*store.KGRelationship{}, Claims: []KGClaimDetail{}}, nil
		}
		chunkIDs := make([]string, 0, len(seeds))
		scoreByChunk = map[string]float64{}
		for _, h := range seeds {
			chunkIDs = append(chunkIDs, h.ChunkID)
			scoreByChunk[h.ChunkID] = h.Score
		}
		// ② 双入口种子集（KB-4②③/M287）：
		//   chunk 路径 = 倒排（KB-16）带 chunk_id 投影，实体继承其所属 chunks 的最大命中分；
		//   实体向量臂 = query 向量 vs kg_entity_vec 全库余弦 TopN（名称+描述 embedding），
		//   并入种子集融合（权重=max 两路）。臂失败/无缓存如实跳过（诚实降级纯 chunk 路径，
		//   沿 KB-7 vector_degraded 先例）。
		seedWeights = map[string]float64{}
		subjects = []string{}
		addSeed := func(name string, score float64) {
			if name == "" {
				return
			}
			if !containsSeed(subjects, name) {
				subjects = append(subjects, name)
			}
			if score > seedWeights[name] {
				seedWeights[name] = score
			}
		}
		if refs, rerr := s.Store.KGEntitiesByChunks(k.ID, chunkIDs); rerr == nil {
			for _, ref := range refs {
				if sc, ok := scoreByChunk[ref.ChunkID]; ok {
					addSeed(ref.Name, sc)
				} else {
					addSeed(ref.Name, 0)
				}
			}
		} else {
			return nil, rerr
		}
		if vecRows, verr2 := s.Store.KGEntityVecs(k.ID); verr2 == nil && len(vecRows) > 0 {
			namesByUID, nerr := s.Store.KGEntityNamesOfKB(k.ID)
			if nerr != nil {
				return nil, nerr
			}
			for _, h := range entityVecTopN(vec, vecRows, namesByUID, maxResults) {
				addSeed(h.Name, h.Score)
			}
		} else if verr2 != nil {
			log.Printf("[kb] warn: 实体向量臂读取失败 (kb=%s): %v → 跳过实体臂", k.ID, verr2)
		}
		if len(subjects) == 0 {
			return nil, errKGEmpty
		}
	}

	// ③ 关系扩展：无类型过滤走递归 CTE 快路径（KB-4①，1~3 跳一次取全程）；
	// 有类型过滤保留逐跳遍历（过滤影响前沿，与 CTE 全程可达语义不同）。
	allRels := []*store.KGRelationship{}
	entitySet := map[string]bool{}
	for _, n := range subjects {
		entitySet[n] = true
	}
	if len(opts.RelTypes) == 0 {
		rels, rerr := s.Store.KGNeighborsMultiHop(k.ID, subjects, hops)
		if rerr != nil {
			return nil, rerr
		}
		allRels = rels
		for _, r := range rels {
			entitySet[r.Source] = true
			entitySet[r.Target] = true
		}
	} else {
		seenRel := map[string]bool{}
		frontier := subjects
		for hop := 0; hop < hops; hop++ {
			rels, rerr := s.Store.KGNeighbors(k.ID, frontier)
			if rerr != nil {
				return nil, rerr
			}
			rels = filterRel(rels)
			next := []string{}
			for _, r := range rels {
				if !seenRel[r.ID] {
					seenRel[r.ID] = true
					allRels = append(allRels, r)
				}
				for _, n := range []string{r.Source, r.Target} {
					if !entitySet[n] {
						entitySet[n] = true
						next = append(next, n)
					}
				}
			}
			if len(next) == 0 {
				break
			}
			frontier = next
		}
	}

	names := make([]string, 0, len(entitySet))
	for n := range entitySet {
		names = append(names, n)
	}
	entities, err := s.Store.KGEntitiesByNames(k.ID, names)
	if err != nil {
		return nil, err
	}
	rawClaims, err := s.Store.KGClaimsWithChunks(k.ID, names, maxResults*6)
	if err != nil {
		return nil, err
	}
	// 排序口径（KB-4③/M287）：默认 PPR 图感知分——种子带权 personalization 在扩展边集上
	// 迭代，取相对分（max 归一 0~1，Hits.Score 区间语义不变）；"hops" 保留原常数对照。
	// PPR 失败（无种子权重/空图）回落常数口径（如实降级，不空转）。
	relPPR := map[string]float64{}
	if opts.Rank != "hops" {
		if ppr := PersonalizedPageRank(names, allRels, seedWeights, pprDamping, 0, pprTol); ppr != nil {
			if rel := relativeScores(ppr); rel != nil {
				relPPR = rel
			}
		}
	}
	claims := make([]KGClaimDetail, 0, len(rawClaims))
	for _, c := range rawClaims {
		score := claimScore(scoreByChunk, c.ChunkID) // 常数对照口径：chunk 继承分/0.8 兜底
		if len(relPPR) > 0 {
			if v, ok := relPPR[c.Subject]; ok {
				score = v
			} else {
				score = pprClaimFloor // subject 未入图（审核过滤等）：兜底而非伪装图分
			}
		}
		detail := KGClaimDetail{
			Subject: c.Subject, Text: c.Text, ChunkID: c.ChunkID, DocID: c.DocID, ChunkSeq: c.ChunkSeq,
			Score: score,
		}
		// B1：出处摘录 + 句级高亮区间（claim 原样命中出处 chunk 才标，不臆造）
		if c.ChunkContent != "" {
			if excerpt, spans := ClaimExcerpt(c.ChunkContent, c.Text, 240); len(spans) > 0 {
				detail.ChunkExcerpt = excerpt
				detail.SpanStart, detail.SpanEnd = spans[0].Start, spans[0].End
			}
		}
		claims = append(claims, detail)
	}

	// ④ hits 组装（实体命中在前、claims 补事实——与原管线同语义，排序分改图感知）
	subjectSet := map[string]bool{}
	for _, n := range subjects {
		subjectSet[n] = true
	}
	type expansion struct {
		name  string
		score float64
	}
	expansions := []expansion{}
	seenName := map[string]bool{}
	for _, r := range allRels {
		for _, n := range []string{r.Source, r.Target} {
			if seenName[n] {
				continue
			}
			seenName[n] = true
			sc := 0.6
			if subjectSet[n] {
				sc = 1.0
			}
			if len(relPPR) > 0 {
				sc = relPPR[n] // PPR 相对分（种子不必然最高——枢纽吸分即「全局证据分布」语义）
			}
			expansions = append(expansions, expansion{name: n, score: sc})
		}
	}
	sort.SliceStable(expansions, func(i, j int) bool { return expansions[i].score > expansions[j].score })
	hits := make([]RetrievalHit, 0, maxResults)
	for _, e := range expansions {
		if len(hits) >= maxResults {
			break
		}
		excerpt := "(未填写描述)"
		if ent := entities[e.name]; ent != nil && ent.Description != "" {
			excerpt = truncateRunes(ent.Description, 200)
		}
		hits = append(hits, RetrievalHit{Doc: k.Name + " · " + e.name, Seq: len(hits), Score: e.score, Excerpt: excerpt})
	}
	for _, c := range claims {
		if len(hits) >= maxResults {
			break
		}
		hits = append(hits, RetrievalHit{Doc: k.Name + " · " + c.Subject, Seq: len(hits),
			Score: c.Score, Excerpt: truncateRunes(c.Text, 200)})
	}
	entList := make([]*store.KGEntity, 0, len(entities))
	for _, n := range names {
		if e := entities[n]; e != nil {
			entList = append(entList, e)
		}
	}
	return &GraphragDetail{Hits: hits, Entities: entList, Relationships: allRels, Claims: claims}, nil
}

// GraphragQueryWithFallbackDetail 带 KG 明细的降级封装（recallKB / graphrag-search 直查共用）。
// KB-11 起委托统一出口 SearchUnified（按能力开关路由；本函数为历史签名兼容层）。
func (s *Service) GraphragQueryWithFallbackDetail(ctx context.Context, k *store.KnowledgeBase, query string, maxResults int, minScore float64, opts GraphragOpts) (*GraphragDetail, string, bool, error) {
	return s.SearchUnified(ctx, k, query, maxResults, minScore, opts)
}

// GraphragQuery 自研 GraphRAG 检索（D-O15 三步：向量命中 → KG 一跳扩展 → 拼上下文）。
// KB-4③/M287 注：主消费链路已收敛 SearchUnified→GraphragQueryDetail（双入口+PPR 排序）；
// 本简版保留 M14 原形态与常数打分作教学对照（legacyGraphragQueryWithFallback 专路），
// 不随升级面扩张——两口径差异由 Rank 参数在 Detail 主路径承载。
func (s *Service) GraphragQuery(ctx context.Context, k *store.KnowledgeBase, query string, maxResults int) ([]RetrievalHit, error) {
	if query == "" {
		return nil, nil
	}
	if maxResults <= 0 {
		maxResults = k.TopK
	}
	if maxResults <= 0 {
		maxResults = 4
	}
	// ① 向量命中（与 rag 共用通道；score 沿用向量相似度）
	vec, err := s.embedder().EmbedOne(ctx, query)
	if err != nil {
		return nil, err
	}
	seeds, err := s.Vector.Search(ctx, k.ID, vec, maxResults, 0)
	if err != nil {
		return nil, err
	}
	if len(seeds) == 0 {
		return []RetrievalHit{}, nil
	}
	chunkIDs := make([]string, 0, len(seeds))
	scoreByChunk := map[string]float64{}
	for _, h := range seeds {
		chunkIDs = append(chunkIDs, h.ChunkID)
		scoreByChunk[h.ChunkID] = h.Score
	}
	// ② 命中 chunk → 提及实体 → 一跳关系扩展（KB-16/M286 倒排路径）
	subjects, err := s.Store.KGChunkSubjectsByChunks(k.ID, chunkIDs)
	if err != nil {
		return nil, err
	}
	if len(subjects) == 0 {
		return nil, errKGEmpty
	}
	rels, err := s.Store.KGNeighbors(k.ID, subjects)
	if err != nil {
		return nil, err
	}
	nameSet := map[string]bool{}
	for _, r := range rels {
		nameSet[r.Source] = true
		nameSet[r.Target] = true
	}
	names := make([]string, 0, len(nameSet))
	for n := range nameSet {
		names = append(names, n)
	}
	entities, err := s.Store.KGEntitiesByNames(k.ID, names)
	if err != nil {
		return nil, err
	}
	claims, err := s.Store.KGClaimsForSubjects(k.ID, names, maxResults*6)
	if err != nil {
		return nil, err
	}
	// ③ 拼上下文：seed 实体（score 1.0）优先，一跳邻居（0.6）次之，claims（继承 seed chunk 分数）补事实
	subjectSet := map[string]bool{}
	for _, n := range subjects {
		subjectSet[n] = true
	}
	type expansion struct {
		name  string
		score float64
	}
	expansions := []expansion{}
	seenName := map[string]bool{}
	for _, r := range rels {
		for _, n := range []string{r.Source, r.Target} {
			if seenName[n] {
				continue
			}
			seenName[n] = true
			sc := 0.6
			if subjectSet[n] {
				sc = 1.0
			}
			expansions = append(expansions, expansion{name: n, score: sc})
		}
	}
	sort.Slice(expansions, func(i, j int) bool { return expansions[i].score > expansions[j].score })
	hits := make([]RetrievalHit, 0, maxResults)
	for _, e := range expansions {
		if len(hits) >= maxResults {
			break
		}
		excerpt := "(未填写描述)"
		if ent := entities[e.name]; ent != nil && ent.Description != "" {
			excerpt = truncateRunes(ent.Description, 200)
		}
		hits = append(hits, RetrievalHit{Doc: k.Name + " · " + e.name, Seq: len(hits), Score: e.score, Excerpt: excerpt})
	}
	for _, c := range claims {
		if len(hits) >= maxResults {
			break
		}
		hits = append(hits, RetrievalHit{Doc: k.Name + " · " + c.Subject, Seq: len(hits),
			Score: claimScore(scoreByChunk, c.ChunkID), Excerpt: truncateRunes(c.Text, 200)})
	}
	return hits, nil
}

// claimScore claim 分数继承其出处 chunk 的向量命中分（无溯源 chunk 时给固定值）。
// KB-4③/M287 注：本函数保留供 Rank="hops" 常数对照口径与简版 GraphragQuery（教学对照）
// 使用；主路径 Rank=ppr 下 claim 分=subject 的 PPR 相对分（见 GraphragQueryDetail）。
func claimScore(scoreByChunk map[string]float64, chunkID string) float64 {
	if chunkID == "" {
		return 0.8
	}
	if v, ok := scoreByChunk[chunkID]; ok && v > 0 {
		return v
	}
	return 0.8
}

// containsSeed 种子集去重判等（KB-4② 双入口融合的小工具；种子集规模=教学尺度线性扫足够）。
func containsSeed(names []string, name string) bool {
	for _, n := range names {
		if n == name {
			return true
		}
	}
	return false
}

// KGEntity / KGRelationship KG 读回元素（O13 策略 B/C 数据源；D-O15 起读自存表）。
type KGEntity struct {
	ID   string `json:"id"`
	Name string `json:"name"`
	Type string `json:"type,omitempty"`
	Desc string `json:"desc,omitempty"` // 轻量抽取/LLM 捕获的首个描述句
}

type KGRelationship struct {
	Source string `json:"source"`
	Target string `json:"target"`
	Type   string `json:"type,omitempty"`
}

// KGData 一个 KB 的 KG 子图。
type KGData struct {
	KBID          string           `json:"kb_id"`
	Method        string           `json:"method,omitempty"` // llm | lightweight（最近一次抽取决策反查）
	Entities      []KGEntity       `json:"entities"`
	Relationships []KGRelationship `json:"relationships"`
}

// GraphragKG 读回某 KB 的 KG 子图（O13 ④ kg-to-spec-json 与策略 B/C 的数据源；自存表直读）。
func (s *Service) GraphragKG(ctx context.Context, kbID string) (*KGData, error) {
	entityRows, relRows, err := s.Store.KGByKB(kbID)
	if err != nil {
		return nil, err
	}
	out := &KGData{KBID: kbID, Entities: []KGEntity{}, Relationships: []KGRelationship{}}
	for _, e := range entityRows {
		out.Entities = append(out.Entities, KGEntity{ID: e.ID, Name: e.Name, Type: e.Type, Desc: e.Description})
	}
	for _, r := range relRows {
		out.Relationships = append(out.Relationships, KGRelationship{Source: r.Source, Target: r.Target, Type: r.Type})
	}
	// method 反查最近一条 kg 决策（GraphragIngest 落痕；无记录留空，不影响映射）
	if decisions, derr := s.Store.ListDecisions("kg", kbID, 1); derr == nil && len(decisions) > 0 {
		var m struct {
			Method string `json:"method"`
		}
		if json.Unmarshal([]byte(decisions[0].MetaJSON), &m) == nil {
			out.Method = m.Method
		}
	}
	return out, nil
}

// GraphragQueryWithFallback M14 ⑥ 降级封装（KB-11 起委托统一出口，历史签名兼容层）。
func (s *Service) GraphragQueryWithFallback(ctx context.Context, k *store.KnowledgeBase, query string, maxResults int, minScore float64) ([]RetrievalHit, string, bool, error) {
	detail, mode, degraded, err := s.SearchUnified(ctx, k, query, maxResults, minScore, GraphragOpts{})
	if detail == nil {
		detail = &GraphragDetail{Hits: []RetrievalHit{}}
	}
	return detail.Hits, mode, degraded, err
}

// legacyGraphragQueryWithFallback M14 ⑥ 原实现保留（教学对照：mode 二选一路由，KB-11 前的历史行为）。
func (s *Service) legacyGraphragQueryWithFallback(ctx context.Context, k *store.KnowledgeBase, query string, maxResults int, minScore float64) ([]RetrievalHit, string, bool, error) {
	if k.Mode != "graphrag" {
		hits, err := s.Search(ctx, k, query, maxResults, minScore)
		return hits, "rag", false, err
	}
	hits, err := s.GraphragQuery(ctx, k, query, maxResults)
	if err == nil && len(hits) > 0 {
		return hits, "graphrag", false, nil
	}
	if err != nil {
		log.Printf("[kb] graphrag query degraded (kb=%s): %v → 回退向量检索", k.ID, err)
	} else {
		log.Printf("[kb] graphrag query 无命中 (kb=%s) → 回退向量检索", k.ID)
	}
	fb, ferr := s.Search(ctx, k, query, maxResults, minScore)
	return fb, "rag", true, ferr
}
