package index

import (
	"context"
	"encoding/json"
	"errors"
	"strings"
	"time"

	"github.com/duke-git/lancet/v2/strutil"

	"github.com/swiftbit/know-agent/common"
	"github.com/swiftbit/know-agent/common/logx"
	"github.com/swiftbit/know-agent/common/utils"
	"github.com/swiftbit/know-agent/internal/domain/document/adapter"
	"github.com/swiftbit/know-agent/internal/domain/document/logic/process/chunk"
	"github.com/swiftbit/know-agent/internal/domain/document/logic/process/chunk/llm"
	"github.com/swiftbit/know-agent/internal/domain/document/logic/process/chunk/recursive"
	"github.com/swiftbit/know-agent/internal/domain/document/logic/process/chunk/semantic"
	"github.com/swiftbit/know-agent/internal/domain/document/model/entity"
	"github.com/swiftbit/know-agent/internal/domain/document/model/enum"
	"github.com/swiftbit/know-agent/internal/domain/document/model/vo"
	errorx "github.com/swiftbit/know-agent/internal/error"
)

const (
	// minChildChunkChars 子块文本字数低于该阈值时，与相邻子块合并为同一子块，避免产生过碎的检索子块
	minChildChunkChars = 40
	// childChunkMergeSeparator 短子块与相邻子块合并时使用的文本分隔符
	childChunkMergeSeparator = "\n\n"
)

// ChunkingStage 切块阶段：执行切块流水线、构建父子块实体、持久化
type ChunkingStage struct {
	repo      adapter.DocumentRepository
	registry  *chunk.Registry
	resolver  IndexingConfigResolver
	tokenizer Tokenizer
}

// NewChunkingStage 创建切块阶段
func NewChunkingStage(repo adapter.DocumentRepository, registry *chunk.Registry, resolver IndexingConfigResolver, tokenizer Tokenizer) *ChunkingStage {
	return &ChunkingStage{
		repo:      repo,
		registry:  registry,
		resolver:  resolver,
		tokenizer: tokenizer,
	}
}

func (p *ChunkingStage) Name() string {
	return "切块阶段"
}

// TaskStage 切块阶段的任务阶段编码：任务阶段越过切块执行（进入切块后处理及之后）说明切块产物已就绪
func (p *ChunkingStage) TaskStage() enum.TaskStage {
	return enum.TaskStageChunkExecute
}

func (p *ChunkingStage) Execute(ctx context.Context, buildCtx *Context) error {
	documentId := buildCtx.DocumentId
	// 查询结构化解析 blocks
	blocks, err := p.repo.SelectDocumentBlocksByTask(ctx, documentId, buildCtx.Task.SourceParseTaskId)
	if err != nil {
		return err
	}
	if len(blocks) == 0 {
		return errors.New("当前文档没有结构化解析 blocks，无法执行 Parent/Child 切块。")
	}

	// 查询策略步骤列表
	pipelineSteps, err := p.repo.SelectStepListByPlanId(ctx, buildCtx.PlanId)
	if err != nil {
		return err
	}

	chunkStartDetail, _ := json.Marshal(map[string]any{"strategySnapshot": buildCtx.Plan.StrategySnapshot})
	chunkStartLog := &entity.DocumentTaskLog{
		TaskId:       buildCtx.TaskId,
		DocumentId:   documentId,
		StageType:    enum.TaskStageChunkExecute,
		EventType:    enum.TaskEventStart,
		LogLevel:     enum.LogLevelInfo,
		OperatorType: enum.OperatorTypeSystem,
		Content:      "开始执行切块流水线",
		DetailJson:   string(chunkStartDetail),
	}
	_ = p.repo.InsertTaskLog(ctx, chunkStartLog)

	if err = p.repo.UpdateStepExecuteStatus(ctx, buildCtx.PlanId, enum.StrategyExecuteStatusExecuting); err != nil {
		return err
	}

	// 按步骤执行切块流水线
	chunkStartTime := time.Now()
	parentCandidates, err := p.BuildParentChunks(ctx, buildCtx, pipelineSteps, blocks)
	if err != nil {
		return err
	}
	buildCtx.ParentCandidates = parentCandidates
	costMillis := time.Since(chunkStartTime).Milliseconds()

	if err = p.repo.UpdateStepExecuteStatus(ctx, buildCtx.PlanId, enum.StrategyExecuteStatusExecuteSuccess); err != nil {
		return err
	}
	chunkEndDetail, _ := json.Marshal(map[string]any{
		"parentCount": len(parentCandidates),
		"childCount":  parentCandidates.CountChildCandidates(),
		"blockCount":  len(blocks),
		"costMillis":  costMillis,
	})
	chunkEndLog := &entity.DocumentTaskLog{
		TaskId:       buildCtx.TaskId,
		DocumentId:   documentId,
		StageType:    enum.TaskStageChunkExecute,
		EventType:    enum.TaskEventComplete,
		LogLevel:     enum.LogLevelInfo,
		OperatorType: enum.OperatorTypeSystem,
		Content:      "切块流水线执行完成",
		DetailJson:   string(chunkEndDetail),
	}
	_ = p.repo.InsertTaskLog(ctx, chunkEndLog)

	return nil
}

