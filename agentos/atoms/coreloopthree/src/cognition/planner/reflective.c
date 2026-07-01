/**
 * @file reflective.c
 * @brief 反思式规划策略 - 生产级双思考实现
 * @copyright (c) 2026 SPHARX Ltd. All Rights Reserved.
 *
 * 实现完整5阶段推理管线:
 * - Phase 0: 指令拆解(S1) -> 识别子任务
 * - Phase 1: 规划生成(S2+S1) -> 构建依赖链
 * - Phase 2: 执行-验证循环 -> 流式批判(S2生成->S1验证->纠正)
 * - Phase 3: 子任务审计 -> 质量门控
 * - Phase 4: 目标对齐检查
 */

#include "../foundation/metacognition.h"
#include "../foundation/thinking_chain.h"
#include "agentos.h"
#include "cognition.h"
#include "logging_compat.h"
#include "memory_compat.h"
#include "string_compat.h"

#include <stdio.h>
#include <stdlib.h>
#include <string.h>

/* LLM客户端接口 — BAN-35合规：使用本地副本 */
#include "llm_client.h"
#include "error.h"
#include "error_compat.h"

#define ATM_RET_ERR(c) \
    do { agentos_error_push_ex((c), __FILE__, __LINE__, __func__, "%s", agentos_error_str(c)); return (c); } while(0)


typedef struct {
    agentos_thinking_chain_t *chain;
    agentos_metacognition_t *meta;
    agentos_llm_service_t *llm;
    int initialized;
    uint64_t session_count;
    char *last_goal;
    int max_verify_rounds;
    float acceptance_threshold;
} reflective_context_t;

static agentos_error_t llm_build_dynamic_plan(reflective_context_t *, const agentos_intent_t *,
                                              agentos_task_plan_t **, int, int);
static agentos_task_plan_t *build_fallback_plan(const agentos_intent_t *, reflective_context_t *,
                                                int, int, uint64_t);

/* ============================================================================
 * 真实S2内容生成器 - 调用LLM服务
 * ============================================================================ */

static agentos_error_t real_s2_generate(const char *input, size_t in_len, char **output,
                                        size_t *out_len, void *user_data)
{
    if (!input || !output || !out_len)
        ATM_RET_ERR(AGENTOS_EINVAL);

    reflective_context_t *ctx = (reflective_context_t *)user_data;

    if (ctx && ctx->llm && agentos_llm_service_is_available(ctx->llm)) {
        char *response = NULL;
        agentos_error_t err = agentos_llm_service_call(ctx->llm, input, &response);
        if (err == AGENTOS_SUCCESS && response) {
            *output = response;
            *out_len = strlen(response);
            return AGENTOS_SUCCESS;
        }
        if (response)
            AGENTOS_FREE(response);
    }

    size_t buf_size = in_len + 256;
    char *buf = (char *)AGENTOS_MALLOC(buf_size);
    if (!buf)
        ATM_RET_ERR(AGENTOS_ENOMEM);

    int written = snprintf(buf, buf_size,
                           "[Reflective Analysis of: %.*s]\n"
                           "Task decomposition into actionable sub-components.\n"
                           "Dependency identification between sub-tasks.\n"
                           "Resource and constraint evaluation.\n"
                           "Risk assessment and mitigation planning.\n",
                           (int)(in_len > 80 ? 80 : in_len), input);

    if (written <= 0 || (size_t)written >= buf_size) {
        snprintf(buf, buf_size, "[Analysis for input %zu bytes]", in_len);
        written = (int)strlen(buf);
    }

    *output = buf;
    *out_len = (size_t)written;
    return AGENTOS_SUCCESS;
}

/* ============================================================================
 * 真实S1验证器 - 调用LLM进行质量评估
 * ============================================================================ */

static int real_s1_verify(const char *content, size_t len, float confidence, void *user_data)
{
    if (!content || len == 0)
        return 0;

    reflective_context_t *ctx = (reflective_context_t *)user_data;

    if (ctx && ctx->llm && agentos_llm_service_is_available(ctx->llm)) {
        char prompt[1024];
        snprintf(prompt, sizeof(prompt),
                 "Rate the quality of this analysis on a scale of 0.0 to 1.0.\n"
                 "Reply with only a number.\n\n%s",
                 len > 800 ? "(truncated)" : content);

        char *response = NULL;
        agentos_error_t err = agentos_llm_service_call(ctx->llm, prompt, &response);
        if (err == AGENTOS_SUCCESS && response) {
            float score = (float)atof(response);
            AGENTOS_FREE(response);
            if (score > 0.0f && score <= 1.0f) {
                return (score >= 0.7f) ? 1 : 0;
            }
        }
        if (response)
            AGENTOS_FREE(response);
    }

    float quality = 0.65f;
    if (len > 50 && strstr(content, "analysis"))
        quality += 0.1f;
    if (len > 100 && strstr(content, "decomposition"))
        quality += 0.1f;
    if (len > 150 && strstr(content, "dependency"))
        quality += 0.05f;
    if (confidence > 0.5f)
        quality += 0.05f;

    return (quality >= 0.7f) ? 1 : 0;
}

