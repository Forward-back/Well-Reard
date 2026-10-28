"""
Flask HTTP API 主服务 —— 暴露 POST /query 接口。
"""

import os, sys, re, atexit, logging, threading, time, json, queue, shutil, tempfile
from difflib import SequenceMatcher
from concurrent.futures import ThreadPoolExecutor

_src = os.path.dirname(os.path.abspath(__file__))
if _src not in sys.path:
    sys.path.insert(0, _src)

from utils import setup_windows_console
setup_windows_console()

from config import (
    MYSQL_CONFIG, FINAL_TOP_K, FAISS_TOP_K, BM25_TOP_K, LOG_LEVEL,
    SQL_CONTEXT_CAP, RERANK_SKIP_SINGLE, EMBEDDING_DIM,
    BGE_EMBED_BACKEND, BGE_RERANK_BACKEND, ENGINE_TOKEN,
    RRF_K, RERANK_META_MIN_SCORE, MAX_CONTEXT_CHARS, DEEPSEEK_MODEL,
    validate as config_validate,
)
import pymysql

logging.basicConfig(
    level=getattr(logging, LOG_LEVEL.upper(), logging.INFO),
    format="%(asctime)s [%(levelname)s] [req:%(trace)s] %(message)s",
)
logger = logging.getLogger("api")

from trace_logging import install_trace_filter, start_trace, clear_trace, submit_with_trace
install_trace_filter()

from flask import Flask, request, jsonify, Response, stream_with_context

from retrieval.faiss_search import FAISSSearcher
from retrieval.bm25_search import BM25Searcher
from retrieval.chunk_store import ChunkStore
from retrieval.text_to_sql import TextToSQLEngine
from retrieval.fusion import FusionEngine
from retrieval.planner import plan_query, execute_plan
from retrieval.query_filter import (
    MetadataSearcher, analyze_query, QueryEntities,
    build_product_mentions,
)
from prompts import get_tag_content, load_prompt_store
from llm.generator import generate_answer, generate_synthesis_answer
from prompt_guard import REFUSAL_ANSWER

app = Flask(__name__)
# 竞赛评测按 UTF-8 文本读响应体，禁用 jsonify 默认的 ASCII 转义（\uXXXX）
app.json.ensure_ascii = False
app.json.mimetype = "application/json; charset=utf-8"

# 允许测试页以 file:// 方式直接打开时跨域调用 API
@app.after_request
def _add_cors_headers(resp):
    resp.headers["Access-Control-Allow-Origin"] = "*"
    resp.headers["Access-Control-Allow-Headers"] = "Content-Type, X-Engine-Token"
    resp.headers["Access-Control-Allow-Methods"] = "POST, GET, OPTIONS"
    return resp

# 服务间鉴权(§2.13 P2): 配置 YLSW_ENGINE_TOKEN 后强制 X-Engine-Token 头;
# 未配置时放行(竞赛评测/离线开发兼容)。/health 永远豁免。
@app.before_request
def _check_engine_token():
    if request.path == "/health" or not ENGINE_TOKEN:
        return None
    token = request.headers.get("X-Engine-Token", "").strip()
    if token != ENGINE_TOKEN:
        logger.warning(f"[鉴权] 请求被拒(path={request.path}, token={'有' if token else '无'})")
        return jsonify({"error": "invalid or missing X-Engine-Token"}), 401
    return None

# ── 延迟初始化 ──
faiss_searcher: FAISSSearcher | None = None
bm25_searcher: BM25Searcher | None = None
sql_engine: TextToSQLEngine | None = None
fusion: FusionEngine | None = None
meta_searcher: MetadataSearcher | None = None
# 连接池（DBUtils）：替代原版单连接 + 全局锁的串行访问
db_pool = None
chunk_store: ChunkStore | None = None


def init_services():
    global faiss_searcher, bm25_searcher, sql_engine, fusion, meta_searcher, \
        db_pool, chunk_store
    config_validate()
    logger.info("正在初始化检索服务...")
    from dbutils.pooled_db import PooledDB
    db_pool = PooledDB(
        creator=pymysql, maxconnections=8, mincached=2, maxcached=4,
        blocking=True, autocommit=True, **MYSQL_CONFIG,
    )
    faiss_searcher = FAISSSearcher()
    sql_engine = TextToSQLEngine()
    fusion = FusionEngine()
    chunk_store = ChunkStore(db_pool)
    # metadata 检索与 chunk 数据访问共用连接池（线程安全，无锁竞争）
    meta_searcher = MetadataSearcher(db_pool)
    load_prompt_store()
    atexit.register(_cleanup)

    # BM25 词法路：启动时从池借连接构建内存索引，失败仅降级关闭该路（不阻断启动）
    try:
        bm25_searcher = BM25Searcher(db_pool.connection())
    except Exception as e:
        logger.error(f"BM25 索引初始化异常，词法路降级关闭: {e}")
        bm25_searcher = None

    # 存量数据：product_mentions 空表时自动构建
    _ensure_product_mentions()

    # 本地模型预热（必须在 app 进程内加载：entrypoint 的预热是独立进程，退出即失效；
    # 不预热则首问触发懒加载 ~4.5s，实测首问检索三段 4493ms）
    if BGE_EMBED_BACKEND == "local" or BGE_RERANK_BACKEND == "local":
        try:
            from models_singleton import encode_texts, rerank_scores
            if BGE_EMBED_BACKEND == "local":
                encode_texts(["预热"], EMBEDDING_DIM)
                logger.info("本地 embedding 模型已预热")
            if BGE_RERANK_BACKEND == "local":
                rerank_scores("预热", ["预热"])
                logger.info("本地 reranker 模型已预热")
        except Exception as e:
            logger.warning(f"本地模型预热失败（首问会慢）: {e}")

    logger.info("所有服务初始化完成 ✓")


def _cleanup():
    if sql_engine:
        sql_engine.close()
    if db_pool:
        db_pool.close()


def _ensure_product_mentions():
    """检测 product_mentions 表是否为空，空则自动构建倒排索引。"""
    try:
        conn = db_pool.connection()
        try:
            with conn.cursor() as cur:
                cur.execute("SELECT COUNT(*) FROM product_mentions")
                count = cur.fetchone()[0]
        finally:
            conn.close()
        if count == 0:
            logger.info("product_mentions 表为空，自动构建倒排索引...")
            build_product_mentions(db_pool.connection())
    except Exception as e:
        logger.warning(f"product_mentions 检测/构建跳过: {e}")