// BuildParentChunks 执行完整的父-子块构建流程：先通过父块流水线生成父种子，再针对每个父种子走子块流水线产出子块
func (p *ChunkingStage) BuildParentChunks(ctx context.Context, buildCtx *Context, steps entity.DocumentStrategySteps, blocks entity.DocumentBlocks) (vo.ParentChunkCandidates, error) {
	// 按父/子流水线拆分并排序步骤；任一缺失则返回相应错误
	parentSteps := steps.GetSortedStepsByPipeline(enum.PipelineTypeParent)
	childSteps := steps.GetSortedStepsByPipeline(enum.PipelineTypeChild)
	if len(parentSteps) == 0 {
		return nil, errorx.ErrParentBlockMissing
	}
	if len(childSteps) == 0 {
		return nil, errorx.ErrChildBlockMissing
	}

	document := buildCtx.Document
	// 恢复 blocks 的原始文本内容
	for _, block := range blocks {
		block.ResumeRawText(buildCtx.RawFileBytes)
	}

	orderedBlocks := blocks.CleanupAndSort()
	if len(orderedBlocks) == 0 {
		return nil, errorx.ErrDocumentBlocksMissing
	}
	blockMap := blocks.ToMap()

	// 加载已解析的文档结构节点（用于结构切块策略）
	var nodes entity.StructureNodes
	var err error
	if document != nil {
		nodes, err = p.repo.SelectStructureNodeListByTask(ctx, document.ID, document.LastParseTaskId)
		if err != nil {
			return nil, err
		}
	}

	options := p.resolver.Resolve(ctx, document)

	// 生成父块种子列表
	parentSeedList := p.buildParentSeedList(ctx, blocks, parentSteps, nodes, options)

	// 为每个父块种子派生其子块；无子块时以父块本身兜底
	parentChunks := make(vo.ParentChunkCandidates, 0)
	for _, parentSeed := range parentSeedList.NormalizeAndDeduplicate() {
		if parentSeed != nil && strutil.IsNotBlank(parentSeed.Text) {
			childSeedList := p.buildChildSeedList(ctx, parentSeed, childSteps, blockMap, options)
			finalChildren := childSeedList.NormalizeAndDeduplicate()
			finalChildren = p.mergeShortChildChunks(finalChildren)

			trim := strutil.Trim(parentSeed.Text)
			if len(finalChildren) == 0 {
				// 兜底策略：子块流水线无产出 → 使用父块本身作为唯一子块
				finalChildren = vo.ChunkCandidates{
					p.cloneChunkCandidate(parentSeed, trim),
				}
			}

			parentChunks = append(parentChunks, &vo.ParentChunkCandidate{
				SectionPath:       parentSeed.SectionPath,
				StructureNodeId:   parentSeed.StructureNodeId,
				StructureNodeType: parentSeed.StructureNodeType,
				Text:              trim,
				SourceType:        parentSeed.SourceType,
				ChildChunks:       finalChildren,
				CanonicalPath:     parentSeed.CanonicalPath,
				ItemIndex:         parentSeed.ItemIndex,
				PageRange:         parentSeed.PageRange,
				SourceBlockIds:    parentSeed.SourceBlockIds,
			})
		}
	}

	// 对父块进行去重与清理后返回
	return parentChunks.NormalizeAndDeduplicate(), nil
}

