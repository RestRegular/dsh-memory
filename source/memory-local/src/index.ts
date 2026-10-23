/**
 * dsh-memory-local — local JSONL provider for the DSH memory service.
 *
 * This entry is intentionally cordis-free so unit tests and standalone tools
 * run without the harness. The Cordis wiring (Service subclass, effects,
 * plugin apply) lives in ./apply.ts and is only loaded inside DSH.
 */
import type {
  MemoryHit,
  MemoryListInput,
  MemoryQuery,
  MemoryRecord,
  MemorySaveInput,
  MemoryScope,
  MemoryServiceApi,
} from 'dsh-memory'
import { MemoryStore, scopeFileName, type ScopeStore } from './store.ts'
import {
  canonicalWorkspacePath,
  isCustomScope,
  normalizeScopeInput,
  projectScopeIdentity,
  resolveCurrentScopes,
  scopeKind,
  scopeTier,
  writeScopeForDefault,
  type ScopeKey,
} from './scope.ts'
import { ScopeNames } from './scope-names.ts'
import {
  SessionVisibilityStore,
  cleanVisibilityRules,
  type SessionVisibilityConfig,
  type VisibilityLevel,
  type VisibilityRule,
} from './session-visibility.ts'
import { mergeInjectSettings, normalizeInjectSettings, type InjectSettings } from './inject-settings.ts'
import { buildStats, lexicalScore, recordScore, tokenize, cosine, normalizeInPlace, hasStrongHit } from './scoring.ts'
import { EmbedClient } from './embed.ts'
import { DailyBudget, blendScores, rerank, type LlmInvoke, type RerankConfig } from './rerank.ts'
import { RerankCache } from './rerank-cache.ts'
import { scanSecrets, redactSecrets } from './secrets.ts'
import { EmbedServerManager, type EmbedServerConfig, type EmbedServerState } from './embed-server.ts'
import { VectorInstaller, detectInstalled, installPaths, type InstallProgress } from './embed-install.ts'
import { existsSync, mkdirSync, readdirSync, readFileSync, rmSync, statSync, writeFileSync } from 'node:fs'
import { basename, dirname, isAbsolute, join, relative, resolve } from 'node:path'
import { homedir } from 'node:os'
import {
  DEFAULT_MODEL_ID,
  EMBEDDING_MODELS,
  findModel,
  findVariant,
  type PoolingKind,
} from './models.ts'
import { probeHardware, type HostHardware, type RuntimeFlavor } from './hardware.ts'
import { pickFlavor, recommendModel } from './recommend.ts'

/** Recursive byte count; 0 for anything unreadable. */
function pathSize(path: string): number {
  try {
    const st = statSync(path)
    if (!st.isDirectory()) return st.size
    let total = 0
    for (const entry of readdirSync(path)) total += pathSize(join(path, entry))
    return total
  } catch {
    return 0
  }
}

/** True when `child` is `parent` or lives under it (both resolved). */
function isInside(parent: string, child: string): boolean {
  const rel = relative(resolve(parent), resolve(child))
  return rel === '' || (!rel.startsWith('..') && !isAbsolute(rel))
}

export interface MemoryLocalConfig {
  /** Store root directory. Created if missing. */
  storeDir?: string
  /**
   * 作用域开关。`global` / `project` / `session` 是布尔(关掉后对应 scope 的**写**一律
   * SCOPE_DISABLED);`custom` 既接受布尔(兼容简写)也接受 `{ enabled, max }`。
   */
  scopes?: {
    global?: boolean
    project?: boolean
    session?: boolean
    custom?: boolean | { enabled?: boolean; max?: number }
  }
  retrieval?: {
    topK?: number
    recallN?: number
    /** Lexical floor for global-scope candidates. */
    globalThreshold?: number
    /** Lexical floor for project-scope candidates (more permissive than global). */
    projectThreshold?: number
    recencyHalfLifeDays?: number
    vector?: {
      enabled?: boolean
      endpoint?: string
      /** 请求里的模型名 + 向量边车身份头的一半。不配 preset 时也用它去清单里找。 */
      model?: string
      dims?: number
      /**
       * 一键安装/托管用哪个模型:清单里的 id(见 models.ts)。不给时按 `model` 字符串
       * 去清单里找,找不到就用内置默认(bge-m3)。
       */
      preset?: string
      /** 量化档位 id(q4_k_m / q8_0 / f16 …);不给用该模型的默认档。 */
      variant?: string
      /** 完全自定义的 GGUF(清单里没有的模型):直连 URL + 维度。 */
      customModel?: {
        url: string
        /** 落盘文件名;不给就从 URL 末段取。 */
        file?: string
        dims: number
        pooling?: PoolingKind
        bytes?: number
        /** 备用下载源(按序回退);不给只用 url。 */
        sources?: string[]
      }
      /** llama.cpp 的 --pooling;不给则用清单里该模型的值('auto' = 不传,由元数据决定)。 */
      pooling?: PoolingKind
      /** 运行时风味:'auto' 按探测到的硬件选,'cpu' 表示纯 CPU(不传 -ngl)。 */
      flavor?: RuntimeFlavor | 'auto'
      /** 传给 llama-server 的 -ngl(卸载到显卡的层数);不给时 GPU 风味用 99。 */
      gpuLayers?: number
      /** Interactive (search-query) budget — keep tight. */
      timeoutMs?: number
      /** Budget for embedding one full record at save time. */
      writeTimeoutMs?: number
      /** Budget for a backfill batch; full record contents are much slower. */
      backfillTimeoutMs?: number
      /** Character ceiling per backfill batch, so one call stays bounded. */
      backfillMaxChars?: number
      minScore?: number
      backfillBatchSize?: number
      /** Manage the llama-server process lifecycle (spawn on start, stop on exit). */
      spawn?: EmbedServerConfig
      /**
       * Where the panel's one-click installer puts llama.cpp + the GGML model.
       * Defaults to the store's parent directory (so the layout is
       * `<root>/llamacpp/llama-server*` + `<root>/models/*.gguf`, matching a
       * hand-made install). Existing files there are adopted automatically —
       * nothing is ever downloaded unless the user clicks the button.
       */
      autoInstall?: {
        dir?: string
        /**
         * Model download URLs tried in order. Defaults to hf-mirror →
         * ModelScope → huggingface.co: the official host is unreachable from
         * mainland China, and the first two serve the identical GGUF.
         */
        modelSources?: string[]
      }
    }
    llm?: Partial<RerankConfig>
  }
  limits?: { maxRecordsPerScope?: number; maxRecordChars?: number }
  /** Secret handling (design §11). Default: refuse obvious credentials. */
  secrets?: { mode?: 'refuse' | 'redact'; enabled?: boolean }
}

export interface ResolvedConfig {
  storeDir: string
  globalEnabled: boolean
  projectEnabled: boolean
  /** 会话 scope 开关(scopes.session,默认 true)。关掉后写路径回退到 project。 */
  sessionEnabled: boolean
  /** 自定义 scope 开关(scopes.custom.enabled,默认 true)。 */
  customEnabled: boolean
  /** 自定义 scope 数量上限(scopes.custom.max,默认 200)。 */
  customMaxScopes: number
  topK: number
  recallN: number
  globalThreshold: number
  projectThreshold: number
  halfLifeDays: number
  vector: {
    enabled: boolean
    /** true when the user actually pointed us at a backend (endpoint and/or spawn) */
    configured: boolean
    endpointConfigured: boolean
    spawnConfigured: boolean
    /** Where the panel's one-click installer puts (or already found) a backend. */
    installRoot: string
    /** Model URLs the installer tries in order (undefined → built-in fallbacks). */
    installModelSources?: string[]
    /** 一键安装用的模型(文件名 + 体积 + 源),由 preset / customModel 解析而来。 */
    installModel: { file: string; bytes?: number; sources?: string[] }
    /** 清单里的模型 id 与档位 id(自定义模型时为 'custom')。 */
    presetId: string
    variantId: string
    modelLabel: string
    /** llama.cpp 的 --pooling(最终值;'auto' 表示不传该参数)。 */
    pooling: PoolingKind
    /** 运行时风味;'auto' 表示等硬件探测结果(面板/安装时解析)。 */
    flavor: RuntimeFlavor | 'auto'
    /** 卸载到显卡的层数(0 = 纯 CPU)。 */
    gpuLayers: number
    /** 有些模型必须给查询/文档加前缀(nomic、e5),这里带着走。 */
    queryPrefix?: string
    documentPrefix?: string
    endpoint: string
    model: string
    dims: number
    timeoutMs: number
    writeTimeoutMs: number
    backfillTimeoutMs: number
    backfillMaxChars: number
    minScore: number
    backfillBatchSize: number
    spawn: EmbedServerConfig
  }
  llm: RerankConfig
  maxRecordsPerScope: number
  maxRecordChars: number
  secrets: { enabled: boolean; mode: 'refuse' | 'redact' }
}

/** vector 配置节的类型别名,给下面的模型解析helpers 用。 */
type VectorConfigInput = NonNullable<NonNullable<MemoryLocalConfig['retrieval']>['vector']>

/** 面板可以在安装时临时指定的模型选择。 */
export interface ModelOverride {
  preset?: string
  variant?: string
  custom?: { url: string; file?: string; dims: number; pooling?: PoolingKind; bytes?: number; sources?: string[] }
  flavor?: RuntimeFlavor | 'auto'
}

/**
 * 「面板选过什么」的记忆,落在安装目录里(<installRoot>/selected-model.json)。
 *
 * 为什么需要它:面板没法改写 profile 配置,而"选了模型 → 重启后配置又指回老模型"
 * 会让装好的模型认不出来。这里是**低于配置**的一层记忆:配置里写了 preset/customModel
 * 就听配置的,没写才用这份。
 */
export const MODEL_STATE_FILE = 'selected-model.json'

interface ModelState {
  presetId?: string
  variantId?: string
  customModel?: ModelOverride['custom']
  flavor?: RuntimeFlavor | 'auto'
}

function readModelState(root: string): ModelState | null {
  try {
    const text = readFileSync(join(root, MODEL_STATE_FILE), 'utf8')
    const parsed = JSON.parse(text) as ModelState
    return parsed !== null && typeof parsed === 'object' ? parsed : null
  } catch {
    return null
  }
}

function writeModelState(root: string, state: ModelState): void {
  try {
    mkdirSync(root, { recursive: true })
    writeFileSync(join(root, MODEL_STATE_FILE), `${JSON.stringify(state, null, 2)}\n`, 'utf8')
  } catch {
    // 记不住不影响本次安装;下次面板仍会显示配置文件里的选择。
  }
}

/** 系统语言(用来判断"中文优先");拿不到就当英文环境。 */
function safeLocale(): string {
  try {
    return Intl.DateTimeFormat().resolvedOptions().locale || 'en'
  } catch {
    return 'en'
  }
}

/** 该模型某个档位的体积(不指定档位时用默认档),用于清单展示与磁盘校验。 */
function variantBytes(model: { variants: Array<{ id: string; bytes: number; isDefault?: boolean }> }, variantId?: string): number {
  const variant = variantId !== undefined ? model.variants.find((v) => v.id === variantId) : undefined
  return (variant ?? model.variants.find((v) => v.isDefault) ?? model.variants[0]!).bytes
}

interface ModelSelection {
  presetId: string
  variantId: string
  label: string
  file: string
  bytes?: number
  sources: string[]
  dims: number
  pooling: PoolingKind
  /** 请求里用的模型名(身份头的一半);显式配了 model 就听配置的。 */
  modelName: string
  queryPrefix?: string
  documentPrefix?: string
  flavor?: RuntimeFlavor | 'auto'
}

/**
 * 把配置里的模型选择解析成安装器要的形态(文件名 / 体积 / 源 / 维度 / pooling / 前缀)。
 *
 * 优先级:customModel(完全自定义) → preset(清单 id) → 用 `model` 字符串去清单里找
 * → 内置默认(bge-m3 Q4_K_M,与老行为逐字一致)。
 * 认不出的 `model` 字符串**不改身份**(请求与边车仍用它),只是安装器退回默认模型 ——
 * 用户指向云端/自建服务时本来就该只写 endpoint + model + dims。
 */
function resolveModelSelection(v: VectorConfigInput, root?: string): ModelSelection {
  const state = root !== undefined ? readModelState(root) : null
  const custom = v.customModel ?? state?.customModel
  if (custom !== undefined) {
    let file = custom.file
    if (file === undefined || file === '') {
      try {
        file = basename(new URL(custom.url).pathname) || 'custom-model.gguf'
      } catch {
        file = 'custom-model.gguf'
      }
    }
    return {
      presetId: 'custom',
      variantId: 'custom',
      label: file,
      file,
      ...(custom.bytes !== undefined ? { bytes: custom.bytes } : {}),
      sources: custom.sources ?? [custom.url],
      dims: custom.dims,
      pooling: custom.pooling ?? 'auto',
      modelName: v.model ?? file.replace(/\.gguf$/i, ''),
      ...(v.flavor ?? state?.flavor ? { flavor: v.flavor ?? state?.flavor } : {}),
    }
  }
  // 配置 > 面板的记忆 > 用 model 字符串去清单里找 > 内置默认。
  const presetId = v.preset
    ?? state?.presetId
    ?? (findModel(v.model) !== undefined ? v.model as string : DEFAULT_MODEL_ID)
  const model = findModel(presetId) ?? findModel(DEFAULT_MODEL_ID)!
  const variant = findVariant(model, v.variant ?? state?.variantId)
  return {
    presetId: model.id,
    variantId: variant.id,
    label: `${model.label} · ${variant.label}`,
    file: variant.file,
    bytes: variant.bytes,
    sources: [...variant.sources],
    dims: model.dims,
    pooling: model.pooling,
    modelName: v.model ?? model.id,
    ...(model.queryPrefix !== undefined ? { queryPrefix: model.queryPrefix } : {}),
    ...(model.documentPrefix !== undefined ? { documentPrefix: model.documentPrefix } : {}),
    ...(v.flavor ?? state?.flavor ? { flavor: v.flavor ?? state?.flavor } : {}),
  }
}

/**
 * 接管已装好的后端时,spawn 该用哪个模型文件。
 *
 * 坑:换模型时 `spawn.model` 可能还留着**上一个**模型的路径(显式配置或上次 adopt
 * 写进去的),而 dims/pooling 已经跟着新模型变了 —— 那会启动一个"模型与参数不匹配"
 * 的服务,而且不报错,只是检索质量悄悄变差。所以只有"配置的模型就是当前选中的那个"
 * 才沿用它,否则一律用刚落盘的那份。
 */
export function pickSpawnModel(currentFile: string, configuredModel: string | undefined, installedModel: string): string {
  if (configuredModel !== undefined && basename(configuredModel) === currentFile) return configuredModel
  return installedModel
}