def _run_query(question: str, collect_timing: bool = False, collect_trace: bool = False,
               collect_refs: bool = False, on_refs=None, on_delta=None,
               on_stage=None,
               kb_ids: list | None = None,
               allowed_sensitivities: list | None = None,
               department: str | None = None):
    """主查询管线：实体检测 → 规划器（tag + 计划）→ 并行检索 → RRF → 精排 → Parent → LLM，返回答案文本。

    collect_timing=True 时返回 (answer, timings, trace, refs)，timings 为各阶段耗时字典（毫秒）。
    collect_trace=True 时 trace 为检索链中间数据（评测用）。
    collect_refs=True 时 refs 为精排后的引用列表（app fusion SSE 用）。
    on_refs(refs)：精排完成后回调（SSE references 事件）。
    on_delta(text)：LLM 增量回调（SSE delta 事件）。
    on_stage(name, counts)：检索阶段回调（SSE stage 事件，前端状态栏如实展示）。
    kb_ids：KB 白名单（RRF 融合后过滤）；None/空 = 全库检索。
    allowed_sensitivities：可看密级白名单（§2.14 B）；None/空 = 全库。
    department：部门过滤（§2.14 C）；None/空 = 不过滤。
    """
    _any = collect_timing or collect_trace or collect_refs
    trace_id = start_trace()
    timing: dict = {}
    trace: dict = {}
    refs: list = []
    t0 = time.perf_counter()

    def _stage(name: str, counts: dict | None = None, detail: dict | None = None):
        if on_stage is not None:
            try:
                on_stage(name, counts or {}, int((time.perf_counter() - t0) * 1000), detail or {})
            except Exception:
                logger.warning(f"[stage] 回调失败: {name}", exc_info=True)

    def _ms(a, b):
        return f"{(b - a) * 1000:.1f}ms"

    def _rec(key, a, b):
        if collect_timing:
            timing[key] = round((b - a) * 1000, 1)

    def _tr_cand(c):
        if not isinstance(c, dict):
            return None
        rs = c.get("rerank_score")
        return {
            "chunk_id": c.get("chunk_id"),
            "document_id": c.get("document_id"),
            "file_name": c.get("file_name", ""),
            "score": round(float(c.get("score") or 0), 4),
            "rerank_score": round(float(rs), 4) if rs is not None else None,
            "sources": c.get("sources") or ([c.get("source")] if c.get("source") else []),
        }

    def _tr_list(key, items):
        if collect_trace:
            trace[key] = [x for x in (_tr_cand(c) for c in items) if x]

    try:
        logger.info(f">>> 查询开始: {question[:80]}")

        # ── 0. 实体检测（非 LLM：产品/机构/类型提示）──
        entities = analyze_query(question)
        expanded_query = question
        logger.info(
            f"[实体] products={entities.products} org={entities.org} "
            f"type_hint={entities.type_hint}"
        )

        # query_type：多产品强制跨文档 > 自动判断
        if len(entities.products) >= 2:
            # 问题涉及多个产品（如 "A和B的关系"），必须跨文档检索
            query_type = "cross_doc"
        else:
            query_type = _detect_query_type(question, entities)
        logger.info(f"  query_type: {query_type}")

        # ── 0.6 问题规划器（全部问题：一次 LLM 调用出问题标签 + 执行计划 + 异常判定）──
        # 标签供生成阶段动态提示词；reject 短路直接拒答；计划失败回退类1管线，标签仍生效
        plan, tag, reject = plan_query(
            question,
            products=[p for p in entities.products] if entities.products else None,
            orgs=[o.value for o in entities.orgs] if entities.orgs else None,
        )
        if reject and (entities.products or entities.orgs):
            # 问题命中已知产品/机构枚举 = 确定性业务问题，覆盖 LLM 的误判拒答
            logger.info(
                f"[PLANNER] 实体命中覆盖拒答 "
                f"(产品={list(entities.products)[:3]} "
                f"机构={[o.value for o in entities.orgs][:3]})"
            )
            reject = False
        if reject:
            logger.info(
                f"[PLANNER] 异常问题拒答 (tag={tag or '兜底'}) | "
                f"规划耗时 {_ms(t0, time.perf_counter())}"
            )
            logger.info(f">>> 查询完成（拒答）")
            _rec("规划改写", t0, time.perf_counter())
            _rec("总计", t0, time.perf_counter())
            if on_refs is not None:
                on_refs([])
            if collect_trace:
                trace["query_type"] = query_type
                trace["planner_multi"] = False
                trace["faiss_hits"] = []
                trace["bm25_hits"] = []
                trace["meta_results"] = []
                trace["rrf_merged"] = []
                trace["reranked"] = []
                trace["n_context"] = 0
                trace["context_chars"] = 0
            return (REFUSAL_ANSWER, timing, trace, refs) if _any else REFUSAL_ANSWER
        tag_content = get_tag_content(tag)
        logger.info(f"  [PLANNER] tag={tag or '兜底'} 动态提示词={'有' if tag_content else '无'}")
        planner_multi = bool(plan and plan["type"] in ("parallel_subq", "multi_hop"))
        if planner_multi:
            query_type = "cross_doc"
        elif plan and plan["type"] == "single":
            planner_q = plan["steps"][0]["query"] or ""
            if planner_q and planner_q != question:
                logger.info(f"[PLANNER] 单步改写: {planner_q[:80]}")
                expanded_query = planner_q
        t_rewrite = time.perf_counter()
        _rec("规划改写", t0, t_rewrite)

        # ── 1-3. 检索 ──
        _stage("retrieval_start")
        if planner_multi:
            # 规划路径：step 轻检索（faiss+bm25+meta 的 RRF top-8）由 planner 执行；
            # SQL 路不参与（表格类单问走模板/类1）
            meta_results = meta_searcher.search(entities, 20, query_type)
            t_faiss = t_bm25 = t_meta = time.perf_counter()
            if collect_timing:
                timing["检索_faiss"] = 0.0
                timing["检索_bm25"] = 0.0
                timing["检索_meta"] = 0.0
                timing["检索_sql"] = 0.0
            planner_exec = execute_plan(plan, {
                "faiss": faiss_searcher,
                "bm25": bm25_searcher,
                "resolve": _resolve_faiss_results,
                "fusion": fusion,
                "meta_results": meta_results,
                "sql": sql_engine,
                "kb_ids": kb_ids,
            })
            merged = planner_exec.candidates
            merged = _filter_by_kb(merged, kb_ids)
            merged = _expand_siblings(merged)
            merged = _attach_doc_meta(merged)
            merged = _filter_by_sensitivity(merged, allowed_sensitivities)
            merged = _filter_by_department(merged, department)
            _stage("retrieval_done", {"meta": len(meta_results)})
            sql_result = None
            t_sql = t_rrf = time.perf_counter()
            _rec("RRF融合", t_rewrite, t_rrf)
            _stage("rrf_done", {"merged": len(merged)}, {"strategy": f"RRF (k={RRF_K})"})
            if collect_trace:
                trace["query_type"] = query_type
                trace["planner_multi"] = True
                _tr_list("faiss_hits", [])
                _tr_list("bm25_hits", [])
                _tr_list("meta_results", meta_results)
        else:
            # 类1完整并行检索（faiss+bm25+meta+sql）
            with ThreadPoolExecutor(max_workers=4) as executor:
                future_faiss = submit_with_trace(
                    executor, faiss_searcher.search, expanded_query, FAISS_TOP_K
                )
                future_bm25 = submit_with_trace(
                    executor, bm25_searcher.search, expanded_query, BM25_TOP_K,
                ) if (bm25_searcher and bm25_searcher.ready) else None
                future_meta = submit_with_trace(
                    executor, meta_searcher.search, entities, 20, query_type
                )
                future_sql = submit_with_trace(
                    executor, sql_engine.query, expanded_query, kb_ids
                )

                faiss_hits = future_faiss.result()
                t_faiss = time.perf_counter()
                bm25_results = future_bm25.result() if future_bm25 else []
                t_bm25 = time.perf_counter()
                meta_results = future_meta.result()
                t_meta = time.perf_counter()
                sql_result = future_sql.result()
                t_sql = time.perf_counter()
            _rec("检索_faiss", t_rewrite, t_faiss)
            _rec("检索_bm25", t_rewrite, t_bm25)
            _rec("检索_meta", t_rewrite, t_meta)
            _rec("检索_sql", t_rewrite, t_sql)

            logger.info(
                f"[并行检索] faiss={len(faiss_hits)}条 meta={len(meta_results)}条 "
                f"sql={'命中' if sql_result else '未命中'} | 并行总耗时 {_ms(t_rewrite, t_sql)}"
            )

            faiss_results = _resolve_faiss_results(faiss_hits)
            _stage("retrieval_done", {
                "faiss": len(faiss_results),
                "bm25": len(bm25_results),
                "meta": len(meta_results),
                "sql": 1 if sql_result else 0,
            })
            if collect_trace:
                trace["query_type"] = query_type
                trace["planner_multi"] = False
                _tr_list("faiss_hits", faiss_results)
                _tr_list("bm25_hits", bm25_results)
                _tr_list("meta_results", meta_results)
            merged = fusion.rrf_fusion(faiss_results, sql_result, meta_results, bm25_results)
            merged = _filter_by_kb(merged, kb_ids)
            merged = _expand_siblings(merged)
            merged = _attach_doc_meta(merged)
            merged = _filter_by_sensitivity(merged, allowed_sensitivities)
            merged = _filter_by_department(merged, department)
            t_rrf = time.perf_counter()
            _rec("RRF融合", t_sql, t_rrf)
            _stage("rrf_done", {"merged": len(merged)}, {"strategy": f"RRF (k={RRF_K})"})

        # ── 5. Reranker 精排 + 源配额 ──
        _stage("rerank_start")
        # top_k 留补位余量：上下文组装会跳过与已选 parent 重叠的 child，需要候选补位
        # 规划路径：对原问题 + 各 step 检索文本多路打分取最大值（防第二问语义稀释）
        # A/B 开关：RERANK_SKIP_SINGLE=1 时单步问题跳过精排 API（RRF 排序直出）
        reranked = fusion.rerank(
            question, merged, top_k=FINAL_TOP_K + 4, query_type=query_type,
            sub_queries=planner_exec.queries if planner_multi else None,
            skip_api=(
                RERANK_SKIP_SINGLE and not planner_multi
                and bool(plan) and plan["type"] == "single"
                and query_type == "single_doc"
            ),
        )
        # 生命周期检索语义(§2.14 A)：废止文档降权 + 时间感知，重排后调整
        reranked = _apply_lifecycle(question, reranked)
        # 邻域补全：入选 chunk 的同文档相邻块（±N）若被精排裁剪，按融合序补入尾部。
        # 法规条款/补贴标准类细节题的正确 chunk 常与已选 chunk 相邻但 rerank 分数低。
        reranked = _append_neighbors(reranked, merged)
        t_rerank = time.perf_counter()
        _rec("精排rerank", t_rrf, t_rerank)
        _stage("rerank_done", {"reranked": len(reranked)}, _rerank_detail(reranked))
        if collect_refs or on_refs is not None:
            refs = _build_refs(reranked)
            if on_refs is not None:
                on_refs(refs)
        _tr_list("rrf_merged", merged)
        _tr_list("reranked", reranked)
        logger.info(f"  精排: {len(reranked)} 条")
        for i, c in enumerate(reranked, 1):
            logger.info(
                f"    [{i}] source={c.get('source')} chunk_id={c.get('chunk_id')} "
                f"doc_id={c.get('document_id')} 文号={c.get('doc_number', '')} "
                f"rerank={c.get('rerank_score')} srcs={','.join(c.get('sources') or [])} "
                f"文件={str(c.get('file_name', ''))[:60]}"
            )

        # ── 6. 取 Parent Chunk 上下文 ──
        # 数据查询类问题 SQL 命中时收紧上下文；foreach 展开除外——逐项证据
        # （如"各公司的邮箱"）只存在于 contexts，收紧会丢失答案素材
        has_foreach = bool(plan and any(s.get("foreach") for s in plan["steps"]))
        contexts = _expand_to_parent_contexts(
            reranked,
            sql_cap=(
                SQL_CONTEXT_CAP
                if (tag == "数据查询" and not has_foreach) else None
            ),
        )
        if collect_trace:
            trace["n_context"] = len(contexts)
            trace["context_chars"] = sum(len(c) for c in contexts)
        t_ctx = time.perf_counter()
        _rec("parent上下文", t_rerank, t_ctx)
        _stage("context_done", {"contexts": len(contexts), "chars": sum(len(c) for c in contexts)},
               {"max_chars": MAX_CONTEXT_CHARS})
        for i, ctx in enumerate(contexts, 1):
            preview = ctx[:200].replace("\n", " / ")
            logger.info(f"  召回上下文[{i}] ({len(ctx)}字符): {preview}...")

        # ── 7. LLM 生成（基础提示词 + 标签动态内容 + 语言规则）──
        _stage("generate_start", None, {"model": DEEPSEEK_MODEL})
        style = compute_answer_style(reranked, question)
        logger.info(
            f"[PROMPT] 标签={tag or '兜底'} 文档语言={style['doc_lang']} "
            f"提问语言={style['answer_lang']} 跨语言={'是' if style['cross_lang'] else '否'}"
        )
        t_gen = time.perf_counter()
        ttft_ms = {"v": 0}

        def _delta_ttft(txt):
            # 首 token 延迟（TTFT）：从 generate_start 到第一个增量到达
            if not ttft_ms["v"]:
                ttft_ms["v"] = int((time.perf_counter() - t_gen) * 1000)
            if on_delta is not None:
                on_delta(txt)

        if planner_multi:
            answer = generate_synthesis_answer(
                question, planner_exec.intermediates, contexts, style, tag_content,
                timing=timing if collect_timing else None,
                on_delta=_delta_ttft,
            )
        else:
            answer = generate_answer(question, contexts, style, tag_content,
                                     timing=timing if collect_timing else None,
                                     on_delta=_delta_ttft)
        t_llm = time.perf_counter()
        _rec("LLM生成", t_ctx, t_llm)
        _rec("总计", t0, t_llm)

        # ── 各阶段耗时汇总 ──
        logger.info(
            f"  耗时: 重写/规划 {_ms(t0, t_rewrite)} | "
            f"并行检索 faiss {_ms(t0, t_faiss)} / bm25 {_ms(t0, t_bm25)} "
            f"/ meta {_ms(t0, t_meta)} / sql {_ms(t0, t_sql)} "
            f"(总 {_ms(t_rewrite, t_sql)}) | "
            f"RRF {_ms(t_sql, t_rrf)} | 精排 {_ms(t_rrf, t_rerank)} | "
            f"Parent {_ms(t_rerank, t_ctx)} | LLM {_ms(t_ctx, t_llm)} | "
            f"总计 {_ms(t0, t_llm)}"
        )

        logger.info(f">>> 查询完成: 答案 {len(answer)} 字")

        # 答案生成后对齐引用位置（内联引用芯片用），done 事件携带
        if _any and refs and answer:
            _align_ref_positions(answer, refs, reranked)
            positioned = sum(1 for r in refs if r.get("start_at") is not None)
            if positioned:
                logger.info(f"  引用对齐: {positioned}/{len(refs)} 条命中位置")

        _stage("generate_done", {"chars": len(answer) if answer else 0},
               {"model": DEEPSEEK_MODEL, "ttft_ms": ttft_ms["v"]})

        return (answer, timing, trace, refs) if _any else answer

    except Exception as e:
        logger.error(f"Query 处理异常: {e}", exc_info=True)
        msg = "系统处理出错，请重试"
        if on_refs is not None:
            on_refs([])
        return (msg, timing, trace, refs) if _any else msg
    finally:
        clear_trace()