/* ============================================================================
 * 反思式规划实现
 * ============================================================================ */

static __attribute__((unused)) agentos_error_t reflective_plan_init(void **out_context)
{
    if (!out_context)
        ATM_RET_ERR(AGENTOS_EINVAL);

    reflective_context_t *ctx;
    SAFE_MALLOC_ARRAY(ctx, 1, sizeof(reflective_context_t));
    if (!ctx)
        ATM_RET_ERR(AGENTOS_ENOMEM);

    ctx->chain = NULL;
    ctx->meta = NULL;
    ctx->llm = NULL;
    ctx->initialized = 0;
    ctx->session_count = 0;
    ctx->last_goal = NULL;
    ctx->max_verify_rounds = 3;
    ctx->acceptance_threshold = 0.7f;

    *out_context = ctx;
    return AGENTOS_SUCCESS;
}

static void reflective_plan_cleanup(agentos_plan_strategy_t *strategy)
{
    if (!strategy || !strategy->data)
        return;
    reflective_context_t *ctx = (reflective_context_t *)strategy->data;
    if (ctx->chain) {
        agentos_tc_chain_stop(ctx->chain);
        agentos_tc_chain_destroy(ctx->chain);
        ctx->chain = NULL;
    }
    if (ctx->meta) {
        agentos_mc_destroy(ctx->meta);
        ctx->meta = NULL;
    }
    if (ctx->last_goal) {
        AGENTOS_FREE(ctx->last_goal);
        ctx->last_goal = NULL;
    }
    AGENTOS_FREE(ctx);
}