export function resolveConfig(config: MemoryLocalConfig = {}): ResolvedConfig {
  const v = config.retrieval?.vector ?? {}
  // Do not touch an embedding backend the user never asked for: pointing at the
  // stock localhost endpoint on a machine that has nothing listening means
  // failed embeds, a tripped breaker and scary log lines for a feature that is
  // optional. Vector retrieval is therefore opt-in by CONFIGURATION — writing
  // `endpoint` (any OpenAI-compatible service), configuring `spawn`, or having
  // the panel's installer put a backend on disk implies intent; an explicit
  // `enabled` always wins.
  const storeDir = config.storeDir ?? '.dsh-memory'
  // Installer target: explicit config → that directory; explicit storeDir →
  // its parent (so a hand-made `<root>/llamacpp` + `<root>/models` layout is
  // recognised as-is); otherwise a stable per-user directory under ~/.dsh.
  const installRoot = v.autoInstall?.dir
    ?? (config.storeDir !== undefined ? dirname(resolve(storeDir)) : join(homedir(), '.dsh', 'memory-vector'))
  // 模型选择:自定义 → 显式 preset → 用 model 字符串去清单里找 → 内置默认。
  // 这一步必须在 detectInstalled 之前:安装判据是「exe + **所选模型的**文件」。
  const selection = resolveModelSelection(v, installRoot)
  const installed = detectInstalled(installRoot, selection.file)
  const endpointConfigured = v.endpoint !== undefined
  // A configured spawn path that no longer exists (plugin uninstalled the
  // backend, or the user moved it) must not count as configured: that would
  // leave the panel showing a managed server that can never start, instead of
  // offering the download button again.
  const spawnExe = v.spawn?.exe
  const spawnExeUsable = spawnExe === undefined || spawnExe === '' || existsSync(spawnExe)
  const spawnConfigured = ((v.spawn?.enabled === true || (spawnExe ?? '') !== '') && spawnExeUsable) || installed !== null
  const configured = endpointConfigured || spawnConfigured
  const vectorEnabled = v.enabled ?? configured
  const flavor = selection.flavor ?? 'cpu'
  // scopes.custom 既可能是布尔(简写)也可能是对象 —— 两种都要认,旧配置(只有
  // global/project 两个布尔)当然照常工作。
  const customCfg = config.scopes?.custom
  const customEnabled = typeof customCfg === 'boolean' ? customCfg : (customCfg?.enabled ?? true)
  const customMax = typeof customCfg === 'object' && customCfg !== null && typeof customCfg.max === 'number'
    ? customCfg.max
    : 200
  return {
    storeDir,
    globalEnabled: config.scopes?.global ?? true,
    projectEnabled: config.scopes?.project ?? true,
    sessionEnabled: config.scopes?.session ?? true,
    customEnabled,
    customMaxScopes: customMax,
    topK: config.retrieval?.topK ?? 5,
    recallN: config.retrieval?.recallN ?? 30,
    globalThreshold: config.retrieval?.globalThreshold ?? 0.12,
    projectThreshold: config.retrieval?.projectThreshold ?? 0.1,
    halfLifeDays: config.retrieval?.recencyHalfLifeDays ?? 30,
    vector: {
      enabled: vectorEnabled,
      configured,
      endpointConfigured,
      spawnConfigured,
      installRoot,
      ...(v.autoInstall?.modelSources ? { installModelSources: v.autoInstall.modelSources } : {}),
      installModel: {
        file: selection.file,
        ...(selection.bytes !== undefined ? { bytes: selection.bytes } : {}),
        ...(selection.sources.length > 0 ? { sources: selection.sources } : {}),
      },
      presetId: selection.presetId,
      variantId: selection.variantId,
      modelLabel: selection.label,
      pooling: v.pooling ?? selection.pooling,
      flavor,
      gpuLayers: v.gpuLayers ?? (flavor === 'cpu' || flavor === 'auto' ? 0 : 99),
      ...(selection.queryPrefix !== undefined ? { queryPrefix: selection.queryPrefix } : {}),
      ...(selection.documentPrefix !== undefined ? { documentPrefix: selection.documentPrefix } : {}),
      endpoint: v.endpoint ?? 'http://127.0.0.1:8078/v1/embeddings',
      model: v.model ?? selection.modelName,
      dims: v.dims ?? selection.dims,
      timeoutMs: v.timeoutMs ?? 300,
      // Full contents are orders of magnitude slower than a short query on CPU
      // (measured 3143ms for three ~600-char records), so write/backfill paths
      // get their own generous budgets instead of the interactive 300ms.
      writeTimeoutMs: v.writeTimeoutMs ?? 10_000,
      backfillTimeoutMs: v.backfillTimeoutMs ?? 30_000,
      backfillMaxChars: v.backfillMaxChars ?? 8_000,
      // BGE CLS baseline noise floor measured ~0.42 on unrelated pairs
      minScore: v.minScore ?? 0.5,
      backfillBatchSize: v.backfillBatchSize ?? 32,
      // Port defaults to the one in the embeddings endpoint so the two can never
      // drift apart; opt-in (enabled:false) keeps dev/test runs from spawning.
      // A backend the panel installed (or a hand-made one at installRoot) is
      // adopted as the spawn target when the user configured no explicit paths.
      spawn: {
        ...(v.spawn ?? {}),
        enabled: v.spawn?.enabled ?? installed !== null,
        ...(installed
          ? {
              exe: v.spawn?.exe ?? installed.exe,
              model: v.spawn?.model ?? installed.model,
              cwd: v.spawn?.cwd ?? installed.cwd,
              logFile: v.spawn?.logFile ?? installed.logFile,
            }
          : {}),
        // 模型自带 pooling 与 GPU 层数:llama-server 拿不到就是错的检索结果,
        // 所以跟着所选模型一起传下去(extraArgs 仍在最后,可覆盖)。
        pooling: v.pooling ?? selection.pooling,
        gpuLayers: v.gpuLayers ?? (flavor === 'cpu' || flavor === 'auto' ? 0 : 99),
        port: v.spawn?.port ?? portOf(v.endpoint ?? 'http://127.0.0.1:8078/v1/embeddings') ?? 8078,
      },
    },
    llm: {
      enabled: config.retrieval?.llm?.enabled ?? false,
      provider: config.retrieval?.llm?.provider ?? '',
      model: config.retrieval?.llm?.model ?? '',
      timeoutMs: config.retrieval?.llm?.timeoutMs ?? 1500,
      dailyBudgetTokens: config.retrieval?.llm?.dailyBudgetTokens ?? 200_000,
      weight: config.retrieval?.llm?.weight ?? 0.6,
      topN: config.retrieval?.llm?.topN ?? 10,
    },
    maxRecordsPerScope: config.limits?.maxRecordsPerScope ?? 2000,
    maxRecordChars: config.limits?.maxRecordChars ?? 4000,
    secrets: {
      enabled: config.secrets?.enabled ?? true,
      mode: config.secrets?.mode ?? 'refuse',
    },
  }
}

/** 面板语义检索的一次结果:排序规则与 memory_search 相同,但不写访问计数。 */
export interface PanelSearchHit {
  record: MemoryRecord
  score: number
}

export interface PanelSearchResult {
  hits: PanelSearchHit[]
  /** `vector` = 向量通道真的参与了排序;`lexical` = 只有词法通道(面板要如实标注)。 */
  mode: 'vector' | 'lexical'
  /** mode 为 lexical 时,为什么没有走向量。 */
  reason?: 'vector-disabled' | 'no-vectors' | 'no-records' | 'embed-failed'
  /** 参与检索的记录里,有多少条已有向量 / 总条数。 */
  embedded: number
  total: number
}

/** 生效中的可见域(已剔除被 scope 开关禁用的项)。 */
export interface VisibilityPolicyView {
  level: VisibilityLevel
  scopes: VisibilityRule[]
}

/** 一条"范围外"命中:给审批浮层展示的完整快照(不落盘,进程内存)。 */
export interface VisibilityApprovalItem {
  id: string
  scope: string
  kind: string
  content: string
  tags: string[]
  importance: number
  updatedAt: number
  /** 为什么需要审批:整个作用域不在可见域里,还是只是类型不在允许列表里。 */
  reason: 'scope' | 'kind'
}

export interface VisibilityApprovalView {
  id: string
  sessionId: string
  tool: string
  /** Agent 的查询关键词 / 语句(id 列表或作用域名)。 */
  query: string
  items: VisibilityApprovalItem[]
  createdAt: number
  expiresAt: number
}

interface PendingVisibilityApproval extends VisibilityApprovalView {
  resolve(outcome: 'allowed-once' | 'rejected'): void
  timer: ReturnType<typeof setTimeout> | undefined
}

/** 普通限制下一次审批最多等多久;超时按拒绝处理(工具不会无限挂住)。 */
const VISIBILITY_APPROVAL_TTL_MS = 5 * 60_000
/** 审批浮层一次最多展示多少条范围外命中(工具侧仍会返回全部允许的命中)。 */
const VISIBILITY_APPROVAL_MAX_ITEMS = 20

export class LocalMemoryService implements MemoryServiceApi {
  readonly cfg: ResolvedConfig
  readonly store: MemoryStore
  readonly embed: EmbedClient
  private rerankBudget: DailyBudget
  private rerankCache = new RerankCache()
  /** Host-provided one-shot LLM call; null = rerank disabled (recall order). */
  private llmInvoke: LlmInvoke | null = null
  /** 写路径的默认口径(tools.defaultScope);'session' 拿不到会话时回退 project。 */
  private defaultWriteScope: 'session' | 'project' | 'global' = 'session'
  /** 显式配置的项目 scope 键(未配置 = undefined,由 resolveCurrentScopes 按会话 cwd 决定)。 */
  private projectScope: MemoryScope | undefined
  /** 上次发现磁盘 scope 的时间(限流用;0 = 还没发现过)。 */
  private discoveredAt = 0
  /** "同一目录不同写法"的项目作用域是否已经合并过(每个进程只做一次)。 */
  private scopesReconciled = false
  /** 作用域别名(project:<路径> → 显示名),落盘 <storeDir>/scopes.json。 */
  private names: ScopeNames
  /** 注入设置(面板「设置」标签页可改;落盘在 <storeDir>/settings.json)。 */
  private inject: InjectSettings
  /** 会话级「记忆可见范围」覆盖;没有覆盖时沿用默认三路集合。 */
  private readonly visibility: SessionVisibilityStore
  /** 可见域变更通知:下一次 pre-step 注入给 Agent 后删除(按会话)。 */
  private readonly visibilityNotices = new Map<string, { config: SessionVisibilityConfig | null; at: number }>()
  /** 普通限制下等待用户审批的范围外访问(按审批 id)。 */
  private readonly pendingApprovals = new Map<string, PendingVisibilityApproval>()
  private approvalSeq = 0
  /**
   * 会话 id → live session 的只读查询(用于沿 parentSession 链继承可见范围)。
   * 宿主侧 apply.ts 注入;旧宿主 / 测试里没有时退化为只看当前会话。
   */
  private sessionLookup: ((id: string) => unknown) | undefined
  /** 注入半边的审计收集器(可选;没有注入半边时保持 null)。 */
  private injectAuditSink: {
    list?(sessionId?: string): unknown
    query?(query?: unknown): unknown
    stats?(): unknown
    clear?(scope: { sessionId?: string; before?: number }): unknown
    dispose?(): void
  } | null = null

  constructor(config: MemoryLocalConfig = {}) {
    this.cfg = resolveConfig(config)
    this.inject = this.loadInjectSettings((config as { inject?: unknown }).inject)
    this.names = new ScopeNames(join(this.cfg.storeDir, 'scopes.json'))
    this.visibility = new SessionVisibilityStore({ root: this.cfg.storeDir })
    this.rerankBudget = new DailyBudget(this.cfg.llm.dailyBudgetTokens)
    this.store = new MemoryStore(this.cfg.storeDir, { onWarn: (m) => console.warn(`[dsh-memory-local] ${m}`) })
    // Identity BEFORE the eager load (issue #1): ScopeStore skips its sidecar
    // validation entirely while the identity is unset (`if (this.vecIdentity && …)`),
    // so loading first would accept vectors from a previous embedding model
    // whenever the dimensions matched — and the next flush would then rewrite the
    // header as the new model, making the mismatch permanent.
    // pooling 也进身份(issue #3):同一个模型换 --pooling 等于换了一个向量空间
    // (last 与 cls 的余弦只有 0.35),以前它不在 identity 里,校验会静默放行。
    this.store.setVecIdentity(this.cfg.vector.model, this.cfg.vector.dims, this.cfg.vector.pooling)
    // 会话 scope 是按会话动态生成的,**不能**在这里 eager 加载(加载谁?);只预载
    // project 与 global 这两个稳定作用域。其余按需 peek/loadDiscovered。
    // eager 只加载"已存在"的 scope(peek),不会为不存在的 scope 建空文件。
    // 项目键此刻还看不到会话(没传 agent),所以这里只能预载"没有显式配置时的兜底键"
    // (= project:<process.cwd()>);真正的项目键在每次调用时按会话 cwd 解析。
    const eager: MemoryScope[] = []
    if (this.cfg.projectEnabled) eager.push(this.defaultProjectScope)
    if (this.cfg.globalEnabled) eager.push('global')
    for (const scope of eager) this.store.peek(scope)
    this.embed = new EmbedClient({
      endpoint: this.cfg.vector.endpoint,
      model: this.cfg.vector.model,
      dims: this.cfg.vector.dims,
      timeoutMs: this.cfg.vector.timeoutMs,
    })
    this.startMaintenance()
    this.startEmbedServer()
  }

  /** 设置文件:与记忆数据同目录,便于一起备份/清理。 */
  get settingsPath(): string {
    return join(this.cfg.storeDir, 'settings.json')
  }

  /** 读取注入设置(归一化后的快照)。 */
  injectSettings(): InjectSettings {
    return normalizeInjectSettings(this.inject, this.inject)
  }

  /** 注入半边注册审计收集器。重复注册时后一个覆盖前一个(激活重载)。 */
  attachInjectAudit(sink: {
    list?(sessionId?: string): unknown
    query?(query?: unknown): unknown
    stats?(): unknown
    clear?(scope: { sessionId?: string; before?: number }): unknown
    dispose?(): void
  } | null): void {
    // 显式解绑:插件半边 dispose 时必须清掉，否则面板会继续读到已停止更新的旧 store。
    if (sink === null) {
      try { this.injectAuditSink?.dispose?.() } catch { /* 审计清理失败不影响 provider */ }
    } else if (this.injectAuditSink !== null && this.injectAuditSink !== sink) {
      // 多激活实例不应悄悄覆盖：保留诊断日志，查询边界仍以最后注册者为准。
      console.warn('[dsh-memory-local] audit sink replaced by another activation')
    }
    this.injectAuditSink = sink
  }