@app.route("/chat", methods=["POST"])
def handle_chat():
    """竞赛标准接口：POST /chat，参数 question（JSON 或表单均可），返回 {"answer": ...}。

    JSON 请求带 "timing": true 时响应附 "timings"（各阶段耗时，毫秒）；
    带 "trace": true 时响应附 "trace"（检索链中间数据，评测用）。
    """
    timing_requested = False
    trace_requested = False
    kb_ids = None
    allowed_sensitivities = None
    department = None
    if request.is_json:
        body = request.get_json(silent=True) or {}
        question = body.get("question")
        timing_requested = bool(body.get("timing"))
        trace_requested = bool(body.get("trace"))
        if body.get("knowledge_base_id"):
            kb_ids = [body["knowledge_base_id"]]
        elif body.get("knowledge_base_ids"):
            kb_ids = list(body["knowledge_base_ids"])
        allowed_sensitivities, department = _parse_access_filters(body)
    else:
        question = request.form.get("question") or request.args.get("question")
    question = (question or "").strip()
    if not question:
        return jsonify({"answer": "请输入您的问题。"})
    if timing_requested or trace_requested:
        answer, timings, trace, _refs = _run_query(
            question, collect_timing=timing_requested, collect_trace=trace_requested,
            kb_ids=kb_ids, allowed_sensitivities=allowed_sensitivities,
            department=department,
        )
        resp = {"answer": answer}
        if timing_requested:
            resp["timings"] = timings
        if trace_requested:
            resp["trace"] = trace
        return jsonify(resp)
    return jsonify({"answer": _run_query(
        question, kb_ids=kb_ids, allowed_sensitivities=allowed_sensitivities,
        department=department,
    )})


def _build_refs(reranked: list[dict]) -> list[dict]:
    """精排结果 → app fusion 客户端期望的引用结构（YLSWReference）。

    id 一律转字符串（Go 端结构体字段为 string，数字会反序列化失败）。
    sql 候选无文档元数据，跳过。
    lifecycle_status 透出（§2.14 portal 引用「已废止」标签）。
    content 为 chunk 原文摘要（前端悬浮引用卡直接展示，不回查 chunk 接口）。
    """
    refs = []
    for c in reranked:
        cid = c.get("chunk_id")
        if c.get("source") == "sql" or cid in (None, -1, "", "-1"):
            continue
        text = c.get("text") or ""
        # 去掉 chunk 开头的 "# 文档标题 > ## 章节" 标题行，悬浮卡直接展示正文
        lines = text.splitlines()
        while lines and (lines[0].startswith("#") or lines[0].startswith(">")):
            lines.pop(0)
        clean = "\n".join(lines).strip()
        excerpt = clean[:400] + ("…" if len(clean) > 400 else "")
        refs.append({
            "chunk_id": str(cid),
            "document_id": str(c.get("document_id", "")),
            "source_doc_id": c.get("source_doc_id", "") or "",
            "knowledge_base_id": c.get("knowledge_base_id", "") or "",
            "file_name": c.get("file_name", ""),
            "doc_number": c.get("doc_number", ""),
            "org_name": c.get("org_name", ""),
            "doc_type": c.get("doc_type", ""),
            "product_name": c.get("product_name", ""),
            "doc_title": c.get("doc_title", ""),
            "content": excerpt,
            "doc_date": str(c.get("doc_date", "") or ""),
            "source": c.get("source", ""),
            "lifecycle_status": c.get("lifecycle_status", ""),
            "rerank_score": c.get("rerank_score"),
        })
    return refs


_SENT_SPLIT_RE = re.compile(r"[。；;!?！？\n]+")
_MIN_ALIGN_CHARS = 10


def _find_align_span(answer: str, text: str):
    """在 answer 中定位 chunk 原文的最长可命中片段，返回 (start, end) 字符偏移。

    按句切分 chunk 文本，逐句先精确查找，未中再用最长公共子串（容忍 LLM 改写）。
    取最长命中（引用越具体越可信）；无命中返回 None（该条不产生内联位置）。
    """
    if not answer or not text:
        return None
    best = None
    for sent in _SENT_SPLIT_RE.split(text):
        frag = re.sub(r"\s+", "", sent)
        if len(frag) < _MIN_ALIGN_CHARS:
            continue
        pos = answer.find(frag)
        if pos >= 0:
            size = len(frag)
        else:
            m = SequenceMatcher(None, answer, frag, autojunk=False)
            block = max(m.get_matching_blocks(), key=lambda b: b.size)
            if block.size < _MIN_ALIGN_CHARS:
                continue
            size, pos = block.size, block.a
        if best is None or size > best[0]:
            best = (size, pos)
    if best is None:
        return None
    size, pos = best
    return (pos, pos + size)


def _align_ref_positions(answer: str, refs: list[dict], reranked: list[dict]) -> None:
    """答案文本与引用 chunk 原文对齐，回填 start_at/end_at（字符偏移）。

    位置供 app 前端插入内联 [n] 上标；无命中则不留位置，
    引用面板/底部列表只展示有位置的引用。命中后把 content 摘要窗口
    对准命中句（前后各留余量），保证悬浮卡里能高亮对应原文。
    同位置冲突时先到先得，避免同一处叠多个标记。
    """
    text_map = {}
    for c in reranked:
        cid = c.get("chunk_id")
        txt = c.get("text") or ""
        if cid is not None and txt:
            text_map[str(cid)] = txt
    used: list[tuple[int, int]] = []
    for r in refs:
        txt = text_map.get(r.get("chunk_id", ""))
        span = _find_align_span(answer, txt) if txt else None
        if span is None:
            continue
        s, e = span
        if any(not (e <= us or s >= ue) for us, ue in used):
            continue
        used.append((s, e))
        r["start_at"] = s
        r["end_at"] = e
        # 摘要窗口对准命中句（命中句可能因空白归一化与原文不完全一致，取不到就保留原窗口）
        frag = re.sub(r"\s+", "", answer[s:e])
        idx = txt.find(frag) if frag else -1
        if idx >= 0:
            window = txt[max(0, idx - 120): idx + len(frag) + 280]
            lines = window.splitlines()
            while lines and (lines[0].startswith("#") or lines[0].startswith(">")):
                lines.pop(0)
            clean = "\n".join(lines).strip()
            if clean:
                r["content"] = clean + ("…" if idx + len(frag) + 280 < len(txt) else "")


def _rerank_detail(reranked: list[dict]) -> dict:
    """重排阶段排障明细：后端/阈值/Top 候选（前端 trace 行展开）。"""
    tops = []
    for c in reranked[:3]:
        if c.get("source") == "sql":
            continue
        lines = (c.get("text") or "").splitlines()
        while lines and (lines[0].startswith("#") or lines[0].startswith(">")):
            lines.pop(0)
        snippet = re.sub(r"\s+", " ", "\n".join(lines)).strip()[:60]
        tops.append({
            "score": round(float(c.get("rerank_score") or 0), 3),
            "doc": (c.get("file_name") or "")[:40],
            "text": snippet,
        })
    return {
        "backend": BGE_RERANK_BACKEND,
        "threshold": RERANK_META_MIN_SCORE,
        "top": tops,
    }