// ---------------- 种子构建 ----------------

func (p *ChunkingStage) buildParentSeedList(ctx context.Context, blocks entity.DocumentBlocks, parentSteps entity.DocumentStrategySteps,
	nodes []*entity.StructureNode, options *vo.IndexingOptions) vo.ChunkCandidates {
	if parentSteps.Contains(enum.StrategyTypeStructure) {
		structureSeeds := p.buildBlockSectionParentSeeds(blocks, nodes, options)
		remainingSteps := parentSteps.DeleteStep(enum.StrategyTypeStructure)

		if len(remainingSteps) == 0 {
			return structureSeeds
		}
		return p.executePipeline(ctx, structureSeeds, remainingSteps, enum.PipelineTypeParent, options)
	}

	maxChars := options.ResolveRecursiveMaxChars(enum.PipelineTypeParent)
	parentSeeds := p.buildBlockWindowParentSeeds(blocks, nil, maxChars)
	remainingSteps := parentSteps.DeleteStep(enum.StrategyTypeRecursive)

	if len(remainingSteps) == 0 {
		return parentSeeds
	}
	return p.executePipeline(ctx, parentSeeds, parentSteps, enum.PipelineTypeParent, options)
}

func (p *ChunkingStage) buildChildSeedList(ctx context.Context, parentSeed *vo.ChunkCandidate, childSteps entity.DocumentStrategySteps,
	blockMap map[int64]*entity.DocumentBlock, options *vo.IndexingOptions) vo.ChunkCandidates {
	blockSeeds := p.buildBlockChildSeeds(parentSeed, blockMap)
	if len(blockSeeds) == 0 {
		blockSeeds = vo.ChunkCandidates{p.cloneChunkCandidate(parentSeed, parentSeed.Text)}
	}
	remainingSteps := childSteps.DeleteStep(enum.StrategyTypeStructure)
	if len(remainingSteps) == 0 {
		return blockSeeds
	}
	// 执行子块流水线
	return p.executePipeline(ctx, blockSeeds, remainingSteps, enum.PipelineTypeChild, options)
}

// buildBlockSectionParentSeeds 构建基于章节分组的父块种子, 按 SectionPath 分组，组内按字符上限决定是否窗口化拆分
func (p *ChunkingStage) buildBlockSectionParentSeeds(blocks entity.DocumentBlocks,
	nodes []*entity.StructureNode, options *vo.IndexingOptions) vo.ChunkCandidates {

	seeds := make(vo.ChunkCandidates, 0)
	currentGroup := make(entity.DocumentBlocks, 0)
	currentSectionKey := ""
	maxChars := options.ResolveRecursiveMaxChars(enum.PipelineTypeParent)

	// 闭包：处理一个完整组的收尾逻辑
	add := func(group entity.DocumentBlocks) {
		if len(group) == 0 {
			return
		}

		text := group.JoinBlockTexts()
		// 若组内总字符数在限制内，直接生成父种子
		if utils.Len(text) <= maxChars {
			seeds = append(seeds, p.toParentSeed(group, nodes))
		} else {
			// 超出限制，走滑动窗口拆分逻辑
			seeds = append(seeds, p.buildBlockWindowParentSeeds(group, nodes, maxChars)...)
		}
	}

	// 遍历所有块，按章节路径分组
	for _, block := range blocks {
		if block == nil {
			continue
		}
		sectionKey := strings.TrimSpace(block.SectionPath)
		sectionChanged := len(currentGroup) > 0 && currentSectionKey != sectionKey

		// 章节发生变化，提交上一组
		if sectionChanged {
			add(currentGroup)
			currentGroup = make(entity.DocumentBlocks, 0)
		}

		// 新组初始化章节标识
		if len(currentGroup) == 0 {
			currentSectionKey = sectionKey
		}

		currentGroup = append(currentGroup, block)
	}

	// 处理最后一组
	add(currentGroup)

	// 兜底策略：若未生成任何种子，则对整个块列表做窗口化拆分
	if len(seeds) == 0 {
		return p.buildBlockWindowParentSeeds(blocks, nodes, maxChars)
	}

	return seeds
}