static agentos_error_t reflective_plan(const agentos_intent_t *intent, void *context,
                                       agentos_task_plan_t **out_plan)
{

    if (!intent || !out_plan)
        ATM_RET_ERR(AGENTOS_EINVAL);

    reflective_context_t *ctx = (reflective_context_t *)context;

    if (!ctx) {
        agentos_error_t init_err = reflective_plan_init((void **)&ctx);
        if (init_err != AGENTOS_SUCCESS)
            return init_err;
    }

    if (!ctx->initialized) {
        agentos_error_t err = agentos_tc_chain_create(
            intent->intent_goal ? (const char *)intent->intent_goal : "reflective_session", 8192,
            64, &ctx->chain);
        if (err != AGENTOS_SUCCESS)
            return err;

        err = agentos_mc_create(&ctx->meta);
        if (err != AGENTOS_SUCCESS) {
            agentos_tc_chain_destroy(ctx->chain);
            ctx->chain = NULL;
            return err;
        }

        agentos_mc_set_chain(ctx->meta, ctx->chain);
        ctx->initialized = 1;
    }

    if (ctx->last_goal)
        AGENTOS_FREE(ctx->last_goal);
    char goal_buf[512];
    int glen = snprintf(goal_buf, sizeof(goal_buf), "%s_flags%u",
                        intent->intent_goal ? (const char *)intent->intent_goal : "unknown",
                        intent->intent_flags);
    ctx->last_goal = AGENTOS_STRDUP(goal_buf);

    agentos_tc_chain_start(ctx->chain);
    ctx->session_count++;

    /* ========== Phase 0: Instruction Decomposition (S1) ========== */
    agentos_thinking_step_t *step_decomp = NULL;
    char decomp_input[512];
    int di_len = snprintf(decomp_input, sizeof(decomp_input),
                          "Decompose this task into sub-tasks with clear dependencies:\n"
                          "Goal: %s\nFlags: %u\nContext: %s\n"
                          "Provide a structured breakdown with numbered steps.",
                          intent->intent_goal ? (const char *)intent->intent_goal : "?",
                          intent->intent_flags,
                          intent->intent_raw_text ? (const char *)intent->intent_raw_text : "");

    agentos_tc_step_create(ctx->chain, TC_STEP_DECOMPOSITION, decomp_input, (size_t)di_len, NULL, 0,
                           &step_decomp);

    char *decomp_output = NULL;
    size_t decomp_out_len = 0;
    real_s2_generate(decomp_input, (size_t)di_len, &decomp_output, &decomp_out_len, ctx);

    if (decomp_output && decomp_out_len > 0) {
        agentos_tc_context_window_append(ctx->chain->ctx_window, decomp_output, decomp_out_len);
    }
    agentos_tc_step_complete(step_decomp, decomp_output ? decomp_output : "decomposition_failed",
                             decomp_output ? decomp_out_len : 19, 0.75f, "S2-decomposer");

    mc_evaluation_result_t eval_decomp;
    char *recent_ctx = NULL;
    size_t recent_ctx_len = 0;
    agentos_tc_context_window_get_recent(ctx->chain->ctx_window, 200, &recent_ctx, &recent_ctx_len);
    agentos_mc_evaluate_step(ctx->meta, step_decomp, recent_ctx, recent_ctx_len, &eval_decomp);
    if (recent_ctx)
        AGENTOS_FREE(recent_ctx);

    if (eval_decomp.strategy == MC_CORRECT_AUTO || eval_decomp.strategy == MC_CORRECT_RERUN) {
        agentos_mc_apply_correction(ctx->meta, step_decomp, &eval_decomp, real_s2_generate, ctx);
    }
    if (eval_decomp.critique_text)
        AGENTOS_FREE(eval_decomp.critique_text);
    if (decomp_output)
        AGENTOS_FREE(decomp_output);

    /* ========== Phase 1: Planning (S2+S1) ========== */
    agentos_thinking_step_t *step_plan = NULL;
    uint32_t deps[] = {step_decomp->step_id};
    char plan_input[512];
    int pi_len = snprintf(plan_input, sizeof(plan_input),
                          "Generate a detailed execution plan based on the decomposition above.\n"
                          "Goal: %s\nInclude: step IDs, dependencies, and verification criteria.",
                          intent->intent_goal ? (const char *)intent->intent_goal : "?");

    agentos_tc_step_create(ctx->chain, TC_STEP_PLANNING, plan_input, (size_t)pi_len, deps, 1,
                           &step_plan);

    char *plan_output = NULL;
    size_t plan_out_len = 0;
    real_s2_generate(plan_input, (size_t)pi_len, &plan_output, &plan_out_len, ctx);

    if (plan_output && plan_out_len > 0) {
        agentos_tc_context_window_append(ctx->chain->ctx_window, plan_output, plan_out_len);
    }
    agentos_tc_step_complete(step_plan, plan_output ? plan_output : "planning_failed",
                             plan_output ? plan_out_len : 15, 0.70f, "S2-planner");

    mc_evaluation_result_t eval_plan;
    agentos_tc_context_window_get_recent(ctx->chain->ctx_window, 300, &recent_ctx, &recent_ctx_len);
    agentos_mc_evaluate_step(ctx->meta, step_plan, recent_ctx, recent_ctx_len, &eval_plan);
    if (recent_ctx)
        AGENTOS_FREE(recent_ctx);

    if (eval_plan.strategy == MC_CORRECT_AUTO || eval_plan.strategy == MC_CORRECT_RERUN) {
        agentos_mc_apply_correction(ctx->meta, step_plan, &eval_plan, real_s2_generate, ctx);
    }
    if (eval_plan.critique_text)
        AGENTOS_FREE(eval_plan.critique_text);
    if (plan_output)
        AGENTOS_FREE(plan_output);

    /* ========== Phase 2: Execution-Verification Loop ========== */
    agentos_thinking_step_t *step_exec = NULL;
    uint32_t exec_deps[] = {step_plan->step_id};
    agentos_tc_step_create(ctx->chain, TC_STEP_GENERATION, plan_input, (size_t)pi_len, exec_deps, 1,
                           &step_exec);

    char *exec_output = NULL;
    size_t exec_out_len = 0;
    int verified = 0;

    for (int round = 0; round < ctx->max_verify_rounds && !verified; round++) {
        if (exec_output) {
            AGENTOS_FREE(exec_output);
            exec_output = NULL;
        }
        exec_out_len = 0;

        real_s2_generate(plan_input, (size_t)pi_len, &exec_output, &exec_out_len, ctx);

        if (!exec_output || exec_out_len == 0)
            break;

        verified = real_s1_verify(exec_output, exec_out_len, 0.7f, ctx);

        if (!verified && round < ctx->max_verify_rounds - 1) {
            char correction_prompt[1024];
            snprintf(correction_prompt, sizeof(correction_prompt),
                     "The previous output did not pass quality verification.\n"
                     "Please improve and regenerate:\n%s",
                     exec_out_len > 500 ? "(content too long, regenerating)" : exec_output);

            AGENTOS_FREE(exec_output);
            exec_output = NULL;

            real_s2_generate(correction_prompt, strlen(correction_prompt), &exec_output,
                             &exec_out_len, ctx);
        }
    }

    if (exec_output && exec_out_len > 0) {
        agentos_tc_context_window_append(ctx->chain->ctx_window, exec_output, exec_out_len);
    }
    agentos_tc_step_complete(step_exec, exec_output ? exec_output : "execution_failed",
                             exec_output ? exec_out_len : 16, verified ? 0.85f : 0.5f,
                             verified ? "S2-executor" : "S2-executor-unverified");

    /* DS-008: 监控执行步骤，异常时尝试恢复 */
    tc_monitor_result_t mon_result;
    agentos_tc_step_monitor(step_exec, NULL, &mon_result);
    if (mon_result.anomaly != TC_ANOMALY_NONE && mon_result.is_critical) {
        tc_recovery_result_t rec_result;
        agentos_tc_step_recover(ctx->chain, step_exec, &mon_result, real_s2_generate, ctx,
                                &rec_result);
        if (rec_result.recovery_log)
            AGENTOS_FREE(rec_result.recovery_log);
    }
    if (mon_result.description)
        AGENTOS_FREE(mon_result.description);

    if (exec_output)
        AGENTOS_FREE(exec_output);

    /* ========== Phase 3: Subtask Audit (S1 quality gate) ========== */
    agentos_thinking_step_t *step_audit = NULL;
    uint32_t audit_deps[] = {step_exec->step_id};
    agentos_tc_step_create(ctx->chain, TC_STEP_AUDIT, goal_buf, (size_t)glen, audit_deps, 1,
                           &step_audit);

    mc_evaluation_result_t eval_audit;
    agentos_tc_context_window_get_recent(ctx->chain->ctx_window, 400, &recent_ctx, &recent_ctx_len);
    agentos_mc_evaluate_step(ctx->meta, step_exec, recent_ctx, recent_ctx_len, &eval_audit);
    if (recent_ctx)
        AGENTOS_FREE(recent_ctx);

    int audit_passed = eval_audit.is_acceptable;
    char audit_result[256];
    int ar_len = snprintf(
        audit_result, sizeof(audit_result), "Audit %s: overall_score=%.2f corrections=%d",
        audit_passed ? "PASSED" : "FAILED", eval_audit.overall_score, step_exec->correction_count);

    agentos_tc_step_complete(step_audit, audit_result, (size_t)ar_len, eval_audit.overall_score,
                             "S1-auditor");

    if (eval_audit.critique_text)
        AGENTOS_FREE(eval_audit.critique_text);

    /* ========== Phase 4: Goal Alignment Check ========== */
    agentos_thinking_step_t *step_align = NULL;
    uint32_t align_deps[] = {step_audit->step_id};
    agentos_tc_step_create(ctx->chain, TC_STEP_ALIGNMENT, goal_buf, (size_t)glen, align_deps, 1,
                           &step_align);

    mc_evaluation_result_t eval_align;
    agentos_mc_evaluate_step(ctx->meta, step_align, intent->intent_goal, intent->intent_goal_len,
                             &eval_align);

    int aligned = eval_align.is_acceptable;
    agentos_tc_step_complete(step_align, aligned ? "goal_aligned" : "goal_drift_detected",
                             aligned ? 12 : 18, eval_align.overall_score, "S1-alignment");

    if (eval_align.critique_text)
        AGENTOS_FREE(eval_align.critique_text);

    /* DS-005: 学习模式检测 + 自适应阈值 */
    agentos_mc_detect_patterns(ctx->meta, NULL, NULL);
    agentos_mc_adapt_threshold(ctx->meta);

    /* ========== Build Output Plan (LLM Dynamic Planning) ========== */
    agentos_task_plan_t *plan = NULL;
    agentos_error_t plan_err = llm_build_dynamic_plan(ctx, intent, &plan, audit_passed, aligned);
    if (plan_err != AGENTOS_SUCCESS || !plan) {
        plan = build_fallback_plan(intent, ctx, audit_passed, aligned, ctx->session_count);
    }

    if (!plan)
        ATM_RET_ERR(AGENTOS_ENOMEM);
    return AGENTOS_SUCCESS;
}