@app.route("/chat/stream", methods=["POST"])
def handle_chat_stream():
    """app(fusion) 流式接口：SSE 事件流，协议对齐 app/internal/fusion/ylsw_client.go。

    事件类型（data: 行内 JSON）：
      references: {"type":"references","references":[YLSWReference...]} —— 检索完成先发
      delta:      {"type":"delta","content":"..."} —— 答案增量
      done:       {"type":"done","references":[...]} —— 结束（携带最终引用）
      error:      {"type":"error","message":"..."} —— 出错

    knowledge_base_id / knowledge_base_ids：KB 白名单，按 chunks.knowledge_base_id
    过滤（单值兼容内部问答，数组供门户多 KB 检索；空 = 全库检索）。
    allowed_sensitivities：可看密级白名单（§2.14 B，app 按角色算好传入；空 = 全库）。
    department：部门过滤（§2.14 C，空 = 不过滤）。
    """
    body = request.get_json(silent=True) or {}
    question = (body.get("question") or "").strip()
    if not question:
        question = (request.form.get("question") or request.args.get("question") or "").strip()
    knowledge_base_id = (body.get("knowledge_base_id") or "").strip()
    knowledge_base_ids = body.get("knowledge_base_ids") or []
    allowed_sensitivities, department = _parse_access_filters(body)
    if not question:
        return jsonify({"answer": "请输入您的问题。"})

    kb_ids = None
    if knowledge_base_ids:
        kb_ids = [str(k).strip() for k in knowledge_base_ids if str(k).strip()]
    elif knowledge_base_id:
        kb_ids = [knowledge_base_id]
    if kb_ids:
        logger.info(f"[fusion] kb_ids={kb_ids}（KB 过滤已启用）")

    def generate():
        q: queue.Queue = queue.Queue()

        def _refs(r):
            q.put(("references", r))

        def _delta(t):
            q.put(("delta", t))

        def _stage(name, counts, t_ms, detail):
            q.put(("stage", {"stage": name, "t_ms": t_ms, "counts": counts or {}, "detail": detail or {}}))

        def _worker():
            try:
                q.put(("result", _run_query(
                    question, collect_refs=True, on_refs=_refs, on_delta=_delta,
                    on_stage=_stage,
                    kb_ids=kb_ids, allowed_sensitivities=allowed_sensitivities,
                    department=department,
                )))
            except Exception as e:
                logger.error(f"[fusion] 流式查询异常: {e}", exc_info=True)
                q.put(("error", f"系统处理出错: {e}"))

        threading.Thread(target=_worker, daemon=True, name="fusion-query").start()

        refs_sent = False
        delta_sent = False
        final_refs = []
        result = None
        while True:
            kind, payload = q.get()
            if kind == "error":
                yield "data: " + json.dumps(
                    {"type": "error", "message": payload}, ensure_ascii=False,
                ) + "\n\n"
                return
            if kind == "references":
                refs_sent = True
                final_refs = payload
                yield "data: " + json.dumps(
                    {"type": "references", "references": payload},
                    ensure_ascii=False,
                ) + "\n\n"
            elif kind == "delta":
                delta_sent = True
                yield "data: " + json.dumps(
                    {"type": "delta", "content": payload}, ensure_ascii=False,
                ) + "\n\n"
            elif kind == "stage":
                yield "data: " + json.dumps(
                    {"type": "stage", **payload}, ensure_ascii=False,
                ) + "\n\n"
            elif kind == "result":
                result = payload
                break

        answer = result[0] if isinstance(result, tuple) else result

        # 兜底：拒答/LLM 失败等路径没有回调，补发整段答案，保证前端有内容
        if not refs_sent:
            yield "data: " + json.dumps(
                {"type": "references", "references": final_refs},
                ensure_ascii=False,
            ) + "\n\n"
        if not delta_sent and answer:
            yield "data: " + json.dumps(
                {"type": "delta", "content": answer}, ensure_ascii=False,
            ) + "\n\n"
        yield "data: " + json.dumps(
            {"type": "done", "references": final_refs}, ensure_ascii=False,
        ) + "\n\n"

    return Response(
        stream_with_context(generate()),
        mimetype="text/event-stream",
        headers={
            "Cache-Control": "no-cache",
            "X-Accel-Buffering": "no",
        },
    )


_CROSS_DOC_SIGNALS = (
    "对比", "比较", "区别", "差异", "哪些", "所有", "全部",
    "汇总", "全景", "分别", "各自", "综述", "梳理",
    "关系", "联系", "关联", "异同", "相同", "不同",
)


def _detect_query_type(question: str, entities: QueryEntities) -> str:
    """auto 模式：根据问法特征判断单文档还是跨文档检索。"""
    # 问题提及 ≥2 个产品 → 需要跨文档检索（如 "全民付蓝鲸和银商大脑的关系"）
    if len(entities.products) >= 2:
        return "cross_doc"
    if any(s in question for s in _CROSS_DOC_SIGNALS):
        return "cross_doc"
    if "2023" in question and "2024" in question:
        return "cross_doc"
    # 产品+机构同时出现且无明确类型意图 → 可能涉及多份文档
    if entities.has_entities and entities.product and entities.org and not entities.type_hint:
        return "cross_doc"
    return "single_doc"


def _resolve_faiss_results(faiss_hits: list) -> list[dict]:
    """将 FAISS 返回的 (vector_id, score) 转为含文本+元数据的结果（内存直查）。"""
    if not faiss_hits or not chunk_store:
        return []
    return chunk_store.resolve(faiss_hits)


_VERSION_RE = re.compile(r"V(\d+)[._](\d+)(?:[._]\d+)*")  # 剥整段版本号 V4.2.7/V1_0
_VERSION_PARSE_RE = re.compile(r"V(\d+)[._](\d+)")        # 取前两位比较


def _parse_version(file_name: str) -> tuple[int, int]:
    """文件名版本号 V数字_数字 → (大版本, 小版本)；无版本号 (0, 0)。"""
    m = _VERSION_PARSE_RE.search(file_name or "")
    return (int(m.group(1)), int(m.group(2))) if m else (0, 0)


def _doc_group_key(file_name: str) -> str:
    """同文档不同版本归组键：去版本号、语言后缀、类型日期前缀。"""
    name = _VERSION_RE.sub("", file_name or "")
    name = re.sub(r"_(ZH|EN)\.md$", "", name)
    name = re.sub(r"^(REG|MAN|NWS|PDT|RPT|TBL|GEN)_\d{8}_", "", name)
    return name


def _dedup_by_latest_version(candidates: list[dict]) -> list[dict]:
    """元数据去重：同文档多版本同时命中召回时，仅保留版本最新文档的候选。

    版本比较：先比第一个数字，相同再比第二个数字（V4.2.7 → (4,2)）。
    输出保持输入原始顺序（多文档题各组交错，聚合重排会打乱重排序位）。
    """
    groups: dict[str, list[tuple]] = {}
    for c in candidates:
        fn = c.get("file_name") or ""
        groups.setdefault(_doc_group_key(fn), []).append((_parse_version(fn), c))

    kept_ids: set[int] = set()
    for key, items in groups.items():
        if len(items) == 1:
            kept_ids.add(id(items[0][1]))
            continue
        versions = {v for v, _ in items}
        if len(versions) == 1:
            kept_ids.update(id(c) for _, c in items)
            continue
        max_ver = max(versions)
        kept = [c for v, c in items if v == max_ver]
        kept_ids.update(id(c) for c in kept)
        logger.info(
            f"[去重] 文档 {key}: {len(items)} 条候选跨 {len(versions)} 个版本，"
            f"仅保留 V{max_ver[0]}_{max_ver[1]}（剔除 {len(items) - len(kept)} 条旧版）"
        )
    return [c for c in candidates if id(c) in kept_ids]


_CJK_RE = re.compile(r"[一-鿿]")


def detect_language(text: str) -> str:
    """CJK 字符占比 >0.5 判中文，否则英文（混合中英问题时优先英文）。"""
    if not text:
        return "zh"
    letters = sum(1 for ch in text if ch.isalnum())
    cjk = len(_CJK_RE.findall(text))
    return "zh" if letters == 0 or cjk / letters > 0.5 else "en"


def compute_answer_style(reranked: list[dict], question: str) -> dict:
    """统计召回候选元数据 → 语言适配参数。

    - 跳过 sql 候选（无 doc_type/file_name）
    - 文档语言按 file_name _ZH/_EN 取多数（并列取先出现者）
    - answer_lang = 提问语言；cross_lang = 文档语言 ≠ 提问语言
    """
    style = {
        "answer_lang": detect_language(question),
        "doc_lang": None,
        "cross_lang": False,
    }

    doc_cands = [
        c for c in reranked
        if c.get("source") != "sql" and (c.get("doc_type") or c.get("file_name"))
    ]
    if not doc_cands:
        return style

    # 文档语言：_ZH/_EN 多数
    lang_votes = {"zh": 0, "en": 0}
    first_lang = None
    for c in doc_cands:
        fn = c.get("file_name") or ""
        lang = "en" if fn.endswith("_EN.md") else "zh"
        lang_votes[lang] += 1
        if first_lang is None:
            first_lang = lang
    style["doc_lang"] = (
        "zh" if lang_votes["zh"] >= lang_votes["en"] else "en"
    ) if lang_votes["zh"] != lang_votes["en"] else first_lang
    style["cross_lang"] = style["doc_lang"] != style["answer_lang"]
    return style