  /** 显式解绑:只有当前 sink 或未指定 sink 时才清理，避免旧实例卸载误清新实例。 */
  detachInjectAudit(sink?: unknown): void {
    if (sink !== undefined && this.injectAuditSink !== null && sink !== this.injectAuditSink) return
    try { this.injectAuditSink?.dispose?.() } catch { /* 审计清理失败不影响 provider */ }
    this.injectAuditSink = null
  }

  /** 兼容旧调用：返回审计条目数组（最新在前）；没有注入半边时为空。 */
  injectAudit(sessionId?: string): unknown {
    try { return this.injectAuditSink?.list?.(sessionId) ?? [] } catch { return [] }
  }

  /** v2 查询：优先用类型化 sink；旧 sink 只有 list 时降级包装成单页。 */
  injectAuditPage(query?: unknown): unknown {
    try {
      const sink = this.injectAuditSink
      if (sink?.query !== undefined) return sink.query(query)
      const q = (query && typeof query === 'object' ? query : {}) as { sessionId?: string }
      const entries = sink?.list?.(q.sessionId) ?? []
      return {
        entries,
        total: Array.isArray(entries) ? entries.length : 0,
        stats: this.injectAuditStats(),
      }
    } catch {
      return { entries: [], total: 0, stats: this.injectAuditStats() }
    }
  }

  /** 审计容量/丢弃/写入错误等健康状态。 */
  injectAuditStats(): unknown {
    try {
      return this.injectAuditSink?.stats?.() ?? {
        entries: 0, capacity: 0, perSessionCapacity: 0, dropped: 0,
        writeErrors: 0, persistence: 'memory',
      }
    } catch {
      return {
        entries: 0, capacity: 0, perSessionCapacity: 0, dropped: 0,
        writeErrors: 0, persistence: 'degraded',
      }
    }
  }

  /** 面板改设置:合并补丁 → 落盘 → 返回新值。写盘失败只告警,不影响运行中的设置。 */
  updateInjectSettings(patch: unknown): InjectSettings {
    this.inject = mergeInjectSettings(this.inject, patch)
    try {
      mkdirSync(this.cfg.storeDir, { recursive: true })
      writeFileSync(this.settingsPath, `${JSON.stringify(this.inject, null, 2)}\n`, 'utf8')
    } catch (error) {
      console.warn(`[dsh-memory-local] 无法写入注入设置 ${this.settingsPath}: ${error instanceof Error ? error.message : String(error)}`)
    }
    return this.injectSettings()
  }

  /** 配置先给底,磁盘上的 settings.json 覆盖它;坏文件忽略而不是启动失败。 */
  private loadInjectSettings(fromConfig: unknown): InjectSettings {
    const base = normalizeInjectSettings(fromConfig)
    try {
      if (existsSync(this.settingsPath)) {
        const parsed = JSON.parse(readFileSync(this.settingsPath, 'utf8')) as unknown
        const digest = (parsed as { digest?: Record<string, unknown> } | null)?.digest
        // 0.9.5 及以前的默认 digest 预算是 400,且没有 hintBudget 字段。
        // 升级到 0.9.6 时把"旧默认值"迁到新默认 800;显式写过 hintBudget 的配置不动。
        const oldDigestDefault = digest !== undefined && digest !== null
          && typeof digest === 'object' && digest.hintBudget === undefined
          && Number(digest.tokenBudget) === 400
        const merged = mergeInjectSettings(base, parsed)
        if (oldDigestDefault) merged.digest.tokenBudget = base.digest.tokenBudget
        return merged
      }
    } catch (error) {
      console.warn(`[dsh-memory-local] 忽略损坏的注入设置 ${this.settingsPath}: ${error instanceof Error ? error.message : String(error)}`)
    }
    return base
  }

  /**
   * 被其他记录 supersedes 指向的记录 id(=已退役)。scope 缺省时扫描全部已加载 scope。
   * 只读、不发现、不创建;注入半边/规则段/自动召回共用这一份口径。
   */
  supersededIds(scopes?: MemoryScope[]): string[] {
    const ids = new Set<string>()
    const stores = scopes === undefined
      ? this.store.allScopes()
      : scopes.map((scope) => this.store.peek(scope)).filter((s): s is NonNullable<typeof s> => s !== undefined)
    for (const store of stores) {
      for (const record of store.records.values()) {
        if (typeof record.supersedes === 'string' && record.supersedes.length > 0) ids.add(record.supersedes)
      }
    }
    return [...ids]
  }

  /**
   * 同步列记录(只读、不触发磁盘发现)。系统提示里的「硬性规则」段每步都要
   * 渲染,必须是同步的;这里直接读已加载 scope 的内存快照。
   *
   * 默认排除已被 supersede 的旧记录;需要历史/审计时显式 includeSuperseded。
   */
  listSync(input: { scopes?: MemoryScope[]; kind?: string; limit?: number; includeSuperseded?: boolean; includeExpired?: boolean; agent?: unknown } = {}): MemoryRecord[] {
    const wanted = (input.scopes ?? []).map((scope) => this.canonicalScope(scope))
    // 注入侧必须按可见域的类型白名单过滤;工具侧不传 agent(它需要范围外命中来发起审批)。
    const visibleFilter = input.agent !== undefined ? this.visibilityFilterFor(input.agent) : undefined
    const seen = new Set<MemoryScope>()
    const stores: ScopeStore[] = []
    for (const scope of wanted) {
      if (seen.has(scope)) continue
      seen.add(scope)
      const s = this.store.peek(scope)
      if (s) stores.push(s)
    }
    const retired = input.includeSuperseded ? new Set<string>() : new Set(this.supersededIds(wanted))
    const now = Date.now()
    const out: MemoryRecord[] = []
    for (const s of stores) {
      for (const rec of s.records.values()) {
        if (retired.has(rec.id)) continue
        // 过期 state 默认不参与任何自动注入/规则渲染;memory_get(id) 与面板仍可取。
        if (!input.includeExpired && rec.expiredAt !== undefined && rec.expiredAt < now) continue
        if (input.kind !== undefined && rec.kind !== input.kind) continue
        if (visibleFilter !== undefined && !visibleFilter(rec.scope, rec.kind)) continue
        out.push(rec)
      }
    }
    out.sort((a, b) => b.updatedAt - a.updatedAt)
    return out.slice(0, input.limit ?? 100)
  }

  /** Own the embedding backend's lifetime: spawn on activation, stop on dispose. */  private startEmbedServer(): void {
    // Nothing configured and retrieval switched off → do not even build the
    // manager, so no probe, no spawn attempt, no misleading panel state.
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return
    this.embedServer = new EmbedServerManager(this.cfg.vector.spawn)
    // fire-and-forget: activation must never block on a model load
    void this.ensureEmbedServer(60_000).catch(() => { /* lifecycle never breaks activation */ })
  }

  /**
   * Start (or adopt) the embedding backend and arm the exit safety net.
   * Shared by the activation path and the panel's manual start button.
   */
  private async ensureEmbedServer(waitMs?: number): Promise<EmbedServerState> {
    const mgr = this.embedServer
    if (!mgr) return 'disabled'
    const state = await mgr.ensureRunning()
    if (state !== 'spawned' && state !== 'adopted-managed') return state
    // hard-exit safety net: cordis disposal covers a clean quit; this covers
    // the host dying without disposing us (the child must not be orphaned)
    if (!this.exitHook) {
      this.exitHook = () => { this.embedServer?.stop() }
      process.once('exit', this.exitHook)
    }
    const ready = await mgr.waitUntilReady(waitMs)
    if (!ready) console.warn('[dsh-memory-local] embed server: 启动超时,检索继续走词法降级')
    return state
  }

  /** Manual start from the memory panel (same semantics as activation). */
  startEmbedServerManually(): Promise<EmbedServerState> {
    return this.ensureEmbedServer(25_000)
  }

  /**
   * Manual stop from the memory panel. An instance we do not own is left alone
   * (it was started outside the app), so the UI can explain the refusal.
   */
  stopEmbedServerManually(): { stopped: boolean; reason: 'STOPPED' | 'EXTERNAL_INSTANCE' | 'NOT_RUNNING' } {
    const mgr = this.embedServer
    if (!mgr) return { stopped: false, reason: 'NOT_RUNNING' }
    if (!mgr.isOwned) return { stopped: false, reason: 'EXTERNAL_INSTANCE' }
    return { stopped: mgr.stop(), reason: mgr.isOwned ? 'NOT_RUNNING' : 'STOPPED' }
  }

  /**
   * Lifecycle snapshot for the memory panel.
   *
   * `mode` is what the panel needs to decide whether a start/stop switch even
   * makes sense:
   *   - 'off'      nothing configured → no switch, show how to opt in
   *   - 'external' we only know an endpoint (cloud or a server the user runs)
   *                → no switch, we must not claim ownership of that process
   *   - 'managed'  spawn is configured → the switch toggles OUR child process
   * `enabled` is the retrieval switch from config; when it is false while a
   * backend IS configured the panel explains the config instead of showing a
   * switch that cannot turn retrieval on.
   */
  async embedServerStatus(): Promise<{
    enabled: boolean
    configured: boolean
    mode: 'off' | 'external' | 'managed'
    endpoint: string
    model: string
    /** 当前选择的模型(面板显示用):清单里的人类可读名字。 */
    modelLabel: string
    presetId: string
    variantId: string
    /** 落盘的模型文件名与维度 —— 换模型时这两个会一起变。 */
    modelFile: string
    dims: number
    pooling: PoolingKind
    flavor: RuntimeFlavor | 'auto'
    spawnConfigured: boolean
    owned: boolean
    pid: number | null
    baseUrl: string
    reachable: boolean
    pendingEmbeds: number
    install: InstallProgress & { installed: boolean; root: string }
    /** What an uninstall would free, and how much data a wipe would remove. */
    maintenance: { usageBytes: number; paths: string[]; storeDir: string; records: number }
  }> {
    const mgr = this.embedServer
    const cfg = this.cfg.vector
    const pendingEmbeds = this.pendingEmbedCount
    const mode = !cfg.configured ? 'off' : cfg.spawnConfigured ? 'managed' : 'external'
    const usage = this.vectorInstallUsage()
    const base = {
      enabled: cfg.enabled,
      configured: cfg.configured,
      mode,
      endpoint: cfg.endpoint,
      model: cfg.model,
      modelLabel: cfg.modelLabel,
      presetId: cfg.presetId,
      variantId: cfg.variantId,
      modelFile: cfg.installModel.file,
      dims: cfg.dims,
      pooling: cfg.pooling,
      flavor: cfg.flavor,
      spawnConfigured: cfg.spawnConfigured,
      pendingEmbeds,
      install: this.installSnapshot(),
      maintenance: {
        usageBytes: usage.bytes,
        paths: usage.paths,
        // NOTE: `cfg` is the VECTOR config here, not the whole config — reading
        // cfg.storeDir would silently yield undefined (and JSON drops it).
        storeDir: this.cfg.storeDir,
        records: this.store.allScopes().reduce((n, s) => n + s.records.size, 0),
      },
    } as const
    if (!mgr) return { ...base, owned: false, pid: null, baseUrl: '', reachable: false }
    const reachable = await mgr.healthCheck()
    return { ...base, ...mgr.info(), reachable, pendingEmbeds }
  }

  /** Installer state for the panel (idle when nothing was ever requested). */
  private installSnapshot(): InstallProgress & { installed: boolean; root: string } {
    const root = this.cfg.vector.installRoot
    const modelFile = this.cfg.vector.installModel.file
    const installed = detectInstalled(root, modelFile) !== null
    const progress = this.installer?.progress ?? {
      phase: 'idle' as const,
      message: '',
      receivedBytes: 0,
      totalBytes: null,
      error: null,
      paths: installed ? installPaths(root, modelFile) : null,
    }
    return { ...progress, installed, root }
  }

  /**
   * 面板的"模型与硬件"报告:清单 + 当前选择 + 硬件 + 推荐。
   *
   * 硬件探测会 spawn 外部命令(Windows 上还有 PowerShell),所以**只在面板问的时候**跑,
   * 并且结果缓存 10 分钟 —— 绝不在插件激活路径上。
   */
  async modelsReport(force = false): Promise<{
    catalog: Array<{
      id: string; label: string; note: string; dims: number; pooling: PoolingKind
      languages: string; contextTokens: number; sizeBytes: number; installed: boolean
      variants: Array<{ id: string; label: string; bytes: number; file: string; installed: boolean }>
    }>
    current: { presetId: string; variantId: string; modelLabel: string; file: string; dims: number; pooling: PoolingKind; flavor: RuntimeFlavor | 'auto'; model: string }
    hardware: HostHardware | null
    recommendation: ReturnType<typeof recommendModel> | null
    locale: string
    records: number
  }> {
    const root = this.cfg.vector.installRoot
    const catalog = EMBEDDING_MODELS.map((model) => ({
      id: model.id,
      label: model.label,
      note: model.note,
      dims: model.dims,
      pooling: model.pooling,
      languages: model.languages,
      contextTokens: model.contextTokens,
      sizeBytes: variantBytes(model, this.cfg.vector.presetId === model.id ? this.cfg.vector.variantId : undefined),
      installed: model.variants.some((variant) => detectInstalled(root, variant.file) !== null),
      // 逐档判断"装没装":bge-m3 装了 Q4_K_M 不等于 Q8_0 也装了。
      // 判据与 detectInstalled 一致 —— 运行时 exe + 该档模型文件都在。
      variants: model.variants.map((variant) => ({
        id: variant.id, label: variant.label, bytes: variant.bytes, file: variant.file,
        installed: detectInstalled(root, variant.file) !== null,
      })),
    }))
    const records = this.store.allScopes().reduce((n, s) => n + s.records.size, 0)
    const locale = safeLocale()
    let hardware: HostHardware | null = null
    try {
      hardware = await this.hardwareSnapshot(force)
    } catch {
      hardware = null // 探测失败就只显示清单,不给推荐 —— 不猜
    }
    const recommendation = hardware === null
      ? null
      : recommendModel({ hardware, locale, recordCount: records, currentModelId: this.cfg.vector.presetId })
    return {
      catalog,
      current: {
        presetId: this.cfg.vector.presetId,
        variantId: this.cfg.vector.variantId,
        modelLabel: this.cfg.vector.modelLabel,
        file: this.cfg.vector.installModel.file,
        dims: this.cfg.vector.dims,
        pooling: this.cfg.vector.pooling,
        flavor: this.cfg.vector.flavor,
        model: this.cfg.vector.model,
      },
      hardware,
      recommendation,
      locale,
      records,
    }
  }

