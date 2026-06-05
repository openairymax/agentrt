#include "memory_compat.h"
#include "error.h"
/**
 * @file ml_based.c
 * @brief 基于机器学习的调度策略实现（生产级）
 * @details 使用加权特征融合模型进行Agent选择预测，包含完整的特征工程和评分函数
 * @copyright (c) 2026 SPHARX. All Rights Reserved.
 */

#include "../../include/scheduler_service.h"
#include "../include/strategy_interface.h"
#include "platform.h"

#include <math.h>
#include <stdbool.h>
#include <stdio.h>
#include <stdlib.h>
#include <string.h>
#include <svc_logger.h>

#define ML_MODEL_VERSION 2
#define FEATURE_COUNT 5
#define HISTORY_WINDOW 64

typedef struct {
    float success_rate_weight;
    float load_factor_weight;
    float latency_weight;
    float recency_weight;
    float weight_priority_weight;
} ml_feature_weights_t;

typedef struct {
    uint64_t task_id;
    time_t timestamp;
    char *agent_id;
    float predicted_score;
    float actual_score;
    uint32_t response_time_ms;
    int success;
} ml_history_entry_t;

typedef struct {
    agent_info_t **agents;
    size_t agent_count;
    size_t max_agents;
    char *model_path;
    void *model;
    bool model_loaded;

    ml_feature_weights_t weights;
    ml_history_entry_t history[HISTORY_WINDOW];
    size_t history_count;
    size_t history_head;
    uint64_t total_predictions;
    uint64_t correct_predictions;
    float mae;
} ml_based_data_t;

static void init_default_weights(ml_feature_weights_t *w)
{
    w->success_rate_weight = 0.35f;
    w->load_factor_weight = 0.25f;
    w->latency_weight = 0.20f;
    w->recency_weight = 0.10f;
    w->weight_priority_weight = 0.10f;
}

static float normalize_load_factor(float lf)
{
    return fminf(fmaxf(lf, 0.0f), 1.0f);
}

static float normalize_latency(float latency_ms)
{
    float normalized = latency_ms / 10000.0f;
    return fminf(fmaxf(normalized, 0.0f), 1.0f);
}

static float normalize_recency(size_t index, size_t total)
{
    if (total == 0)
        return 0.5f;
    return (float)(total - index) / (float)total;
}

static float predict_score(const ml_based_data_t *mld, const agent_info_t *agent,
                           size_t agent_index)
{
    if (!agent || !mld)
        return 0.0f;

    const ml_feature_weights_t *w = &mld->weights;
    float score = 0.0f;

    score += w->success_rate_weight * agent->success_rate;
    score += w->load_factor_weight * (1.0f - normalize_load_factor(agent->load_factor));
    score += w->latency_weight * (1.0f - normalize_latency(agent->avg_response_time_ms));
    score += w->recency_weight * normalize_recency(agent_index, mld->agent_count);
    score += w->weight_priority_weight * fminf(agent->weight / 10.0f, 1.0f);

    float confidence_boost =
        (mld->total_predictions > 10)
            ? fminf((float)mld->correct_predictions / (float)mld->total_predictions, 1.0f)
            : 0.5f;
    score *= (0.8f + 0.2f * confidence_boost);

    return score;
}

static void record_prediction(ml_based_data_t *mld, const char *agent_id, float pred_score,
                              uint32_t resp_time_ms, int success)
{
    if (!mld || !agent_id)
        return;

    size_t idx = mld->history_count % HISTORY_WINDOW;
    ml_history_entry_t *entry = &mld->history[idx];

    AGENTOS_FREE(entry->agent_id);
    entry->task_id = mld->total_predictions + 1;
    mld->total_predictions++;
    entry->timestamp = (time_t)(agentos_time_ms() / 1000ULL);
    entry->agent_id = AGENTOS_STRDUP(agent_id);
    entry->predicted_score = pred_score;
    entry->actual_score = success ? 1.0f : 0.0f;
    entry->response_time_ms = resp_time_ms;
    entry->success = success;

    if (success)
        mld->correct_predictions++;

    if (mld->history_count > 0) {
        float error = fabsf(pred_score - entry->actual_score);
        mld->mae = (mld->mae * (float)(mld->history_count - 1) + error) / (float)mld->history_count;
    }
    mld->history_count++;
    mld->history_head = idx + 1;
}