def _expand_siblings(merged: list[dict], radius: int = 2,
                     max_add: int = 8) -> list[dict]:
    """检索邻域扩展：融合池中每个语料候选的同文档相邻 child 补入池尾部，
    补偿语义检索对相邻条款块（如补贴标准的分段条款）的漏召回。"""
    if not chunk_store:
        return merged
    out = list(merged)
    seen = {str(c.get("chunk_id")) for c in merged}
    added = 0
    for c in merged:
        if added >= max_add:
            break
        doc = c.get("document_id")
        ps = c.get("position_start")
        if not (isinstance(doc, int) and isinstance(ps, int)):
            continue
        for r in chunk_store.neighbors(doc, ps, radius):
            if str(r["id"]) in seen:
                continue
            seen.add(str(r["id"]))
            out.append({
                "id": r["id"],
                "chunk_id": r["id"],
                "text": r["chunk_text"],
                "source": "faiss",
                "document_id": r["document_id"],
                "file_name": r.get("file_name", ""),
                "org_name": r.get("org_name", ""),
                "doc_type": r.get("doc_type", ""),
                "product_name": r.get("product_name", ""),
                "knowledge_base_id": r.get("knowledge_base_id", ""),
                "doc_number": r.get("doc_number", ""),
                "doc_date": str(r.get("doc_date", "") or ""),
                "doc_title": r.get("doc_title", ""),
                "position_start": r.get("position_start"),
                "position_end": r.get("position_end"),
            })
            added += 1
            if added >= max_add:
                break
    if added:
        logger.info(f"[邻域扩展] 融合池补入 {added} 条相邻块")
    return out


def _append_neighbors(reranked: list[dict], merged: list[dict],
                      radius: int = 5, max_extra: int = 8) -> list[dict]:
    """邻域补全：把融合链中与已入选 chunk 同文档相邻（chunk 序号差 ≤ radius）
    但被精排裁剪的候选补入重排列表尾部，防条款类细节丢失。"""
    selected = []
    for c in reranked:
        doc = c.get("document_id")
        ps = c.get("position_start")
        if not (isinstance(doc, int) and isinstance(ps, int)):
            continue
        selected.append((doc, ps))
    if not selected:
        return reranked

    out = list(reranked)
    seen_ids = {str(c.get("chunk_id")) for c in reranked}
    extra = 0
    for c in merged:
        if extra >= max_extra:
            break
        cid = str(c.get("chunk_id"))
        if cid in seen_ids:
            continue
        doc = c.get("document_id")
        ps = c.get("position_start")
        if not (isinstance(doc, int) and isinstance(ps, int)):
            continue
        if any(doc == d and abs(ps - p) <= radius for d, p in selected):
            c = dict(c)
            c["rerank_score"] = None  # 补位候选无精排分，置尾部
            out.append(c)
            seen_ids.add(cid)
            extra += 1
    if extra:
        logger.info(f"[邻域补全] 补入 {extra} 条相邻候选")
    return out


def _expand_to_parent_contexts(reranked: list[dict], max_contexts: int = FINAL_TOP_K,
                               sql_cap: int | None = None) -> list[str]:
    """分层上下文组装：每源第 1 条取 parent chunk（完整上下文），其余取 child chunk（节省 token）。

    去重：child 完全落在已收录 span 内（同文档）时跳过——Top-1 的 parent 已覆盖其内容，
    跳过后由后续候选补位，最多组装 max_contexts 条不重复上下文。

    合并：同文档上下文 span 重叠或相邻（相接）时合并为一条——取并集区间的 child 单元
    文本重建（无重叠、无遗漏），沿用首条标签。跨章节（span 不相接）不合并，
    保证列表式问题各章节各自成条。

    sql_cap：数据查询类问题 SQL 命中时收紧上下文上限（见 config.SQL_CONTEXT_CAP）。
    """
    # 元数据去重：同文档多版本召回只留最新版
    reranked = _dedup_by_latest_version(reranked)

    # 数据查询类问题 SQL 命中：答案主体在结构化结果里，语料块多为噪声，收紧上限
    if sql_cap and any(c.get("source") == "sql" for c in reranked):
        max_contexts = min(max_contexts, sql_cap)

    if not chunk_store:
        return [c["text"] for c in reranked[:max_contexts]]

    TYPE_LABELS = {
        "regulation": "法规", "manual": "手册", "product": "产品", "report": "报告",
        "news": "新闻", "table": "表格", "general": "通用",
    }

    def _build_label(item: dict) -> str:
        meta_parts = []
        if item.get("doc_number"):
            meta_parts.append(f"文号:{item['doc_number']}")
        if item.get("org_name"):
            meta_parts.append(f"机构:{item['org_name']}")
        if item.get("doc_type"):
            label = TYPE_LABELS.get(item["doc_type"], item["doc_type"])
            meta_parts.append(f"类型:{label}")
        if item.get("product_name"):
            meta_parts.append(f"产品:{item['product_name']}")
        if item.get("lifecycle_status") == "expired":
            meta_parts.append("状态:已废止")
        if item.get("file_name"):
            meta_parts.append(f"来源:{item['file_name']}")
        return f"[{' | '.join(meta_parts)}]" if meta_parts else ""

    def _fetch_union_text(doc_id: int, start: int, end: int) -> str:
        """取 [start, end) 区间内全部 child 单元文本按序拼接（内存直查）。"""
        return chunk_store.union_text(doc_id, start, end)

    entries: list[dict] = []  # kind: "sql" | "chunk"；chunk 含 doc_id/start/end/label
    seen = set()
    source_count: dict[str, int] = {}

    for item in reranked:
        src = item.get("source", "")

        if src == "sql":
            if item.get("text"):
                entries.append({"kind": "sql", "text": f"[结构化查询结果]\n{item['text']}"})
                if len(entries) >= max_contexts:
                    break
            continue

        chunk_id = item.get("chunk_id")
        if not chunk_id or chunk_id == -1 or chunk_id in seen:
            continue

        # parent 反查走内存预计算映射（启动时已算好，无 DB 查询）
        row = chunk_store.parent_of(chunk_id)

        if not row:
            continue

        doc_id = row["document_id"]
        c_start, c_end = row["position_start"], row["position_end"]

        # 去重：child 完全落在已收录 span 内 → 与已选 parent/child 内容重复，跳过。
        # 仅当已收录条目是完整文本（top1 parent 或合并后 union 全文）时才可据此跳过；
        # 若已收录条目只是局部 child 文本，其 span 不构成覆盖证据，不得跳过。
        if any(
            e["kind"] == "chunk" and e["doc_id"] == doc_id
            and e["start"] <= c_start and c_end <= e["end"]
            and e.get("full")
            for e in entries
        ):
            continue

        seen.add(chunk_id)
        source_count[src] = source_count.get(src, 0) + 1
        is_top1 = (source_count[src] == 1)
        label = _build_label(item)

        if is_top1 and row.get("parent_text") is not None:
            text = f"{label}\n{row['parent_text']}" if label else row["parent_text"]
            span = (row["p_start"], row["p_end"])
            is_full = True
        else:
            text = item.get("text", "")
            text = f"{label}\n{text}" if label else text
            span = (c_start, c_end)
            is_full = False

        # 合并：与同文档已有条目 span 重叠或相接 → 并集区间重建正文
        merged = False
        for e in entries:
            if e["kind"] != "chunk" or e["doc_id"] != doc_id:
                continue
            if span[0] <= e["end"] and e["start"] <= span[1]:
                us, ue = min(e["start"], span[0]), max(e["end"], span[1])
                body = _fetch_union_text(doc_id, us, ue)
                if body:
                    keep_label = e["label"] if e["start"] <= span[0] else label
                    e["start"], e["end"] = us, ue
                    e["text"] = f"{keep_label}\n{body}" if keep_label else body
                    e["full"] = True  # union 重建为区间完整文本
                    logger.info(
                        f"  合并上下文: doc_id={doc_id} 并集 [{us},{ue}) "
                        f"(吸收 span [{span[0]},{span[1]})，省 1 条)"
                    )
                merged = True
                break
        if not merged:
            entries.append({
                "kind": "chunk", "doc_id": doc_id,
                "start": span[0], "end": span[1],
                "text": text, "label": label, "full": is_full,
            })

        if len(entries) >= max_contexts:
            break

    total_chars = sum(len(e["text"]) for e in entries)
    logger.info(f"[上下文] 组装 {len(entries)} 条 共 {total_chars} 字符")
    return [e["text"] for e in entries]


def _run_retrieval(question: str, top_k: int = None,
                   kb_ids: list | None = None,
                   allowed_sensitivities: list | None = None,
                   department: str | None = None) -> list[dict]:
    """纯检索子管线（无规划器/LLM 生成）：实体检测 → 类1并行检索 → RRF → 精排 → 邻域补全。

    Agent 检索场景（/search）专用：查询已是 Agent 改写后的检索文本，
    不做规划器改写；不生成答案，返回精排后的 chunk 候选（含 text 与元数据）。
    kb_ids：KB 白名单（RRF 融合后过滤）；None/空 = 全库检索。
    allowed_sensitivities/department：§2.14 密级/部门过滤（同 /chat）。
    """
    entities = analyze_query(question)
    query_type = (
        "cross_doc" if len(entities.products) >= 2
        else _detect_query_type(question, entities)
    )

    with ThreadPoolExecutor(max_workers=4) as executor:
        future_faiss = submit_with_trace(
            executor, faiss_searcher.search, question, FAISS_TOP_K
        )
        future_bm25 = submit_with_trace(
            executor, bm25_searcher.search, question, BM25_TOP_K,
        ) if (bm25_searcher and bm25_searcher.ready) else None
        future_meta = submit_with_trace(
            executor, meta_searcher.search, entities, 20, query_type
        )
        future_sql = submit_with_trace(executor, sql_engine.query, question, kb_ids)

        faiss_hits = future_faiss.result()
        bm25_results = future_bm25.result() if future_bm25 else []
        meta_results = future_meta.result()
        sql_result = future_sql.result()

    faiss_results = _resolve_faiss_results(faiss_hits)
    merged = fusion.rrf_fusion(faiss_results, sql_result, meta_results, bm25_results)
    merged = _filter_by_kb(merged, kb_ids)
    merged = _expand_siblings(merged)
    merged = _attach_doc_meta(merged)
    merged = _filter_by_sensitivity(merged, allowed_sensitivities)
    merged = _filter_by_department(merged, department)
    reranked = fusion.rerank(
        question, merged, top_k=(top_k or FINAL_TOP_K) + 4, query_type=query_type,
    )
    reranked = _apply_lifecycle(question, reranked)
    return _append_neighbors(reranked, merged)