  /** 硬件探测结果缓存(默认 10 分钟),'auto' 风味与推荐共用它。 */
  private async hardwareSnapshot(force = false): Promise<HostHardware> {
    const now = Date.now()
    if (!force && this.hardwareCache !== null && now - this.hardwareAt < 600_000) return this.hardwareCache
    const hw = await probeHardware({ dir: this.cfg.vector.installRoot })
    this.hardwareCache = hw
    this.hardwareAt = now
    return hw
  }

  /** 把 'auto' 风味解析成具体风味(需要探测;失败则退回 CPU)。 */
  private async resolveFlavor(): Promise<RuntimeFlavor> {
    const configured = this.cfg.vector.flavor
    if (configured !== 'auto') return configured
    try {
      return pickFlavor(await this.hardwareSnapshot())
    } catch {
      return 'cpu'
    }
  }

  /** 面板选了模型/风味之后,把选择写进安装目录的 state 文件并更新运行中的配置。 */
  private applyModelSelection(override: ModelOverride): RuntimeFlavor | 'auto' {
    const synthetic: VectorConfigInput = override.custom !== undefined
      ? { customModel: override.custom }
      : { ...(override.preset !== undefined ? { preset: override.preset } : {}), ...(override.variant !== undefined ? { variant: override.variant } : {}) }
    const sel = resolveModelSelection(synthetic)
    const cfg = this.cfg.vector
    cfg.installModel = {
      file: sel.file,
      ...(sel.bytes !== undefined ? { bytes: sel.bytes } : {}),
      ...(sel.sources.length > 0 ? { sources: sel.sources } : {}),
    }
    cfg.presetId = sel.presetId
    cfg.variantId = sel.variantId
    cfg.modelLabel = sel.label
    cfg.pooling = sel.pooling
    cfg.dims = sel.dims
    cfg.model = sel.modelName
    cfg.spawn.pooling = sel.pooling
    if (override.flavor !== undefined) cfg.flavor = override.flavor
    cfg.spawn.gpuLayers = cfg.flavor === 'cpu' || cfg.flavor === 'auto' ? 0 : (cfg.spawn.gpuLayers || 99)
    writeModelState(cfg.installRoot, {
      presetId: sel.presetId === 'custom' ? undefined : sel.presetId,
      variantId: sel.variantId === 'custom' ? undefined : sel.variantId,
      ...(override.custom !== undefined ? { customModel: override.custom } : {}),
      ...(override.flavor !== undefined ? { flavor: override.flavor } : {}),
    })
    return cfg.flavor
  }

  /**
   * Panel action: download llama.cpp + the GGML model into installRoot, then
   * adopt them (start the managed server). Never runs on its own — a fresh
   * install downloads nothing until the user asks.
   *
   * `override` 是面板的选择(预设/档位/自定义 URL/风味):它会先落进安装目录的
   * state 文件(下次启动仍然生效),再按新选择下载。配置里写了 preset/customModel
   * 的话,配置永远优先 —— state 只是"面板选过什么"的记忆。
   */
  installVectorBackend(override: ModelOverride = {}): void {
    const flavor = this.applyModelSelection(override)
    const model = this.cfg.vector.installModel
    if (detectInstalled(this.cfg.vector.installRoot, model.file)) {
      this.adoptInstalledBackend()
      return
    }
    // 换模型时把上一个安装器的进度丢掉:它描述的是另一个文件。
    this.installer?.cancel()
    this.installer = new VectorInstaller({
      root: this.cfg.vector.installRoot,
      model: { file: model.file, ...(model.bytes !== undefined ? { bytes: model.bytes } : {}), ...(model.sources !== undefined ? { sources: model.sources } : {}) },
      ...(flavor === 'auto' ? {} : { flavor }),
      ...(this.cfg.vector.installModelSources && model.sources === undefined ? { modelSources: this.cfg.vector.installModelSources } : {}),
      onProgress: (progress) => {
        if (progress.phase === 'done') this.adoptInstalledBackend()
      },
    })
    this.installer.start()
  }

  /** Panel action: abort an in-flight download. */
  cancelVectorInstall(): void {
    this.installer?.cancel()
  }

  /**
   * What the installer put on disk, so the panel can say "释放 xxx MB" before
   * offering to remove it. Counts only our own layout (runtime dir, models dir,
   * log + pid), never the memory store.
   */
  vectorInstallUsage(): { bytes: number; paths: string[] } {
    const paths = installPaths(this.cfg.vector.installRoot, this.cfg.vector.installModel.file)
    const roots = [paths.dir, join(this.cfg.vector.installRoot, 'models')]
    const files = [paths.logFile, `${paths.logFile}.pid`, `${paths.logFile}.err`]
    let bytes = 0
    const seen: string[] = []
    for (const p of [...roots, ...files]) {
      if (!existsSync(p)) continue
      seen.push(p)
      bytes += pathSize(p)
    }
    return { bytes, paths: seen }
  }

  /**
   * Remove the vector backend we installed (runtime + model + logs).
   *
   * Refuses when the configured backend lives outside installRoot: that is a
   * server the user installed and manages, and deleting it would be destroying
   * something we never created. The memory store is never touched — it lives
   * beside the runtime, not inside it.
   */
  uninstallVectorBackend(): {
    removed: boolean
    reason: 'REMOVED' | 'NOT_INSTALLED' | 'EXTERNAL_BACKEND'
    freedBytes: number
    paths: string[]
  } {
    const root = this.cfg.vector.installRoot
    const configuredExe = this.cfg.vector.spawn.exe
    if (configuredExe && !isInside(root, configuredExe)) {
      return { removed: false, reason: 'EXTERNAL_BACKEND', freedBytes: 0, paths: [] }
    }
    const usage = this.vectorInstallUsage()
    if (usage.paths.length === 0) {
      return { removed: false, reason: 'NOT_INSTALLED', freedBytes: 0, paths: [] }
    }
    // Stop our child first: on Windows the executable and its DLLs are locked
    // while it runs, so removal would fail with EBUSY/EPERM.
    try { this.embedServer?.stop() } catch { /* best effort */ }
    const removedPaths: string[] = []
    for (const p of usage.paths) {
      // Belt and braces: never step outside the install root, and never delete
      // the memory store even if someone pointed storeDir inside it.
      if (!isInside(root, p)) continue
      if (isInside(p, this.cfg.storeDir) || resolve(p) === resolve(this.cfg.storeDir)) continue
      try {
        rmSync(p, { recursive: true, force: true })
        removedPaths.push(p)
      } catch { /* leave it; the panel reports what went */ }
    }
    this.cfg.vector.configured = false
    this.cfg.vector.spawnConfigured = false
    this.cfg.vector.enabled = false
    this.embedServer = null
    return { removed: true, reason: 'REMOVED', freedBytes: usage.bytes, paths: removedPaths }
  }

  /**
   * Delete every memory record in every scope (the panel's "delete all data"
   * action, used when someone wants the plugin gone without leaving notes
   * behind). Goes through the store so the JSONL + vector sidecars stay
   * consistent instead of ripping files out from under a live store.
   */
  wipeAllRecords(): { removed: number; scopes: string[] } {
    let removed = 0
    const scopes: string[] = []
    for (const scope of this.store.allScopes()) {
      const ids = [...scope.records.keys()]
      if (ids.length === 0) continue
      let local = 0
      for (const id of ids) if (scope.remove(id)) local += 1
      removed += local
      scopes.push(scope.scope)
    }
    try { this.store.flush() } catch { /* scheduled flush covers it */ }
    return { removed, scopes }
  }

  /**
   * Switch the provider over to a backend that is now on disk: fill the spawn
   * config from the installed layout and start it. Idempotent.
   */
  private adoptInstalledBackend(): void {
    const paths = detectInstalled(this.cfg.vector.installRoot, this.cfg.vector.installModel.file)
    if (!paths) return
    this.cfg.vector.configured = true
    this.cfg.vector.spawnConfigured = true
    this.cfg.vector.enabled = true
    this.cfg.vector.spawn = {
      ...this.cfg.vector.spawn,
      enabled: true,
      exe: this.cfg.vector.spawn.exe ?? paths.exe,
      // 模型路径必须跟着**当前选择的模型**:换了模型就不能继续用上一个的文件(见 pickSpawnModel)。
      model: pickSpawnModel(this.cfg.vector.installModel.file, this.cfg.vector.spawn.model, paths.model),
      cwd: this.cfg.vector.spawn.cwd ?? paths.cwd,
      logFile: this.cfg.vector.spawn.logFile ?? paths.logFile,
      pooling: this.cfg.vector.pooling,
      gpuLayers: this.cfg.vector.flavor === 'cpu' || this.cfg.vector.flavor === 'auto' ? 0 : (this.cfg.vector.spawn.gpuLayers || 99),
      port: this.cfg.vector.spawn.port,
    }
    if (!this.embedServer) {
      this.startEmbedServer()
      return
    }
    void this.ensureEmbedServer(60_000).catch(() => { /* panel shows the outcome */ })
  }

  /**
   * Hourly expired-record purge + capacity eviction. M4 housekeeping; the
   * timer is unref'd so it never holds the process open, and cleared by
   * flushSync()/dispose.
   */
  private maintenanceTimer: ReturnType<typeof setInterval> | null = null

  private startMaintenance(): void {
    this.maintenanceTimer = setInterval(() => {
      this.store.purgeExpired()
      this.store.enforceLimit(this.cfg.maxRecordsPerScope)
      this.store.scheduleFlush(0)
    }, 3_600_000)
    this.maintenanceTimer.unref?.()
    // Pending-embed drain: the store queues ids whose embed failed (backend
    // down at save time, or vectors restored from a jsonl-only backup). Until
    // this timer existed nothing ever drained that queue — a single outage
    // stranded them forever (observable as 待嵌入>0 in the memory panel).
    this.embedRetryTimer = setInterval(() => {
      void this.retryPendingEmbeds().catch(() => {})
    }, 60_000)
    this.embedRetryTimer.unref?.()
    // First drain shortly after boot, when the backend is usually already up.
    const initial = setTimeout(() => {
      this.initialDrainTimer = null
      void this.retryPendingEmbeds().catch(() => {})
    }, 5_000)
    initial.unref?.()
    this.initialDrainTimer = initial
  }

  private embedRetryTimer: ReturnType<typeof setInterval> | null = null
  private initialDrainTimer: ReturnType<typeof setTimeout> | null = null
  /** Owns the llama-server child process when vector.spawn.enabled. */
  private embedServer: EmbedServerManager | null = null
  /** Lazily created by the panel's "download and configure" action. */
  private installer: VectorInstaller | null = null
  /** 硬件探测缓存(面板问了才探测,10 分钟内复用)。 */
  private hardwareCache: HostHardware | null = null
  private hardwareAt = 0
  private exitHook: (() => void) | null = null

  /**
   * Drain the pending-embed queue, probing through the circuit breaker first so
   * a backend that came back online is noticed (backfillEmbeddings itself
   * refuses to touch the network while marked unhealthy, and embed() is the
   * only path that can flip that flag back to healthy).
   */
  async retryPendingEmbeds(): Promise<number> {
    // Vector retrieval opt-in: with no configured backend there is nothing to
    // retry, and probing would only produce failed requests in the log.
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return 0
    // Scopes load lazily, so without discovery the queue of an untouched scope
    // (e.g. a project store written by a previous session) is invisible here and
    // would never drain — exactly the 待嵌入>0 the panel showed on 2026-10-10.
    try { this.store.loadDiscovered() } catch { /* discovery is best-effort */ }
    if (this.pendingEmbedCount === 0) return 0
    if (!this.embed.isHealthy) {
      const probe = await this.embed.embed(['ping'], undefined, { timeoutMs: this.cfg.vector.writeTimeoutMs }).catch(() => null)
      if (!probe) return 0
    }
    return this.backfillAll({ throttleMs: 100 })
  }

  /**
   * 写路径默认 scope 口径(tools.defaultScope 取值)。
   * 兼容:旧调用方传的是**具体 scope 键**(如 'project:<cwd>'),此时按"固定项目"处理。
   */
  setDefaultScope(scope: 'session' | 'project' | 'global' | MemoryScope): void {
    if (scope === 'session' || scope === 'project' || scope === 'global') {
      this.defaultWriteScope = scope
      return
    }
    this.defaultWriteScope = 'project'
    this.projectScope = scope as MemoryScope
  }

  /** 固定项目 scope(只有**显式配置**才调);缺省由会话 cwd 决定。 */
  setProjectScope(scope: MemoryScope): void {
    this.projectScope = scope
  }

  /**
   * 拿不到会话时的项目键:显式配置优先,否则 `project:<process.cwd()>`
   * (用于构造期预载、以及任何没有 agent 上下文的兜底读写)。
   */
  private get defaultProjectScope(): MemoryScope {
    return (this.projectScope ?? `project:${process.cwd()}`) as MemoryScope
  }

  /**
   * Provide the one-shot LLM caller used by the rerank stage. Passing null
   * (or never calling) keeps retrieval on recall-order only. The cordis
   * wiring adapts `ctx.llm` into this; it is optional by design — the service
   * must never sit PENDING just because no LLM adapter is loaded.
   */
  setLlmInvoke(invoke: LlmInvoke | null): void {
    this.llmInvoke = invoke
  }

  /** 写路径默认口径('session' | 'project' | 'global')。 */
  get activeDefaultScope(): 'session' | 'project' | 'global' {
    return this.defaultWriteScope
  }

  /**
   * 当前项目键(诊断/测试用)。没有会话时就是兜底键 —— 真实调用请用 `scopeRefs(agent)`,
   * 那里的优先级是 会话 cwd > 显式配置 > process.cwd()。
   */
  get activeProjectScope(): MemoryScope {
    return this.defaultProjectScope
  }

  private assertScopeAllowed(scope: MemoryScope): void {
    if (scope === 'global') {
      if (!this.cfg.globalEnabled) throw memoryError('SCOPE_DISABLED', 'global scope is disabled by configuration')
      return
    }
    if (scope.startsWith('project:')) {
      if (!this.cfg.projectEnabled) throw memoryError('SCOPE_DISABLED', 'project scope is disabled by configuration')
      return
    }
    if (scope.startsWith('session:')) {
      if (!this.cfg.sessionEnabled) throw memoryError('SCOPE_DISABLED', 'session scope is disabled by configuration')
      return
    }
    if (!this.cfg.customEnabled) throw memoryError('SCOPE_DISABLED', 'custom scopes are disabled by configuration')
  }