static int ml_based_create(const sched_config_t *manager, void **data)
{
    if (!manager || !data)
        return AGENTOS_ERR_INVALID_PARAM;

    ml_based_data_t *mld = (ml_based_data_t *)AGENTOS_CALLOC(1, sizeof(ml_based_data_t));
    if (!mld)
        return AGENTOS_ERR_OUT_OF_MEMORY;

    mld->max_agents = manager->max_agents > 0 ? manager->max_agents : 128;
    mld->agents = (agent_info_t **)AGENTOS_CALLOC(mld->max_agents, sizeof(agent_info_t *));
    if (!mld->agents) {
        AGENTOS_FREE(mld);
        return AGENTOS_ERR_OUT_OF_MEMORY;
    }

    mld->agent_count = 0;
    mld->model_path = manager->ml_model_path ? AGENTOS_STRDUP(manager->ml_model_path) : NULL;
    mld->model_loaded = false;
    mld->total_predictions = 0;
    mld->correct_predictions = 0;
    mld->mae = 0.0f;
    mld->history_count = 0;
    mld->history_head = 0;
    AGENTOS_MEMSET(mld->history, 0, sizeof(mld->history));

    init_default_weights(&mld->weights);

    if (mld->model_path) {
        FILE *model_file = fopen(mld->model_path, "rb");
        if (model_file) {
            typedef struct {
                uint32_t magic;
                uint32_t version;
                uint32_t feature_count;
                ml_feature_weights_t trained_weights;
                uint64_t training_samples;
                float training_mae;
                char reserved[256];
            } ml_model_header_t;

            ml_model_header_t file_header;
            size_t bytes_read = fread(&file_header, sizeof(ml_model_header_t), 1, model_file);
            fclose(model_file);

            mld->model = AGENTOS_CALLOC(1, sizeof(ml_model_header_t));
            if (mld->model) {
                ml_model_header_t *header = (ml_model_header_t *)mld->model;
                if (bytes_read == 1 && file_header.magic == 0x4D4C4F53 &&
                    file_header.version == ML_MODEL_VERSION &&
                    file_header.feature_count == FEATURE_COUNT) {
                    header->magic = file_header.magic;
                    header->version = file_header.version;
                    header->feature_count = file_header.feature_count;
                    header->trained_weights = file_header.trained_weights;
                    header->training_samples = file_header.training_samples;
                    header->training_mae = file_header.training_mae;
                    mld->weights = file_header.trained_weights;
                    mld->model_loaded = true;
                    SVC_LOG_INFO("ML model loaded from %s (samples=%llu, mae=%.4f)",
                                 mld->model_path, (unsigned long long)file_header.training_samples,
                                 file_header.training_mae);
                } else {
                    header->magic = 0x4D4C4F53;
                    header->version = ML_MODEL_VERSION;
                    header->feature_count = FEATURE_COUNT;
                    header->trained_weights = mld->weights;
                    header->training_samples = 0;
                    header->training_mae = 0.0f;
                    mld->model_loaded = false;
                    SVC_LOG_WARN(
                        "ML model file %s has incompatible format, using default heuristic weights",
                        mld->model_path);
                }
            }
        } else {
            SVC_LOG_INFO("ML model file not found: %s, using default heuristic weights",
                         mld->model_path);
        }
    }

    *data = mld;
    return 0;
}

static int ml_based_destroy(void *data)
{
    if (!data)
        return 0;

    ml_based_data_t *mld = (ml_based_data_t *)data;

    for (size_t i = 0; i < mld->agent_count; i++) {
        if (mld->agents[i]) {
            AGENTOS_FREE(mld->agents[i]->agent_id);
            AGENTOS_FREE(mld->agents[i]->agent_name);
            AGENTOS_FREE(mld->agents[i]);
        }
    }
    AGENTOS_FREE(mld->agents);

    for (size_t i = 0; i < HISTORY_WINDOW; i++) {
        AGENTOS_FREE(mld->history[i].agent_id);
    }

    AGENTOS_FREE(mld->model_path);
    AGENTOS_FREE(mld->model);
    AGENTOS_FREE(mld);
    return 0;
}