@app.route("/search", methods=["POST"])
def handle_search():
    """app(fusion) Agent 检索接口：纯检索无生成，供 knowledge_search 工具调用。

    参数（JSON）:
      queries:            检索文本数组（Agent 一次工具调用的多查询）
      knowledge_base_ids: KB 标识数组（白名单过滤；空 = 全库检索）
      top_k:              返回条数（默认 FINAL_TOP_K）

    返回: {"results": [{chunk_id, document_id, file_name, content, score,
                        rerank_score, org_name, doc_type, product_name,
                        doc_number, doc_date, source}]}
    """
    body = request.get_json(silent=True) or {}
    queries = body.get("queries") or []
    if isinstance(queries, str):
        queries = [queries]
    queries = [q.strip() for q in queries if q and q.strip()]
    if not queries:
        return jsonify({"results": []})

    knowledge_base_ids = body.get("knowledge_base_ids") or []
    allowed_sensitivities, department = _parse_access_filters(body)
    try:
        top_k = int(body.get("top_k") or 0)
    except (TypeError, ValueError):
        top_k = 0
    if top_k <= 0:
        top_k = FINAL_TOP_K

    if knowledge_base_ids:
        logger.info(f"[search] knowledge_base_ids={knowledge_base_ids}（KB 过滤已启用）")
    if allowed_sensitivities:
        logger.info(f"[search] allowed_sensitivities={allowed_sensitivities}（密级过滤已启用）")

    kb_ids = list(knowledge_base_ids) or None

    merged_by_id: dict[str, dict] = {}
    for q in queries:
        try:
            reranked = _run_retrieval(q, top_k=top_k, kb_ids=kb_ids,
                                      allowed_sensitivities=allowed_sensitivities,
                                      department=department)
        except Exception as e:
            logger.error(f"[search] 查询 {q[:60]} 检索异常: {e}", exc_info=True)
            continue
        for c in reranked:
            cid = c.get("chunk_id")
            if c.get("source") == "sql" or cid in (None, -1, "", "-1"):
                continue
            key = str(cid)
            prev = merged_by_id.get(key)
            if prev is None or (c.get("rerank_score") or 0) > (prev.get("rerank_score") or 0):
                merged_by_id[key] = c

    results = sorted(
        merged_by_id.values(),
        key=lambda c: -(c.get("rerank_score") or 0),
    )[:top_k]

    out = []
    for c in results:
        out.append({
            "chunk_id": str(c.get("chunk_id")),
            "document_id": str(c.get("document_id", "")),
            "file_name": c.get("file_name", ""),
            "content": c.get("text", ""),
            "score": c.get("score"),
            "rerank_score": c.get("rerank_score"),
            "org_name": c.get("org_name", ""),
            "doc_type": c.get("doc_type", ""),
            "product_name": c.get("product_name", ""),
            "doc_number": c.get("doc_number", ""),
            "doc_date": str(c.get("doc_date", "") or ""),
            "source": c.get("source", ""),
        })
    logger.info(f"[search] {len(queries)} 查询 → {len(out)} 条结果 (top_k={top_k})")
    return jsonify({"results": out})


def _filter_by_kb(candidates: list[dict], kb_ids) -> list[dict]:
    """按知识库白名单过滤融合后候选。kb_ids 为空（全库）不过滤。

    SQL 候选（source=="sql"）无 knowledge_base_id，但查询本身已按 kb_ids
    行级作用域执行（tables_structured/schema_registry 的 knowledge_base_id
    条件），结果天然落在白名单内 → 直接保留。
    离线管线入库的存量文档 kb 为空，同样被滤掉——需挂到 KB 时手动 UPDATE。
    """
    if not kb_ids:
        return candidates
    kbs = set(kb_ids)
    kept = [
        c for c in candidates
        if c.get("knowledge_base_id") in kbs or c.get("source") == "sql"
    ]
    dropped = len(candidates) - len(kept)
    if dropped:
        logger.info(f"[KB过滤] kb={sorted(kbs)} 剔除 {dropped} 条候选，保留 {len(kept)} 条")
    return kept


def _attach_doc_meta(candidates: list[dict]) -> list[dict]:
    """语料候选补文档级企业元数据（生命周期/密级/部门，§2.14 检索语义）。

    chunk_store 启动时载入 documents 全表，此处纯内存直查。
    SQL 候选无 document_id，按默认值处理（internal/effective）。
    """
    for c in candidates:
        if c.get("source") == "sql" or not chunk_store:
            c.setdefault("sensitivity", "internal")
            c.setdefault("lifecycle_status", "effective")
            continue
        meta = chunk_store.doc_meta(c.get("document_id")) or {}
        c["lifecycle_status"] = meta.get("lifecycle_status") or "effective"
        c["effective_date"] = str(meta.get("effective_date") or "")
        c["expiry_date"] = str(meta.get("expiry_date") or "")
        c["sensitivity"] = meta.get("sensitivity") or "internal"
        c["department"] = meta.get("department") or ""
        # app 侧文档 UUID / KB id：跳转 app 详情页、引用面板「所属知识库」用
        if not c.get("source_doc_id"):
            c["source_doc_id"] = meta.get("source_doc_id") or ""
        if not c.get("knowledge_base_id"):
            c["knowledge_base_id"] = meta.get("knowledge_base_id") or ""
    return candidates


def _filter_by_sensitivity(candidates: list[dict], allowed_sensitivities) -> list[dict]:
    """密级白名单过滤（§2.14 B）：allowed 空 = 全库；缺字段视为 internal。

    YLSW 只机械过滤不持有角色语义——角色 → 可看密级集合由 app 算好传入。
    """
    if not allowed_sensitivities:
        return candidates
    allowed = set(allowed_sensitivities)
    kept = [
        c for c in candidates
        if (c.get("sensitivity") or "internal") in allowed
    ]
    dropped = len(candidates) - len(kept)
    if dropped:
        logger.info(f"[密级过滤] allowed={sorted(allowed)} 剔除 {dropped} 条候选，保留 {len(kept)} 条")
    return kept


def _filter_by_department(candidates: list[dict], department) -> list[dict]:
    """部门过滤（§2.14 C）：department 空 = 不过滤；只做标签级过滤不做硬隔离。"""
    if not department:
        return candidates
    kept = [c for c in candidates if c.get("department") == department]
    dropped = len(candidates) - len(kept)
    if dropped:
        logger.info(f"[部门过滤] department={department} 剔除 {dropped} 条候选，保留 {len(kept)} 条")
    return kept


_YEAR_RE = re.compile(r"(19|20)\d{2}")


def _apply_lifecycle(question: str, candidates: list[dict]) -> list[dict]:
    """生命周期检索语义（§2.14 A）：废止降权（非硬滤）+ 时间感知。

    - status=expired：rerank_score × 0.7，加「已废止」标签（引用/上下文透出）
    - 问题含年份：该时点有效（生效 ≤ 年 ≤ 废止）→ × 1.1；时点外 → × 0.8
    无 rerank_score 的候选（SQL/邻域补位）跳过数值调整，仅打标签。
    """
    m = _YEAR_RE.search(question or "")
    year = int(m.group(0)) if m else None
    for c in candidates:
        status = c.get("lifecycle_status") or "effective"
        if status == "expired":
            c["lifecycle_label"] = "已废止"
        score = c.get("rerank_score")
        if score is None:
            continue
        if status == "expired":
            c["rerank_score"] = score * 0.7
        elif year is not None:
            eff = c.get("effective_date") or ""
            exp = c.get("expiry_date") or ""
            eff_y = int(eff[:4]) if len(eff) >= 4 and eff[:4].isdigit() else None
            exp_y = int(exp[:4]) if len(exp) >= 4 and exp[:4].isdigit() else None
            in_win = (eff_y is None or eff_y <= year) and (exp_y is None or exp_y >= year)
            c["rerank_score"] = score * (1.1 if in_win else 0.8)
    return candidates


# ── /ingest /delete_document：app 推送数据流（内存状态同步 + FAISS 增量）──

_ingest_lock = threading.Lock()  # FAISS add + 索引写回 + 内存重载串行化


def _reload_memory_state():
    """重建 chunk_store / BM25 内存索引（ingest/delete 后调用，个人规模秒级）。"""
    global chunk_store, bm25_searcher
    chunk_store = ChunkStore(db_pool)
    try:
        bm25_searcher = BM25Searcher(db_pool.connection())
    except Exception as e:
        logger.error(f"BM25 重建失败，词法路降级关闭: {e}")
        bm25_searcher = None


_LIFECYCLE_KEYS = ("lifecycle_status", "effective_date", "expiry_date",
                   "superseded_by", "sensitivity", "department")


def _lifecycle_fields(meta: dict) -> dict:
    """meta dict → 企业级元数据字段(§2.14 默认值:effective/internal)。

    旧格式键(status/effective_date/expiry_date)兼容:Go 侧新 payload 用
    lifecycle_status,离线管线/旧调用方可能仍用 status。
    """
    def _v(*keys, default=""):
        for k in keys:
            v = (meta or {}).get(k)
            if v not in (None, ""):
                return str(v).strip()
        return default
    return {
        "lifecycle_status": _v("lifecycle_status", "status", default="effective"),
        "effective_date": _v("effective_date"),
        "expiry_date": _v("expiry_date"),
        "superseded_by": _v("superseded_by"),
        "sensitivity": _v("sensitivity", default="internal"),
        "department": _v("department"),
    }