  /**
   * scopes.custom.max 只统计**新建**的自定义 scope,而且只统计自定义的
   * (会话 / project / global 既不计入也不受限)。
   *
   * 计数走 `store.customScopeCount()`,它会顺带扫一遍磁盘 —— 只在"内存里的已加载数已经触到
   * 上限"时才真扫,否则直接放行,避免每次保存都读一遍 projects/ 目录。
   */
  private assertCustomScopeBudget(scope: MemoryScope): void {
    if (!isCustomScope(scope)) return
    if (this.store.peek(scope) !== undefined) return // 已存在(内存或磁盘)→ 写入不受限
    const loaded = this.store.allScopes().filter((s) => isCustomScope(s.scope)).length
    if (loaded < this.cfg.customMaxScopes && this.store.customScopeCount() < this.cfg.customMaxScopes) return
    throw memoryError(
      'SCOPE_LIMIT',
      `custom scope limit reached (${this.cfg.customMaxScopes}); reuse an existing scope instead. ${this.scopeInventory(5)}`,
    )
  }

  /** 作用域清单(名字 + 条数),给 SCOPE_LIMIT 之类的错误提示用。 */
  scopeInventory(limit = 20): string {
    const scopes = this.scopeStats()
    const lines = scopes.slice(0, limit).map((s) => `${s.scope}(${s.records})`)
    const rest = scopes.length - lines.length
    return rest > 0 ? `${lines.join(', ')}, …另有 ${rest} 个` : lines.join(', ')
  }

  /**
   * 写路径的 scope 解析:agent 上下文 → 当前会话 / 当前项目;模型省略 scope 时按
   * `tools.defaultScope`(默认 'session')落点。拿不到会话信息就回退 project,**不抛错**。
   */
  resolveWriteScope(agent: unknown, requested?: string): MemoryScope {
    const refs = this.scopeRefs(agent)
    const want = requested?.trim()
    if (want === undefined || want === '' || want.toLowerCase() === 'session') {
      // scopes.session 关掉时"当前会话"不存在:按 defaultScope 口径回退(默认口径是
      // session 而会话被关 → project),而不是让写撞上 SCOPE_DISABLED。
      const session = this.cfg.sessionEnabled ? refs.session : undefined
      return writeScopeForDefault(this.defaultWriteScope, { ...refs, session })
    }
    if (want.toLowerCase() === 'project') return refs.project
    if (want.toLowerCase() === 'global') return 'global'
    return requested as MemoryScope // 具体键(project:/session:/自定义名)由工具层 normalize 后传入
  }

  /** agent 上下文 → { session?, project }(会话能否用由调用方按 scopes.session 决定)。 */
  scopeRefs(agent: unknown): { session?: MemoryScope; project: MemoryScope } {
    return resolveCurrentScopes(agent, { projectScope: this.projectScope })
  }

  /**
   * 当前项目 key(= `scopeRefs(agent).project`)。工具层用它解析 `scope:'project'`,保证与服务端
   * 读/写口径**同一处** —— 0.5.5 及以前工具层自己算了一份 `project:<process.cwd()>`,于是同一个
   * 概念在两个层各有各的答案。
   */
  projectKeyFor(agent: unknown): MemoryScope {
    return this.scopeRefs(agent).project
  }

  /** 宿主注入 live session 查询(用于沿 parentSession 链继承可见范围)。 */
  setSessionLookup(lookup: ((id: string) => unknown) | undefined): void {
    this.sessionLookup = lookup
  }

  /** 只保留当前配置允许的 scope(覆盖集合里若含被禁用的 scope,静默剔除)。 */
  private filterEnabledRules(rules: readonly VisibilityRule[]): VisibilityRule[] {
    const out: VisibilityRule[] = []
    for (const raw of rules) {
      const scope = this.canonicalScope(raw.scope)
      if (out.some((rule) => rule.scope === scope)) continue
      switch (scopeKind(scope)) {
        case 'global': if (!this.cfg.globalEnabled) continue; break
        case 'project': if (!this.cfg.projectEnabled) continue; break
        case 'session': if (!this.cfg.sessionEnabled) continue; break
        default: if (!this.cfg.customEnabled) continue; break
      }
      const kinds = Array.isArray(raw.kinds) ? raw.kinds.filter((kind) => typeof kind === 'string' && kind !== '') : []
      out.push(kinds.length > 0 ? { scope, kinds } : { scope })
    }
    return out
  }

  /**
   * 从会话 id 沿 parentSession 链找最近的显式可见域。
   *
   * 起点用**当前会话自己的 id**(不是 resolveCurrentScopes 映射后的父会话):
   * 子 Agent 自己也可以有一份覆盖;没有时才沿链继承父会话 / 根会话。
   */
  private visibilityForSession(sessionId: string | undefined): SessionVisibilityConfig | undefined {
    let id = sessionId ?? ''
    const seen = new Set<string>()
    while (id !== '' && !seen.has(id)) {
      seen.add(id)
      const found = this.visibility.get(id)
      if (found !== undefined) return found
      let parent: string | undefined
      try {
        const session = this.sessionLookup?.(id) as { header?: { parentSession?: unknown } } | undefined
        parent = typeof session?.header?.parentSession === 'string' && session.header.parentSession !== ''
          ? session.header.parentSession
          : undefined
      } catch { parent = undefined }
      id = parent ?? ''
    }
    return undefined
  }

  /** agent 上真实的会话 id(不映射到父会话);用于可见范围自己的文件。 */
  private rawSessionIdOf(agent: unknown): string | undefined {
    try {
      const session = (agent as { session?: { id?: unknown; header?: { id?: unknown } } } | undefined)?.session
      const id = session?.header?.id ?? session?.id
      return typeof id === 'string' && id !== '' ? id : undefined
    } catch {
      return undefined
    }
  }

  /**
   * 显式「记忆可见域」的完整策略(含等级与每个 scope 的类型白名单)。
   * undefined = 没有覆盖;level='none' 时 scopes 仍保留(供面板/下次切换),
   * 但**不参与**读取限制。
   */
  visibilityPolicy(agent: unknown): VisibilityPolicyView | undefined {
    const explicit = this.visibilityForSession(this.rawSessionIdOf(agent))
    if (explicit === undefined) return undefined
    return { level: explicit.level, scopes: this.filterEnabledRules(explicit.scopes) }
  }

  /**
   * 显式「记忆可见范围」的 scope 键列表。
   * undefined = 不限制(没有覆盖,或等级为 none);
   * [] = 显式设置了范围但全部被 scope 开关禁用,调用方必须按空处理。
   */
  visibleScopes(agent: unknown): MemoryScope[] | undefined {
    const policy = this.visibilityPolicy(agent)
    if (policy === undefined || policy.level === 'none') return undefined
    return policy.scopes.map((rule) => this.canonicalScope(rule.scope))
  }

  /** 某个 scope 下允许的记忆类型;undefined = 不限制(可见且没有类型白名单)。 */
  visibleKinds(agent: unknown, scope: string): string[] | undefined {
    const policy = this.visibilityPolicy(agent)
    if (policy === undefined || policy.level === 'none') return undefined
    const key = this.canonicalScope(scope)
    const rule = policy.scopes.find((item) => this.canonicalScope(item.scope) === key)
    if (rule === undefined) return []
    return rule.kinds !== undefined && rule.kinds.length > 0 ? [...rule.kinds] : undefined
  }

  /** 一条记录(scope + kind)是否落在当前可见域内;等级 none / 无覆盖时恒为 true。 */
  isRecordVisible(agent: unknown, scope: string, kind: string): boolean {
    const policy = this.visibilityPolicy(agent)
    if (policy === undefined || policy.level === 'none') return true
    const key = this.canonicalScope(scope)
    const rule = policy.scopes.find((item) => this.canonicalScope(item.scope) === key)
    if (rule === undefined) return false
    if (rule.kinds === undefined || rule.kinds.length === 0) return true
    return rule.kinds.includes(kind)
  }

  /**
   * 批量过滤用的可见域判定(策略只解析一次,避免每条记录都走一遍 parentSession 链)。
   * undefined = 不限制。
   */
  private visibilityFilterFor(agent: unknown): ((scope: string, kind: string) => boolean) | undefined {
    const policy = this.visibilityPolicy(agent)
    if (policy === undefined || policy.level === 'none') return undefined
    const byScope = new Map<string, string[] | undefined>()
    for (const rule of policy.scopes) {
      byScope.set(this.canonicalScope(rule.scope), rule.kinds !== undefined && rule.kinds.length > 0 ? rule.kinds : undefined)
    }
    return (scope, kind) => {
      const key = this.canonicalScope(scope)
      if (!byScope.has(key)) return false
      const kinds = byScope.get(key)
      return kinds === undefined || kinds.includes(kind)
    }
  }

  /** 面板:读取某会话自己的覆盖(null = 没有覆盖,继续用默认集合)。 */
  sessionVisibility(sessionId: string): SessionVisibilityConfig | null {
    if (typeof sessionId !== 'string' || sessionId.trim() === '') return null
    const config = this.visibility.get(sessionId.trim())
    return config === undefined ? null : config
  }

  /**
   * 面板:写入/清除某会话的覆盖。null = 恢复默认。
   * 也接受 0.18 的 `string[]`(按绝对限制 + 全部类型),避免外部调用方升级即断。
   */
  setSessionVisibility(sessionId: string, config: SessionVisibilityConfig | readonly string[] | null): SessionVisibilityConfig | null {
    if (typeof sessionId !== 'string' || sessionId.trim() === '') return null
    const normalized: SessionVisibilityConfig | null = config === null
      ? null
      : Array.isArray(config)
        ? { scopes: (config as readonly string[]).map((scope) => ({ scope })), level: 'absolute' as VisibilityLevel }
        : config as SessionVisibilityConfig
    const cleaned = normalized === null ? null : this.normalizeVisibilityConfig(normalized)
    const written = this.visibility.set(sessionId.trim(), cleaned)
    // 变更通知:下一次 pre-step 以 user 消息注入,让 Agent 知道新范围与新规则。
    this.visibilityNotices.set(sessionId.trim(), { config: written, at: Date.now() })
    return written
  }

  /** 校验并规范化面板提交的可见域(必须是具体作用域键;不接受 all/current-*)。 */
  private normalizeVisibilityConfig(config: SessionVisibilityConfig): SessionVisibilityConfig {
    const rules = cleanVisibilityRules(config.scopes)
    if (rules === undefined || rules.length === 0) {
      throw memoryError('SCOPE_EMPTY', '至少选择一个可见的记忆范围')
    }
    const out: VisibilityRule[] = []
    for (const rule of rules) {
      const normalized = normalizeScopeInput(rule.scope)
      if (!normalized.ok) throw memoryError(normalized.code, normalized.message)
      if (normalized.kind === 'all' || normalized.kind === 'current-session' || normalized.kind === 'current-project') {
        throw memoryError('SCOPE_INVALID', `可见范围必须是具体作用域键: ${JSON.stringify(rule.scope)}`)
      }
      if (normalized.scope === undefined) continue
      const scope = this.canonicalScope(normalized.scope)
      if (out.some((item) => item.scope === scope)) continue
      const kinds = Array.isArray(rule.kinds)
        ? [...new Set(rule.kinds.filter((kind) => typeof kind === 'string' && kind.trim() !== '').map((kind) => kind.trim()))]
        : []
      out.push(kinds.length > 0 ? { scope, kinds } : { scope })
    }
    if (out.length === 0) throw memoryError('SCOPE_EMPTY', '至少选择一个可见的记忆范围')
    const level: VisibilityLevel = config.level === 'normal' || config.level === 'none' ? config.level : 'absolute'
    return { scopes: out, level }
  }

  /**
   * 取出并删除某会话待注入的「可见域变更」通知。
   * 沿 parentSession 链找:子 Agent 继承父会话的范围,也应该收到父会话的变更。
   */
  takeVisibilityNotice(agent: unknown): { config: SessionVisibilityConfig | null } | undefined {
    let id = this.rawSessionIdOf(agent) ?? ''
    const seen = new Set<string>()
    while (id !== '' && !seen.has(id)) {
      seen.add(id)
      const found = this.visibilityNotices.get(id)
      if (found !== undefined) {
        this.visibilityNotices.delete(id)
        return { config: found.config }
      }
      let parent: string | undefined
      try {
        const session = this.sessionLookup?.(id) as { header?: { parentSession?: unknown } } | undefined
        parent = typeof session?.header?.parentSession === 'string' && session.header.parentSession !== ''
          ? session.header.parentSession
          : undefined
      } catch { parent = undefined }
      id = parent ?? ''
    }
    return undefined
  }

  /** 每个 scope 下按类型统计条数(面板「类型」选择器用)。 */
  scopeKindStats(): Array<{ scope: MemoryScope; kind: string; records: number }> {
    const out: Array<{ scope: MemoryScope; kind: string; records: number }> = []
    for (const scope of this.store.allScopes()) {
      const counts = new Map<string, number>()
      for (const record of scope.records.values()) counts.set(record.kind, (counts.get(record.kind) ?? 0) + 1)
      for (const [kind, records] of [...counts].sort((a, b) => a[0].localeCompare(b[0]))) {
        out.push({ scope: scope.scope, kind, records })
      }
    }
    return out
  }

  /** 普通限制:范围外命中时创建一条待审批,等待面板回答(超时按拒绝)。 */
  requestOutOfScope(
    agent: unknown,
    input: { tool: string; query: string; items: readonly VisibilityApprovalItem[]; signal?: AbortSignal },
  ): Promise<'allowed-once' | 'rejected'> {
    if (input.items.length === 0) return Promise.resolve('allowed-once')
    if (input.signal?.aborted) return Promise.resolve('rejected')
    const sessionId = this.rawSessionIdOf(agent) ?? ''
    const id = `vis-${Date.now().toString(36)}-${++this.approvalSeq}`
    const createdAt = Date.now()
    const expiresAt = createdAt + VISIBILITY_APPROVAL_TTL_MS
    return new Promise((resolve) => {
      let timer: ReturnType<typeof setTimeout> | undefined
      const onAbort = () => finish('rejected')
      const finish = (outcome: 'allowed-once' | 'rejected'): void => {
        const pending = this.pendingApprovals.get(id)
        if (pending === undefined) return
        this.pendingApprovals.delete(id)
        if (timer !== undefined) clearTimeout(timer)
        try { input.signal?.removeEventListener('abort', onAbort) } catch { /* 已卸载 */ }
        pending.resolve(outcome)
      }
      timer = setTimeout(() => finish('rejected'), VISIBILITY_APPROVAL_TTL_MS)
      timer.unref?.()
      this.pendingApprovals.set(id, {
        id,
        sessionId,
        tool: input.tool,
        query: input.query,
        items: input.items.slice(0, VISIBILITY_APPROVAL_MAX_ITEMS).map((item) => ({
          ...item,
          tags: [...item.tags],
        })),
        createdAt,
        expiresAt,
        resolve: resolve,
        timer,
      })
      try { input.signal?.addEventListener('abort', onAbort, { once: true }) } catch { /* 已中止 */ }
    })
  }