// buildBlockChildSeeds 构建父块对应的子块种子列表，根据父块的源块ID列表，从blockMap中提取对应的文档块，生成独立的子块候选对象
func (p *ChunkingStage) buildBlockChildSeeds(parentSeed *vo.ChunkCandidate, blockMap map[int64]*entity.DocumentBlock) vo.ChunkCandidates {
	if parentSeed == nil || len(blockMap) == 0 {
		return nil
	}
	// 解析父块中的源块ID列表
	sourceBlockIds := make([]int64, 0)
	if err := json.Unmarshal([]byte(parentSeed.SourceBlockIds), &sourceBlockIds); err != nil {
		logx.Errorf("解析父块源块ID列表失败: %s\n", err.Error())
		return nil
	}

	if len(sourceBlockIds) == 0 {
		return nil
	}

	seeds := make(vo.ChunkCandidates, 0, len(sourceBlockIds))
	for _, blockID := range sourceBlockIds {
		block, exists := blockMap[blockID]
		if !exists || block == nil {
			continue
		}

		// 纯标题块不单独生成检索子块（避免白占索引、在 BM25 短文本归一化中截胡正文）
		if block.IsTitleBlock() {
			continue
		}

		var child *vo.ChunkCandidate
		// 拆分父种子场景：父种子是超长块被递归切分出的子片段（仅一个源块且文本不同于该块全文），
		// 其子块应继承父种子的切分文本，而非重新取回整块全文，避免多个拆分父块派生出相同的子块
		if len(sourceBlockIds) == 1 && utils.Trim(block.RenderBlockContent()) != utils.Trim(parentSeed.Text) {
			child = p.cloneChunkCandidate(parentSeed, parentSeed.Text)
		} else {
			child = p.toBlockChunkCandidate(block)
		}
		// 子块的 SectionPath 优先继承父种子的完整层级链（已从 StructureNode 重建）
		child.SectionPath = utils.BlankToDefault(parentSeed.SectionPath, child.SectionPath)
		child.StructureNodeId = parentSeed.StructureNodeId
		child.StructureNodeType = parentSeed.StructureNodeType
		child.CanonicalPath = utils.BlankToDefault(child.CanonicalPath, parentSeed.CanonicalPath)
		child.ItemIndex = parentSeed.ItemIndex
		seeds = append(seeds, child)
	}

	return seeds
}

// buildBlockWindowParentSeeds 构建块窗口父种子
func (p *ChunkingStage) buildBlockWindowParentSeeds(blocks entity.DocumentBlocks, nodes []*entity.StructureNode, maxChars int) vo.ChunkCandidates {
	seeds := make(vo.ChunkCandidates, 0)
	currentBlocks := make(entity.DocumentBlocks, 0)
	currentChars := 0
	recursiveSplit := p.registry.Get(enum.StrategyTypeRecursive)
	for _, block := range blocks {
		blockText := strings.TrimSpace(block.RenderBlockContent())
		if blockText == "" {
			continue
		}

		// 处理超长块：递归拆分
		if utils.Len(blockText) > maxChars {
			if len(currentBlocks) > 0 {
				seeds = append(seeds, p.toParentSeed(currentBlocks, nodes))
			}
			currentBlocks = make(entity.DocumentBlocks, 0)
			currentChars = 0

			// 递归拆分超长文本
			parts, _ := recursiveSplit.Chunk(context.TODO(), blockText,
				recursive.WithMaxChars(maxChars),
				recursive.WithOverlapChars(0))
			for _, splitText := range parts {
				seeds = append(seeds, p.toSplitBlockSeed(block, nodes, splitText))
			}
			continue
		}

		// 检查窗口是否已满（考虑块间分隔符长度）
		if len(currentBlocks) > 0 && currentChars+utils.Len(blockText)+2 > maxChars {
			seeds = append(seeds, p.toParentSeed(currentBlocks, nodes))
			currentBlocks = make(entity.DocumentBlocks, 0)
			currentChars = 0
		}

		currentBlocks = append(currentBlocks, block)
		currentChars += utils.Len(blockText) + 2
	}

	// 处理剩余块
	if len(currentBlocks) > 0 {
		seeds = append(seeds, p.toParentSeed(currentBlocks, nodes))
	}

	return seeds
}

