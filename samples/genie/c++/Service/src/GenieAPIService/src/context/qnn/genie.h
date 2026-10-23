//==============================================================================
//
// Copyright (c) 2023, Qualcomm Innovation Center, Inc. All rights reserved.
// 
// SPDX-License-Identifier: BSD-3-Clause
//
//==============================================================================

#pragma once

#ifndef _GENIEBUILDER_H
#define _GENIEBUILDER_H

#include <thread>
#include <mutex>
#include <atomic>
#include <condition_variable>
#include <vector>
#include <chrono>
#include <string>

#include <GenieCommon.h>
#include <GenieDialog.h>
#include <GenieSampler.h>
#include "../context_base.h"
#include "log.h"

struct QnnWatermarkState;

class GenieContext : public ContextBase
{
public:
    explicit GenieContext(const ModelInstanceConfig &config);

    ~GenieContext() override;

    bool Query(const ModelInput &, const Callback &,
               PrefillHeartbeatCallback prefill_heartbeat = nullptr) override;

    bool Stop() override;

    int SetParams(const std::string &key, const std::string &value) override
    {
        // custom（水印）采样模式下 SDK 明确禁止 sampler JSON 同时出现 temp/top-k/top-p/greedy，
        // 请求侧的运行期覆盖沿用既有 SetParams/ApplyParams 通路会试图违反这条约束；保守起见
        // 直接忽略这类覆盖，避免破坏已生效的 custom 采样配置（水印关闭时此分支不生效，零改动）。
        if (watermark_active_ &&
            (key == "temp" || key == "top-k" || key == "top_k" ||
             key == "top-p" || key == "top_p" || key == "greedy"))
        {
            My_Log{My_Log::Level::kWarning}
                    << "[Watermark] ignoring runtime sampler override '" << key
                    << "' while token-level watermark (custom sampler) is active\n";
            return GENIE_STATUS_SUCCESS;
        }
        return GenieSamplerConfig_setParam(m_SamplerConfigHandle, key.c_str(), value.c_str());
    }

    int ApplyParams() override
    {
        // 见 SetParams() 注释：水印生效时不再走 GenieSampler_applyConfig，避免触碰
        // 尚未证实是否真的能把 custom 类型改回 basic 的运行期切换路径。
        if (watermark_active_)
        {
            return GENIE_STATUS_SUCCESS;
        }
        return GenieSampler_applyConfig(m_SamplerHandle, m_SamplerConfigHandle);
    }

    json HandleProfile() override;

    size_t TokenLength(const std::string &text) override;

    bool SetStopSequence(const std::string &stop_sequences) override;

    void applyLora(const std::string &engineRole,
                   const std::string &loraAdapterName) override;

    void setLoraStrength(const std::string &engineRole,
                         const std::unordered_map<std::string, float> &alphaValue) override;

    void Reset() override;

    void ClearConversationState() override;

    struct QInterfaceImpl;

    class ConfigFixer;

private:
    void inference_thread();

    // 释放已成功创建的全部 QNN/Genie SDK 句柄（含 GenieDialog_create 内部已注册的
    // HTP/memRegister 状态）。既被 ~GenieContext() 复用，也被构造函数在任意一步失败时
    // 复用（构造函数抛异常时 ~GenieContext() 永不会被调用，若不在此显式清理，已创建
    // 的句柄会被静默泄漏，另见 model_manager.md 关于 qwen3_vl_8b-8480 堆损坏崩溃根因分析）。
    void ReleaseHandles();

    // 释放本模型实例持有的水印插件侧状态（`token_hook_free` + 释放 QnnWatermarkState）。
    // 既被 ~GenieContext() 复用，也被构造函数在任意一步失败时复用；已注册的
    // callback-name 无法从 SDK 全局表中撤销（无 unregister API），这是已知限制，不在此处理。
    void ReleaseWatermarkState();

    static GenieLog_Level_t get_genie_log_level();

    bool GenerateTextToken(const std::string &text, const int32_t *&buf, uint32_t &len);

    GenieDialogConfig_Handle_t m_ConfigHandle = nullptr;
    GenieDialog_Handle_t m_DialogHandle = nullptr;
    GenieSamplerConfig_Handle_t m_SamplerConfigHandle = nullptr;
    GenieSampler_Handle_t m_SamplerHandle = nullptr;
    GenieProfile_Handle_t m_ProfileHandle = nullptr;
    GenieLog_Handle_t m_LogHandle = nullptr;

    // Inference thread.
    std::unique_ptr<std::thread> m_stream_thread{nullptr};
    std::mutex m_request_lock;
    // 以下四个变量在主线程（Query/析构）和推理线程之间并发读写，
    // 必须声明为 std::atomic<bool> 以避免数据竞争（data race）UB。
    // 在 ARM 弱内存模型（Android/Snapdragon）上，普通 bool 的跨线程读写
    // 可能导致主线程 while(m_inference_busy) 永远读到缓存旧值，造成死循环。
    std::atomic<bool> m_request_ready{false};
    std::condition_variable m_request_cond;
    std::atomic<bool> m_thread_exit{false};
    std::atomic<bool> m_inference_busy{false};
    std::atomic<bool> inference_succeed_{true};

    std::string m_stream_answer;
    std::mutex m_stream_lock;
    std::condition_variable m_stream_cond;  // Condition variable for stream data
    QInterfaceImpl *inf_impl_{};

    // 水印：仅当 WatermarkProviderHost::Instance().HasTokenHook() 为真且本实例的
    // GenieSampler_registerUserDataCallback 注册成功时才为 true；为 false 时 sampler
    // 配置/Dialog 创建流程与现状完全一致，不涉及本节任何逻辑。
    bool watermark_active_{false};
    QnnWatermarkState *wm_state_{nullptr};

    bool stopped_by_output_limit_{false};
    std::string m_model_dir_;
    std::string kv_path_;

public:
    bool was_stopped_by_output_limit() const override { return stopped_by_output_limit_; }

    const std::string &get_model_name() const { return model_config_.get_model_name(); }

    const char *get_query_type_label(const ModelInput &model_input) const
    {
        const std::string &prompt = model_input.text_;
        if (prompt.find("You are a security classifier") != std::string::npos)
            return "SECURITY_CHECK";
        if (prompt.find("You are a task complexity classifier") != std::string::npos)
            return "COMPLEXITY_CHECK";
        if (prompt.find("You are a redaction assistant") != std::string::npos)
            return "DESENSITIZE";
        // Phase -1 长文本摘要推理：system prompt 固定为 "You are a compression assistant"
        // 需要与 SECURITY_CHECK / COMPLEXITY_CHECK / DESENSITIZE 一样执行 post-query reset，
        // 防止摘要推理的 KV cache 状态污染后续主推理。
        if (prompt.find("You are a compression assistant") != std::string::npos)
            return "SUMMARIZATION";
        if (model_input.agent_type_ == "main")
            return "MAINAGENT_INFERENCE";
        return "SUBAGENT_INFERENCE";
    }

    static constexpr int HEARTBEAT_INTERVAL_MS = 5000;
};

#endif