static int ml_based_register_agent(void *data, const agent_info_t *agent_info)
{
    if (!data || !agent_info)
        return AGENTOS_ERR_INVALID_PARAM;

    ml_based_data_t *mld = (ml_based_data_t *)data;

    if (mld->agent_count >= mld->max_agents)
        return AGENTOS_ERR_OVERFLOW;

    for (size_t i = 0; i < mld->agent_count; i++) {
        if (strcmp(mld->agents[i]->agent_id, agent_info->agent_id) == 0) {
            AGENTOS_FREE(mld->agents[i]->agent_id);
            AGENTOS_FREE(mld->agents[i]->agent_name);
            mld->agents[i]->agent_id = AGENTOS_STRDUP(agent_info->agent_id);
            mld->agents[i]->agent_name = AGENTOS_STRDUP(agent_info->agent_name);
            mld->agents[i]->load_factor = agent_info->load_factor;
            mld->agents[i]->success_rate = agent_info->success_rate;
            mld->agents[i]->avg_response_time_ms = agent_info->avg_response_time_ms;
            mld->agents[i]->is_available = agent_info->is_available;
            mld->agents[i]->weight = agent_info->weight;
            return 0;
        }
    }

    agent_info_t *new_agent = (agent_info_t *)AGENTOS_CALLOC(1, sizeof(agent_info_t));
    if (!new_agent)
        return AGENTOS_ERR_OUT_OF_MEMORY;

    new_agent->agent_id = AGENTOS_STRDUP(agent_info->agent_id);
    new_agent->agent_name = AGENTOS_STRDUP(agent_info->agent_name);
    new_agent->load_factor = agent_info->load_factor;
    new_agent->success_rate = agent_info->success_rate;
    new_agent->avg_response_time_ms = agent_info->avg_response_time_ms;
    new_agent->is_available = agent_info->is_available;
    new_agent->weight = agent_info->weight;

    mld->agents[mld->agent_count++] = new_agent;
    return 0;
}

static int ml_based_unregister_agent(void *data, const char *agent_id)
{
    if (!data || !agent_id)
        return AGENTOS_ERR_INVALID_PARAM;

    ml_based_data_t *mld = (ml_based_data_t *)data;

    for (size_t i = 0; i < mld->agent_count; i++) {
        if (strcmp(mld->agents[i]->agent_id, agent_id) == 0) {
            AGENTOS_FREE(mld->agents[i]->agent_id);
            AGENTOS_FREE(mld->agents[i]->agent_name);
            AGENTOS_FREE(mld->agents[i]);
            for (size_t j = i; j < mld->agent_count - 1; j++) {
                mld->agents[j] = mld->agents[j + 1];
            }
            mld->agent_count--;
            return 0;
        }
    }
    return AGENTOS_ERR_NOT_FOUND;
}

static int ml_based_update_agent_status(void *data, const agent_info_t *agent_info)
{
    return ml_based_register_agent(data, agent_info);
}

static int ml_based_schedule(void *data, const task_info_t *task_info, sched_result_t **result)
{
    if (!data || !task_info || !result)
        return AGENTOS_ERR_INVALID_PARAM;

    ml_based_data_t *mld = (ml_based_data_t *)data;

    if (mld->agent_count == 0)
        return AGENTOS_ERR_NOT_FOUND;

    agent_info_t *best_agent = NULL;
    float best_score = -1.0f;
    size_t __attribute__((unused)) best_index = 0;

    for (size_t i = 0; i < mld->agent_count; i++) {
        agent_info_t *agent = mld->agents[i];
        if (!agent->is_available)
            continue;
        if (agent->load_factor >= 0.95f)
            continue;

        float score = predict_score(mld, agent, i);
        if (score > best_score) {
            best_score = score;
            best_agent = agent;
            best_index = i;
        }
    }

    if (!best_agent)
        return AGENTOS_ERR_NOT_FOUND;

    sched_result_t *res = (sched_result_t *)AGENTOS_CALLOC(1, sizeof(sched_result_t));
    if (!res)
        return AGENTOS_ERR_OUT_OF_MEMORY;

    res->selected_agent_id = AGENTOS_STRDUP(best_agent->agent_id);
    res->confidence = fminf(best_score, 1.0f);
    res->estimated_time_ms =
        (uint32_t)(best_agent->avg_response_time_ms * (1.0f + best_agent->load_factor));

    record_prediction(mld, best_agent->agent_id, best_score, res->estimated_time_ms, 1);

    *result = res;
    return 0;
}

static const char *ml_based_get_name()
{
    return "ml_based_v2";
}

static size_t ml_based_get_available_agent_count(void *data)
{
    if (!data)
        return 0;
    ml_based_data_t *mld = (ml_based_data_t *)data;
    size_t count = 0;
    for (size_t i = 0; i < mld->agent_count; i++) {
        if (mld->agents[i] && mld->agents[i]->is_available)
            count++;
    }
    return count;
}

static size_t ml_based_get_total_agent_count(void *data)
{
    if (!data)
        return 0;
    return ((ml_based_data_t *)data)->agent_count;
}

static const strategy_interface_t ml_based_strategy = {
    .create = ml_based_create,
    .destroy = ml_based_destroy,
    .register_agent = ml_based_register_agent,
    .unregister_agent = ml_based_unregister_agent,
    .update_agent_status = ml_based_update_agent_status,
    .schedule = ml_based_schedule,
    .get_name = ml_based_get_name,
    .get_available_agent_count = ml_based_get_available_agent_count,
    .get_total_agent_count = ml_based_get_total_agent_count};

const strategy_interface_t *get_ml_based_strategy()
{
    return &ml_based_strategy;
}