// mergeShortChildChunks 将文本字数低于阈值的子块与相邻子块合并。
// 规则：
//  1. 连续短块先合并成一组（短并短）
//  2. 短块组总长度 ≤ 阈值 → 归并到相邻长块；否则独立
func (p *ChunkingStage) mergeShortChildChunks(children []*vo.ChunkCandidate) []*vo.ChunkCandidate {
	if len(children) <= 1 {
		return children
	}

	type item struct {
		candidate *vo.ChunkCandidate
		rawLen    int
	}

	// ========== 第一遍：连续短块合并为一组 ==========
	items := make([]item, 0, len(children))
	for i := 0; i < len(children); {
		child := children[i]
		if child == nil || strings.TrimSpace(child.Text) == "" {
			i++
			continue
		}
		child.Text = strings.TrimSpace(child.Text)
		childLen := utils.Len(child.Text)

		if childLen >= minChildChunkChars {
			// 长块，直接保留
			items = append(items, item{candidate: child, rawLen: childLen})
			i++
		} else {
			// 收集连续短块
			texts := []string{child.Text}
			totalLen := childLen
			j := i + 1
			for j < len(children) {
				if children[j] == nil || strings.TrimSpace(children[j].Text) == "" {
					j++
					continue
				}
				t := strings.TrimSpace(children[j].Text)
				tLen := utils.Len(t)
				if tLen >= minChildChunkChars {
					break
				}
				texts = append(texts, t)
				totalLen += tLen
				j++
			}
			items = append(items, item{
				candidate: p.cloneChunkCandidate(child, strings.Join(texts, childChunkMergeSeparator)),
				rawLen:    totalLen,
			})
			i = j
		}
	}

	// ========== 第二遍：短块组归并到相邻长块 ==========
	result := make([]*vo.ChunkCandidate, 0, len(items))
	for i := 0; i < len(items); i++ {
		if items[i].rawLen < minChildChunkChars {
			if len(result) > 0 {
				// 优先合并到前一个长块
				result[len(result)-1].Text += childChunkMergeSeparator + items[i].candidate.Text
			} else if i+1 < len(items) {
				// 开头短块组，合并到后一个长块
				items[i+1].candidate.Text = items[i].candidate.Text + childChunkMergeSeparator + items[i+1].candidate.Text
			} else {
				// 全是短块，直接保留
				result = append(result, items[i].candidate)
			}
		} else {
			// 长块，独立追加
			result = append(result, items[i].candidate)
		}
	}

	return result
}

// cloneChunkCandidate 克隆 ChunkCandidate
func (p *ChunkingStage) cloneChunkCandidate(original *vo.ChunkCandidate, text string) *vo.ChunkCandidate {
	text = strings.TrimSpace(text)
	if original == nil {
		return &vo.ChunkCandidate{
			Text:       text,
			SourceType: enum.ChunkSourceTypeOriginal,
		}
	}
	candidate := *original
	candidate.Text = text
	if text != strings.TrimSpace(original.Text) {
		keywords := candidate.ExtractKeywords(p.tokenizer)
		candidate.Keywords = marshal(keywords)
		candidate.Questions = marshal(candidate.ExtractQuestions(keywords))
		candidate.ContentWithWeight = candidate.ExtractContentWithWeight(keywords, "")
	}

	return &candidate
}