def _parse_access_filters(body: dict) -> tuple:
    """请求体 → (allowed_sensitivities, department)（§2.14 B/C 过滤参数）。"""
    allowed = body.get("allowed_sensitivities") or []
    if isinstance(allowed, str):
        allowed = [allowed]
    allowed = [str(s).strip() for s in allowed if str(s).strip()] or None
    department = (body.get("department") or "").strip() or None
    return allowed, department


def _ingest_markdown(kb_id: str, doc_uid: str, file_name: str,
                     file_type: str, markdown: str, meta: dict) -> dict:
    """app 推送的单文档摄取：入库 → 领域切分 → 嵌入 → FAISS 追加 → 内存重载。"""
    from ingest.pipeline import DB as IngestDB, call_bge_embedding
    from ingest.chunker import chunk_file
    import faiss

    db = IngestDB()
    try:
        # 幂等替换：同 source_doc_id 已入库 → 级联删旧重建（FAISS 残留向量靠检索层过滤）
        with db.conn.cursor() as cur:
            cur.execute("SELECT id FROM documents WHERE source_doc_id=%s", (doc_uid,))
            old = cur.fetchone()
        if old:
            logger.info(f"[ingest] 文档 {doc_uid} 已存在(doc_id={old[0]})，删旧重建")
            with db.conn.cursor() as cur:
                cur.execute("DELETE FROM documents WHERE id=%s", (old[0],))
            db.commit()

        life = _lifecycle_fields(meta)
        doc_id = db.insert_document(
            file_name=file_name, file_type=file_type,
            file_size=len(markdown.encode("utf-8")), file_path="",
            doc_number=meta.get("doc_number", ""), org_name=meta.get("org_name", ""),
            doc_date_str=meta.get("doc_date", ""),
            doc_title=meta.get("doc_title") or file_name,
            doc_type=meta.get("doc_type", ""), product_name=meta.get("product_name", ""),
            source_doc_id=doc_uid, knowledge_base_id=kb_id,
            lifecycle_status=life["lifecycle_status"],
            effective_date=life["effective_date"], expiry_date=life["expiry_date"],
            superseded_by=life["superseded_by"], sensitivity=life["sensitivity"],
            department=life["department"],
            custom_metadata=meta.get("custom_metadata"),
        )
        log_id = db.insert_parse_log(doc_id, "chunking", "running")

        chunks = chunk_file(markdown, file_name, [])
        logger.info(f"[ingest] doc_id={doc_id} 分块 {len(chunks)} chunks")

        child_map: dict = {}
        chunk_idx = 0
        for chunk in chunks:
            if chunk.level == "child":
                cid = db.insert_chunk(
                    document_id=doc_id, chunk_index=chunk_idx,
                    chunk_text=chunk.text, chunk_level="child",
                    keywords=chunk.keywords, pos_start=chunk.position_start,
                    pos_end=chunk.position_end, org_name=meta.get("org_name", ""),
                    doc_type=meta.get("doc_type", ""),
                    product_name=meta.get("product_name", ""),
                    knowledge_base_id=kb_id,
                    lifecycle_status=life["lifecycle_status"],
                    effective_date=life["effective_date"],
                    expiry_date=life["expiry_date"],
                    sensitivity=life["sensitivity"], department=life["department"],
                )
                child_map[id(chunk)] = cid
                chunk_idx += 1
        for chunk in chunks:
            if chunk.level == "parent":
                first_child = child_map.get(id(chunk.child_chunks[0])) if chunk.child_chunks else None
                db.insert_chunk(
                    document_id=doc_id, chunk_index=chunk_idx,
                    chunk_text=chunk.text, chunk_level="parent",
                    parent_chunk_id=first_child,
                    keywords=chunk.keywords, pos_start=chunk.position_start,
                    pos_end=chunk.position_end, org_name=meta.get("org_name", ""),
                    doc_type=meta.get("doc_type", ""),
                    product_name=meta.get("product_name", ""),
                    knowledge_base_id=kb_id,
                    lifecycle_status=life["lifecycle_status"],
                    effective_date=life["effective_date"],
                    expiry_date=life["expiry_date"],
                    sensitivity=life["sensitivity"], department=life["department"],
                )
                chunk_idx += 1
        db.commit()
        db.update_parse_log(log_id, "success", f"{len(chunks)} chunks")

        # 嵌入 child chunks（复用管线批量嵌入函数；失败留 pending，rebuild_faiss 兜底）
        child_ids = [cid for cid in child_map.values()]
        child_texts = []
        with db.conn.cursor() as cur:
            ph = ",".join(["%s"] * len(child_ids))
            cur.execute(
                f"SELECT id, chunk_text FROM chunks WHERE id IN ({ph}) ORDER BY id",
                child_ids,
            )
            child_texts = cur.fetchall()
        embedded = 0
        if child_texts and faiss_searcher is not None:
            texts = [t for _, t in child_texts]
            embs = call_bge_embedding(texts)
            if embs is not None and len(embs) == len(texts):
                with _ingest_lock:
                    import numpy as np
                    base = faiss_searcher.index.ntotal
                    vectors = np.array(embs, dtype=np.float32)
                    faiss_searcher.index.add(vectors)
                    id_pairs = [
                        (cid, base + i) for i, (cid, _) in enumerate(child_texts)
                    ]
                    db.batch_update_vector_ids(id_pairs)
                    tmp = tempfile.NamedTemporaryFile(delete=False, suffix=".bin")
                    tmp_path = tmp.name
                    tmp.close()
                    try:
                        faiss.write_index(faiss_searcher.index, tmp_path)
                        shutil.copy2(tmp_path, faiss_searcher.index_path)
                    finally:
                        if os.path.exists(tmp_path):
                            os.unlink(tmp_path)
                embedded = len(id_pairs)
                logger.info(f"[ingest] doc_id={doc_id} FAISS 追加 {embedded} 向量")
            else:
                logger.warning(f"[ingest] doc_id={doc_id} 嵌入失败，chunks 留 pending 待 rebuild")

        db.update_document_status(doc_id, "success", chunk_count=len(chunks))
        db.insert_parse_log(doc_id, "done", "success", "入库完成")

        # 内存镜像重建（chunk_store/BM25 纳入新文档；锁内做，避免与并发查询竞争旧镜像）
        with _ingest_lock:
            _reload_memory_state()

        return {
            "status": "success", "document_id": doc_uid, "doc_id": doc_id,
            "chunks": len(chunks), "embedded": embedded,
        }
    except Exception:
        db.rollback()
        raise
    finally:
        db.close()


def _ingest_xlsx(kb_id: str, doc_uid: str, file_name: str,
                 file_bytes: bytes, meta: dict) -> dict:
    """app 推送的 xlsx 原始文件摄取：parse_xlsx → tables_structured + schema_registry（带 kb）。

    走 Text2SQL 链路，不产 chunks（检索触发靠 SQL_TABLE_TRIGGERS 关键词）。
    幂等：同 source_doc_id 已入库 → 级联删旧重建。
    """
    from ingest.pipeline import DB as IngestDB
    from ingest.parsers import parse_xlsx

    db = IngestDB()
    try:
        with db.conn.cursor() as cur:
            cur.execute("SELECT id FROM documents WHERE source_doc_id=%s", (doc_uid,))
            old = cur.fetchone()
        if old:
            logger.info(f"[ingest:xlsx] 文档 {doc_uid} 已存在(doc_id={old[0]})，删旧重建")
            with db.conn.cursor() as cur:
                # schema_registry FK 为 SET NULL 不随文档级联删,先显式清旧行
                cur.execute("DELETE FROM schema_registry WHERE document_id=%s", (old[0],))
                cur.execute("DELETE FROM documents WHERE id=%s", (old[0],))
            db.commit()

        life = _lifecycle_fields(meta)
        doc_id = db.insert_document(
            file_name=file_name, file_type="xlsx",
            file_size=len(file_bytes), file_path="",
            doc_number=meta.get("doc_number", ""), org_name=meta.get("org_name", ""),
            doc_date_str=meta.get("doc_date", ""),
            doc_title=meta.get("doc_title") or file_name,
            doc_type=meta.get("doc_type", "") or "table",
            product_name=meta.get("product_name", ""),
            source_doc_id=doc_uid, knowledge_base_id=kb_id,
            lifecycle_status=life["lifecycle_status"],
            effective_date=life["effective_date"], expiry_date=life["expiry_date"],
            superseded_by=life["superseded_by"], sensitivity=life["sensitivity"],
            department=life["department"],
            custom_metadata=meta.get("custom_metadata"),
        )
        log_id = db.insert_parse_log(doc_id, "parsing", "running")

        # 表名按文件 basename 构造(parsers.py):temp 名须保留业务文件名,
        # 否则 SQL 触发键(_table_real_name LIKE %key%)无法命中
        stem = os.path.splitext(os.path.basename(file_name))[0][:50]
        with tempfile.NamedTemporaryFile(delete=False, prefix=stem + "_", suffix=".xlsx") as tmp:
            tmp.write(file_bytes)
            tmp_path = tmp.name
        try:
            parsed = parse_xlsx(tmp_path)
        finally:
            if os.path.exists(tmp_path):
                os.unlink(tmp_path)

        if parsed.parse_error:
            logger.error(f"[ingest:xlsx] 解析失败: {parsed.parse_error}")
            db.update_document_status(doc_id, "failed", parsed.parse_error)
            db.update_parse_log(log_id, "failed", parsed.parse_error)
            return {"status": "failed", "document_id": doc_uid, "error": parsed.parse_error}

        n_tables = 0
        for table in parsed.tables:
            if table.rows:
                db.insert_table_data(doc_id, table.table_name, table.sheet_name,
                                     table.rows, knowledge_base_id=kb_id)
                db.insert_schema_registry(table.table_name, table.columns,
                                          table.rows[:5], doc_id,
                                          knowledge_base_id=kb_id)
                n_tables += 1
                logger.info(
                    f"[ingest:xlsx] 表格 {table.table_name}: "
                    f"{len(table.rows)} 行 x {len(table.columns)} 列"
                )

        if n_tables == 0:
            db.update_document_status(doc_id, "failed", "无结构化表格数据")
            db.update_parse_log(log_id, "failed", "无结构化表格数据")
            return {"status": "failed", "document_id": doc_uid, "error": "无结构化表格数据"}

        db.update_parse_log(log_id, "success", f"{n_tables} 表")
        db.update_document_status(doc_id, "success", chunk_count=0)
        db.insert_parse_log(doc_id, "done", "success", f"{n_tables} 表入库")
        return {
            "status": "success", "document_id": doc_uid, "doc_id": doc_id,
            "tables": n_tables, "chunks": 0, "embedded": 0,
        }
    except Exception:
        db.rollback()
        raise
    finally:
        db.close()