/* ============================================================================
 * P2-B04: LLM 动态规划 - 调用LLM生成结构化任务计划
 * ============================================================================ */

typedef struct {
    char name[64];
    char role[64];
    int timeout_ms;
    int priority;
    int depends_on_count;
    char depends_on[4][64];
} llm_plan_node_t;

static agentos_error_t parse_llm_plan_json(const char *json_text, llm_plan_node_t *nodes,
                                           size_t *node_count, size_t max_nodes)
{

    *node_count = 0;
    if (!json_text || !nodes)
        ATM_RET_ERR(AGENTOS_EINVAL);

    const char *p = json_text;

    while (*p && *node_count < max_nodes) {
        const char *name_start = strstr(p, "\"name\"");
        if (!name_start)
            break;
        const char *name_val = strchr(name_start + 6, ':');
        if (!name_val)
            break;
        while (*name_val && (*name_val == ' ' || *name_val == '\t' || *name_val == '"'))
            name_val++;
        const char *name_end = name_val;
        while (*name_end && *name_end != '"' && *name_end != ',' && *name_end != '}')
            name_end++;

        const char *role_start = strstr(name_end, "\"role\"");
        const char *role_val = role_start ? strchr(role_start + 5, ':') : NULL;
        if (role_val) {
            while (*role_val && (*role_val == ' ' || *role_val == '\t' || *role_val == '"'))
                role_val++;
        }

        llm_plan_node_t *node = &nodes[*node_count];
        __builtin_memset(node, 0, sizeof(*node));
        size_t nlen = (size_t)(name_end - name_val);
        if (nlen >= sizeof(node->name))
            nlen = sizeof(node->name) - 1;
        AGENTOS_MEMCPY_SAFE(node->name, name_val, nlen, sizeof(node->name));

        if (role_val) {
            const char *role_end = role_val;
            while (*role_end && *role_end != '"' && *role_end != ',' && *role_end != '}')
                role_end++;
            size_t rlen = (size_t)(role_end - role_val);
            if (rlen >= sizeof(node->role))
                rlen = sizeof(node->role) - 1;
            AGENTOS_MEMCPY_SAFE(node->role, role_val, rlen, sizeof(node->role));
        } else {
            snprintf(node->role, sizeof(node->role), "worker");
        }
        node->timeout_ms = 30000;
        node->priority = 200 - (int)(*node_count) * 20;

        const char *deps_start = strstr(name_end, "\"depends\"");
        if (deps_start) {
            const char *dep_arr = strchr(deps_start + 8, '[');
            if (dep_arr) {
                const char *dep = dep_arr + 1;
                while (*dep && *dep != ']' && node->depends_on_count < 4) {
                    while (*dep && (*dep == ' ' || *dep == '"' || *dep == '\t'))
                        dep++;
                    const char *de = dep;
                    while (*de && *de != '"' && *de != ',' && *de != ']')
                        de++;
                    size_t dlen = (size_t)(de - dep);
                    if (dlen > 0 && dlen < sizeof(node->depends_on[0])) {
                        AGENTOS_MEMCPY_SAFE(node->depends_on[node->depends_on_count], dep, dlen, sizeof(node->depends_on[0]));
                        node->depends_on_count++;
                    }
                    dep = de;
                    if (*dep == ',')
                        dep++;
                }
            }
        }

        (*node_count)++;
        p = name_end;
    }

    return (*node_count > 0) ? AGENTOS_SUCCESS : AGENTOS_EINVAL;
}