// ---------------- 流水线调度 ----------------

func (p *ChunkingStage) executePipeline(ctx context.Context, seeds vo.ChunkCandidates,
	steps entity.DocumentStrategySteps, pipelineType string, options *vo.IndexingOptions) vo.ChunkCandidates {
	// 初始清洗与去重
	chunks := seeds.NormalizeAndDeduplicate()
	if len(chunks) == 0 {
		return chunks
	}

	// 按配置的步骤顺序执行分块策略
	for _, step := range steps {
		strategy := p.registry.Get(step.StrategyType)
		// 跳过未注册的策略或结构型策略（由其他流程处理）
		if strategy == nil || step.StrategyType == enum.StrategyTypeStructure {
			continue
		}

		// 为当前策略构建运行时参数
		extraOpts := p.buildPipelineOptions(options, step.StrategyType, pipelineType)
		currentChunks := make(vo.ChunkCandidates, 0, len(chunks))

		// 对每一个候选文本块执行分块策略
		for _, candidate := range chunks {
			if candidate == nil || strutil.IsBlank(candidate.Text) {
				continue
			}
			outputs, err := strategy.Chunk(ctx, candidate.Text, extraOpts...)
			if err != nil {
				logx.Errorf("分块策略 %d 处理块 %s 时出错: %v", step.StrategyType, candidate.Text, err)
				continue
			}
			// 将策略输出转换为新的候选块，并继承父块元数据
			for _, output := range outputs {
				currentChunks = append(currentChunks, p.cloneChunkCandidate(candidate, output))
			}
		}

		// 合并新生成的块并重新清洗去重，作为下一轮的输入
		chunks = append(chunks, currentChunks...)
		chunks = currentChunks.NormalizeAndDeduplicate()
	}

	// 最终清洗并返回结果
	return chunks.NormalizeAndDeduplicate()
}

// buildPipelineOptions 根据流水线类型和策略类型生成额外的策略选项
func (p *ChunkingStage) buildPipelineOptions(options *vo.IndexingOptions, strategyType int, pipelineType string) []common.Option {
	switch strategyType {
	case enum.StrategyTypeRecursive:
		maxChars := options.ResolveRecursiveMaxChars(pipelineType)
		overlap := options.ResolveRecursiveOverlap(pipelineType, maxChars)
		return []common.Option{
			recursive.WithMaxChars(maxChars),
			recursive.WithOverlapChars(overlap),
		}
	case enum.StrategyTypeSemantic:
		maxChars := options.ResolveSemanticMaxChars(pipelineType)
		minChars := options.ResolveSemanticMinChars(pipelineType)
		return []common.Option{
			semantic.WithMaxChars(maxChars),
			semantic.WithMinChars(minChars),
			semantic.WithSimilarityThreshold(options.Chunk.ChildSemanticSimilarityThreshold),
		}
	case enum.StrategyTypeLLM:
		return []common.Option{
			llm.WithLlmMaxChars(options.ResolveLlmMaxChars(pipelineType)),
		}
	default:
		return nil
	}
}