@app.route("/ingest", methods=["POST"])
def handle_ingest():
    """app 数据流推送：markdown 文本或 xlsx 原始文件（base64）+ 元数据 → 入库。

    参数（JSON）:
      knowledge_base_id: app 侧 KB UUID（必填）
      document_id:       app 侧文档 UUID（必填，幂等键，重复推送=删旧重建）
      file_name / file_type: 必填
      markdown: 文本内容（常规文档必填）
      file_bytes: xlsx 原始文件 base64（file_type=xlsx 时可选，缺则回退 markdown）
      doc_number / org_name / doc_date / doc_title / doc_type / product_name: 可选元数据
    """
    body = request.get_json(silent=True) or {}
    kb_id = (body.get("knowledge_base_id") or "").strip()
    doc_uid = (body.get("document_id") or "").strip()
    file_name = (body.get("file_name") or "").strip()
    file_type = (body.get("file_type") or "").strip().lower() or "md"
    markdown = body.get("markdown") or ""
    file_b64 = (body.get("file_bytes") or "").strip()
    if not kb_id or not doc_uid or not file_name:
        return jsonify({"error": "knowledge_base_id/document_id/file_name 必填"}), 400
    if not (markdown.strip() or (file_type == "xlsx" and file_b64)):
        return jsonify({"error": "markdown 必填（xlsx 可改传 file_bytes）"}), 400

    meta = {k: (body.get(k) or "").strip() for k in (
        "doc_number", "org_name", "doc_date", "doc_title", "doc_type", "product_name",
        "lifecycle_status", "effective_date", "expiry_date",
        "superseded_by", "sensitivity", "department",
    )}
    if isinstance(body.get("custom_metadata"), dict):
        meta["custom_metadata"] = body["custom_metadata"]

    if file_type == "xlsx" and file_b64:
        import base64
        try:
            file_bytes = base64.b64decode(file_b64)
        except Exception as e:
            return jsonify({"error": f"file_bytes base64 解码失败: {e}"}), 400
        logger.info(
            f"[ingest:xlsx] kb={kb_id} doc={doc_uid} file={file_name} "
            f"{len(file_bytes)} 字节"
        )
        try:
            result = _ingest_xlsx(kb_id, doc_uid, file_name, file_bytes, meta)
            return jsonify(result)
        except Exception as e:
            logger.error(f"[ingest:xlsx] 摄取异常 doc={doc_uid}: {e}", exc_info=True)
            return jsonify({"status": "failed", "document_id": doc_uid, "error": str(e)}), 500

    logger.info(
        f"[ingest] kb={kb_id} doc={doc_uid} file={file_name} "
        f"markdown {len(markdown)} 字符"
    )
    try:
        result = _ingest_markdown(kb_id, doc_uid, file_name, file_type, markdown, meta)
        return jsonify(result)
    except Exception as e:
        logger.error(f"[ingest] 摄取异常 doc={doc_uid}: {e}", exc_info=True)
        return jsonify({"status": "failed", "document_id": doc_uid, "error": str(e)}), 500


@app.route("/delete_document", methods=["POST"])
def handle_delete_document():
    """app 文档删除同步：按 app 侧 document_id 删（MySQL 级联 + 内存镜像重载）。

    FAISS 为 HNSW 增量索引不支持删向量，残留由检索层过滤
    （vector_id → chunk 映射已清），物理清理靠 rebuild_faiss.py。
    """
    body = request.get_json(silent=True) or {}
    doc_uid = (body.get("document_id") or "").strip()
    if not doc_uid:
        return jsonify({"error": "document_id 必填"}), 400

    from ingest.pipeline import DB as IngestDB
    db = IngestDB()
    try:
        with db.conn.cursor() as cur:
            cur.execute("SELECT id FROM documents WHERE source_doc_id=%s", (doc_uid,))
            old = cur.fetchone()
        if not old:
            return jsonify({"deleted": 0, "document_id": doc_uid})
        with db.conn.cursor() as cur:
            cur.execute("DELETE FROM documents WHERE id=%s", (old[0],))
        db.commit()
        logger.info(f"[delete] doc={doc_uid} (doc_id={old[0]}) 已删除")
    finally:
        db.close()

    with _ingest_lock:
        _reload_memory_state()
    return jsonify({"deleted": 1, "document_id": doc_uid})


@app.route("/documents/ids", methods=["GET"])
def handle_document_ids():
    """对账用(§2.2 ③)：返回全部 source_doc_id（即 app 侧 document_id 镜像）。"""
    from ingest.pipeline import DB as IngestDB
    db = IngestDB()
    try:
        with db.conn.cursor() as cur:
            cur.execute("SELECT source_doc_id FROM documents")
            ids = [row[0] for row in cur.fetchall()]
    finally:
        db.close()
    return jsonify({"ids": ids})


@app.route("/health", methods=["GET"])
def health():
    return jsonify({"status": "ok"})


def _start_keepalive():
    """防网关 serverless 冷池再冷却（冷启动 40-60s，主办方 30s 作答硬约束下首问撞冷=必超时）。

    每 KEEPALIVE_INTERVAL 秒 ping 一次仍在走网关的端点（chat 恒网关；
    embedding/rerank 仅对应开关为 gateway 时），best-effort 失败静默。
    """
    from config import (
        DEEPSEEK_URL, DEEPSEEK_API_KEY, DEEPSEEK_MODEL,
        BGE_EMBEDDING_URL, BGE_RERANKER_URL, BGE_API_KEY,
        BGE_EMBED_BACKEND, BGE_RERANK_BACKEND, KEEPALIVE_INTERVAL,
    )
    from http_client import post_json

    if KEEPALIVE_INTERVAL <= 0:
        return

    h = {"Authorization": f"Bearer {BGE_API_KEY}", "Content-Type": "application/json"}
    targets = [
        ("chat", DEEPSEEK_URL,
         {"model": DEEPSEEK_MODEL,
          "messages": [{"role": "user", "content": "只回复OK"}],
          "max_tokens": 4, "thinking": {"type": "disabled"}}),
    ]
    if BGE_EMBED_BACKEND == "gateway":
        targets.append(("embedding", BGE_EMBEDDING_URL,
                        {"model": "BAAI/bge-m3", "input": ["预热"]}))
    if BGE_RERANK_BACKEND == "gateway":
        targets.append(("rerank", BGE_RERANKER_URL,
                        {"model": "BAAI/bge-reranker-v2-m3",
                         "query": "预热", "documents": ["预热"]}))

    def loop():
        while True:
            time.sleep(KEEPALIVE_INTERVAL)
            for name, url, payload in targets:
                try:
                    post_json(url, payload, h, 10, retries=1)
                except Exception:
                    pass

    threading.Thread(target=loop, daemon=True, name="gateway-keepalive").start()
    logger.info(
        f"[keepalive] 已启动（每 {KEEPALIVE_INTERVAL}s ping "
        f"{'/'.join(t[0] for t in targets)}）"
    )


def _start_reembed_daemon():
    """定时重嵌 pending chunks（嵌入失败自愈链）：每 REEMBED_INTERVAL_MINUTES 检查，
    有 pending 则走 _build_faiss_index 增量追加 + 内存镜像重建。
    与 /ingest 共用 _ingest_lock 串行化 FAISS 写；rebuild_faiss.py 留作手动工具。
    """
    from config import REEMBED_INTERVAL_MINUTES
    from ingest.pipeline import DB as IngestDB, _build_faiss_index

    if REEMBED_INTERVAL_MINUTES <= 0:
        logger.info("REEMBED_INTERVAL_MINUTES<=0，重嵌 daemon 关闭")
        return

    def loop():
        while True:
            time.sleep(REEMBED_INTERVAL_MINUTES * 60)
            try:
                db = IngestDB()
                try:
                    with db.conn.cursor() as cur:
                        cur.execute(
                            "SELECT COUNT(*) FROM chunks "
                            "WHERE chunk_level='child' AND status='pending'"
                        )
                        pending = cur.fetchone()[0]
                    if pending == 0:
                        continue
                    logger.info(f"[reembed] 发现 {pending} 个 pending chunks，开始重嵌")
                    with _ingest_lock:
                        _build_faiss_index(db)
                        _reload_memory_state()
                finally:
                    db.close()
            except Exception as e:
                logger.error(f"[reembed] daemon 异常: {e}", exc_info=True)

    threading.Thread(target=loop, daemon=True, name="reembed-daemon").start()
    logger.info(f"重嵌 daemon 已启动（每 {REEMBED_INTERVAL_MINUTES} 分钟检查一次）")


if __name__ == "__main__":
    init_services()
    _start_keepalive()
    _start_reembed_daemon()
    # 主办方固定问答端口经 PORT 环境变量传入（.env），默认 5000
    port = int(os.getenv("PORT", "5000"))
    app.run(host="0.0.0.0", port=port, debug=False)