static void reflective_destroy_single_node(agentos_task_node_t *node)
{
    if (!node)
        return;
    AGENTOS_FREE(node->task_node_id);
    AGENTOS_FREE(node->task_node_agent_role);
    if (node->task_node_depends_on) {
        for (size_t d = 0; d < node->task_node_depends_count; d++)
            AGENTOS_FREE(node->task_node_depends_on[d]);
        AGENTOS_FREE(node->task_node_depends_on);
    }
    AGENTOS_FREE(node);
}

static agentos_error_t llm_build_dynamic_plan(reflective_context_t *ctx,
                                              const agentos_intent_t *intent,
                                              agentos_task_plan_t **out_plan, int audit_passed,
                                              int aligned)
{

    if (!ctx || !intent || !out_plan)
        ATM_RET_ERR(AGENTOS_EINVAL);

    if (!ctx->llm || !agentos_llm_service_is_available(ctx->llm)) {
        ATM_RET_ERR(AGENTOS_ESERVICE);
    }

    char prompt[2048];
    int plen = snprintf(
        prompt, sizeof(prompt),
        "You are a task planning AI. Analyze this goal and create a structured execution plan.\n\n"
        "Goal: %s\n"
        "Flags: %u\n"
        "Audit Status: %s\n"
        "Alignment Status: %s\n\n"
        "Return ONLY valid JSON array of subtasks:\n"
        "[{\"name\":\"task_name\",\"role\":\"agent_role\","
        "\"depends\":[\"prev_task_id\"]}, ...]\n\n"
        "Rules:\n"
        "- Each task must have a unique name and role\n"
        "- Dependencies reference previous task names\n"
        "- Include: analysis, planning, execution, verification steps\n"
        "- If audit failed, add a correction step\n"
        "- If alignment failed, add a realignment step",
        intent->intent_goal ? (const char *)intent->intent_goal : "(none)", intent->intent_flags,
        audit_passed ? "passed" : "FAILED", aligned ? "aligned" : "DRIFTED");

    if (plen <= 0 || (size_t)plen >= sizeof(prompt))
        ATM_RET_ERR(AGENTOS_EUNKNOWN);

    char *response = NULL;
    agentos_error_t err = agentos_llm_service_call(ctx->llm, prompt, &response);
    if (err != AGENTOS_SUCCESS || !response) {
        if (response)
            AGENTOS_FREE(response);
        return err ? err : AGENTOS_EUNKNOWN;
    }

    llm_plan_node_t parsed_nodes[16];
    size_t parsed_count = 0;
    err = parse_llm_plan_json(response, parsed_nodes, &parsed_count, 16);
    AGENTOS_FREE(response);

    if (err != AGENTOS_SUCCESS || parsed_count == 0) {
        return err;
    }

    agentos_task_plan_t *plan;
    SAFE_MALLOC_ARRAY(plan, 1, sizeof(agentos_task_plan_t));
    if (!plan) {
        AGENTOS_LOG_ERROR("reflective: plan allocation failed");
        ATM_RET_ERR(AGENTOS_ENOMEM);
    }

    char plan_id[128];
    snprintf(plan_id, sizeof(plan_id), "llm_dynamic_%zu", ctx->session_count);
    plan->task_plan_id = AGENTOS_STRDUP(plan_id);
    if (!plan->task_plan_id) {
        AGENTOS_LOG_ERROR("reflective: plan id allocation failed");
        AGENTOS_FREE(plan);
        ATM_RET_ERR(AGENTOS_ENOMEM);
    }

    size_t total = parsed_count;
    if (!audit_passed)
        total++;
    if (!aligned)
        total++;

    SAFE_MALLOC_ARRAY(plan->task_plan_nodes, total, sizeof(agentos_task_node_t *));
    if (!plan->task_plan_nodes && total > 0) {
        AGENTOS_LOG_ERROR("reflective: task_plan_nodes allocation failed (count=%zu)", total);
        AGENTOS_FREE(plan->task_plan_id);
        AGENTOS_FREE(plan);
        ATM_RET_ERR(AGENTOS_ENOMEM);
    }

    for (size_t i = 0; i < parsed_count; i++) {
        agentos_task_node_t *node;
        SAFE_MALLOC_ARRAY(node, 1, sizeof(agentos_task_node_t));
        if (!node) {
            AGENTOS_LOG_WARN("reflective: node allocation failed at step %zu, skipping", i);
            continue;
        }

        char nid[256];
        snprintf(nid, sizeof(nid), "%s_%s", plan_id,
                 parsed_nodes[i].name[0] ? parsed_nodes[i].name : "task");

        node->task_node_id = AGENTOS_STRDUP(nid);
        if (!node->task_node_id) {
            AGENTOS_LOG_WARN("reflective: node id STRDUP failed at step %zu, skipping", i);
            reflective_destroy_single_node(node);
            continue;
        }
        node->task_node_agent_role =
            AGENTOS_STRDUP(parsed_nodes[i].role[0] ? parsed_nodes[i].role : "worker");
        if (!node->task_node_agent_role) {
            AGENTOS_LOG_WARN("reflective: node role STRDUP failed at step %zu, skipping", i);
            reflective_destroy_single_node(node);
            continue;
        }
        node->task_node_timeout_ms =
            parsed_nodes[i].timeout_ms > 0 ? parsed_nodes[i].timeout_ms : 30000;
        node->task_node_priority =
            parsed_nodes[i].priority > 0 ? parsed_nodes[i].priority : (int)(200 - i * 15);

        if (parsed_nodes[i].depends_on_count > 0) {
            SAFE_MALLOC_ARRAY(node->task_node_depends_on, parsed_nodes[i].depends_on_count, sizeof(char *));
            if (node->task_node_depends_on) {
                node->task_node_depends_count = (uint32_t)parsed_nodes[i].depends_on_count;
                for (int d = 0; d < parsed_nodes[i].depends_on_count; d++) {
                    char dep_id[256];
                    snprintf(dep_id, sizeof(dep_id), "%s_%s", plan_id,
                             parsed_nodes[i].depends_on[d]);
                    node->task_node_depends_on[d] = AGENTOS_STRDUP(dep_id);
                    if (!node->task_node_depends_on[d]) {
                        /* SEC-09: STRDUP 失败时清理已分配的所有依赖项 */
                        for (int e = 0; e < d; e++)
                            AGENTOS_FREE(node->task_node_depends_on[e]);
                        AGENTOS_FREE(node->task_node_depends_on);
                        node->task_node_depends_on = NULL;
                        node->task_node_depends_count = 0;
                        break;
                    }
                }
            }
        }

        plan->task_plan_nodes[plan->task_plan_node_count++] = node;
    }

    if (!audit_passed) {
        agentos_task_node_t *cn;
        SAFE_MALLOC_ARRAY(cn, 1, sizeof(agentos_task_node_t));
        if (cn) {
            char cid[256];
            snprintf(cid, sizeof(cid), "%s_correction", plan_id);
            cn->task_node_id = AGENTOS_STRDUP(cid);
            cn->task_node_agent_role = AGENTOS_STRDUP("corrector");
            cn->task_node_timeout_ms = 20000;
            cn->task_node_priority = 250;
            if (plan->task_plan_node_count > 2) {
                SAFE_MALLOC_ARRAY(cn->task_node_depends_on, 1, sizeof(char *));
                if (cn->task_node_depends_on) {
                    cn->task_node_depends_count = 1;
                    cn->task_node_depends_on[0] = AGENTOS_STRDUP(
                        plan->task_plan_nodes[plan->task_plan_node_count - 1]->task_node_id);
                    if (!cn->task_node_depends_on[0]) {
                        /* SEC-09: STRDUP 失败时清理已分配资源 */
                        AGENTOS_FREE(cn->task_node_depends_on);
                        cn->task_node_depends_on = NULL;
                        cn->task_node_depends_count = 0;
                    }
                }
            }
            plan->task_plan_nodes[plan->task_plan_node_count++] = cn;
        }
    }

    if (!aligned) {
        agentos_task_node_t *rn;
        SAFE_MALLOC_ARRAY(rn, 1, sizeof(agentos_task_node_t));
        if (rn) {
            char rid[256];
            snprintf(rid, sizeof(rid), "%s_realignment", plan_id);
            rn->task_node_id = AGENTOS_STRDUP(rid);
            rn->task_node_agent_role = AGENTOS_STRDUP("realigner");
            rn->task_node_timeout_ms = 15000;
            rn->task_node_priority = 254;
            if (plan->task_plan_node_count > 2) {
                SAFE_MALLOC_ARRAY(rn->task_node_depends_on, 1, sizeof(char *));
                if (rn->task_node_depends_on) {
                    rn->task_node_depends_count = 1;
                    rn->task_node_depends_on[0] = AGENTOS_STRDUP(
                        plan->task_plan_nodes[plan->task_plan_node_count - 1]->task_node_id);
                    if (!rn->task_node_depends_on[0]) {
                        AGENTOS_FREE(rn->task_node_depends_on);
                        rn->task_node_depends_on = NULL;
                        rn->task_node_depends_count = 0;
                    }
                }
            }
            plan->task_plan_nodes[plan->task_plan_node_count++] = rn;
        }
    }

    SAFE_MALLOC_ARRAY(plan->task_plan_entry_points, 1, sizeof(char *));
    if (plan->task_plan_entry_points && plan->task_plan_node_count > 0) {
        plan->task_plan_entry_count = 1;
        plan->task_plan_entry_points[0] = AGENTOS_STRDUP(plan->task_plan_nodes[0]->task_node_id);
    }

    agentos_tc_chain_stop(ctx->chain);
    *out_plan = plan;
    return AGENTOS_SUCCESS;
}