  /** 面板:当前所有待审批(可按会话过滤)。 */
  pendingVisibilityApprovals(sessionId?: string): VisibilityApprovalView[] {
    const out: VisibilityApprovalView[] = []
    for (const pending of this.pendingApprovals.values()) {
      if (sessionId !== undefined && sessionId !== '' && pending.sessionId !== sessionId) continue
      out.push({
        id: pending.id,
        sessionId: pending.sessionId,
        tool: pending.tool,
        query: pending.query,
        // 轮询载荷保持轻量:正文截到 1200 字,悬浮需要全文时面板再按 id 取一次。
        items: pending.items.map((item) => ({
          ...item,
          content: item.content.length > 1200 ? `${item.content.slice(0, 1200)}…` : item.content,
          tags: [...item.tags],
        })),
        createdAt: pending.createdAt,
        expiresAt: pending.expiresAt,
      })
    }
    return out.sort((a, b) => a.createdAt - b.createdAt)
  }

  /** 面板:回答一条待审批。返回 false = 已经不存在/已超时。 */
  answerVisibilityApproval(id: string, outcome: 'allowed-once' | 'rejected'): boolean {
    const pending = this.pendingApprovals.get(id)
    if (pending === undefined) return false
    this.pendingApprovals.delete(id)
    if (pending.timer !== undefined) clearTimeout(pending.timer)
    pending.resolve(outcome)
    return true
  }

  /**
   * 无显式 scope 时的**读取**合并集合:当前会话 + 当前项目 + global(各自开关生效、按 key 去重)。
   * 工具 / 注入都用它。会话设置了「可见范围」时以覆盖为准(不再并入默认集合)。
   */
  resolveReadScopes(agent: unknown): MemoryScope[] {
    const explicit = this.visibleScopes(agent)
    // level='none' 时 visibleScopes 返回 undefined:不限制读取,继续用默认三路集合。
    if (explicit !== undefined) return explicit
    const refs = this.scopeRefs(agent)
    const out: MemoryScope[] = []
    const push = (scope: MemoryScope | undefined, enabled: boolean): void => {
      if (scope === undefined || !enabled || out.includes(scope)) return
      out.push(scope)
    }
    push(refs.session, this.cfg.sessionEnabled)
    push(refs.project, this.cfg.projectEnabled)
    push('global', this.cfg.globalEnabled)
    return out
  }

  async save(input: MemorySaveInput): Promise<MemoryRecord> {
    // 省略 scope 时按当前会话落点 —— 会话上下文必须**从调用方带进来**
    // (工具 handler 拿得到 exec.agent,provider 自己看不到)。
    const requestedScope = input.scope ?? this.resolveWriteScope((input as MemorySaveInput & { agent?: unknown }).agent)
    const scope = this.canonicalScope(requestedScope)
    this.assertScopeAllowed(scope)
    // 0.7.0:项目作用域可以带一个显示名(别名)。同一路径同名幂等,不同路径同名拒绝。
    const requestedName = (input as MemorySaveInput & { name?: unknown }).name
    if (requestedName !== undefined && requestedName !== null && String(requestedName).trim() !== '') {
      if (!scope.startsWith('project:')) {
        throw memoryError('SCOPE_NAME_UNSUPPORTED', '只有项目作用域支持重命名(需要 path 或 project:<路径>)')
      }
      this.names.claim(scope, String(requestedName))
    }
    // 自定义 scope 的**新建**受 scopes.custom.max 限制;写已存在的 scope 不受限。
    this.assertCustomScopeBudget(scope)
    let content = input.content?.trim()
    if (!content) throw memoryError('CONTENT_EMPTY', 'content must be a non-empty string')
    if (content.length > this.cfg.maxRecordChars) {
      throw memoryError('CONTENT_TOO_LONG', `content exceeds ${this.cfg.maxRecordChars} chars`)
    }
    if (input.supersedes && !this.store.scope(scope).records.get(input.supersedes)) {
      throw memoryError('SUPERSEDES_UNKNOWN', `supersedes target ${input.supersedes} not found in ${scope}`)
    }
    // 状态型记忆(state)默认带 TTL:写入时算一次绝对 expiresAt,读取时只比较时间。
    // 显式 expiresAt 优先;ttlMs 对任何 kind 都生效(便于测试/特殊用途)。
    const timing = input as MemorySaveInput & { ttlMs?: unknown; expiresAt?: unknown }
    const explicitExpiresAt = typeof timing.expiresAt === 'number' && Number.isFinite(timing.expiresAt)
      ? timing.expiresAt
      : undefined
    const explicitTtl = typeof timing.ttlMs === 'number' && Number.isFinite(timing.ttlMs) && timing.ttlMs > 0
      ? timing.ttlMs
      : undefined
    const stateTtl = input.kind === 'state' ? this.injectSettings().state.ttlMs : undefined
    const expiresAt = explicitExpiresAt
      ?? (explicitTtl !== undefined ? Date.now() + explicitTtl
        : stateTtl !== undefined ? Date.now() + stateTtl : undefined)
    const saveInput = expiresAt !== undefined ? { ...input, expiredAt: expiresAt } : input
    // design §11: keep credentials out of the plaintext store and the embedder
    if (this.cfg.secrets.enabled) {
      const findings = scanSecrets(content)
      if (findings.length > 0) {
        if (this.cfg.secrets.mode === 'refuse') {
          throw memoryError('SECRET_DETECTED', `content matches credential denylist: ${[...new Set(findings.map((f) => f.kind))].join(', ')}`)
        }
        content = redactSecrets(content)
      }
    }
    const { record } = this.store.save(
      { ...saveInput, scope, content },
      { importance: input.source?.origin === 'auto' ? 0.4 : 0.8, source: { origin: 'explicit' } },
    ) 
    void this.embedRecord(record).catch(() => {})
    this.store.scheduleFlush()
    return record
  }

  private async embedRecord(record: MemoryRecord): Promise<void> {
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return
    const s = this.store.scope(record.scope)
    // save-time budget: one full record, much slower than a search query
    // 记录按"文档"嵌入:有些模型(nomic/e5)要求文档与查询带不同前缀,不带质量会掉。
    const vec = await this.embed.embed([`${this.cfg.vector.documentPrefix ?? ''}${record.content}`], undefined, { timeoutMs: this.cfg.vector.writeTimeoutMs }).catch(() => null)
    if (vec?.[0]) s.appendVector(record.id, normalizeInPlace(vec[0]))
    else s.embedPending.add(record.id) // backfill queue; the retry timer drains it
  }

  /**
   * Retry pending embeddings in batches; returns number embedded.
   * Batches are bounded by count AND total characters, and use the backfill
   * budget: full record contents on CPU take seconds per batch, so the
   * interactive timeout would abort every attempt.
   */
  async backfillEmbeddings(): Promise<number> {
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return 0
    if (!this.embed.isHealthy) return 0
    let done = 0
    for (const s of this.store.allScopes()) {
      if (s.embedPending.size === 0) continue
      const texts: string[] = []
      const valid: string[] = []
      let chars = 0
      for (const id of s.embedPending) {
        if (valid.length >= this.cfg.vector.backfillBatchSize) break
        const t = s.records.get(id)?.content
        if (!t) continue
        if (valid.length > 0 && chars + t.length > this.cfg.vector.backfillMaxChars) break
        texts.push(`${this.cfg.vector.documentPrefix ?? ''}${t}`)
        valid.push(id)
        chars += t.length
      }
      if (texts.length === 0) continue
      const vecs = await this.embed.embed(texts, undefined, { timeoutMs: this.cfg.vector.backfillTimeoutMs }).catch(() => null)
      if (!vecs) return done
      for (let i = 0; i < valid.length; i++) {
        if (s.records.has(valid[i]!) && vecs[i]) s.appendVector(valid[i]!, normalizeInPlace(vecs[i]!))
        s.embedPending.delete(valid[i]!)
        done++
      }
    }
    return done
  }

  /**
   * 编辑之后立即重建**这一条**的向量，不等 60s 的回填窗口。
   * 旧向量同时从内存与磁盘作废（vectorsDirty），失败则留在 pending 里由重试兜底 ——
   * 绝不能让"新内容 + 旧向量"在重启后被当成已嵌入。
   */
  async reindexRecord(scope: MemoryScope, id: string): Promise<boolean> {
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return false
    const s = this.store.peek(scope)
    const record = s?.records.get(id)
    if (!s || !record) return false
    s.vectors.delete(id)
    s.vectorsDirty = true
    s.embedPending.add(id)
    try {
      await this.embedRecord(record)
    } catch { /* 失败留给重试定时器 */ }
    if (!s.vectors.has(id)) return false
    s.embedPending.delete(id)
    this.store.scheduleFlush()
    return true
  }

  /**
   * 作废全部向量并按当前模型重新嵌入。给"换模型残留了旧向量 / 怀疑向量有问题"用:
   * 同步部分只清空 + 排队,真正的重嵌在后台跑(别让 HTTP 等几分钟)。
   * 返回排队条数;进度由面板的「待嵌入」计数与自动刷新体现。
   */
  reindexAll(): { total: number; queued: number } {
    if (!this.cfg.vector.enabled || !this.cfg.vector.configured) return { total: 0, queued: this.pendingEmbedCount }
    this.discoverScopes()
    let total = 0
    for (const s of this.store.allScopes()) {
      for (const id of s.records.keys()) {
        s.vectors.delete(id)
        s.embedPending.add(id)
        total += 1
      }
      s.vectorsDirty = true
    }
    this.store.scheduleFlush()
    void this.backfillAll({ throttleMs: 50 }).catch(() => { /* 失败留给 60s 重试 */ })
    return { total, queued: this.pendingEmbedCount }
  }

  /**
   * First-fill: embed the ENTIRE backlog (unlike backfillEmbeddings' single
   * batch per scope), in throttled batches so a big import does not hammer
   * llama-server or block the caller. Yields to the event loop between
   * batches and stops early on abort/unhealthy embedder.
   */
  async backfillAll(opts: { signal?: AbortSignal; throttleMs?: number } = {}): Promise<number> {
    const throttle = opts.throttleMs ?? 50
    let done = 0
    while (!opts.signal?.aborted) {
      const n = await this.backfillEmbeddings()
      done += n
      if (n === 0) break // per-scope batch was empty → backlog drained
      if (!this.embed.isHealthy) break
      await new Promise((r) => setTimeout(r, throttle))
    }
    return done
  }