// toParentSeed 从文档块列表创建父块候选
func (p *ChunkingStage) toParentSeed(blocks entity.DocumentBlocks, nodes entity.StructureNodes) *vo.ChunkCandidate {
	sectionPath := blocks.FirstBlankSectionPath()
	canonicalPath := blocks.FirstBlankCanonicalPath()
	node := nodes.FindNodeByPath(sectionPath, canonicalPath)
	keywords := blocks.ExtractKeywords(p.tokenizer)
	candidate := &vo.ChunkCandidate{
		SectionPath:       sectionPath,
		CanonicalPath:     canonicalPath,
		Text:              blocks.JoinBlockTexts(),
		SourceType:        enum.ChunkSourceTypeOriginal,
		ContentWithWeight: blocks.ExtractContentWithWeight(keywords, blocks.JoinBlockWeightedContents(p.tokenizer)),
		ChunkType:         blocks.ResolveChunkType(),
		Title:             blocks.ResolveTitle(sectionPath),
		Keywords:          marshal(keywords),
		Questions:         marshal(blocks.ExtractQuestions(keywords)),
		PageNo:            blocks.FirstPageNo(),
		PageRange:         blocks.PageRange(),
		SourceBlockIds:    blocks.Ids(),
	}
	if node != nil {
		candidate.StructureNodeId = node.ID
		candidate.StructureNodeType = node.NodeType
		candidate.ItemIndex = node.ItemIndex
		candidate.CanonicalPath = utils.BlankToDefault(node.CanonicalPath, canonicalPath)
		// 使用 StructureNode 从 parent_node_id 回溯重建的完整层级路径，
		// 覆盖 blocks 中原本单级的 SectionPath（document_block 是解析产物，不在其内部改写）。
		candidate.SectionPath = utils.BlankToDefault(node.SectionPath, sectionPath)
	}
	if len(blocks) > 0 {
		candidate.BboxJson = blocks[0].BboxJson
	}

	return candidate
}

// toSplitBlockSeed 处理超长文档块被递归拆分后的单个子块
func (p *ChunkingStage) toSplitBlockSeed(block *entity.DocumentBlock, nodes entity.StructureNodes, splitText string) *vo.ChunkCandidate {
	clone := block.CloneWithText(splitText)
	node := nodes.FindNodeByPath(clone.SectionPath, clone.CanonicalPath)
	keywords := clone.ExtractKeywords(p.tokenizer)
	candidate := &vo.ChunkCandidate{
		SectionPath:       clone.SectionPath,
		CanonicalPath:     clone.CanonicalPath,
		Text:              clone.Text,
		SourceType:        enum.ChunkSourceTypeOriginal,
		ContentWithWeight: clone.ExtractContentWithWeight(keywords, ""),
		ChunkType:         clone.ResolveChunkType(),
		Title:             clone.ResolveTitle(),
		Keywords:          marshal(keywords),
		Questions:         marshal(clone.ExtractQuestions(keywords)),
		PageNo:            clone.PageNo,
		PageRange:         clone.PageRange,
		BboxJson:          clone.BboxJson,
		SourceBlockIds:    clone.Ids(),
	}

	// 如果找到结构节点，覆盖相关字段
	if node != nil {
		candidate.StructureNodeId = node.ID
		candidate.StructureNodeType = node.NodeType
		candidate.ItemIndex = node.ItemIndex
		candidate.CanonicalPath = utils.BlankToDefault(node.CanonicalPath, clone.CanonicalPath)
		candidate.SectionPath = utils.BlankToDefault(node.SectionPath, clone.SectionPath)
	}

	return candidate
}

// ToBlockChunkCandidate 将文档块转换为ChunkCandidate
func (p *ChunkingStage) toBlockChunkCandidate(block *entity.DocumentBlock) *vo.ChunkCandidate {
	keywords := block.ExtractKeywords(p.tokenizer)
	questions := block.ExtractQuestions(keywords)
	return &vo.ChunkCandidate{
		SectionPath:       block.SectionPath,
		CanonicalPath:     block.CanonicalPath,
		Text:              block.RenderBlockContent(),
		SourceType:        enum.ChunkSourceTypeOriginal,
		ContentWithWeight: block.ExtractContentWithWeight(keywords, block.RenderBlockWeightedContent(keywords)),
		ChunkType:         block.ResolveChunkType(),
		Title:             block.ResolveTitle(),
		Keywords:          marshal(keywords),
		Questions:         marshal(questions),
		PageNo:            block.PageNo,
		PageRange:         block.PageRange,
		BboxJson:          block.BboxJson,
		SourceBlockIds:    block.Ids(),
	}
}

func marshal(v any) string {
	bytes, _ := json.Marshal(v)
	return string(bytes)
}