static agentos_task_plan_t *build_fallback_plan(const agentos_intent_t *intent,
                                                reflective_context_t *ctx, int audit_passed,
                                                int aligned, uint64_t session_count)
{

    agentos_task_plan_t *plan;
    SAFE_MALLOC_ARRAY(plan, 1, sizeof(agentos_task_plan_t));
    if (!plan) return NULL;

    char plan_id[128];
    snprintf(plan_id, sizeof(plan_id), "fallback_%zu", session_count);
    plan->task_plan_id = AGENTOS_STRDUP(plan_id);
    if (!plan->task_plan_id) {
        AGENTOS_LOG_ERROR("reflective: fallback plan id allocation failed");
        AGENTOS_FREE(plan);
        return NULL;
    }

    size_t nc = 5 + (audit_passed ? 0 : 1) + (aligned ? 0 : 1);
    SAFE_MALLOC_ARRAY(plan->task_plan_nodes, nc, sizeof(agentos_task_node_t *));
    if (!plan->task_plan_nodes) {
        AGENTOS_FREE(plan->task_plan_id);
        AGENTOS_FREE(plan);
        AGENTOS_ERROR_NULL(AGENTOS_ERR_INVALID_PARAM, "null parameter");
    }

    static const struct {
        const char *name;
        const char *role;
        int to;
        int pri;
    } defaults[] = {{"decompose", "analyzer", 20000, 200},
                    {"plan", "planner", 30000, 180},
                    {"execute", "executor", 45000, 160},
                    {"audit", "auditor", 15000, 240},
                    {"align", "validator", 10000, 255}};

    for (int s = 0; s < 5; s++) {
        agentos_task_node_t *node;
        SAFE_MALLOC_ARRAY(node, 1, sizeof(agentos_task_node_t));
        if (!node) {
            AGENTOS_LOG_WARN("reflective: fallback node allocation failed at step %d", s);
            break;
        }

        char nid[256];
        snprintf(nid, sizeof(nid), "%s_%s", plan_id, defaults[s].name);
        node->task_node_id = AGENTOS_STRDUP(nid);
        if (!node->task_node_id) {
            AGENTOS_LOG_WARN("reflective: fallback node id STRDUP failed at step %d", s);
            AGENTOS_FREE(node);
            break;
        }
        node->task_node_agent_role = AGENTOS_STRDUP(defaults[s].role);
        if (!node->task_node_agent_role) {
            AGENTOS_LOG_WARN("reflective: fallback node role STRDUP failed at step %d", s);
            AGENTOS_FREE(node->task_node_id);
            AGENTOS_FREE(node);
            break;
        }
        node->task_node_timeout_ms = defaults[s].to;
        node->task_node_priority = defaults[s].pri;

        if (s > 0) {
            SAFE_MALLOC_ARRAY(node->task_node_depends_on, 1, sizeof(char *));
            if (node->task_node_depends_on) {
                node->task_node_depends_count = 1;
                node->task_node_depends_on[0] =
                    AGENTOS_STRDUP(plan->task_plan_nodes[s - 1]->task_node_id);
            }
        }
        plan->task_plan_nodes[plan->task_plan_node_count++] = node;
    }

    if (!audit_passed) {
        agentos_task_node_t *cn;
        SAFE_MALLOC_ARRAY(cn, 1, sizeof(agentos_task_node_t));
        if (cn) {
            char cid[256];
            snprintf(cid, sizeof(cid), "%s_reaudit", plan_id);
            cn->task_node_id = AGENTOS_STRDUP(cid);
            cn->task_node_agent_role = AGENTOS_STRDUP("corrector");
            cn->task_node_timeout_ms = 20000;
            cn->task_node_priority = 250;
            SAFE_MALLOC_ARRAY(cn->task_node_depends_on, 1, sizeof(char *));
            if (cn->task_node_depends_on && plan->task_plan_node_count > 0) {
                cn->task_node_depends_count = 1;
                cn->task_node_depends_on[0] = AGENTOS_STRDUP(
                    plan->task_plan_nodes[plan->task_plan_node_count - 1]->task_node_id);
            }
            plan->task_plan_nodes[plan->task_plan_node_count++] = cn;
        }
    }

    if (!aligned) {
        agentos_task_node_t *rn;
        SAFE_MALLOC_ARRAY(rn, 1, sizeof(agentos_task_node_t));
        if (rn) {
            char rid[256];
            snprintf(rid, sizeof(rid), "%s_realign", plan_id);
            rn->task_node_id = AGENTOS_STRDUP(rid);
            rn->task_node_agent_role = AGENTOS_STRDUP("realigner");
            rn->task_node_timeout_ms = 15000;
            rn->task_node_priority = 254;
            SAFE_MALLOC_ARRAY(rn->task_node_depends_on, 1, sizeof(char *));
            if (rn->task_node_depends_on && plan->task_plan_node_count > 0) {
                rn->task_node_depends_count = 1;
                rn->task_node_depends_on[0] = AGENTOS_STRDUP(
                    plan->task_plan_nodes[plan->task_plan_node_count - 1]->task_node_id);
            }
            plan->task_plan_nodes[plan->task_plan_node_count++] = rn;
        }
    }

    SAFE_MALLOC_ARRAY(plan->task_plan_entry_points, 1, sizeof(char *));
    if (plan->task_plan_entry_points && plan->task_plan_node_count > 0) {
        plan->task_plan_entry_count = 1;
        plan->task_plan_entry_points[0] = AGENTOS_STRDUP(plan->task_plan_nodes[0]->task_node_id);
    }

    if (ctx && ctx->chain)
        agentos_tc_chain_stop(ctx->chain);
    return plan;
}

const agentos_plan_strategy_t g_reflective_strategy = {
    .plan = reflective_plan, .destroy = reflective_plan_cleanup, .data = NULL};