  async search(query: MemoryQuery): Promise<MemoryHit[]> {
    // 多 scope 合并由调用方显式给出(工具层传"会话 + 项目 + global");宿主类型里的
    // MemoryQuery 只有单值 scope,所以这里按结构化读一次可选数组,保持原语义不变。
    const queryScopes = (query as MemoryQuery & { scopes?: MemoryScope[] }).scopes
    // 显式空集合 = 什么都不允许读(会话可见范围把所有勾选项都禁用了)。不能退回
    // 默认项目 + global,否则"看不见任何范围"反而会搜出默认范围的记录。
    if (query.scope === undefined && queryScopes !== undefined && queryScopes.length === 0) return []
    const topK = query.topK ?? this.cfg.topK
    const recallN = query.recallN ?? this.cfg.recallN
    const now = Date.now()
    const queryTokens = [...new Set(tokenize(query.text))]
    // 面板的语义检索复用这条流水线,但它是"看一眼"的浏览:不写访问计数,也不在
    // 没有任何向量时白跑一次嵌入请求。这两个开关只给面板的 searchForPanel 用,
    // 工具 / 注入调用不会传。
    const internal = query as MemoryQuery & { touch?: boolean; vector?: boolean; includeSuperseded?: boolean; includeExpired?: boolean; kinds?: Record<string, readonly string[]> }
    const allowVector = internal.vector !== false && this.cfg.vector.enabled && this.cfg.vector.configured
    const includeSuperseded = internal.includeSuperseded === true
    const includeExpired = internal.includeExpired === true
    // 注入侧按可见域的类型白名单检索(scope → 允许的类型;未列出的 scope 不限制)。
    // 工具侧不传 kinds:它需要看到范围外命中,才能发起审批。
    const kindFilter = internal.kinds === undefined
      ? undefined
      : (scope: string, kind: string): boolean => {
          const allowed = internal.kinds![this.canonicalScope(scope)]
          return allowed === undefined || allowed.length === 0 || allowed.includes(kind)
        }

    // 候选 scope:显式 pin(单值)优先;否则用调用方给的合并集合(query.scopes,
    // 工具 / 注入传"会话 + 项目 + global");两者都没有才退回旧的 project + global。
    // `peek` 而不是 `scope`:读路径不创建,不存在的 scope 直接跳过。
    const wanted: MemoryScope[] = (query.scope
      ? [query.scope]
      : (queryScopes ?? []).length > 0
        ? queryScopes!
        : [this.defaultProjectScope, 'global']).map((scope) => this.canonicalScope(scope))
    const stores: { store: ScopeStore; scope: MemoryScope; isGlobal: boolean }[] = []
    const seen = new Set<MemoryScope>()
    for (const scope of wanted) {
      if (seen.has(scope)) continue // 按 scope key 去重(也顺手消掉 defaultScope==='global' 时的重复 push)
      seen.add(scope)
      const store = this.store.peek(scope)
      if (!store) continue
      stores.push({ store, scope, isGlobal: scope === 'global' })
    }

    // 退役(superseded)记录默认不参与召回:它们只是被新记录修正过的历史版本,
    // 继续返回会让模型拿旧结论当现行事实。memory_get(id)/面板历史仍可直接取。
    const retired = new Set<string>()
    for (const { store } of stores) {
      for (const record of store.records.values()) {
        if (record.supersedes) retired.add(record.supersedes)
      }
    }

    // --- channel 1: lexical recall, scored per scope with local IDF ---
    type Cand = { record: MemoryRecord; recallScore: number; isGlobal: boolean }
    const candidates = new Map<string, Cand>()
    for (const { store, isGlobal } of stores) {
      const all = [...store.records.values()]
      // 词法通道把标签也当可检索文本:自动召回用标签做触发词时,记忆正文里
      // 不一定出现这个标签(例如 tags=['release'] 但正文是中文),不并进来就搜不到。
      const searchableText = (record: MemoryRecord): string =>
        `${record.content} ${(record.tags ?? []).join(' ')}`
      const tokenSets = all.map((r) => new Set(tokenize(searchableText(r))))
      const stats = buildStats(tokenSets)
      for (let i = 0; i < all.length; i++) {
        const rec = all[i]!
        if (!includeExpired && rec.expiredAt && rec.expiredAt < now) continue
        if (!includeSuperseded && retired.has(rec.id)) continue
        if (kindFilter !== undefined && !kindFilter(rec.scope, rec.kind)) continue
        const lex = lexicalScore(queryTokens, tokenSets[i]!, stats)
        if (lex <= 0) continue
        // Weak-only overlap (no shared word/bigram) must clear the "real hit"
        // floor, not the permissive threshold — kills single-char collisions.
        // 阈值只分两档:global 用 globalThreshold,其余(session / project / 自定义)用
        // projectThreshold —— 不新增配置项。
        const floor = isGlobal ? this.cfg.globalThreshold : this.cfg.projectThreshold
        const effective = hasStrongHit(queryTokens, tokenSets[i]!) ? floor : Math.max(floor, REAL_HIT_FLOOR)
        if (lex < effective) continue
        candidates.set(rec.id, { record: rec, recallScore: lex, isGlobal })
      }
    }

    // --- channel 2: vector recall over embedded records ---
    // Skipped entirely when no backend is configured (lexical recall above
    // already produced the candidates; a request here would just fail).
    const qvec = allowVector
      ? await this.embed.embed([`${this.cfg.vector.queryPrefix ?? ''}${query.text}`], query.signal).catch(() => null)
      : null
    if (qvec?.[0]) {
      const vectorScores = new Map<string, number>()
      for (const { store } of stores) {
        for (const [id, vec] of store.vectors) {
          if (!store.records.has(id)) continue
          const sim = cosine(qvec[0]!, vec)
          if (sim >= this.cfg.vector.minScore) vectorScores.set(id, sim)
        }
      }
      for (const [id, sim] of vectorScores) {
        if (!includeSuperseded && retired.has(id)) continue
        const existing = candidates.get(id)
        if (existing) {
          existing.recallScore = Math.max(existing.recallScore, sim) // best channel wins
          continue
        }
        const rec = this.findById(id)
        if (!rec) continue
        if (!includeExpired && rec.expiredAt !== undefined && rec.expiredAt < now) continue
        if (kindFilter !== undefined && !kindFilter(rec.scope, rec.kind)) continue
        if (!(rec.scope === 'global' && sim < this.cfg.globalThreshold)) {
          candidates.set(id, { record: rec, recallScore: sim, isGlobal: rec.scope === 'global' })
        }
      }
    }

    // shape with recency/importance, sort, cut
    const shape = (c: Cand): number =>
      recordScore(c.recallScore, c.record.importance, c.record.accessCount, c.record.lastAccessedAt, {
        now,
        halfLifeDays: this.cfg.halfLifeDays,
        superseded: retired.has(c.record.id),
      })

    // 稳定 tie-break:同分时 session > project > 自定义 > global,再同分按 record id ——
    // 否则 Map 的插入顺序(取决于 scope 顺序)会让同一查询在不同进程间给出不同结果。
    const ranked = [...candidates.values()]
      .sort((a, b) => shape(b) - shape(a)
        || scopeTier(a.record.scope) - scopeTier(b.record.scope)
        || a.record.id.localeCompare(b.record.id))
      .slice(0, recallN)

    // --- channel 3: LLM rerank (optional; any skip/failure keeps recall order) ---
    // 键必须是 **record.id**。这里曾经写成 `c.id`(Cand 上没有 id 字段),所有候选都落到
    // 同一个 `undefined` 键上:排序数组本身是对的,但每条命中拿到的都是最后一个候选的
    // 分数(面板上表现为「每条相关度都一样」),重排的候选 id 也全成了 undefined。
    const finalScores = new Map<string, number>(ranked.map((c) => [c.record.id, shape(c)]))
    if (this.cfg.llm.enabled && this.llmInvoke && ranked.length >= 2) {
      const asCands = ranked.map((c) => ({ id: c.record.id, content: c.record.content, recallScore: finalScores.get(c.record.id)! }))
      const cacheKey = RerankCache.key(query.text, ranked.map((c) => c.record.id), this.cfg.llm.model)
      let outcome = this.rerankCache.get(cacheKey)
      if (!outcome) {
        outcome = await rerank({
          invoke: this.llmInvoke,
          cfg: this.cfg.llm,
          query: query.text,
          candidates: asCands,
          budget: this.rerankBudget,
          signal: query.signal,
        })
        if (outcome) this.rerankCache.set(cacheKey, outcome)
      }
      if (outcome) {
        for (const { id, score } of blendScores(asCands, outcome, this.cfg.llm.weight)) {
          finalScores.set(id, score)
        }
      }
      // 重排必须能改变顺序,否则它只改了显示分数、召回序列原样输出。没有重排时
      // finalScores 就等于 shape(),这个二次排序与原顺序完全一致(同一套 tie-break)。
      ranked.sort((a, b) => finalScores.get(b.record.id)! - finalScores.get(a.record.id)!
        || scopeTier(a.record.scope) - scopeTier(b.record.scope)
        || a.record.id.localeCompare(b.record.id))
    }

    const hits: MemoryHit[] = ranked.map((c) => ({
      record: internal.touch === false ? c.record : touch(c.record),
      score: round4(finalScores.get(c.record.id)!),
    }))

    this.store.scheduleFlush()
    return hits.slice(0, topK)
  }

  /**
   * 面板「语义检索」:和 memory_search 走**同一套**双通道召回与打分(向量 + 词法 +
   * 可选重排),区别只有两点:
   *   1. 只读浏览器:不 `touch` 记录(访问计数/最近访问时间是检索排序的输入,
   *      面板里浏览一次不该把排序带偏);
   *   2. 报告这一次向量通道到底有没有参与 —— 面板得如实写「语义排序」还是
   *      「向量没跑起来,按关键词排」,而不是把词法结果冒充语义结果。
   *
   * `scopes` 由面板显式给出(全部作用域或下拉选中的那个),不做"默认项目"回退。
   */
  async searchForPanel(input: { text: string; scopes: MemoryScope[]; topK?: number }): Promise<PanelSearchResult> {
    const scopes: MemoryScope[] = []
    const seen = new Set<MemoryScope>()
    let total = 0
    let embedded = 0
    for (const raw of input.scopes) {
      const scope = this.canonicalScope(raw)
      if (seen.has(scope)) continue
      seen.add(scope)
      const store = this.store.peek(scope) // 只读:不创建 scope
      if (!store) continue
      scopes.push(scope)
      total += store.records.size
      embedded += store.vectors.size
    }
    const configured = this.cfg.vector.enabled && this.cfg.vector.configured
    // 空集合不能交给 search():它在 scopes 为空时会退回"默认项目 + global",
    // 那等于用户点了一个不存在的 scope 却搜出别的 scope 的记录。
    if (scopes.length === 0) {
      return {
        hits: [],
        mode: 'lexical',
        reason: 'no-records',
        embedded: 0,
        total: 0,
      }
    }
    // 没有向量 / 嵌入服务已被熔断时不要白打一次请求:直接走词法通道。
    const vector = configured && embedded > 0 && this.embed.isHealthy
    const hits = await this.search({
      text: input.text,
      scopes,
      topK: input.topK ?? 20,
      // 面板是**历史浏览器**:退役/过期记录也要能搜到,否则用户无法从面板确认旧版本。
      includeSuperseded: true,
      includeExpired: true,
      vector,
      touch: false,
    } as MemoryQuery & { vector: boolean; touch: boolean; includeSuperseded: boolean; includeExpired: boolean })
    // 嵌入请求失败会被 EmbedClient 熔断(markDown),所以"跑完还健康"就等于向量通道
    // 真的产出了分数;否则这次只能算词法排序。
    const vectorRan = vector && this.embed.isHealthy
    return {
      hits,
      mode: vectorRan ? 'vector' : 'lexical',
      ...(vectorRan ? {} : { reason: !configured ? 'vector-disabled' as const : total === 0 ? 'no-records' as const : embedded === 0 ? 'no-vectors' as const : 'embed-failed' as const }),
      embedded,
      total,
    }
  }

  private findById(id: string): MemoryRecord | undefined {
    for (const s of this.store.allScopes()) {
      const r = s.records.get(id)
      if (r) return r
    }
    return undefined
  }

  async forget(input: { id?: string; query?: string; scope?: MemoryScope; scopes?: MemoryScope[] }): Promise<{ removed: number; ids: string[] }> {
    const ids: string[] = []
    if (input.id) {
      // 按 id 删除天然跨 scope:调用方给的是精确 id,不存在误删别的 scope 的风险。
      for (const s of this.store.allScopes()) {
        if (s.remove(input.id)) ids.push(input.id)
      }
      if (ids.length === 0) throw memoryError('RECORD_NOT_FOUND', `id ${input.id} not found`)
    } else if (input.query) {
      // 按 query 删除的默认范围由工具层显式给出(默认只有当前会话);这里不再回退到
      // provider 的默认 scope —— 那正是"以为删了会话记忆、其实删了 global"的来源。
      const targets = (input.scope !== undefined
        ? [input.scope]
        : (input.scopes ?? []).length > 0
          ? input.scopes!
          : [this.defaultProjectScope]).map((scope) => this.canonicalScope(scope))
      const seen = new Set<MemoryScope>()
      for (const scope of targets) {
        if (seen.has(scope)) continue
        seen.add(scope)
        const store = this.store.peek(scope) // 读/删路径不创建
        if (!store) continue
        const hit = this.store.findIdsByQuery(scope, input.query)
        for (const id of hit) if (store.remove(id)) ids.push(id)
      }
      if (ids.length === 0) throw memoryError('RECORD_NOT_FOUND', `no record matching query in ${targets.join(', ')}`)
    } else {
      throw memoryError('RECORD_NOT_FOUND', 'forget requires id or query')
    }
    this.store.scheduleFlush()
    return { removed: ids.length, ids }
  }

  /**
   * 列记录。显式 scope 只列它;`scopes` 数组用于"全部作用域";两者都没有时退回项目 scope。
   * 一律走 `peek`,所以列一个不存在的 scope 只会得到空数组,不会造出文件。
   */
  async list(input: MemoryListInput = {}): Promise<MemoryRecord[]> {
    const internal = input as MemoryListInput & { includeExpired?: boolean; includeSuperseded?: boolean; agent?: unknown }
    // 注入侧(摘要)传入 agent 时按可见域的类型白名单过滤;工具侧不传,以便处理范围外审批。
    const visibleFilter = internal.agent !== undefined ? this.visibilityFilterFor(internal.agent) : undefined
    // 显式空集合 = 无可见范围(见 search 的同口径说明)。
    if (input.scope === undefined && input.scopes !== undefined && input.scopes.length === 0) return []
    const wanted = (input.scope !== undefined
      ? [input.scope]
      : (input.scopes ?? []).length > 0
        ? input.scopes!
        : [this.defaultProjectScope]).map((scope) => this.canonicalScope(scope))
    const seen = new Set<MemoryScope>()
    const stores: ScopeStore[] = []
    for (const scope of wanted) {
      if (seen.has(scope)) continue
      seen.add(scope)
      const store = this.store.peek(scope)
      if (store) stores.push(store)
    }
    const retired = internal.includeSuperseded ? new Set<string>() : new Set(this.supersededIds(wanted))
    const now = Date.now()
    let records: MemoryRecord[] = []
    for (const store of stores) {
      for (const rec of store.records.values()) {
        if (retired.has(rec.id)) continue
        if (internal.includeExpired !== true && rec.expiredAt !== undefined && rec.expiredAt < now) continue
        records.push(rec)
      }
    }
    if (input.kind) records = records.filter((r) => r.kind === input.kind)
    if (visibleFilter !== undefined) records = records.filter((r) => visibleFilter(r.scope, r.kind))
    records.sort((a, b) => b.updatedAt - a.updatedAt)
    return records.slice(0, input.limit ?? 50)
  }

  /**
   * 按 id 批量取记录(memory_get)。接受完整 id,也接受摘要里给出的前 8 位前缀
   * (前缀命中多条时全部返回,由调用方/模型自行判断)。取全文不需要再检索。
   */
  getByIds(ids: string[]): MemoryRecord[] {
    this.discoverScopes()
    const scopes = this.store.allScopes()
    const out: MemoryRecord[] = []
    const seen = new Set<string>()
    for (const token of ids) {
      if (typeof token !== 'string' || token.length === 0) continue
      for (const s of scopes) {
        for (const rec of s.records.values()) {
          if (seen.has(rec.id)) continue
          if (rec.id === token || rec.id.startsWith(token)) {
            seen.add(rec.id)
            out.push(rec)
          }
        }
      }
    }
    return out
  }

  /**
   * 面板新建一条记忆 / 规则。scope 必须是**明确的键**(global / project:<路径> /
   * session:<id> / 自定义名)—— 面板拿不到会话上下文,'project'/'session' 这种
   * 相对写法没法解析,直接拒绝比猜一个错的强。
   */
  async createRecord(input: {
    scope?: string
    kind?: string
    content?: string
    tags?: string[]
    importance?: number
    ttlMs?: number
    expiresAt?: number
  }): Promise<MemoryRecord> {
    const normalized = normalizeScopeInput(input.scope)
    if (!normalized.ok) throw memoryError('SCOPE_INVALID', normalized.message)
    if (normalized.scope === undefined) {
      throw memoryError('SCOPE_INVALID', '面板写入需要明确的 scope(global / project:<路径> / session:<id> / 自定义名)')
    }
    return this.save({
      scope: normalized.scope as MemoryScope,
      kind: (input.kind ?? 'note') as MemoryRecord['kind'],
      content: String(input.content ?? ''),
      ...(input.tags !== undefined ? { tags: input.tags } : {}),
      ...(input.importance !== undefined ? { importance: input.importance } : {}),
      ...(input.ttlMs !== undefined ? { ttlMs: input.ttlMs } : {}),
      ...(input.expiresAt !== undefined ? { expiresAt: input.expiresAt } : {}),
    } as MemorySaveInput)
  }

  /**
   * 导出全部记忆为**纯文本**文档(不含向量)。向量在导入时按当前模型重新算,
   * 所以换过模型也照样导得回去。
   */
  exportAll(now = Date.now()): {
    version: 1
    exportedAt: number
    records: Array<{
      scope: MemoryScope
      kind: string
      content: string
      tags: string[]
      importance: number
      createdAt: number
      updatedAt: number
      /** 流程触发词(0.15.1 起导出)。 */
      triggers?: string[]
      /** 状态记忆的过期时间(0.15.0 起导出)。 */
      expiredAt?: number
    }>
  } {
    this.discoverScopes()
    const records = []
    for (const s of this.store.allScopes()) {
      for (const rec of s.records.values()) {
        records.push({
          scope: rec.scope,
          kind: rec.kind,
          content: rec.content,
          tags: rec.tags,
          importance: rec.importance,
          createdAt: rec.createdAt,
          updatedAt: rec.updatedAt,
          ...(Array.isArray((rec as MemoryRecord & { triggers?: unknown }).triggers)
            ? { triggers: ((rec as MemoryRecord & { triggers?: unknown }).triggers as unknown[]).map(String) }
            : {}),
          ...(rec.expiredAt !== undefined ? { expiredAt: rec.expiredAt } : {}),
        })
      }
    }
    records.sort((a, b) => a.scope.localeCompare(b.scope) || a.createdAt - b.createdAt)
    return { version: 1, exportedAt: now, records }
  }

  /**
   * 导入文本记忆。逐条走 `save()`(凭据扫描 / 上限 / 去重 / 向量回填都在那条路上),
   * 所以导入的记录会自动按当前模型重新嵌入。返回计数,失败不中断其余条目。
   */
  async importRecords(input: unknown): Promise<{ imported: number; skipped: number; rejected: number; errors: string[] }> {
    const list = Array.isArray(input)
      ? input
      : (input && typeof input === 'object' && Array.isArray((input as { records?: unknown }).records))
        ? (input as { records: unknown[] }).records
        : null
    if (list === null) throw memoryError('IMPORT_INVALID', '导入格式不对:需要 {version, records:[...]} 或记录数组')
    if (list.length > 5000) throw memoryError('IMPORT_TOO_LARGE', `一次最多导入 5000 条(收到 ${list.length} 条)`)

    let imported = 0
    let skipped = 0
    let rejected = 0
    const errors: string[] = []
    for (const [index, raw] of list.entries()) {
      try {
        const rec = raw as {
          scope?: unknown; kind?: unknown; content?: unknown; tags?: unknown; importance?: unknown
          triggers?: unknown; expiredAt?: unknown
        }
        const content = typeof rec.content === 'string' ? rec.content : ''
        if (content.trim().length === 0) throw new Error('content 为空')
        const normalized = normalizeScopeInput(typeof rec.scope === 'string' ? rec.scope : undefined)
        if (!normalized.ok) throw new Error(normalized.message)
        if (normalized.scope === undefined) throw new Error('缺少明确的 scope')
        const scope = normalized.scope as MemoryScope
        if (this.store.hasContent(scope, content)) {
          skipped += 1
          continue
        }
        await this.save({
          scope,
          kind: (typeof rec.kind === 'string' && rec.kind.length > 0 ? rec.kind : 'note') as MemoryRecord['kind'],
          content,
          ...(Array.isArray(rec.tags) ? { tags: rec.tags.map(String) } : {}),
          ...(typeof rec.importance === 'number' ? { importance: rec.importance } : {}),
          ...(Array.isArray(rec.triggers) ? { triggers: rec.triggers.map(String) } : {}),
          ...(typeof rec.expiredAt === 'number' && Number.isFinite(rec.expiredAt) ? { expiresAt: rec.expiredAt } : {}),
        } as MemorySaveInput)
        imported += 1
      } catch (error) {
        rejected += 1
        if (errors.length < 20) errors.push(`#${index}: ${error instanceof Error ? error.message : String(error)}`)
      }
    }
    this.store.scheduleFlush()
    return { imported, skipped, rejected, errors }
  }

  /** 规则条数(面板设置页显示;只数已加载/已发现的作用域,排除退役规则)。 */
  ruleStats(): { total: number; scopes: number } {
    this.discoverScopes()
    const retired = new Set(this.supersededIds())
    let total = 0
    let scopes = 0
    for (const s of this.store.allScopes()) {
      const n = [...s.records.values()].filter((r) => r.kind === 'rule' && !retired.has(r.id)).length
      if (n > 0) { total += n; scopes += 1 }
    }
    return { total, scopes }
  }

  /** 作用域别名（没有则 undefined，调用方回退到路径/键本身）。 */
  scopeName(scope: MemoryScope): string | undefined {
    return this.names.nameOf(scope)
  }

  /** 名字 → 作用域键：读路径允许直接用别名找作用域。 */
  scopeKeyForName(name: string): MemoryScope | undefined {
    return this.names.scopeOf(name) as MemoryScope | undefined
  }

  /**
   * 作用域键归一:自定义名可能是别名 → 转回真实键;`project:<路径>` 统一路径写法。
   *
   * 项目键必须过 `canonicalWorkspacePath`:工具层的 `path`、模型显式给的
   * `project:D:/x`、面板 HTTP 写入都从这里落盘,同一个目录不能因为 `/` 与 `\` 的差别
   * 变成两个 scope(0.11.1;读路径的键来自 resolveCurrentScopes,也走同一套规范化)。
   */
  private canonicalScope(scope: MemoryScope): MemoryScope {
    if (scope === 'global' || scope.startsWith('session:')) return scope
    if (scope.startsWith('project:')) {
      const path = scope.slice('project:'.length)
      if (path === '') return scope
      const canonical = canonicalWorkspacePath(path)
      return (canonical === path ? scope : `project:${canonical}`) as MemoryScope
    }
    return (this.names.scopeOf(scope) as MemoryScope | undefined) ?? scope
  }

  /**
   * 作用域清单(名字 + 条数 + 待嵌入 + 最近活跃时间),给面板 /status 与 memory_list 的尾部清单用。
   *
   * 先 `discoverScopes()`:进程内 store 是懒加载的,只列"已加载"的 scope 会让面板/清单
   * 漏掉别的进程(上一次会话、另一个 agent)写下的作用域。
   * 排序键是"最近活跃"(`updatedAt`):面板据此只给最近活跃的前 N 个会话 scope 查标题。
   */
  scopeStats(): Array<{ scope: MemoryScope; name?: string; records: number; pendingEmbeds: number; updatedAt: number }> {
    this.discoverScopes()
    return this.store.allScopes()
      .map((s) => ({
        scope: s.scope,
        ...(this.names.nameOf(s.scope) !== undefined ? { name: this.names.nameOf(s.scope) } : {}),
        records: s.records.size,
        pendingEmbeds: s.embedPending.size,
        updatedAt: [...s.records.values()].reduce((max, r) => Math.max(max, r.updatedAt), 0),
      }))
      .sort((a, b) => b.updatedAt - a.updatedAt || b.records - a.records || a.scope.localeCompare(b.scope))
  }

  /**
   * 发现磁盘上的 scope(带时间缓存)。面板每次 /status、每次 memory_list 都要一份完整
   * 清单,而 discovery 要读每个文件的第一条记录 —— 限流到最短 3 秒一次,既保证清单够新,
   * 也不至于把 projects/ 目录读成热路径(面板侧还有一层同样时长的缓存,旧 provider 也能受益)。
   */
  /**
   * 当前进程已知的 scope 键:**只读**,不触发发现(要完整清单用 discoverScopes()/scopeStats())。
   */
  knownScopes(): MemoryScope[] {
    return this.store.allScopes().map((s) => s.scope)
  }

  /**
   * 发现磁盘上的 scope(带时间缓存)。面板每次 /status、每次 memory_list 都要一份完整
   * 清单,而 discovery 要读每个文件的第一条记录 —— 限流到最短 3 秒一次,既保证清单够新,
   * 也不至于把 projects/ 目录读成热路径(面板侧还有一层同样时长的缓存,旧 provider 也能受益)。
   */
  discoverScopes(): MemoryScope[] {
    const now = Date.now()
    if (this.discoveredAt === 0 || now - this.discoveredAt >= DISCOVER_TTL_MS) {
      this.discoveredAt = now
      try {
        this.store.loadDiscovered()
      } catch {
        // 发现失败不影响读写,清单里少几个而已
      }
      try {
        this.reconcileScopes()
      } catch {
        // 合并失败同样不影响读写:留着两个 scope 也比丢数据强
      }
    }
    return this.knownScopes()
  }

  /**
   * 把"同一个目录的不同写法"合并成一个项目作用域(0.11.1,每个进程只跑一次)。
   *
   * 0.7.0 引入 `memory_save({ path })` 之后, `D:/repositories/x` 与 `D:\repositories\x`
   * 会落成两个 scope 文件;工作区里的会话用宿主给的 `header.cwd`,于是另一份里的记忆
   * 永远读不到(面板里还会看到两个同名作用域)。写入侧已在 `canonicalScope` 统一写法,
   * 这里负责把**历史数据**并到规范键上:
   *   - 同组的判定走 `projectScopeIdentity`(Windows 盘符路径再折叠大小写,POSIX 不动);
   *   - 目标键优先选"写法已经规范"的那一个,其次记录多的(稳定时按键名);**只有变体存在时
   *     改名**到规范键(否则会话读规范键、永远看不到这份记忆);
   *   - 记录按 id 并入目标(目标已有同 id 就跳过);向量长度与当前配置一致时一起搬;
   *   - 别名跟着走(目标没有别名时才接管),迁空的 scope 由 flush 顺手删掉文件。
   * 多进程并发时,flush 的"锁内重新读盘 + 只合并本进程增量"兜底:这里只发 upsert/delete,
   * 不会把别的进程刚写的内容覆盖掉。
   */
  reconcileScopes(): { merged: number } {
    if (this.scopesReconciled) return { merged: 0 }
    this.scopesReconciled = true
    // 直接调用(装配期)时还没有发现过磁盘 scope:先发现,否则只能看到已加载的那两个,
    // 合并会漏、而且这唯一一次机会被浪费掉。
    if (this.discoveredAt === 0) {
      this.discoveredAt = Date.now()
      try {
        this.store.loadDiscovered()
      } catch {
        // 发现失败:清单少几个,不影响读写
      }
    }
    const groups = new Map<string, { scope: MemoryScope; store: ScopeStore; records: number }[]>()
    for (const store of this.store.allScopes()) {
      if (!store.scope.startsWith('project:')) continue
      const path = store.scope.slice('project:'.length)
      if (path === '') continue
      const identity = projectScopeIdentity(path)
      const list = groups.get(identity)
      const entry = { scope: store.scope, store, records: store.records.size }
      if (list === undefined) groups.set(identity, [entry])
      else list.push(entry)
    }
    let merged = 0
    for (const list of groups.values()) {
      const canonicalOf = (scope: MemoryScope): MemoryScope =>
        `project:${canonicalWorkspacePath(scope.slice('project:'.length))}` as MemoryScope
      // 1) 写法已经规范的优先 2) 记录多的 3) 键名字典序(稳定,避免每次合并目标漂移)
      list.sort((a, b) =>
        Number(canonicalOf(b.scope) === b.scope) - Number(canonicalOf(a.scope) === a.scope)
        || b.records - a.records
        || a.scope.localeCompare(b.scope))
      const targetScope = list[0]!.scope
      // 只有变体存在时(用 path 参数写进来的记忆,会话还没写过那个目录)也要**改名**:
      // 会话读的是规范键,不改名等于这份记忆永远看不见。改名后 records 一条不少。
      const canonicalTarget = canonicalOf(targetScope)
      const finalTarget = canonicalTarget === targetScope ? targetScope : canonicalTarget
      const sources = list.filter((entry) => entry.scope !== finalTarget)
      if (sources.length === 0) continue
      const targetStore = this.store.scope(finalTarget)
      for (const source of sources) {
        for (const record of [...source.store.records.values()]) {
          if (!targetStore.records.has(record.id)) {
            targetStore.insert({ ...record, scope: finalTarget })
            const vector = source.store.vectors.get(record.id)
            // 向量只有在维度与当前配置一致时才可信(换过模型/池化的边车已被 loadScope 校验过,
            // 这里再按维度兜一层);搬不动的留给回填/重启后重新嵌入。
            if (vector !== undefined && vector.length === this.cfg.vector.dims) {
              targetStore.setVector(record.id, vector)
            }
          }
          source.store.remove(record.id)
        }
        const alias = this.names.nameOf(source.scope)
        if (alias !== undefined) {
          this.names.release(source.scope)
          if (this.names.nameOf(finalTarget) === undefined) {
            try {
              this.names.claim(finalTarget, alias)
            } catch {
              // 名字已被别的 scope 占用 → 放弃别名(路径本身仍可引用)
            }
          }
        }
        merged += 1
      }
    }
    if (merged > 0) {
      this.store.flush()
      console.warn(`[dsh-memory-local] 已合并 ${merged} 个"同一目录不同写法"的项目作用域`)
    }
    return { merged }
  }

  /** Force a synchronous flush (dispose/HMR path). */
  flushSync(): void {
    // 审计 sink 属于注入半边：provider 退出时解绑并释放，避免面板继续读旧 store。
    try { this.injectAuditSink?.dispose?.() } catch { /* 审计清理失败不影响 provider */ }
    this.injectAuditSink = null
    if (this.maintenanceTimer) {
      clearInterval(this.maintenanceTimer)
      this.maintenanceTimer = null
    }
    if (this.embedRetryTimer) {
      clearInterval(this.embedRetryTimer)
      this.embedRetryTimer = null
    }
    if (this.initialDrainTimer) {
      clearTimeout(this.initialDrainTimer)
      this.initialDrainTimer = null
    }
    if (this.embedServer) this.embedServer.stop()
    if (this.exitHook) {
      process.removeListener('exit', this.exitHook)
      this.exitHook = null
    }
    this.store.purgeExpired()
    this.store.enforceLimit(this.cfg.maxRecordsPerScope)
    this.store.close()
  }

  get pendingEmbedCount(): number {
    return this.store.allScopes().reduce((n, s) => n + s.embedPending.size, 0)
  }
}

function touch(record: MemoryRecord): MemoryRecord {
  record.lastAccessedAt = Date.now()
  record.accessCount += 1
  return record
}

function round4(n: number): number {
  return Math.round(n * 10_000) / 10_000
}

/** Port of an http(s) endpoint, or null when it cannot be parsed. */
function portOf(endpoint: string): number | null {
  try {
    const port = new URL(endpoint).port
    return port ? Number.parseInt(port, 10) : null
  } catch {
    return null
  }
}

/**
 * Measured score floor of genuine lexical hits; below this only single-char
 * coincidences live. Used to gate weak-only overlaps regardless of config.
 */
const REAL_HIT_FLOOR = 0.25

function memoryError(code: string, message: string): Error & { code: string } {
  const err = new Error(`[memory:${code}] ${message}`) as Error & { code: string }
  err.code = code
  return err
}

/** discoverScopes() 的最短间隔:清单要够新,但 projects/ 目录不该被读成热路径。 */
const DISCOVER_TTL_MS = 3000

export function createMemoryService(config: MemoryLocalConfig = {}): LocalMemoryService {
  return new LocalMemoryService(config)
}
